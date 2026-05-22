# /data-profile-iterate — Closed-loop dataset profiling with verifier-driven iteration

Run `data-profile-proposer` + `data-profile-verifier` as a closed loop:
the proposer drafts; the verifier audits; if any claim fails, the proposer
re-derives those claims using the verifier's `fix_hint`; repeat. Cap at
N=5 iterations. Terminate on PASS, on PARTIAL (flag to user), on cap, or
on no-progress (failed-claim set unchanged between iterations).

Always runs the verifier on every iteration. There is no bypass.

## Usage

```text
/data-profile-iterate <config-path>
```

## Arguments

- `<config-path>` — absolute path to a JSON or YAML file with the
  `data-profile-proposer` invocation parameters (`dataset_path`,
  `schema`, `subset_levels`, `artefact_checks`, `date_columns`,
  `spatial_columns`, `output_dir`, `venv_python`, etc.; see
  `~/.claude/agents/data-profile-proposer.md` for the full Input
  contract). The config can also be a shell-style param list passed
  inline, but a file is preferred for reproducibility.

## Behaviour

The slash command is a thin orchestrator. It performs **no reasoning
about the content** of either agent's output. Its only substantive
actions are: invoke agents, pass `corrections.jsonl` between them,
track iteration state, and decide when to terminate. All content
judgement lives inside the agents.

### Iteration policy (settled 2026-05-22)

- **Iteration cap:** `N=5`. Hard stop; do not silently extend.
- **Iterate on FAIL only.** PARTIAL verdicts surface to the user
  with full divergence details; the driver does not auto-iterate.
  This is deliberate — PARTIAL means tolerance exceeded but within
  the partial-tolerance band (see verifier spec); whether it
  matters is the user's call, not the loop's.
- **No-progress termination.** If iteration *k* produces the same
  set of FAIL `claim_id`s as iteration *k-1*, terminate. The
  proposer can't fix what it keeps producing.
- **Flag PARTIAL clearly.** When the loop terminates on PARTIAL,
  return the verifier's full integrated output with a banner
  flagging the partial divergences for user review.

### Pre-flight

Before iteration 0:

1. Read the config file. Validate it has the required
   `data-profile-proposer` parameters. Fail fast on missing
   required fields.
2. Create the iteration workspace:
   ```bash
   ITERATE_ROOT="${OUTPUT_DIR}/iterate-$(date +%Y%m%d-%H%M%S)"
   mkdir -p "$ITERATE_ROOT"
   ```
   Each iteration writes to `${ITERATE_ROOT}/iter-{N}/` so the full
   trajectory is preserved for inspection.
3. Initialise the no-progress tracker: `LAST_FAIL_SET=""`.

### Iteration loop

For `N` in 0..5:

#### Step A — Invoke the proposer

- **Iteration 0 (first-run mode):** invoke `data-profile-proposer`
  via the `Agent` tool with the config parameters, setting
  `output_dir = ${ITERATE_ROOT}/iter-0/`. No `previous_corrections_path`
  is passed.
- **Iterations 1..5 (iterate mode):** invoke with the same config
  parameters PLUS:
  - `previous_corrections_path = ${ITERATE_ROOT}/iter-{N-1}/corrections.jsonl`
  - `previous_output_dir = ${ITERATE_ROOT}/iter-{N-1}/`
  - `output_dir = ${ITERATE_ROOT}/iter-{N}/`

  Run in foreground (verification cannot start until the proposer
  returns).

#### Step B — Invoke the verifier

Invoke `data-profile-verifier` via the `Agent` tool with:

- `profile_report_dir = ${ITERATE_ROOT}/iter-{N}/`
- `dataset_path` = same as config
- `venv_python` = same as config
- `output_dir = ${ITERATE_ROOT}/iter-{N}/`

Run in foreground.

#### Step C — Read the verdict

Parse the verdict from `${ITERATE_ROOT}/iter-{N}/verdict.md`. Three
cases:

##### C.1 — PASS

Loop terminates successfully. Skip to "Final reporting" with status
`PASS`.

##### C.2 — PARTIAL

Loop terminates with the PARTIAL flag. The driver does not iterate
on PARTIAL. Skip to "Final reporting" with status `PARTIAL`.

##### C.3 — FAIL

Continue to no-progress check.

#### Step D — No-progress check (FAIL only)

Read `${ITERATE_ROOT}/iter-{N}/corrections.jsonl`. Compute the set
of `claim_id`s where `status == "fail"`. Call this `CURRENT_FAIL_SET`.

If `CURRENT_FAIL_SET == LAST_FAIL_SET` and `N > 0`, terminate with
status `NO_PROGRESS` — the proposer is unable to fix the remaining
claims. Skip to "Final reporting".

Otherwise: `LAST_FAIL_SET = CURRENT_FAIL_SET`, increment `N`, loop.

#### Step E — Cap check

If `N == 5` and the verdict is still FAIL, terminate with status
`CAP_REACHED`. Skip to "Final reporting".

### Final reporting

Always return:

```markdown
# Data-profile-iterate result

**Status:** <PASS | PARTIAL | FAIL | NO_PROGRESS | CAP_REACHED>
**Iterations run:** <0..5>
**Workspace:** ${ITERATE_ROOT}

## Per-iteration trajectory

| Iter | Verdict | FAIL count | PARTIAL count | UNVERIFIABLE count | Notes |
|------|---------|-----------|---------------|---------------------|-------|
| 0    | FAIL    | 12        | 3             | 0                   | initial draft |
| 1    | FAIL    | 4         | 3             | 0                   | 8 claims fixed |
| 2    | FAIL    | 4         | 3             | 0                   | no progress — same FAIL set |

(Generate from each iter's `corrections.jsonl`.)

## Outcome detail

(Status-specific block — see below.)

---

**Final verifier report:** ${ITERATE_ROOT}/iter-{N}/verdict.md
**Final corrections audit:** ${ITERATE_ROOT}/iter-{N}/corrections.md
**Machine-readable per-claim audit:** ${ITERATE_ROOT}/iter-{N}/corrections.jsonl
**Final claims (post-iteration):** ${ITERATE_ROOT}/iter-{N}/claims.jsonl
**Full per-iteration trajectory:** ${ITERATE_ROOT}/iter-*/
```

#### Outcome-detail blocks

- **PASS** — "Loop converged after N iterations. All claims pass
  verifier tolerance. Final report at
  `${ITERATE_ROOT}/iter-{N}/summary.md`."

- **PARTIAL** — Show the verifier's PARTIAL summary verbatim from
  `verdict.md`, plus a `head -20` of the PARTIAL rows from
  `corrections.jsonl`. Header: "**⚠ PARTIAL VERDICT — DRIVER DID NOT
  ITERATE.** Tolerance exceeded but within the partial-tolerance
  band on N claims. Review the divergences below and decide whether
  to (a) accept the report as-is, (b) re-invoke with a stricter
  tolerance, or (c) manually re-run the proposer with explicit
  guidance on the partial claims."

- **FAIL** (only via CAP_REACHED) — Header: "**⚠ ITERATION CAP
  REACHED.** Five iterations did not produce a PASS or PARTIAL
  verdict. The proposer may be unable to satisfy the verifier on
  the remaining FAIL claims. Manual investigation required."

- **NO_PROGRESS** — Header: "**⚠ LOOP STALLED.** Iteration {N}
  produced the same FAIL `claim_id` set as iteration {N-1}. The
  proposer can read the fix_hints but cannot act on them — either
  the hints are ambiguous, the data does not admit the requested
  re-derivation, or there is a methodology mismatch the proposer
  cannot resolve unaided. Review iter-{N}/decisions.md for the
  proposer's ambiguous-hint reports."

### Persistence and recovery

- Each iteration's full output (markdown reports, claims.jsonl,
  corrections.jsonl, decisions.md, run.log) is preserved under
  `${ITERATE_ROOT}/iter-{N}/`. Nothing is deleted between
  iterations.
- On any agent failure (timeout, error, malformed output):
  terminate the loop, return the iteration trajectory up to that
  point, and explicitly flag the failure mode. Do not retry the
  failing agent automatically — that decision is the user's.

## Examples

```text
/data-profile-iterate ~/Code/inscriptions/configs/lire-profile.json
```

Config file shape (example):

```json
{
  "dataset_path": "/home/shawn/Code/inscriptions/data/lire-2026-05.parquet",
  "schema": "infer",
  "subset_levels": [
    {"name": "dataset", "columns": []},
    {"name": "province", "columns": ["province"],
     "threshold_candidates": [100, 1000, 10000]},
    {"name": "urban-area", "columns": ["urban_area"],
     "threshold_candidates": [10, 100, 1000]}
  ],
  "artefact_checks": "default",
  "date_columns": ["not_before", "not_after"],
  "spatial_columns": ["Latitude", "Longitude"],
  "output_dir": "/home/shawn/Code/inscriptions/profiles/lire-2026-05",
  "venv_python": "/home/shawn/Code/inscriptions/venv/bin/python3",
  "max_runtime_minutes": 30,
  "comprehensive_mode": false,
  "primary_key": "LIST-ID"
}
```

## Failure modes and recovery

| Failure | Symptom | Recovery |
|---------|---------|----------|
| Proposer errors at iter 0 | Agent returns error, no draft | Re-run `/data-profile-iterate` after fixing the config; nothing has been persisted that could conflict. |
| Proposer errors at iter N>0 | Iterate mode failure | Manually invoke `data-profile-proposer` with `previous_corrections_path = ${ITERATE_ROOT}/iter-{N-1}/corrections.jsonl` to reproduce; debug from there. |
| Verifier errors | Step B returns error | The iter-{N}/ output remains. Manually invoke `data-profile-verifier` against it. |
| Cap reached | Status CAP_REACHED | Inspect the final FAIL claims and their fix_hints; the methodology may need adjustment by the human before the loop can converge. |
| Stall | Status NO_PROGRESS | Same as cap-reached, but earlier — same hints, same outcome. Manual intervention required. |
| Out of band cancellation | User aborts mid-iteration | The current iter directory may be incomplete; future runs should use a new ITERATE_ROOT. |

## Notes

- The proposer and verifier both run in foreground as separate
  sub-agent calls. Each gets a fresh context window. Neither can
  see the other's reasoning or tool-call history.
- The main conversation is the channel between them; by design it
  does no reasoning about the content, only mechanical forwarding
  of file paths.
- Iteration cap of 5 is rule-of-thumb and rests on the assumption
  that the no-progress check and PARTIAL-flag policy catch most
  pathological loops before the cap matters. Tune in light of real
  iteration experience.
- PARTIAL severity is currently rule-of-thumb (within 5× the PASS
  tolerance — see verifier spec). Quantifying "how partial" more
  precisely is deferred pending experience with actual partial
  outcomes.
- Each iteration is one full proposer call + one full verifier
  call. On a 100k-row dataset with `comprehensive_mode: false`,
  expect ~5–10 minutes per iteration; comprehensive mode can run
  20–40 minutes per iteration. Plan the cap accordingly.
- Do NOT attempt to invoke the verifier from inside the proposer's
  context or vice versa. The Claude Code harness forbids nested
  sub-agent dispatch. Serial dispatch from the main conversation
  is the only realisable path.
