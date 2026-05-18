# Handover — Agent Learning from Feedback

**Branch:** `feat/sentinel-learning-system`
**Handover date:** 2026-05-05
**Companion doc:** [`agent-learning-from-feedback-2026-05-03.md`](./agent-learning-from-feedback-2026-05-03.md) (design — ~570 lines, 10 main sections + Appendices A–E)

---

## 1. What this branch contains

Two commits against `main`:
- `3e0d02b full learning plan` — initial design report (sections 1–10 + Appendices A, B).
- `97de02c docs update` — Appendices C (MR feedback validation + provenance), D (stack vs project scope), E (prompt budget + caching), plus Phase 3 rewrite from webhooks to pull-on-demand.

**No code written yet.** This branch is design-only. The report is the artifact; code landing points are called out but not touched.

## 2. Status at handover

| Area | Status |
|---|---|
| Design report | ✅ Complete, reviewed in conversation, committed |
| Phase 1 / 2 / 3 breakdown | ✅ Documented with exit criteria |
| Webhook → pull-on-demand correction | ✅ Applied (no inbound network path) |
| MR feedback validation + provenance (Appendix C) | ✅ Schema + distiller contract + CLI surface |
| Stack vs project scope (Appendix D) | ✅ Scope values, physical homes, widening rules |
| Prompt budget + caching (Appendix E) | ✅ 12k-token static cap, cache boundary placement |
| Agent roster for implementation | 🟡 Designed in conversation, **not yet in any file** — see §6 below |
| Phase 1 code (verifier-retry loop, cap-out, postmortem insert) | ✅ Implemented and reviewer-approved (756 tests passing, zero regressions) |
| Migration `003_postmortems.sql` | ✅ Applied |
| Phase 2A — Pitfalls visible (read path; tasks 8 + 9) | ✅ Implemented |
| Phase 2B — Closed loops (tasks 12 + 13) | ✅ Implemented |
| Phase 2C — Promotion path (tasks 10 + 11; FeedbackDistiller; `sentinel rules` CLI) | ✅ Implemented |
| Phase 2 sub-phase split (2A/2B/2C) | ✅ Documented in design doc §8 / §10 |
| Phase 3 sub-phase split (3A/3B/3C; task 18 deferred) | ✅ Documented in design doc §8 / §10 |
| Phase 3 code | ❌ Not started — gate is open, 3A is next |

## 3. The design document — table of contents

For the next session, the load-bearing sections are:

| Section | What's there |
|---|---|
| §1 Executive recommendation | Hybrid Karpathy + CoALA; single highest-leverage change = grounded verifier-retry loop on developer |
| §2 What this project looks like today | Agent roster, orchestration primitives, feedback already flowing, gaps |
| §5 Karpathy loops applied here | Loops A–E with async/sync split |
| §6 CoALA applied here | Mapping + minimum viable implementation |
| §8 Implementation blueprint | Phase 1 / 2 / 3 tasks with exit criteria |
| §10 Phased rollout plan | Why each phase order, rollback strategy |
| Appendix C | MR feedback → rule pipeline with full provenance ledger |
| Appendix D | Stack vs project scope, widening mechanics |
| Appendix E | Prompt budget, retrieval layer, cache alignment |

## 4. Key design decisions (do not re-litigate without strong evidence)

These were settled in the conversation that produced this branch. Changing any of them invalidates downstream design:

1. **Hybrid of Karpathy loops + CoALA named memory, with Karpathy first.** Grounded verification before any memory; memory only as a stable secondary layer.
2. **Default scope for new rules is `project:<KEY>`, not stack.** Widening to stack scope requires ≥3 observations across ≥2 projects from ≥2 distinct reviewers **and** human-approved widening PR.
3. **Physical separation of scope homes.** Stack rules in `prompts/overlays/*.md` (Sentinel repo). Project rules in `.sentinel/project-rules.md` (project repo). No exceptions.
4. **Provenance ledger is append-only.** Observations are never mutated or deleted. Rule revocation is a terminal status, not a DELETE.
5. **DB is canonical, markdown is generated.** When a rule is promoted, both exist, but the DB row drives lifecycle and revocation.
6. **Prompt budget is a hard cap.** ≤ 12k static tokens, ≤ 15 rules in "Known pitfalls", deterministic truncation with a `PromptBudgetExceeded` event.
7. **Rules snapshot is frozen per execution.** Cache boundary goes after the snapshot so every turn hits the cache.
8. **Pull-on-demand, not webhooks.** Sentinel has no inbound network path. Outcome ingestion runs during regular `sentinel` invocations + explicit `sentinel outcomes sync` CLI.
9. **Never learn from Sentinel's own MR comments.** `reviewer_is_bot` filter at distiller input.
10. **Never paraphrase source comments.** `raw_comment` preserved verbatim.

## 5. Open questions — require a decision before Phase 1 code starts

None of these block reading the design, but all should be resolved before writing code:

1. **Exact retry cap for Loop A.** Design says N=3. Do we want a per-stack override (Drupal tests slower → allow 4)?
2. **Distiller model choice.** Design suggests Haiku for cost. Confirm — the Sentinel config has `claude-4-5-haiku` in the allowed model list.
3. **Probation rules in prompt — inject or not?** Design injects Tier 0 probation rules with a `[probation]` tag; some teams prefer "nothing in the prompt until promoted." Default is inject-with-tag; easy to flag off.
4. **Where the widening PR auto-opens.** Proposed: Sentinel repo for stack widening; project repo for project-scoped overlay edits. Confirm the client-repo flow with a Sentinel maintainer before Phase 2 — it changes the trust model.
5. **Overlay file character cap enforced how?** §9 risks mention overlay bloat; a committed CI check or just a PR-review discipline? Probably the latter for now.
6. **`project_sync_state` — per installation or per repo?** If Sentinel instances proliferate (dev, staging, prod), does each track its own watermark? Default: per installation. Confirm.

## 6. Agent roster for implementation (captured here — not in any file yet)

The design conversation agreed on a 5-agent Phase 1 roster. Not yet written to any agent-config file. Deferred roster for Phase 2 / 3 listed so the gate is explicit.

### Phase 1 — create these now

| Agent | Owns | Writes code? |
|---|---|---|
| **sentinel-learning-reviewer** | The design doc as source of truth; PR reviews against invariants; phase-gate sign-off | **No.** Tool allowlist: Read, Grep, Glob, Bash, WebFetch. **No** Edit/Write/NotebookEdit. |
| **sentinel-learning-integrator** | `src/prompt_loader.py` boundary; `src/cli.py` surface; `src/core/events/types.py`; orchestrator hooks | Yes, **seams only** — no deep work in any vertical |
| **sentinel-persistence-expert** | `src/core/persistence/*`; migration `003_postmortems.sql`; future `004_feedback_rules.sql` | Yes |
| **sentinel-verifier-loop-expert** | `src/agents/base_developer.py`, `drupal_developer.py`, `python_developer.py`; structured test output; PHPStan/composer-validate wiring | Yes |
| **sentinel-test-harness-expert** | `tests/core/`, `tests/integration/`; fixtures for verifier-retry, postmortem insert | Yes |

### Phase 2 — create only after Phase 1 gate passes

Phase 2 is split into three independently shippable sub-phases (design doc §8). Plan each as a separate `prp-plan` invocation; the full Phase 2 in one synthesis turn has been observed to stall.

| Sub-phase | Tasks (§8) | Owning agents (this section) | Independent of |
|---|---|---|---|
| **2A — Pitfalls visible** (read path) | 8, 9 | `sentinel-retrieval-expert`, `sentinel-learning-integrator` (loader + event seam) | 2B; must precede 2C |
| **2B — Closed loops** (planner feedback) | 12, 13 | `sentinel-learning-integrator` (event + post_execute), planner-side work in `plan_generator.py` | 2A and 2C entirely |
| **2C — Promotion path** (write + human gate) | 10, 11 | `sentinel-distiller-expert`, `sentinel-cli-rules-expert`, `sentinel-persistence-expert` | 2B; depends on 2A |

- `sentinel-distiller-expert` — FeedbackDistiller subagent design, prompt, JSON schema, calibration. (2C)
- `sentinel-retrieval-expert` — prompt budget, cache boundary, ranking query, `executions.rules_snapshot_json` freezing. (2A)
- `sentinel-cli-rules-expert` — `sentinel rules {show,list,search,active-at,supersede,revoke}`. (2C; the inspector CLI for 2A is `sentinel postmortems list`, owned by the integrator.)

**`prp-plan` invocations** (run each in a fresh session):
- 2A: `prp-plan "Phase 2A of sentinel/docs/agent-learning-from-feedback-2026-05-03.md"`
- 2B: `prp-plan "Phase 2B of sentinel/docs/agent-learning-from-feedback-2026-05-03.md"`
- 2C: `prp-plan "Phase 2C of sentinel/docs/agent-learning-from-feedback-2026-05-03.md"`

### Phase 3 — create only after Phase 2 gate passes

Phase 3 is split into three independently shippable sub-phases (design doc §8). Plan each as a separate `prp-plan` invocation; the existing single-shot artifact at `.claude/PRPs/plans/phase-3-cautious-autonomy.plan.md` predates the split — treat it as background, not as the source of truth.

| Sub-phase | Tasks (§8) | Owning agents (this section) | Independent of |
|---|---|---|---|
| **3A — Outcome ingestion** (pull path) | 14, 15 | `sentinel-outcome-poller-expert`, `sentinel-learning-integrator` (event + CLI seam), `sentinel-persistence-expert` (migration) | Nothing — must precede 3B and 3C |
| **3B — Outcome-weighted memory** | 16 | `sentinel-persistence-expert`, `sentinel-retrieval-expert` (consistency with §C.6 formula) | 3C; depends on 3A |
| **3C — Skill promotion** | 17 | `sentinel-skill-library-expert`, `sentinel-cli-rules-expert` | 3B; depends on 3A |

- `sentinel-outcome-poller-expert` — `check_merge_outcomes`, `check_pipeline_failures`, `sentinel outcomes sync`, `project_sync_state` watermarking. (3A)
- `sentinel-skill-library-expert` — Voyager-style subagent skill promotion under `commands/`. (3C)

**Task 18** (optional Letta / Mem0) is gated and not part of any sub-phase. Revisit only if SQLite measurably caps out.

**`prp-plan` invocations** (run each in a fresh session):
- 3A: `prp-plan "Phase 3A of sentinel/docs/agent-learning-from-feedback-2026-05-03.md"`
- 3B: `prp-plan "Phase 3B of sentinel/docs/agent-learning-from-feedback-2026-05-03.md"`
- 3C: `prp-plan "Phase 3C of sentinel/docs/agent-learning-from-feedback-2026-05-03.md"`

### Reviewer invocation policy (not every PR)

The reviewer agent is expensive if invoked per-commit. Invocation policy:

- Before merging any PR touching `src/core/events/types.py`, `src/core/persistence/migrations/`, `src/prompt_loader.py`, `src/agents/base_developer.py`, `src/core/execution/post_execute.py`, or the design doc itself.
- Before declaring a phase complete.
- Never for cosmetic-only changes. Test-only changes are skipped UNLESS the test is closing a Phase 1 exit-criterion box (e.g. the `DeveloperCappedOut` subscriber test) — those go through review.

## 7. Phase 1 exit criteria (copy from §10 of the design doc)

The reviewer agent checks these before blessing "Phase 1 done, Phase 2 may start":

- [ ] `base_developer.run_tests()` returns `{passed, test_results, structured_errors[]}` (not just stdout).
- [ ] Developer Karpathy loop retries with structured feedback, caps at N=3; test exists.
- [ ] PHPStan + composer-validate verifier wired; test exists.
- [ ] `DeveloperCappedOut` event in `src/core/events/types.py` (integrator); `post_execute.py` subscriber posts MR comment + re-asserts draft (integrator, D7); test exists.
- [ ] Migration `003_postmortems.sql` applied; schema matches §6.2 of the design doc.
- [ ] Postmortem row inserted on capped execution; test exists.
- [ ] **(Operational gate — not an implementation task.)** Loop A observed over ≥ 20 real executions with no runaway cost. Verified by manual SQL against `events` (count `TestResultRecorded` per execution; flag any execution whose token usage exceeds 2× median).
- [ ] **(Operational gate — not an implementation task.)** Cap-hit rate and first-pass verifier-pass rate computable from raw events. No rollup dashboard for Phase 1; reviewer runs the SQL at gate time. Phase 2 may add aggregation if needed.

**Only when every box ticks does the Phase 2 agent roster get created.** Implementation tasks (boxes 1–6) are owned by the Phase 1 agents; operational gates (boxes 7–8) are owned by the reviewer at gate time.

## 8. Next actions — prioritized for the next session

Phase 1 and Phase 2 (2A/2B/2C) are complete. The gate to Phase 3 is open. The action list below is the live one; the historical Phase 1 / Phase 2 startup checklists have been retired and are preserved in git history.

1. **Resolve open question §5.6 before 3A code starts:** is `project_sync_state` per Sentinel installation or per repo? Default per installation. This is the only §5 question that gates 3A — others (retry cap, distiller model, probation injection, widening PR location, overlay character cap) were resolved during Phase 1/2 implementation. Append a decision entry to `agent-learning-from-feedback-DECISIONS.md`.
2. **Plan Phase 3A** (`prp-plan "Phase 3A of sentinel/docs/agent-learning-from-feedback-2026-05-03.md"`) in a fresh session. The existing artifact at `.claude/PRPs/plans/phase-3-cautious-autonomy.plan.md` predates the sub-phase split — archive or rename to `.archive` before re-planning so prp-plan writes a fresh per-sub-phase file.
3. **Implement 3A** (`prp-implement <plan-file>`), reviewer-approve, observe `OutcomeRecorded` events flowing on a fixture project before opening the gate to 3B and 3C.
4. **Plan and implement 3B** once 3A is merged and outcome rows are accumulating. 3B writes confidence; it is meaningless before 3A produces signal.
5. **Plan and implement 3C** after 3A is merged. Recommended after 3B so promotion candidates are picked from outcome-weighted confidence rather than raw observation counts.
6. **Do not** plan Phase 3 in a single shot, and do not pull Task 18 (Letta / Mem0) into any sub-phase. Task 18 is gated and only revisited if SQLite measurably caps out.

### 8.1 Phase 2A follow-up — flip the feature flag (2026-05-08)

Phase 2A landed (`.claude/PRPs/plans/completed/phase-2a-pitfalls-visible.plan.md`; report at `.claude/PRPs/reports/phase-2a-pitfalls-visible-report.md`). It ships with `POSTMORTEM_INJECTION=0` as the default.

**Action**: after the PR merges and CI observes `tests/integration/test_postmortem_injection.py` consistently green for at least one full execution cycle, flip the default in `src/prompt_loader.py::_postmortem_injection_enabled` from `'0'` to `'1'` (or remove the env-var gate entirely) in a one-line follow-up PR.

**Why a separate PR**: the flag's purpose is rollback, not perpetual gating (plan §Risks "Reviewer signal erosion"). Bundling the flip with other work makes rollback non-trivial. A standalone one-line PR keeps revert cheap if the planner-prompt change misbehaves in production.

**Pre-flip checklist**:
- CI green on `tests/integration/test_postmortem_injection.py` (the exit-criterion fixture).
- A real Sentinel run on a Drupal project with at least one postmortem in the DB shows the `## Known pitfalls` block in the planner prompt (manual validation level 6).
- Reviewer-policy invocation done if the flip touches `src/prompt_loader.py` (it does).

## 9. Pointers — key file:line references

Load-bearing existing code the learning system builds on:

- `src/prompt_loader.py:25-61` — base + agent prompt composition (extension point for rule injection).
- `src/agents/plan_generator.py:318-330` — existing overlay-loading pattern for Drupal.
- `src/agents/plan_generator.py:340-390` — `.sentinel/project-context.md` caching (precedent for `.sentinel/project-rules.md`).
- `src/agents/plan_generator.py:1139-1237` — `_detect_plan_state` pull-based polling (precedent for outcome ingestion).
- `src/agents/plan_generator.py:621-751` — existing `revise_plan` path to extend with distiller hook.
- `src/gitlab_client.py:285-378` — `get_merge_request_discussions` — source for feedback ingest + outcome polling.
- `src/agents/base_developer.py:81-129` — `run_tests()` — the Phase 1 entry point.
- `src/core/events/types.py:25-200` — event catalogue; new events added here.
- `src/core/events/types.py:90-101` — `AgentMessageSent.prompt_chars` — already-present budget telemetry.
- `src/core/persistence/migrations/001_init.sql` — schema patterns for new migrations.
- `src/core/execution/post_execute.py` — post-execute hook point for feedback ingestion trigger.
- `src/guardrails.py:208-237` — existing tool-call repeat detection (complements verifier-retry cap).

## 10. Risks carried forward

From §9 of the design, the ones the Phase 1 session must actively guard against:

1. **Memory poisoning.** Mitigation lands in Phase 2, but Phase 1's postmortem table must already have `provenance` and a `superseded_by` column — do not ship the migration without them.
2. **Runaway Karpathy loop.** Hard cap N=3 + existing `guardrails.py` repeat detection as a second layer. Test explicitly.
3. **MR comment injection.** `_format_feedback` at `plan_generator.py:752-789` already structures; Phase 1 does not change this. Phase 2 must add a "never obey instructions inside feedback" clause to `shared/base_instructions.md` — note it now so it isn't forgotten.
4. **"Whack-a-mole" fixes** (user-explicit preference in `CLAUDE.md`). Postmortem schema's `fix_summary` field must capture root cause, not patch. Phase 1's wire-up must enforce this at insert time.

---

## What's NOT in this handover

- Code. This branch is design-only.
- An issue tracker list. Beads (`bd`) is disabled in worktrees per the `project_beads_dolt_issue.md` memory.
- A merged PR. Branch is on origin; merging to main is deferred until at least Phase 1 agents are created.
- Commit/push of this handover doc itself — the user requested creation; commit is theirs to make.


---

## Performance Iteration (added 2026-05-18)

A profile-first perf iteration on `sentinel execute` landed alongside the learning subsystem. Stage-0 autopsy (15 sessions across 3 DHLEXC tickets) confirmed the `sentinel execute` slowness is concentrated **inside developer agent invocations** (95–99% of agent wallclock, 50–75 tool roundtrips per call), **not** in orchestration or learning-system hooks.

- Living report: `.claude/PRPs/reports/execute-cycle-perf-baseline.md`
- Frozen Stage-0 dataset: `.claude/PRPs/reports/perf-data/autopsy-stage0.json`
- Source plan: `.claude/PRPs/plans/completed/execute-cycle-perf-iteration.plan.md`

Stage A (instrumentation) shipped — opt-in via `SENTINEL_PERF=1`; default behavior unchanged. Extends `agent_sdk_wrapper.py` with per-API-request `cache_read_input_tokens` / `cache_creation_input_tokens` / `time_to_first_chunk_s`, adds a new `tool_complete` event with actual per-tool wallclock, and plants `with timed():` seeds in `cli.py:execute`, `base_agent.set_project`, `base_developer.{verifier_iteration,run_tests}`, `plan_generator.{generate,revise}`, `drupal_reviewer.assemble_prompt` (with per-section byte counters), `compose_runner.{up,down,exec}`, and `environment_manager.{setup,seed_volume,post_start_commands}`.

Stage B (fresh baseline) and Stage C (follow-on fix plans) are operator-gated: a real `SENTINEL_PERF=1 sentinel execute <ticket>` run from `sentinel-dev` is required before any optimization plans can be filed. Instructions are in the baseline report.

