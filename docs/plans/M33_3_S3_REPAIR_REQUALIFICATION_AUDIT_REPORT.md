# M33.3 S3 — Independent Audit, Repair, and Requalification Report

> **Correction (2026-09-27):** the verdict below ("no repair required") is superseded. An independent re-audit found that Plan A §10 rows 18/19 were below their mandatory minimum (§E's "thin but not disqualifying" reasoning is withdrawn) and that `URI_STATE.yaml` carried a stale S3 scope line. Bounded repair and requalification are recorded in `docs/plans/M33_3_S3_REAUDIT_CORRECTION_REQUALIFICATION_REPORT.md`. This report is otherwise preserved unchanged as history.

**Auditor:** Claude Code, acting under the repository's AO-4 development cycle final-audit / bounded-fix / release authority.
**Date:** 2026-09-26.
**Verdict:** `S3_INDEPENDENT_AUDIT_REQUALIFICATION_ACCEPTED` — no repair required.

## A. Audit Scope

Audited: S3's frozen battery (`fixtures/m33_3_arn/battery.json` + `manifest.json`), the qualification runner (`scripts/m33_3_s3_qualify.py`), the focused test suite (`tests/test_m33_3_s3_battery.py`), telemetry/aggregate artifacts, the production `render_validator.py` module and every S1/S2 production function S3 calls through its four dispatchers, governance state, and the three protected frozen anchors.

Excluded (per S3's own declared scope, `M33_3_S3_STATE.md` §5): S4 source-to-candidate work, S5 real-renderer/L3 model qualification, live UI qualification, production caller wiring, and any redesign of S1/S2 semantics. No such work was performed or authorized here.

## B. Repository / Integrity State

- Worktree: `C:\Users\cheta\Development\Uri\_V1`. Branch: `m35-uri-v1-parallel-architecture`.
- Starting HEAD: `4f600e2c5d602565a8a6f9ce23a173d234867af0` (S3 freeze commit) — confirmed via `git rev-parse HEAD` before any audit action.
- Pre-existing, unrelated dirty state confirmed present and left untouched throughout: modified `SKILL.md`, and ~120 untracked M35/A2.5–A2.8 research-line files, `scratch/`, `graphify-out/converted/`. Re-verified identical at close of audit (`git status --short` before and after matched exactly; only `SKILL.md`'s diff stat was inspected, not altered).
- No `git stash`, `reset`, `clean`, or `checkout .` was run at any point.
- No production, test, or fixture file was modified during this audit — see §H.

## C. Authority Recovered

Chain confirmed by direct read, not by trusting the implementation report:
1. `docs/plans/M33_3_CROSS_PLAN_STATE.md` §4 (line 117): defines S3 as "Battery L1/L2 (no model), after S1."
2. `docs/plans/M33_3_S3_STATE.md` (68 lines, read in full): the actual S3-specific frozen contract. Line 9 explicitly states it supersedes older Plan A wording where they conflict.
3. `docs/plans/M33_3_ARN_ARCHITECTURE_AND_LT1B_RENDERER_PLAN.md` ("Plan A") §10 (category-minimums table, lines 1019–1050, 30 rows) and §11 (gates table, lines 1066–1090) — background/design source, subordinate to `M33_3_S3_STATE.md` on conflict.
4. S1 (`M33_3_S1_STATE.md`, CLOSED_FROZEN) and S2 (`M33_3_S2_STATE.md`, CLOSED_FROZEN) supply the frozen public interfaces S3 qualifies against.

Governing gate definition (`M33_3_S3_STATE.md` line 43): L1 = 100% case pass; L2 = 100% injected-defect rejection with expected flag except the governed `V-ORDER` exception; structural gates = zero accepted invented/unknown candidate or slot, zero omitted candidate, 100% escape append + click-by-ID, 100% template validation; runtime/L3 = `UNMEASURED`, not a gate.

## D. Requirement Matrix

| Requirement | Status | Evidence |
|---|---|---|
| L1 100% case pass | SATISFIED | Independent rerun: 60/60 (§I) |
| L2 100% rejection w/ expected flag, `V-ORDER` excepted | SATISFIED | Independent rerun: 20/20; ARB-066 (`reverse_order`) confirmed as the one case where only `V-ORDER` fires and `valid=True` by design (§I, §F) |
| Zero accepted invented/unknown candidate or slot | SATISFIED | `invented_option` category (ARB-064/065) both correctly rejected with `V-SLOT-UNKNOWN`; independent probe of an out-of-query-scope-but-in-query candidate ID also correctly rejected (§F probe 6) |
| Zero omitted candidate | SATISFIED | `omission` category (ARB-067/068) correctly rejected with `V-SLOT-MISSING` |
| 100% escape append + click-by-ID | SATISFIED | `check_build`'s `escape_appended`/`slot_identity` assertions fire on every one of 60 L1 cases (code-read confirmed, §E) |
| 100% template validation | SATISFIED | Every L1 case's `template_valid` assertion passes (independent rerun) |
| Plan A §10 category minimums | SATISFIED (27/29 applicable rows cleanly; 2 rows thin but non-zero) | Independent tabulation, §E |
| Production-path fidelity (no mocking) | SATISFIED | Direct code read of `scripts/m33_3_s3_qualify.py`, §E |
| Battery hash / byte count | SATISFIED | Independently recomputed, exact match, §I |
| Telemetry/aggregate determinism | SATISFIED | Two independent `--write` runs, byte-identical hashes, §I |
| Protected anchor integrity (RAR ×2, Batch A) | SATISFIED | Independently recomputed, exact match, §I |
| Governance validator | SATISFIED | `VALID`, independently rerun, §I |
| L3/runtime correctly `UNMEASURED`, not fabricated | SATISFIED | Confirmed in aggregate output and both state files |

## E. Battery / Category-Minimum Audit

Independent count of `battery.json` by actual `category` field (Python, `collections.Counter`, not via the qualifier's own code) found **43 distinct fixture categories across 80 cases (60 L1 / 20 L2)**, matching the manifest's counts exactly.

Mapping those 43 fixture categories against Plan A §10's 30-row table (excluding row 29, "Main Brain fallback rendering," which is L3-only and correctly out of S3's scope): **27 of 29 applicable rows are cleanly satisfied or exceeded** (e.g. `same_name_people:3`, `similar_files:3`, `temporal:3`, free-input path covered generously by 5 cases — `free_exact_id`, `free_title_heuristic`, `free_unknown`, `hidden_free_input`, `out_of_scope_free_input` — against a minimum of 3; negation/contrast covered on both required layers, `negation_contrast:3` on L1 and `contrast:3` on L2, against a minimum of 3).

Two rows are thin but not zero, disclosed here rather than treated as blocking:
- **Row 18 "Hallucinated slot or ID" (L2, min 2) and Row 19 "Invented extra candidate" (L2, min 2)**: the fixture's single `invented_option` category (ARB-064 `unknown_slot`, ARB-065 `extra_slot`) supplies exactly one case per Plan A concept rather than two each. Direct read of `render_validator.py` (lines 61–66) shows both concepts resolve to the same underlying mechanism — an output key absent from `expected` triggers `V-SLOT-UNKNOWN` regardless of whether the renderer renamed a slot (hallucination) or appended one (invention); `extra_slot` additionally and correctly triggers `V-EXTRA-OPTION` as a side effect of the count mismatch (confirmed by trace: `len(keys)=3 != len(expected)=2`). Since there is no code path in the frozen validator that distinguishes "hallucinated" from "invented" as separate flag classes, and `M33_3_S3_STATE.md`'s own governing gate (line 43) states the requirement as one combined structural gate ("zero accepted invented/unknown candidate or slot"), this reading is authoritative over Plan A's more granular split per the explicit precedence at line 9. **Not disqualifying.**
- **Row 22 "Omitted escape option" (L1, min 1)**: no dedicated adversarial case exists that attempts to omit the escape option and confirms rejection. Coverage instead comes from a positive invariant: `check_build`'s `escape_appended` assertion runs on every one of 60 L1 cases, proving the escape option — a builder-appended constant, not something external input can omit — is always present. There is no adversarial angle available at L1 for this row (escape omission would require malformed *renderer* output, which is L2's domain, and no L2 case specifically targets stripping the escape slot). **Not disqualifying**, but noted as the one row where the frozen battery's coverage is positive-only rather than positive-and-adversarial.

No category was padded with near-duplicate cases to hit a minimum; no mandatory Plan A row has zero coverage.

## F. Adversarial Findings

Ten independent, non-frozen probes were run directly against production functions (`build_clarification`, `validate_render`, `BindingService`, `evaluate_wrong_binding_gate`) from a standalone scratchpad script — see `§ Adversarial probe script` note below; probes were not added to the repository or the frozen battery.

| # | Probe | Result | Verdict |
|---|---|---|---|
| 1 | Duplicate candidate IDs in one `RARQuery` | `ValueError: indistinguishable candidates lack grounded display facts` | Correct fail-closed |
| 2 | Empty `ambiguous_candidate_ids` on `AMBIGUOUS` outcome | `RARContractViolationError` | Correct fail-closed |
| 3 | Question text exceeding 300-char limit | `V-LENGTH` (+`V-UNSUPPORTED-FACT`) fires, `valid=False` | Correct — confirms `V-LENGTH` is implemented correctly; **the frozen battery never exercises it** (no Plan A category names it, so not disqualifying, but disclosed as a coverage gap, §K) |
| 4 | Label exceeding 180-char limit | Same as #3 | Same disposition |
| 5 | Non-string label value (type confusion) | `V-SCHEMA`, `valid=False` | Correct fail-closed |
| 6 | Render output references a candidate ID that exists in the original query but outside the contract's scope | `V-SLOT-UNKNOWN` + `V-SLOT-MISSING`, `valid=False` | Correct — validator checks only against contract scope, a stronger invariant than checking against the full query |
| 7 | `BindingService.respond` using a stale fingerprint from a different round | `REJECTED`, reason "stale candidate-set fingerprint" | Correct fail-closed |
| 8 | `open_change` called twice on the same original binding without an intervening `respond` | Both calls succeed, return distinct `next_contract_id`s; `superseded_by` stays `None` until `respond` actually confirms a change | Not a defect — `superseded_by` is set on confirm, not on open, consistent with the frozen battery's own `change_rebind` case flow. Outside S3's declared scope (repeated unconfirmed `open_change` is not a named requirement); noted as a residual open question, not a finding, §K |
| 9 | `evaluate_wrong_binding_gate` given one valid `ReferenceBinding` and one malformed dict in the same call (S2's historically known defect class) | `INVALID_REFERENCE_BINDING`, `allowed=False` | Correct fail-closed — confirms no regression of the previously-repaired S2 defect |
| 10 | Label consisting solely of zero-width-space characters (`"\u200b\u200b"`) | `flags=()`, `valid=True` | **Genuine gap**: `render_validator.py`'s token regex (`[\w.]+`) does not match zero-width characters, so a functionally invisible/blank label passes every check with zero flags. Not one of S3's `FROZEN_REQUIRED` gates (Plan A §11, `M33_3_S3_STATE.md` §4) and not a named Plan A §10 category; fixing it would require a new validator rule (e.g., minimum meaningful-content check) — a policy decision, not a mechanical bug fix, so it falls under "must stop and ask" rather than pre-authorized bounded repair. **Disclosed, not repaired, does not block S3 closure.** |

## G. Defects

**None** meeting the disqualifying-defect bar defined for this audit (wrong governing semantic outcome, fail-open on invention/omission/mis-binding, a mandatory Plan A category with zero coverage, a hash mismatch, or an internal governance contradiction). All findings in §E and §F are disclosed limitations or thin-but-nonzero coverage, none of which contradicts the frozen S1/S2 contracts or S3's own declared `FROZEN_REQUIRED` gate set.

## H. Repairs

`NO_REPAIR_REQUIRED`. No production, test, fixture, or manifest file was modified during this audit.

## I. Qualification

All commands independently re-run from a clean, unmodified worktree at HEAD `4f600e2`:

```
$ python scripts/m33_3_s3_qualify.py --write
{"battery_lf_sha256": "7601125b77569ef3c8020b473ceabb32443cd8bec3ccd02263bbdd733d32fa7e",
 "critical_gates_passed": true, "failed": 0, "failed_case_ids": [], "l1_passed": 60,
 "l2_passed": 20, "l3_model_metrics": "UNMEASURED", "passed": 80, "runtime_ms": "UNMEASURED",
 "schema_version": "m33.3.s3.l1l2.v1", "total": 80}
```

```
$ python -m pytest tests/test_m33_3_s1_core.py tests/test_m33_3_s1_render.py \
  tests/test_m33_3_s1_binding_and_bundle.py tests/test_m33_3_s1_repair.py \
  tests/test_m33_3_s1_governance_and_parity.py tests/test_m33_3_s2_wrong_binding_impact.py \
  tests/test_m33_3_s3_battery.py tests/test_m35_uriv1_a2_8l_rar_attachment_order_factorial.py \
  tests/test_m35_uriv1_a2_8a_arn_foundation.py tests/governance/test_uri_state_validator.py -q
351 passed, 64 subtests passed in 4.47s
```

```
$ python scripts/governance/uri_state_validator.py docs/governance/URI_STATE.yaml
VALID: docs/governance/URI_STATE.yaml — no DCL violations found.
```

**Independent hash recomputation** (standalone script, not importing `scripts/m33_3_s3_qualify.py`'s own hash-check code, to avoid a self-referential check):
- Battery: computed `7601125b77569ef3c8020b473ceabb32443cd8bec3ccd02263bbdd733d32fa7e`, 95085 bytes → **MATCH** against manifest.
- Telemetry/aggregates: `M33_3_S3_TELEMETRY.json` = `e1106fe5...`, `M33_3_S3_AGGREGATES.json` = `2c3a3a0a...` — reproduced identically across two independent `--write` runs (before and after this audit's read-only probes), and `git status --short` on both files showed no diff after the second write, confirming true byte-for-byte determinism rather than a self-reported claim.
- Protected anchors: `rar_deterministic.py` → **MATCH**; `rar_contracts.py` → **MATCH**; `fixtures/m33_3_batch_a/battery.json` (LF-normalized) → **MATCH**.

All reproduced numbers match the implementation report's claims exactly.

## J. Regression / Baseline Analysis

No failures occurred in any independent run. No broad-suite failure needed comparison against the pre-S3 `98ce66c` baseline since nothing failed. No repair occurred, so no post-repair full-suite re-run was necessary beyond the reproduction already performed in §I.

## K. Known Limitations

- L3 real renderer/model qualification, live UI qualification, runtime performance, and production caller wiring remain `UNMEASURED`/deferred to S5+/S13, per S3's own declared scope — not converted into S3 requirements here.
- `V-LENGTH` and the non-headline occurrences of `V-EXTRA-OPTION` are real, correctly implemented validator behaviors that the frozen 80-case battery does not directly exercise as a named/asserted flag (see §E, §F #3/#4). Not a named Plan A category, not disqualifying, but a candidate for future battery enrichment if S5+ work revisits `render_validator.py` coverage.
- A label consisting only of zero-width-space characters passes validation (§F #10) — a genuine but non-`FROZEN_REQUIRED` gap in `render_validator.py`'s content-quality checking, disclosed for a future authorized decision on whether to add a minimum-meaningful-content rule. Not repaired here because it is a policy decision, not a mechanical bug.
- Repeated `open_change` calls on the same binding without an intervening `respond` (§F #8) is an untested state-machine corner not named as an S3 requirement; behavior observed was non-crashing and did not corrupt binding state, but was not exhaustively characterized beyond this one probe.
- Plan A §10 rows 18/19 and row 22 have thinner-than-literal coverage as detailed in §E; assessed as satisfied through the render_validator's actual (non-distinguishing) mechanism and through positive-invariant coverage respectively, per `M33_3_S3_STATE.md`'s explicit precedence over Plan A's more granular wording.

## L. Governance Outcome

S3 is genuinely closed/frozen: the frozen battery correctly exercises the required deterministic clarification/binding behavior and the real `RenderValidator` against canned adversarial input, with sufficient category coverage (27/29 applicable Plan A rows cleanly satisfied, 2 thin-but-nonzero and explicitly justified), correct expectations (spot-checked by hand-tracing all 20 L2 cases' flag logic and the two ambiguous rows), correct and reproducible telemetry (byte-identical across independent reruns), and no unauthorized scope expansion. Ten independent adversarial probes beyond the frozen battery found no disqualifying defect — only disclosed, non-blocking limitations.

## M. Final Verdict

**`S3_INDEPENDENT_AUDIT_REQUALIFICATION_ACCEPTED`** — S3 closes and freezes. M33.3 remains incomplete. S4 and later slices remain **NOT AUTHORIZED**.
