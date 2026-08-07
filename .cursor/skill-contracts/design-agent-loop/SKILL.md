---
name: design-agent-loop
description: >-
  Design a reusable agent loop as a graph before running it. Take a TASK and
  COMPLETION CRITERIA, draw the node graph (input, plan, act, verify, retry or
  escalate, done), specify context, tools, expected output, and evidence per
  node, label every transition trigger, set max retries, budget ceilings, and
  human approval gates, keep unverifiable steps manual, design five eval cases
  with a pass or fail scorecard, and pick the single biggest bottleneck to
  automate first. Two-step handshake, design only until the user says execute
  now, then run one test case and improve the loop. Use when the user invokes
  /design-agent-loop or asks to design an agent loop, routine, workflow graph,
  or state machine for repeated agent work.
disable-model-invocation: true
user-invocable: false
---
# Design agent loop

## Role

You design the **loop** a repeated task travels through, not the prompt that runs it once. You take a TASK and its COMPLETION CRITERIA and return a **graph**: nodes with context, tools, expected output, and evidence; transitions with named triggers; retry and escalation edges with ceilings; human approval gates on irreversible work; five eval cases with a scorecard; and one bottleneck to automate first.

This is a **two-step handshake**. Step one, you design the graph and stop. Step two, only after a later explicit **execute now**, you run **one** test case through the loop and improve the loop from what happened. Approving the graph is not permission to run the workload.

## When to use

Use when the user invokes `/design-agent-loop`, or asks to design a reusable agent routine, workflow graph, or state machine for work that **repeats** and needs verification between steps. For a single delegated run with no repetition or verify cycle, use `define-agent-goal`. For raising artifact quality against a real reference, use `gauntlet-loop`. For choosing which business workflow to automate at all, use `automation-roi-audit`.

## Loop charter

> Repetition first, or route away. Graph before prompt. Every node states context, tools, expected output, and evidence. Every edge names its trigger. Retries capped, budget ceilinged, irreversible work gated on a human. Unverifiable steps stay manual. Evals sized to volume. One bottleneck first. Design and halt; run one case only on execute now.

## Workflow

Run phases in order. Do **not** start the underlying TASK while designing, and do not run the loop until a later explicit **execute now**.

### Phase 0: Intake

1. Require two fields:
   - **TASK**: the work the loop performs on each pass
   - **COMPLETION CRITERIA**: the exact, observable definition of done for one pass
2. Optionally accept: available tools, **BUDGET** (wall-clock, token, or spend ceiling), retry preferences, and **volume** (how often this loop runs).
3. If TASK or COMPLETION CRITERIA is missing, ask **one focused question per gap**. Do not invent the criteria and do not design against a vague bar like "make it good".
4. **Repetition check.** If the work runs once, has no verification step, and has no retry cycle, say so and route to `define-agent-goal` instead of drawing a graph. Do not build a loop for a one-shot delegation.
5. Do not execute the TASK, edit code, or run destructive commands in this phase.

### Phase 1: Graph draft

1. Draw the node graph as mermaid. The default spine is `input` → `plan` → `act` → `verify` → `retry` | `escalate` → `done`; adapt it to the real work.
2. Add or merge nodes to match the task. Do not pad the graph with nodes that produce no artifact.
3. Publish the graph, then continue. Do not wait indefinitely for approval of the draft shape.

### Phase 2: Node specification

For **every** node, state all four fields:

- **Context**: what the agent must be able to read at that node
- **Tools**: what it may call there, named explicitly
- **Expected output**: the artifact the node produces
- **Evidence**: the observable signal that proves the node worked

A node with **no evidence is not a node**. Fold it into its neighbour or mark it a manual step. Evidence must be observable (exit code, diff, test result, schema match, row count, screenshot). "Looks good", "seems fine", and "the model says it worked" are not evidence.

### Phase 3: Transitions

1. Every edge names the **condition that fires it**. Unlabeled arrows are incomplete.
2. `verify` → `retry` and `verify` → `escalate` need **distinct, non-overlapping triggers**. State which failures are retryable and which go straight to a human.
3. Do not write "if it fails" without saying what failure looks like at that node.

### Phase 4: Controls

1. **Max retries** on every retry edge (default **3**). An uncapped retry edge is a defect.
2. **BUDGET**: wall-clock, token, or spend ceiling, and what happens when it is hit. If there is no budget, say so explicitly rather than leaving it blank.
3. **Approval gates**: any irreversible or externally visible action (production write, customer-facing send, payment, delete, merge, deploy) requires **human approval before the node runs**. An approval gate is a gate, not a retry edge; never let a retry loop drive an irreversible action unattended.
4. **Manual carve-outs**: steps that cannot be verified reliably stay **manual**. Name them and say why. Do not invent a verify node for a step whose success cannot be observed.

### Phase 5: Eval design

1. Design **five representative cases** covering at minimum: happy path, verify-fails-then-retry-succeeds, escalation to human, budget or retry exhaustion, and malformed or missing input.
2. Give each case a **pass or fail scorecard** row with the observable signal that decides the verdict.
3. **Size evals to volume.** For a high-volume repeated loop, build the suite. For a one-off or low-volume loop, say that a formal suite costs more than it returns, keep the scorecard as a manual checklist, and rely on human judgment. Do not demand a suite for work that runs twice.

### Phase 6: Bottleneck

Name **one** node as the first to automate: the one that costs the most human time today and has the clearest evidence. Everything else stays manual or human-in-the-loop for this pass. Do not automate the whole graph at once.

### Phase 7: Deliver and halt

1. Post the report using the template below.
2. End with the **two-step approval handshake** (use this wording):

   > **Approve or edit this loop before I run anything.** I will not execute until you confirm.
   >
   > After you approve the graph, say **execute now** (or equivalent) in a later message and I will run **one** test case and report back. Graph approval alone is not permission to run the workload.

3. Stop. Do not run the loop, the test case, or the TASK in this turn.

### Phase 8: Test run (only after execute now)

1. Run **exactly one** eval case end to end through the loop.
2. Record, per node, what it actually produced against the expected output and evidence.
3. Report the **first node where reality diverged** from the design.
4. Propose **loop revisions** from that run: nodes to split or merge, triggers to sharpen, evidence to strengthen, ceilings to change.
5. Respect approval gates during the test run. A test run does not waive a gate.
6. Stop after one case. Do not run the remaining cases or the real workload without a new instruction.

## Deliverable template

```markdown
# Agent loop: <short title>

## 1. Intake
- TASK: ...
- COMPLETION CRITERIA: ...
- Volume: one-off / low / high (how often this runs)
- BUDGET: none | wall-clock / token / spend ceiling
- Available tools: ...

## 2. Graph

~~~mermaid
flowchart TD
  input --> plan --> act --> verify
  verify -->|criteria met| done
  verify -->|retryable failure| retry --> act
  verify -->|non-retryable failure| escalate
~~~

## 3. Nodes

| Node | Context | Tools | Expected output | Evidence |
|------|---------|-------|-----------------|----------|
| ... | ... | ... | ... | ... |

## 4. Transitions

| From | To | Trigger |
|------|----|---------|
| ... | ... | ... |

## 5. Controls

| Control | Value |
|---------|-------|
| Max retries (per retry edge) | N (default 3) |
| Budget ceiling | none / ... and behavior on exhaustion |
| Approval gates | node(s) requiring human approval before running |
| Manual carve-outs | step(s) kept manual, and why |

## 6. Eval cases

| # | Case | Input | Expected path | Pass signal | Fail signal |
|---|------|-------|---------------|-------------|-------------|
| 1 | happy path | ... | ... | ... | ... |
| 2 | retry then succeed | ... | ... | ... | ... |
| 3 | escalate to human | ... | ... | ... | ... |
| 4 | budget / retry exhaustion | ... | ... | ... | ... |
| 5 | malformed or missing input | ... | ... | ... | ... |

Eval posture: full suite (high volume) | manual checklist (one-off or low volume), and why.

## 7. First bottleneck
The single node to automate first, the human time it costs today, and why its evidence is trustworthy.

## 8. Halt
Approve or edit this loop before I run anything. Say execute now later to run one test case.
```

## Safety

- Do not execute the TASK, edit code, or run destructive commands while designing the loop, or after graph approval alone.
- Redact secrets, tokens, credentials, PII, and PHI in intake, the graph, and the report.
- Irreversible or externally visible nodes require an approval gate before they run, including during the test run.
- Never route an irreversible action through an unattended retry edge.
- Do not claim a node is verified when its evidence is unobservable.
- Do not run more than one eval case on the first execute now.

## Distinction from other commands

- **`define-agent-goal`**: six-part Goal for a **single** delegated run (outcome, verification, constraints, boundaries, iteration policy, stopping condition). This skill designs a **repeatable graph** with per-node evidence and named transition triggers.
- **`gauntlet-loop`**: builder and critic loop that beats a real-world reference. This skill designs the **general** loop for a task; gauntlet-loop is one specific quality loop against a reference pack.
- **`automation-roi-audit`**: interviews a business function and picks which workflow to automate. This skill runs **after** that choice and designs the loop for it.
- **`structure-prompt`**: turns a rough ask into a runnable prompt. This skill designs the **routine around** the prompt, not the wording inside it.
- **`prompt-eval-debug`**: tiny eval suite for a pasted prompt. This skill designs eval cases for a **loop path**, not prompt wording.

## Guardrails

- **TASK and completion criteria required.** Ask one focused question per missing field; never invent the completion criteria or design against a vague bar.
- **Design the graph before running anything.** Do not execute the TASK, edit code, or run destructive commands while designing the loop.
- **Every node names its evidence.** State context, tools, expected output, and evidence per node; a node with no observable evidence is folded into its neighbour or marked manual.
- **Name the trigger on every transition.** No unlabeled arrows; retry and escalate need distinct, non-overlapping triggers.
- **Bound the loop with retries and a budget.** Cap every retry edge (default 3) and state the budget ceiling and exhaustion behavior, or state explicitly that there is none.
- **Gate irreversible nodes on human approval.** Production writes, sends, payments, deletes, merges, and deploys need approval before the node runs; a gate is not a retry edge.
- **Keep unverifiable steps manual.** Do not invent a verify node for a step whose success cannot be observed; name the carve-out and why.
- **Automate one bottleneck, not the whole pipeline.** Pick the single node costing the most human time with the clearest evidence; leave the rest manual this pass.
- **Match evals to volume, judgment to one-offs.** Build the suite for high-volume loops; for one-off or low-volume work keep a manual checklist and say a formal suite costs more than it returns.
- **Graph approval is not permission to execute.** Deliver the loop and stop; acknowledge approval and wait for a later execute now.
- **Run one test case, then improve the loop.** On execute now, run exactly one case, report the first node where reality diverged, propose revisions, and stop before the remaining cases.
- **Route one-shot delegation to define-agent-goal.** When the work runs once with no verification or retry cycle, say so and route instead of drawing a graph.
