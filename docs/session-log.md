# Session log

Where the work stopped and what is still undecided. [`CLAUDE.md`](../CLAUDE.md) holds the standing
rules; this file holds the position. Update it at the end of every session.

---

## Session 1 — 2026-08-11

### Position

Branch `main`, pushed and in sync with `origin/main`.

| Commit | Subject |
|---|---|
| `a4ada01` | Add CLAUDE.md with standing project context |
| `ddca021` | Restore natural comparison order in set assertions |
| `1499db4` | Add case state machine, trust model, and case stores |
| `db3b797` | Scaffold project and pin Strands SDK surfaces |

**183 passed, 2 skipped. `ruff check` and `ruff format --check` clean.** The 2 skips are terminal
states in `test_failed_is_reachable_from_every_non_terminal_state` — correctly skipped, not
silently passing.

### Done

- **Commit 1** — repo scaffolding (Apache-2.0, `.gitignore`, `.gitattributes`, `pyproject.toml`)
  and the SDK spike. Findings in [`spike-findings.md`](spike-findings.md); four environment facts
  are mirrored into `CLAUDE.md` because they were expensive to establish.
- **Commit 2** — `provenance/` (TrustLevel, ArgClass, Fact, `promote()`) and `state/` (frozen
  `Case`, transition table, `CaseStore` protocol, SQLite + in-memory stores, timeline).
  `provenance/` moved forward from the planned commit 3 because `Case` embeds `Fact`.

Two invariants added during commit 2 that were **not** in the approved plan, both now covered by
tests: promotion is non-idempotent (otherwise trust launders by validating twice), and `Case`
collections are tuples so the freeze is deep rather than shallow.

### Next — commit 3: policy engine and tool registry

Built together, not stubbed: load-time validation that cannot resolve against a real registry is
not validation.

- `tools/registry.py` — tool names and **argument classes** (registry owns them; `rules.yaml` may
  reference classes, never define them). Names and arg classes only at this stage; no tool bodies.
- `policy/verdicts.py` — `Verdict` enum and the closed `ReasonCode` enum:
  `DESTINATION_NOT_TRUSTED`, `REQUIRES_HUMAN_APPROVAL`, `WRONG_CASE_STATE`,
  `INSUFFICIENT_FACT_TRUST`, `NO_RULE_MATCH`. Extend centrally as rules demand; keep it closed.
- `policy/schema.py` — Pydantic model of the rules file. Each rule carries `reason_code`
  (model-visible, enum member) and `diagnostic` (timeline-only, free text).
- `policy/engine.py` — deny-by-default; match order **DENY → REQUIRE_HUMAN → ALLOW → default**,
  fixed in code and not configurable from YAML.
- `policy/rules.yaml` — the three rules from the approved plan.
- **Load-time validation fails startup** if any rule names an unknown tool, an unknown argument, or
  an unknown reason code.

Tests for commit 3: verdict matrix, reason-code closure, and the drift check (every rule resolves
against the registry).

### Then

4. `tools/` bodies, mock executor, idempotency keys.
5. `llm/` mock provider + real provider config; `agents/` schemas, prompts, Triage, Planner.
6. `graph/` nodes, conditions, GraphBuilder wiring, `BeforeToolCall` policy hook.
7. `events/` simulator and fixtures, then **T1** (happy path).
8. **T2** (injection), **T3** (idempotency), **T4** (loop bound).
9. `cli.py`, README, final ruff pass.

---

## Open decisions

Carry these forward. Nothing here is blocking commit 3.

1. **Model provider benchmark — PENDING.** Bedrock Nova Lite is the intended primary and an
   OpenAI-compatible endpoint the fallback, both wired via env vars and never exercised in tests.
   Neither has been run against a real endpoint. No AWS credentials exist in the dev environment.
   Open: whether Nova Lite is strong enough for Planner intents, or whether Triage and Planner
   should sit on different models. Decide before the demo, not before the spine is finished.
2. **`ReasonCode` vocabulary is expected to grow.** The five codes cover the planned rules. New
   codes are added centrally to the enum, never as free text on a rule. Any growth should be
   recorded here so the vocabulary does not sprawl unnoticed.
3. **`WAITING_EXTERNAL` is in the state machine but has no producer yet.** Nothing transitions into
   it until a tool can genuinely block on a third party. It is tested as a table entry only. Either
   wire it in a later session or note in the README that it is reserved.
4. **Approval expiry is unmodelled.** `Approval` has `PENDING` / `APPROVED` / `REJECTED` and no
   timeout. A case can sit in `AWAITING_HUMAN` forever. The `AWAITING_HUMAN → FAILED` edge exists
   for it; nothing drives it. Fine for the hackathon spine; flag it in the README as known.
5. **Verification is not yet specified.** `VERIFYING` exists and `DONE` is reachable only from it,
   but what "verified" *means* per action type is undefined. T1 needs a concrete answer, even a
   mock one. Decide when writing the verify node.
6. **Repo visibility.** Private now, public at submission (2026-09-14). Nothing in the history
   contains secrets; the `.gitignore` covers `.env`. Re-check before flipping.

## Standing risks

- **The mock model is the only model the tests ever see.** Everything green means the spine is
  correct, not that a real model produces well-formed intents. The first real-provider run is a
  genuine unknown; budget time for it.
- **`strands-agents` is pinned to `==1.51.0`** deliberately. A bump must re-run the spike — the
  four verified facts are version-specific, and two of them (the `MultiAgentBase` node contract and
  the async-generator `structured_output`) fail loudly but confusingly if they shift.
