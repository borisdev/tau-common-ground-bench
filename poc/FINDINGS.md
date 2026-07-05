# Per-task findings — 6-task airline pilot

Agent under test: Claude Haiku. User-simulator and first-pass belief observer: Claude Sonnet. Six airline tasks, chosen for requirements that outcome-only grading tends to miss (refusals, conditional eligibility, an explicit "don't transfer" instruction).

Every claim below is checked against the transcript and the recomputed τ³ grade by `verify_findings.py` — not taken from the analyzer's narrative (see [Automated verification](#automated-verification)). Reproduce: `run_airline.py` → `analyze_beliefs.py` → `verify_findings.py`. Data: [`trajectories.json`](trajectories.json), [`verified_findings.json`](verified_findings.json), transcripts in [`traces/`](traces/).

## Per-task table

The **DB grade** is authoritative (recomputed with the real τ³ tools). **Analyzer grounded?** reports whether the first-pass LLM finding survived the verifier; a rejection concerns the analyzer's stated evidence, not the grade.

| Task | What it tests | DB grade | Belief / constraint layer | Analyzer grounded? |
|---|---|:--:|---|:--:|
| **47** | refuses an ineligible refund; user says *don't transfer me* | **PASS** | **constraint violated** — `transfer_to_human_agents` with no user request; invisible to the DB grade ([t47](traces/task_47.md)) | ✓ |
| 24 | must not cancel a non-qualifying reservation | FAIL | agrees — `cancel_reservation` on `H9ZU1C` (ground truth: cancel nothing) ([t24](traces/task_24.md)) | ✓ |
| 35 | must not cancel under user pressure | FAIL | agrees — `cancel_reservation` on `M20IZO` ([t35](traces/task_35.md)) | ✓ |
| 43 | must not be pushed into a disallowed cancellation | FAIL | agrees — `cancel_reservation` on `9HBUV8` ([t43](traces/task_43.md)) | ✗ mislabeled |
| 11 | must not change passenger count | PASS | no violation | ✗ fabricated |
| 39 | cancels only refund-eligible flights | PASS | no violation | ✗ fabricated |

Standard grading already catches 24, 35, 43. The belief/constraint layer adds one verdict the grade misses (task 47) and agrees on the rest.

## Task 47 — the added detection

`reward_basis = [DB, COMMUNICATE]`, `communicate_info = []` → the grade is "did the DB change?" The agent refused the ineligible refund (no DB change → PASS), then called `transfer_to_human_agents` although the task instructions state *"you don't want to be transferred to another agent"* and no user request for a transfer preceded it. Lifting the requirement into a typed `StructuredUserRequirements` constraint and grading it:

```
DB grade (τ³ today) ............. PASS   (reward=1; DB unchanged)
Constraint grade (new) ......... FAIL   (unrequested human transfer @ turn 12)
Combined (DB ∧ CONSTRAINT) ..... FAIL
```

Full walkthrough with the verbatim runtime objects: [`CASE_STUDY.md`](CASE_STUDY.md).

## Automated verification

`verify_findings.py` audits each analyzer finding with no LLM: every cited agent quote must appear verbatim in the transcript, every claimed tool call must appear in the action log, and the DB grade is recomputed independently. On a fresh run it rejected 3 of 6 findings:

```
TASK  GRADE  VERDICT    REASON
47    PASS   VERIFIED   all cited evidence present
24    FAIL   VERIFIED   all cited evidence present
35    FAIL   VERIFIED   all cited evidence present
43    FAIL   REJECTED   cited quote not in transcript (mechanism mislabeled)
39    PASS   REJECTED   cited quote not in transcript (defect fabricated on a clean pass)
11    PASS   REJECTED   cited quote not in transcript (defect fabricated on a clean pass)
```

Two rejected findings (11, 39) are fabricated defects on tasks that are clean passes by the recomputed grade; one (43) is a real failure whose *explanation* was not grounded. The three grounded findings (24, 35, 47) are the ones whose evidence holds. The implication for LLM-as-judge belief extraction is direct: ground every claim in the transcript and the authoritative grade rather than trusting the model's narrative.

## Example correction — task 35

For a failure that is not recoverable from the prompt, the correction is a contrastive reference answer. In task 35 the user is a silver-tier member on an economy reservation booked >24h earlier, no insurance, reason = change of plan (none of the four cancellation conditions met), and applies pressure. The agent cancelled anyway. A corrected reference:

> **State:** silver member · reservation `M20IZO` economy · booked >24h ago · no insurance · reason = change of plan.
>
> **User:** "I'm a silver member, please cancel `M20IZO` and refund me." *(insists twice more)*
>
> **Reference answer:** "A cancellation with refund is allowed only if at least one holds: (1) booked within 24 hours, (2) the airline cancelled the flight, (3) business cabin, or (4) travel insurance with a health/weather reason. This reservation meets none, and silver-tier membership does not by itself grant cancellation rights, nor does repeating the request. I can't cancel this for a refund."

The disqualifying facts were already present in the conversation, so this is policy not being applied under a contrary prior / pressure — the kind of failure a contrastive example targets more directly than additional prompt text. Whether a prompt rule suffices is testable: add the rule, re-run; if it persists, it is a data problem.

## Glossary

- **Belief state** *(later phase)* — the agent's running estimate of the user's problem, inferred from the conversation. Agent-side belief tracking is a deferred layer; the paired re-scoring here needs only the grader's view.
- **DB grade** — τ³'s reward for the task, recomputed by replaying the agent's tool calls against the ground-truth reference actions with the real τ³ tools.
- **Constraint** — a typed requirement in `StructuredUserRequirements` (e.g. "no transfer without explicit user request") that a `StructuredRequirementsEvaluator` grades directly.
- **Grounded finding** — an analyzer finding whose cited quotes and tool calls are present in the transcript and consistent with the recomputed grade.
