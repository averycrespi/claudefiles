# autopilot

Pi extension that runs an autonomous plan → implement → verify pipeline from a design doc to a PR-ready branch.

## Command reference

### `/autopilot-start <design-file>`

One positional argument: the path to a design document (typically `.designs/YYYY-MM-DD-<topic>.md`). No flags in v1.

Only one autopilot run may be active at a time — invoking `/autopilot-start` while a run is in progress errors immediately. Use `/autopilot-cancel` to stop the active run first.

### `/autopilot-cancel`

Signals the active autopilot run to stop. The orchestrator aborts its current subagent (via `AbortSignal`), skips any remaining phases, tears down the status widget, and emits the final report with a `Cancelled by user at MM:SS` banner and `Verify: skipped (cancelled by user)`. Any commits the implement phase already landed remain on the branch.

If no run is active, the command is a no-op with an informational notification.

## Status widget

While a run is active, a sticky widget is rendered above the editor (key `autopilot`). It updates in place on every subagent event.

Layout:

```
autopilot · plan › implement › verify · MM:SS
  ↳ <subagent intent> (MM:SS)
     - <recent tool event>
     - <recent tool event>
     - <recent tool event>
type /autopilot-cancel to stop
```

The header is a stage breadcrumb: `plan › implement › verify`. The currently-running stage is rendered bold+accent; the others are muted. Before the plan subagent dispatches, no stage is highlighted. Sub-phases (task index, validation vs. reviewers vs. fix rounds) are not surfaced in the header — the `↳` subagent line already names the active unit of work.

Task rows are not rendered inside the autopilot widget. The `task-list` extension renders the task list in its own sticky widget below the editor; the autopilot widget shows phase, subagent, clock, and breadcrumb only. Both widgets are visible simultaneously during a run.

The autopilot widget is torn down when the run ends (success, implement failure, or cancel).

**Pre-flight checks** (run before any subagent is dispatched):

1. The design file exists and is readable.
2. The working tree is clean (no uncommitted or staged changes).
3. Capture the current `HEAD` SHA as the pipeline's base SHA (used for diffing during verify).

If any pre-flight check fails, the pipeline aborts immediately and prints a short reason. No branches are created or modified.

## Pipeline overview

The orchestrator is a single `async` TypeScript function that sequences three phases — **plan**, **implement**, **verify** — and always ends by printing a final report. No LLM runs in the main session during the pipeline; every LLM call is a fresh subagent dispatched via the `subagents` extension.

```mermaid
flowchart TD
    A[/autopilot-start <design.md>/] --> B{pre-flight}
    B -->|fail| Z[abort + report]
    B -->|ok| P[plan subagent]
    P -->|parse fail| Z
    P -->|ok| I[implement loop]
    I -->|task fails| Z
    I -->|all tasks done| V[verify phase]
    V --> R[final report]
```

_Caption: Top-level pipeline flow. Any parse or implement failure routes to the final report with partial state; the pipeline never hangs._

## Phase reference

### Plan

**What it does.** Reads the design doc and produces an implementation plan: a short `architecture_notes` blob plus an ordered list of 1–15 outline-level tasks.

**Subagent prompt.** See `prompts/plan.md`. The prompt substitutes `{DESIGN_PATH}` and enforces the "outline-level tasks, no TDD steps, no code, no sub-bullets" contract designed for GPT-5-class models.

**Output schema:**

```json
{
  "architecture_notes": "string (<=200 words)",
  "tasks": [{ "title": "string", "description": "string" }]
}
```

**Orchestrator responsibilities.**

1. Dispatch the plan subagent once.
2. `parseJsonReport(output, PlanReportSchema)`.
3. On parse or validation failure → abort the pipeline.
4. On success → `taskList.create(tasks)` and move to implement.

**Caps & failure modes.** Dispatch failures are retried exactly once (transient crashes / timeouts). A malformed plan — valid-but-unparseable response — aborts the pipeline immediately with no retry. See the Retry policy section below for the full guard list.

### Implement

**What it does.** Walks the task list in order. For each pending task, dispatches a fresh implement subagent with `architecture_notes` + that task's description only. Parses the structured report, verifies a commit landed, and moves to the next task. First failure halts the pipeline.

**Subagent prompt.** See `prompts/implement.md`. Key GPT-5 guardrails: "do only what this task describes", "do not re-read or re-edit files you've already handled", "STOP, end your turn" on blocked tasks.

**Output schema:**

```json
{
  "outcome": "success | failure",
  "commit": "<sha> | null",
  "summary": "string"
}
```

**Orchestrator responsibilities.**

1. `taskList.start(task.id)` and set activity line to `"dispatching subagent…"`.
2. Record `pre-task HEAD`.
3. Dispatch the subagent with the filled prompt. Transient dispatch failures retry exactly once (intent becomes `Implement: <title> (retry)`).
4. `parseJsonReport(output, ImplementReportSchema)`.
5. Verify a new commit landed: `git rev-list <pre-task-head>..HEAD --count >= 1`.
6. On success → `taskList.complete(id, summary)`.
7. On parse failure, `outcome: "failure"`, or missing commit → `taskList.fail(id, reason)` and **break** the loop.

**Caps & failure modes.** At most one retry per task, and only for dispatch failures (process crash, transport error). Parse failures, `outcome: "failure"`, and phantom successes are _not_ retried — the first two are systematic and the third signals a real bug we want to surface. Any unrecovered task failure halts the pipeline; later tasks are never attempted.

```mermaid
flowchart TD
    S([start]) --> N{next pending task?}
    N -->|no| D([all tasks done])
    N -->|yes| ST[taskList.start]
    ST --> DS[dispatch implement subagent]
    DS --> PR{parse + commit check}
    PR -->|success| C[taskList.complete]
    C --> N
    PR -->|failure| F[taskList.fail]
    F --> H([halt pipeline])
```

_Caption: Per-task implement loop. Tasks run sequentially; a transient dispatch failure is retried once, any other failure halts the pipeline. No skipping ahead._

### Verify

**What it does.** Five steps:

1. **Validation** — a validation subagent discovers and runs the project's tests, lint, and typecheck. If any category fails, a fixer subagent addresses the failure and validation is re-run. **Cap: 2 fix rounds.**
2. **Parallel reviewers** — three reviewer subagents (`plan-completeness`, `integration`, `security`) run in parallel, one shot each, over the pipeline's full diff.
3. **Synthesize** — orchestrator drops findings with confidence < 80, dedupes by file-and-line proximity, and triages: `blocker` + `important` → fix loop; `suggestion` → known issues.
4. **Post-reviewer fix loop** — fixer subagent resolves blockers and importants; reviewers re-run on the post-fix diff. **Cap: 2 fix rounds.** Anything still present becomes a known issue.
5. **Final report** — printed; pipeline ends.

**Subagent prompts.** `prompts/validation.md` (used by `phases/validate.ts`), `prompts/reviewer-plan-completeness.md`, `prompts/reviewer-integration.md`, `prompts/reviewer-security.md`, `prompts/fixer-validation.md`, and `prompts/fixer-review.md`.

**Output schemas.** `ValidationReportSchema`, `ReviewerReportSchema`, `FixerReportSchema` — all validated via `parseJsonReport`.

**Orchestrator responsibilities.** Detect all fix-loop exits, flag partial results as known issues, and always proceed to the final report. Verify never loops back into implement.

**Caps & failure modes.** Both fix loops are capped at 2 rounds. A failed reviewer is silently skipped and noted in the report. A fixer that introduces a new regression does not trigger rollback — the regression becomes a known issue.

```mermaid
stateDiagram-v2
    [*] --> Validation
    Validation --> ValidationFix: any check fails
    ValidationFix --> Validation: re-check (round < 2)
    ValidationFix --> Reviewers: cap reached / known issues
    Validation --> Reviewers: all pass or skipped
    Reviewers --> Synthesize
    Synthesize --> PostFix: blocker/important findings
    Synthesize --> FinalReport: suggestions only
    PostFix --> Synthesize: re-run reviewers (round < 2)
    PostFix --> FinalReport: cap reached / known issues
    FinalReport --> [*]
```

_Caption: Verify phase with two capped fix loops (validation at most 2 rounds, post-reviewer at most 2 rounds). When a cap is hit, remaining issues become known issues and the pipeline still proceeds to the final report — there is no loopback into the implement phase._

## Task state machine

The orchestrator drives every transition on the shared `task-list` API. Valid transitions are enforced by the API and throw on illegal moves.

```mermaid
stateDiagram-v2
    [*] --> pending: create / add
    pending --> in_progress: start
    pending --> failed: fail (impossible)
    in_progress --> completed: complete (requires summary)
    in_progress --> failed: fail (requires reason)
    failed --> pending: retry
    failed --> in_progress: retry directly
    completed --> [*]: sticky (terminal)
```

_Caption: Task states and transitions. **Completion is sticky** — once a task reaches `completed`, there is no edge out. This is the anti-perfectionism nudge that lets the pipeline actually finish instead of re-opening "done" work._

## Subagent output contract

Every subagent (plan, implement, validation, reviewers, fixer) returns its report as a **strict JSON object** matching a per-subagent TypeBox schema. One parser, one validation path, no ad-hoc delimiters.

All subagent prompts end with the shared suffix:

```
Output ONLY the JSON object. No prose before or after. No markdown code fences.
```

The orchestrator uses a shared helper:

```ts
parseJsonReport<T>(output: string, schema: TSchema):
  | { ok: true, data: T }
  | { ok: false, error: string }
```

It strips common wrappers (leading/trailing prose, ` ```json ... ``` ` fences), `JSON.parse`s the stripped content, then validates against the schema. Any parse or validation error yields `{ ok: false, error }` with a concise description. Each phase specifies what to do on `ok: false` — typically "treat as failure for this subagent, do not retry".

## Failure matrix

Unified principle: **always terminate with a report. Never leave the user in a stuck state.**

| Failure                                                  | Handling                                                                                                   |
| -------------------------------------------------------- | ---------------------------------------------------------------------------------------------------------- |
| Plan subagent dispatch crashes/times out                 | Retry once (intent becomes `Plan (retry)`). If the second attempt also fails → abort pipeline, report.     |
| Plan subagent returns invalid/unparseable output         | Abort pipeline. No retry — parse failures are systematic, not transient. Report.                           |
| Implement subagent dispatch crashes/times out on task N  | Retry once. If the second attempt also fails → stop pipeline, fail task N, tasks N+1..end never attempted. |
| Implement subagent reports `outcome: "failure"`          | Stop pipeline immediately. No retry — the subagent deliberately gave up.                                   |
| Implement subagent claims success but HEAD didn't move   | Stop pipeline. No retry — signals a real bug we want to surface, not a transient glitch to paper over.     |
| Verify automated checks still failing after 2 fix rounds | Pipeline still completes. Checks flagged as known issues in report. User gets branch.                      |
| Reviewer subagent fails to run                           | Orchestrator skips that reviewer (no retry — reviewers are advisory). Skip noted in report.                |
| Fix subagent breaks something that was passing           | Record as known issue. Do not roll back.                                                                   |
| Dirty working tree at `/autopilot-start` invocation      | Abort immediately before plan phase.                                                                       |
| User runs `/autopilot-cancel` mid-run                    | Abort current subagent. Skip remaining phases and any pending retry. Emit report with cancelled banner.    |

### Retry policy

Only two dispatches are retried automatically, both bounded at exactly **one retry** (at most 2 total attempts):

1. **Plan dispatch** — highest blast radius (failure here burns the whole run before any commits land).
2. **Implement dispatch, per task** — halting at task N discards the remaining tasks; a transient crash shouldn't cost that.

Retry guards (all checked before the second attempt):

- The first attempt's `aborted` flag is false — a cancelled subagent is never retried.
- The run-level abort signal is not already set — `/autopilot-cancel` short-circuits pending retries.
- The first attempt returned `ok: false` — a successful response with bad JSON is a caller problem, not a dispatch problem, and is never retried.

On retry, the status widget shows the intent suffixed with `(retry)` so the user can see it happened. Verify's fix loops (validation fixer, post-reviewer fixer) are an independent, domain-specific retry mechanism and are documented in the Verify section above.

No implicit rollbacks. Every commit that lands during the pipeline stays on the branch.

## Final report

Printed as a single transcript message at pipeline end:

```
━━━ Autopilot Report ━━━

Design:  .designs/2026-04-12-rate-limiter.md
Branch:  workflow  (5 commits ahead of main)

Tasks (5/5):
  ✔ 1. Add rate limiter config          (abc1234)
  ✔ 2. Wire config into middleware      (def5678)
  ✔ 3. Add tests for rate limiter       (ghi9012)
  ✔ 4. Add IP-based rate limit key      (jkl3456)
  ✔ 5. Update README                    (mno7890)

Verify:
  Automated checks:  ✔ tests  ✔ lint  ✔ typecheck
  Reviewers:         plan-completeness  integration  security
  Fixed:             2 findings  (1 blocker, 1 important)
  Known issues:      1 suggestion
    └ src/middleware.ts:42 | suggestion | rate limit could be extracted to a helper

Log: ~/.pi/workflow-runs/autopilot/20260412T143022-rate-limiter/
```

Reading the blocks:

- **Design / Branch** — what ran and where the work landed. The branch is whatever the user had checked out at invocation; autopilot never switches branches.
- **Tasks** — one row per planned task with its glyph (`✔` done, `✗` failed, `◻` not attempted) and the commit SHA that implemented it.
- **Verify → Automated checks** — results of the validation subagent, possibly after up to 2 fix rounds.
- **Verify → Reviewers** — which reviewers ran (a skipped reviewer is listed with a `(skipped)` suffix).
- **Verify → Fixed** — what the post-reviewer fix loop resolved.
- **Verify → Known issues** — everything the pipeline deliberately left for the human: low-severity suggestions, findings that survived the fix cap, validation failures that survived the fix cap, and regressions the fixer introduced.
- **Log** — path to the per-run log directory under `~/.pi/workflow-runs/autopilot/`. Contains `run.json`, `events.jsonl`, `prompts/`, `outputs/`, `final-report.txt`, and `workflow/design.md` (a copy of the input design doc). Appended automatically by the framework.

Autopilot does not push, does not open PRs, and does not switch branches. Review the branch and ship it yourself.

**Report variants.** On implement failure on task N, tasks 1..N-1 are `✔`, task N is `✗` with its failure reason, tasks N+1..end are `◻`, and the verify section is replaced with `skipped (implement failed)`. On verify partial, unresolved findings appear under known issues.

## How it works

- **Orchestrator is code, not an LLM.** `/autopilot-start` is implemented as an `async` TypeScript function that sequences subagent dispatches and state updates programmatically. Keeping the orchestrator deterministic means the pipeline's control flow — caps, failure routing, commit verification — is not itself subject to LLM drift.
- **One subagent per unit of work.** Each task gets its own fresh implement subagent with no shared context. This resets the perfectionism ratchet between tasks and exploits the instruction-literalist strength of GPT-5-class models: a single crisply-scoped task per fresh context.
- **Sequential implement, parallel reviewers.** Implement runs one task at a time so each task's base SHA is predictable and concurrent subagents don't collide on merge conflicts. Reviewers run in parallel because they're read-only and independent — no shared write state, no ordering hazards.
- **No loopback from verify.** Verify never re-opens the implement phase. A failing check after two fix rounds becomes a known issue and the pipeline still completes. The alternative — "keep going until verify is clean" — is the exact open-ended loop that GPT-5 thrashes in.
- **Every commit sticks.** There is no rollback path. If the fixer breaks something that was passing, that's a known issue on the user's branch, not a revert. The user always gets _something_ to look at.

## Architecture

Autopilot is built on the `_workflow-core` shared library. The framework handles slash-command registration (`/autopilot-start` / `/autopilot-cancel`), the single-active-run lock, abort plumbing, widget lifecycle, per-run log directory creation, and the `Log:` line appended to every report. Autopilot owns the pipeline logic: pre-flight checks, phase sequencing, task-list management, and the Tasks / Verify report sections.

For the full framework API reference — `registerWorkflow`, `ctx.subagent`, `ctx.widget`, `ctx.log`, `render.ts` helpers, `report.ts` helpers, `preflight.ts`, and testing patterns — see [`../_workflow-core/INTEGRATION.md`](../_workflow-core/INTEGRATION.md).

## Inspiration

- [tmustier/pi-extensions/ralph-wiggum](https://github.com/tmustier/pi-extensions/tree/main/ralph-wiggum) — iterative loop pattern with periodic reflection checkpoints
- [klaudworks/ralph-meets-rex](https://github.com/klaudworks/ralph-meets-rex) — plan → implement → verify three-phase pipeline with loopback routing
- [ruizrica/agent-pi](https://github.com/ruizrica/agent-pi) — declarative YAML pipelines, role specialization, multi-model fan-out
- [davidorex/pi-project-workflows](https://github.com/davidorex/pi-project-workflows) — DAG execution engine with schema-validated step boundaries
- [tmdgusya/roach-pi](https://github.com/tmdgusya/roach-pi) — phase-gated state machine (clarify → plan → build → review), depth-capped subagent spawning
- Claude Code's [`executing-plans`](../../../../claude/skills/executing-plans/SKILL.md) skill (adapted from [obra/superpowers](https://github.com/obra/superpowers)) — task triplet structure (implement → spec review → code review) and subagent dispatch per phase
- Claude Code's [`verifying-work`](../../../../claude/skills/verifying-work/SKILL.md) skill — parallel reviewers, confidence filtering, auto-fix vs ambiguous triage
