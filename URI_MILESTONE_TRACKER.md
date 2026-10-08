# URI Milestone Tracker

**2026-10-04 — Non-milestone direct camera/voice/Gemma work:** Partial uncommitted input adapter and hardware evidence recorded in [implementation handoff](docs/plans/CAMERA_VOICE_GEMMA_IMPLEMENTATION_REPORT.md). Camera/storage stop conditions remain active; Gemma live qualification and final User acceptance pending. No numbered milestone state, independent verification or release checkpoint changed.

**2026-10-04 — Intent clarification formal plan, DRAFT_FOR_USER_APPROVAL:** Codex plans under the User's temporary planning assignment. [Plan](docs/plans/INTENT_CLARIFICATION_INTEGRATION_PLAN.md), [self-review](docs/plans/INTENT_CLARIFICATION_INTEGRATION_SELF_REVIEW.md), [source pins](docs/plans/INTENT_CLARIFICATION_PLAN_SOURCE_MANIFEST.json). No implementation/test/model execution; self-review is not independent verification.

**2026-10-04 — Next-milestone direction accepted, planning only:** Intent clarification proceeds as **MINIMAL EXTENSION** of existing controller, binding, retrieval, context and preparation boundaries, followed by combined behavior qualification. Standalone Revision 3 proposal closed; evidence preserved. [Scope](docs/plans/INTENT_CLARIFICATION_MINIMAL_EXTENSION_SCOPE.md). Formal Claude planning/pre-audit pending; no implementation, model qualification, production promotion or completion claimed.

**2026-10-03 — Harness desktop completion (provisional, acceptance blocked):** Direct User assignment authorizes Codex implementation of desktop management/selection and adapter completion. Existing `_V1` seam now has live discovery, explicit harness choice, persisted execution/checkpoints, cancellation and recovery. Fresh Claude repair is quota-blocked; Antigravity execution remains disabled pending containment. No production promotion, independent verification, commit, push or freeze. See [completion report](docs/plans/HARNESS_DESKTOP_COMPLETION_REPORT.md).


**2026-10-02 — Desktop Claude Code qualification (provisional):** Direct User instruction assigns the isolated test integration and authentication/layout repairs to Codex. Work is in `_V1` at `62d564c`; the installed Core is a different checkout, `uri-m37-m39-integration`. No frozen M38/Core edits, production promotion, commit or push. Self-tests: 105 Python / 7 Flutter pass; fixed-task real native desktop path passed (11.367 s response, 11.369 s displayed); independent Claude review and production canonical-loop acceptance pending. See [review package](docs/plans/DESKTOP_HARNESS_CLAUDE_REVIEW_PACKAGE.md) and the stage artifacts it links.


**Batch handoff — 2026-09-28: M38 Harness Execution Minimum implemented, PROVISIONAL / NOT FROZEN; batch stopped before the Office demonstrator.**
State: `M38_IMPLEMENTED_PROVISIONAL_NOT_FROZEN`. Built on unaudited M36 (`405db1f`) and M37 (`5460d64`), dependencies recorded. [Plan](docs/plans/M38_HARNESS_EXECUTION_MINIMUM_PLAN.md), [report](docs/plans/M38_IMPLEMENTATION_REPORT.md), [Codex audit package](docs/plans/URI_BATCH_M36_M37_M38_AUDIT_PACKAGE.md). Next: one independent Codex audit of the M36 -> M37 -> M38 chain. No freeze, no production integration.

**Batch handoff — 2026-09-28: M37 Edge Minimum implemented, PROVISIONAL / NOT FROZEN.**
State: `M37_IMPLEMENTED_PROVISIONAL_NOT_FROZEN`. Claude planned and implemented the Edge minimum under the User's batched-audit workflow, on unaudited M36 repair commit `405db1f` (dependency recorded). [Plan](docs/plans/M37_EDGE_MINIMUM_PLAN.md), [report](docs/plans/M37_IMPLEMENTATION_REPORT.md). Self-qualification only; the independent audit is the batched Codex package covering M36 -> M37 -> M38. No freeze, no production integration.

**Current handoff — 2026-09-28: M36 closing audit performed; bounded repairs applied.**
State: `M36_AUDIT_REPAIRED_AWAITING_FREEZE_DECISION`. Claude performed the independent closing audit of Codex commit `be4451c` ([report](docs/plans/M36_INDEPENDENT_CLOSING_AUDIT_REPORT.md)): verdict REPAIRS_REQUIRED with six code findings (F-1 negation cropping could yield wrong CONFIRMED; F-2 negated status keywords; F-3 verifier-registry mismatch on reload; F-4 forget could hide verdicts; F-5 stem regex diverged from frozen RAR; F-6 hidden files blocked all exact-title certainty) and D-1 (URI_STATE.yaml PG-M1 verdict overwritten). The User authorized the repairs, commit and push, not freeze. Repairs are confined to `uri_v1/memory/`, M36 tests, the M36 driver/battery and governance. The focused re-verification was performed by the same session that made the repairs, so it is not independent. Freeze requires a User decision. No S13, INT-*, Office/Edge/Harness or frozen-file change. The entry below is historical.

**Current implementation handoff — 2026-09-28: M36 URI-Memory Minimum.**
State: `M36_IMPLEMENTED_VERIFICATION_READY_FOR_INDEPENDENT_AUDIT`. The direct User task package supplies accepted PG-M1 and grants PG-M2; no separate final A4 report supplied/located. All nine implementation waves are delivered and self-qualified; independent closing audit remains required. See [implementation report](docs/plans/M36_IMPLEMENTATION_REPORT.md), [qualification matrix](docs/plans/M36_QUALIFICATION_MATRIX.md) and [M36 state](docs/plans/M36_STATE.md). No freeze, production agent-loop/UI wiring, INT-* event, Office/Harness/Edge implementation or push. Prior planning handoffs below are historical.

**Planning handoff — 2026-09-28: M36 A4 ready for final PG-M1 re-check.**
A2 repairs hold; A3 initial projection grounding is accepted per the latest
User-supplied focused finding. [A4 plan §19](docs/plans/M36_URI_MEMORY_MINIMUM_PLAN.md)
repairs only clarification FREE_INPUT grounding before BindingService.respond(),
with Q-A3-1 H1–H3. Status: PLAN_A4_REPAIRED_AWAITING_FINAL_PG_M1_FOCUSED_RECHECK.
Readiness: M36_A4_READY_FOR_FINAL_PG_M1_RECHECK. PG-M1 still awaits final focused
acceptance; PG-M2 remains blocked. No Memory implementation or push.
Exact re-check prompt: plan §19.5; evidence/validation: [M36 state](docs/plans/M36_STATE.md).
A2/A3, frozen M33.3, Memory boundary and all preserved rulings/deferrals/Edge
limitations remain unchanged. Earlier A2/A3 handoffs below are historical.

**Planning handoff — 2026-09-28: M36 A3 ready for final focused PG-M1 re-check.**
The [A2 focused report](docs/plans/M36_PG_M1_A2_FOCUSED_RECHECK_REPORT.md)
confirms F-1…F-11 hold and identifies N-1 as the sole remaining blocker.
[A3](docs/plans/M36_URI_MEMORY_MINIMUM_PLAN.md) §18 repairs exact-expression
provenance only. Status: PLAN_A3_REPAIRED_AWAITING_FINAL_PG_M1_FOCUSED_RECHECK.
PG-M1 is not fully accepted; PG-M2 remains blocked. The A2 handoff below is
historical. No implementation, boundary expansion or milestone completion.

**Planning handoff — 2026-09-28: M36 A2 ready for focused PG-M1 re-check.**
PG_M1_ACCEPTED_WITH_BOUNDED_REPAIRS (F-1…F-11); bounded documentation repairs
recorded in [M36 plan §17](docs/plans/M36_URI_MEMORY_MINIMUM_PLAN.md) and
[M36 state](docs/plans/M36_STATE.md). Current status:
PLAN_A2_REPAIRED_AWAITING_PG_M1_FOCUSED_RECHECK. PG-M1 is not fully accepted;
PG-M2 remains blocked pending focused re-check. No Memory implementation or
milestone completion is claimed. The M33.3 delivery checkpoint below is unchanged.

**Latest delivery checkpoint — 2026-09-28: M33.3 `CLOSED_FROZEN`,
`ACCEPT_WITH_DOCUMENTED_LIMITATIONS`.** Independent audit of `d1feaf7`, bounded
repairs and requalification completed under the User's direct session authority.
3,261 passed, 9 baseline failures, 66 skipped, 218 subtests passed; no new regression. Flutter 204 passed.
Template-only wording; S8 one-route replay; S12 fixture-only. S9 remains
URI-Memory/D4, S13 a future INT-* milestone; neither is authorized here.
Full evidence, scope and limitations: `docs/plans/M33_3_R_INDEPENDENT_CLOSING_AUDIT_REPORT.md`.
The commit containing this checkpoint is the closure release; older entries
retain their historical meaning. No next milestone is automatically opened.

**Scope:** M6 onward — the actual implementation-milestone scheme used in this
repository's commit history. This is the canonical, actively maintained record
of delivery status for M-numbered milestones.

**Current documented baseline:** M22.3 is complete, independently verified by
Claude Code as third-layer reviewer (10 Sep 2026), with **1,218/1,218 backend
tests passing** and **103/103 Flutter tests passing** at delivery. This
verification does not repeat the M22, M22.1, or M22.2 architecture/security
audits (change-aware scope only). The commit that delivers M22.3 also carries
the previously-uncommitted Flutter Windows/platform scaffolding and M22.2 UI
parity work noted below, and the AO-4 development-cycle documentation update
(`ORCHESTRATION.md`, `AGENTS.md`, `PROJECT_MEMORY.md`).

**Current documented baseline (11 Sep 2026): M22.7 — DONE, VERIFIED.** Codex
implemented the accepted
[usage metering plan](docs/plans/M22.7_USAGE_METERING_PLAN.md); Claude Code
independently verified it (see
[M22.7_STATE.md](docs/plans/M22.7_STATE.md) for the full trace and evidence)
and released it, along with M22.6 (`5b97e12`) verified and released
immediately before it in the same session. Full regression suite:
1,433/1,433 Python tests passing, 29 subtests passing, 0 failures.

**Current documented baseline (11 Sep 2026): M22.8 — DONE, VERIFIED.** Codex
began implementing the accepted
[modes/tiered-UX plan](docs/plans/M22.8_MODES_TIERED_UX_PLAN.md) and
exhausted its daily quota mid-implementation. Under explicit, direct User
authorization for this specific instance ("since codex has run out of
quota... i want you to implement"), Claude completed the implementation
(finding and fixing real defects the interruption left behind — see
[M22.8_STATE.md](docs/plans/M22.8_STATE.md) for the full list) and
independently audited its own completed work. All 8 acceptance criteria
traced against source; full regression: 1,460/1,460 Python tests passing, 0
failures; Flutter: 0 analyze errors, 112/112 tests passing. This is a
recorded exception to standing role separation, not a new default — see
`ORCHESTRATION.md` §3.1 (the permanent quota-exhaustion invariant) for the
default (`WAITING_FOR_MODEL`) this instance deliberately did not use, by the
User's own choice. M22.6, M22.7, and M22.8 all verified and released this
session.

**Current documented baseline (19 Sep 2026): M34 — DONE, VERIFIED, CLOSED / ACCEPTED.** Three
independently audited slices, each committed and pushed separately by Claude
under standing AO-4 release authority: Graphify Hint Activation (`78fb5e1`),
C3.3 Heterogeneous Multi-Capability Routing (`4aa3478`), and Attachment-Turn
Brain/Tool-Selection Reliability (`b994270`). Full closure record, evidence,
and residuals: `docs/governance/URI_ACTIVE_MILESTONE.md` §1/§1c/§6g. See the
M34 row below. **Note on numbering gap:** milestones M24–M33 are tracked in
`docs/governance/URI_ACTIVE_MILESTONE.md` rather than backfilled into this
table (that file became this repository's active per-milestone record
starting with M30); M33 and M33.1 are tracked there. M33 and M33.1 are
CLOSED / ACCEPTED. M33.1's final Batch 4 closure accepted the extension matrix,
natural-language/UI lifecycle seam, live `/ask` wiring, and compatibility
evidence; see `docs/plans/M33_1_REAL_INTEGRATIONS_EXTENSION_VALIDATION_PLAN.md`
§13.H. M33.2 Batch B.2 is **CLOSED / ACCEPTED** for Edge Perception
Qualification (Batch A/B/B.1/B.2 are all CLOSED / ACCEPTED, per Claude's
2026-09-20 independent audit); its separate planning checkpoint records the
three four-stage artifacts. M33.3 is reserved for Unified URI Interaction &
Capability UI; M33.4 is reserved for Knowledge Fabric / Sources / Watches.
M32.1/M35 remain
reserved/NOT STARTED and none of these records block M34's closure.

**Current documented baseline (20 Sep 2026): ARN.1 — Deterministic Narrowing Core — DONE, VERIFIED.**
Independently audited by Gemini per direct User instruction. 10/10 focused tests passed,
60/60 M33.2 predecessor regressions passed, 130 passed + 13 subtests passed on core suite,
full regression: 2,259 passed, 16 failed (all 16 verified historical/environmental, 0 ARN.1 regressions).
Full evidence: `docs/plans/ARN_1_COMPLETION_REPORT.md` and `docs/plans/ARN_1_STATE.md`.
ARN milestone paused after ARN.1. Next authorized direction: **Resume M31 Hybrid UI after ARN.1 closure**.

## Relationship to the older Phase 0–4 checklist

This tracker does **not** replace, relabel, or rewrite the earlier
Phase 0–4 architecture-planning checklist, preserved unchanged at:

`OneDrive\Desktop\URI_Project_Management_Session_001_Closed_29_Aug_2026\URI_Project_Management\URI_MILESTONE_CHECKLIST.md`

That document reflects an earlier, pre-implementation planning scheme
(architecture-freeze phases 0–4) from a closed project-management session
dated 29 Aug 2026. It is retained as historical documentation only and is
not actively maintained. Current implementation work is tracked exclusively
by the M-numbered milestones below.

---

## Milestones

| Milestone ID | Milestone Name | Status | Commit Hash | Verification / Test Status | Purpose (short) | Major Deferred Items |
|---|---|---|---|---|---|---|
| M6 | Capability Awareness | DONE | `89169c1` | **Verified 5 Sep 2026:** 60/60 tests pass — `test_capability_planner.py`, `test_capability_registry.py`, `test_capability_authority_boundary.py`, `test_ollama_provider.py`, `test_server_capabilities_endpoint.py` | One authoritative capability descriptor (status, availability, permissions, approval requirement, risk) plus read-only model/provider self-knowledge (`ModelProvider.describe()`), exposed via `GET /capabilities`. Reporting-only — dispatcher, workflow executor, and tool-selection scoring remain unaware of it. | Capability awareness still does not influence tool selection or execution (by design, enforced by boundary tests). `PC/System Optimization` remains a documented `not_implemented`, high-risk example capability with zero executable backing. |
| M7 | Real Approval Gate + Self-Knowledge Protection | DONE | `b967ff3` | **Verified 5 Sep 2026:** 73/73 tests pass — `test_approval_gate.py`, `test_approval_store.py`, `test_authoritative_facts_immutability.py`, `test_capability_authority_boundary.py`, `test_orchestrator_approval_gate.py`, `test_server_approval_endpoints.py` | `ApprovalStore` (bound to action_id + capability_id + session_id + argument fingerprint, single-use, fail-closed) and `ApprovalGate` sit in front of `ToolDispatcher` for both direct and dynamic-workflow execution paths. Also locks identity/purpose and verified capability facts against mutation via user input, model output, or memory/profile APIs (proven by static analysis + file-hash invariance). | None recorded in the commit message — **not yet confirmed with project owner.** |
| M8A | Live Conversational Response Foundation | DONE (superseded by correction, see M8A-fix) | `3570651` | **Verified 5 Sep 2026 (combined with M8A-fix below):** see M8A-fix row — the two commits' test suites were run together against current HEAD since M8A's own behavior is only meaningful post-correction | Grounded natural-language narrative alongside every deterministic response (drafted after the outcome is decided, validated for claim-consistency); a Tasks screen wired to the real approval gate; `extract_student_records` / `draft_institutional_note` rewritten to parse actual request text through the real service chain instead of returning fixed, input-independent content; learned-skill path re-executes through the real dispatcher/approval gate instead of a fake "recognized" response. | Known gaps at merge time, all closed by M8A-fix: gap-reason phrasing didn't distinguish "doesn't exist" from "exists but unavailable now"; `workflow_capability_router`'s generic bucket could report success on failure; ambiguous student identifiers were silently resolved to the first match. |
| M8A-fix | M8A correction: honest gap reasons + student-record ambiguity handling | DONE, VERIFIED | `744d05c` | **Verified 5 Sep 2026:** 85/85 tests pass — `test_orchestrator_response_narrative.py`, `test_response_drafting.py`, `test_server_ask_narrative.py`, `test_extract_student_records.py`, `test_draft_institutional_note.py`, `test_workflow_capability_router.py`, `test_response_drafting_gap_condensation.py`, `test_response_validation.py` | Adds `CapabilityDescriptor.gap_reason` distinguishing `not_implemented` (no execution adapter exists) from `unavailable_runtime` (adapter exists, runtime can't use it now), threaded through response drafting/validation so URI never implies more detail or approval would unblock a capability that doesn't exist. Fixes `workflow_capability_router`'s generic bucket to report real failure instead of faking success. Makes `extract_student_records` detect and surface ambiguous identifiers instead of silently picking one. | Not specified in commit message — **not yet confirmed with project owner.** |
| M10A | Unified Query Context Foundation | DONE, VERIFIED | *pending commit — implemented on top of `e259ae5`, working tree not yet committed at time of writing* | **Verified 5 Sep 2026:** targeted suite 57/57 passing — `test_query_context.py`, `test_response_drafting.py`, `test_capability_authority_boundary.py`, `test_orchestrator_response_narrative.py`. Full repo `python -m unittest discover -p "test_*.py"`: 722 collected, 719 passing, 3 pre-existing collection errors unrelated to this milestone (see Major Deferred Items). Flutter `flutter test`: 70/70 passing (no Dart/UI changes in this milestone). | New pure, read-only module `uri_core/core/query_context.py` assembles one bounded, model-facing context — identity/character/principles, personalization + consent-eligible memory, current session/task state, VERIFIED-only evidence, and the capability catalogue with its approval-requirement/risk/gap-reason fields — reusing existing sources (`ModelReasoningGateway.load_policy()`, `personalization_context.build_personalization_context()`, `UriOrchestrator._build_model_session_context()`, `evidence_context.get_verified_evidence()`/`evidence_summary()`, `CapabilityRegistry.list_capabilities()`) with no new storage and no duplicated logic. Wired into `response_drafting.DraftRequest` as one new optional `query_context` field and supplied by `UriOrchestrator._build_query_context()` — closing the gap identified in the M10A audit where session/evidence/capability context reached only the shadow `ModelReasoningGateway.reason()` path (never shown to a user) while the live, user-visible narrative-drafting path saw only personalization. Capability information is reporting-only, exactly as `CapabilityDescriptor` already intends — no selection/scoring logic was added, and `CapabilityPlanner` is untouched. | Does not change capability selection/planning — the Brain now *receives* the capability catalogue but nothing yet acts on that awareness (`CapabilityPlanner`'s deterministic keyword scoring is unchanged by design). No multi-turn conversation transcript exists or was added — session/task context remains the existing fact-and-workflow-shaped state, not a raw dialogue history. `ModelReasoningGateway.reason()`'s shadow path was not changed to also receive personalization/query context, so the two model-facing pipelines documented in the M10A audit remain distinct; unifying them further is explicitly out of scope for this milestone. M11's general problem-solving loop over this context is out of scope. Not yet confirmed with project owner. |
| M11.1 | Brain proposal promotion | DONE | `0fcfc85` | Commit checkpoint; later M11 work is the relevant cumulative state. | Promotes Brain proposals into controlled execution. | M11.2 completed the workflow path. |
| M11.2 | Brain-composed workflow execution and correction loop | DONE | `6738289`, `e44e717` | Commit checkpoints. | Adds Brain-composed workflows, re-evaluation, and reference-only learned-skill feedback while preserving runtime control. | Subsequent milestones are the current baseline. |
| M12.1 | Reliable Brain reasoning to execution | DONE | `4879965` | Commit checkpoint. | Ensures real Brain reasoning reaches the execution path. | Superseded as the operational baseline by later milestones. |
| M13.1–M13.2 | Pre-execution sanity and user feedback hooks | DONE | `181d7ba`, `2df41e1` | Commit checkpoints. | Adds pre-execution Brain sanity checks and user satisfaction/acceptance interaction hooks. | No separate active work recorded. |
| M14.1 | Persistent LAN-reachable server | DONE | `001cc98` | Commit checkpoint. | Establishes the persistent server milestone. | Remote hardening is deferred to M22.3; do not infer non-loopback readiness. |
| M15.1 | Brain Internet research access | DONE | `0839b94` | Commit checkpoint. | Gives the Brain a real `web_search` capability under runtime controls. | Bounded/reachable research refinements arrived in M20. |
| M16 | Attachments, honest UI state, backend capability exposure | DONE | `d65d3b3` | Commit checkpoint. | Adds file attachments and connects the Flutter client to existing backend capabilities. | Current uncommitted Windows/platform UI work is not part of M16 or any later milestone. |
| M17 | Brain-authored institutional drafting | DONE | `32500d1` | Commit checkpoint. | Replaces templated institutional drafting with Brain-authored, rule-driven drafting. | No separate active work recorded. |
| M18 | Per-user memory, learning, and safe skill-install foundation | DONE | `ec261b6` | Commit checkpoint. | Adds per-user isolation and learning/memory foundations. | Promotion and broader skill surfaces remain governed/deferred work. |
| M19 | Office readiness | DONE | `f16e5e8` | Commit checkpoint. | Adds honest tool status, document generation, and gated Gmail/Drive writes. | Connection-management authorization is next addressed by M22.3. |
| M20 | Feasibility, recovery, research, and latency safeguards | DONE | `66d1433` | Commit checkpoint. | Makes capability selection feasibility-aware and adds bounded recovery/research safeguards. | No separate active work recorded. |
| M21 | Context-window awareness, provider seam, file-store isolation | DONE | `5957eb2` | Commit checkpoint. | Adds prompt/context bounding, provider configuration seam, and completes file-store user isolation. | Provider/secrets work remains deferred to M22.5. |
| M22.1 | Cleanup and honest baseline | DONE | `a647c39` | Commit checkpoint. | Establishes the cleaned M22 baseline. | M22.2 completed next. |
| M22.2 | Roles, accounts, and durable sessions | DONE, VERIFIED | `34839ce` | **1,141/1,141 tests passing at delivery.** | Adds `USER`/`ADMIN` roles, `BASIC`/`ADVANCED` zero-authority experience tiers, deterministic first-admin and legacy migration, persisted hashed sessions, device session management, and self-scoped auth endpoints. Existing routes were intentionally not retrofitted. | Superseded as the operational baseline by M22.3. |
| M22.3 | Endpoint authorization and edge hardening | **DONE, VERIFIED** | `8acbad5` | **Independently verified by Claude Code (third-layer review) 10 Sep 2026: 1,218/1,218 backend tests passing (confirmed by direct `unittest discover` run, not the worker's claimed count), 103/103 Flutter tests passing (confirmed by direct `flutter test` run), `flutter analyze` — 0 errors/warnings, 8 pre-existing-pattern info-level style lints (non-blocking). `wc -l uri_core/core/orchestrator.py` confirmed unchanged at 5,476 lines. `approval_gate.py`, `dispatcher.py`, `capability_registry.py`, `principal_context.py` confirmed untouched (absent from `git status`).** Plan: `docs/plans/M22.3_SECURITY_ARCHITECTURE_PLAN.md`. | Closes S1 (5 previously-unauthenticated mutating endpoints — `enable_skill`, `disable_skill`, `remove_skill`, `authorize_connection`, `disconnect_connection` — now ADMIN-gated via `uri_core/core/authorization.py`'s `require_admin`, 401 anonymous / 403 non-admin / success ADMIN-only, verified by a negative-authorization matrix) and S5 (`/auth/login` 5/60s/IP, `/auth/signup` 3/300s/IP fixed-window rate limiting in `uri_core/app/edge.py`, every attempt counted per the accepted decision, fail-closed, 429 + `Retry-After`). Adds `/ask` request-size protection (64 KB field bound + 1 MB Content-Length precheck, verified rejecting *before* Pydantic parsing), CORS lockdown (explicit allowlist via `URI_CORS_ALLOWED_ORIGINS` in production, anchored loopback-only regex in dev, `allow_origins=["*"]` never used), and loopback-only default binding in `scripts/run_uri_server.py` (refuses non-loopback without TLS or explicit `--allow-insecure-bind`/`URI_ALLOW_INSECURE_BIND=1`). New `uri_core/app/route_classification.py` is the single source of truth for all 39 application routes (+4 FastAPI doc routes), enforced by a route-enumeration test that fails if a route is ever added unclassified. `experience_tier` confirmed never read by any new authorization code. The five diagnostic-GET endpoints (Decision 1) remain deliberately PUBLIC/deferred, not silently reclassified. Four pre-existing test files (`test_m22_2_roles_sessions.py`, `test_m21_file_store_isolation.py`, `test_multi_client_runtime.py`, `test_multi_user_isolation.py`) gained only `edge.reset_rate_limiters()` calls in `setUp`/`tearDown` — necessary fixture isolation against the new rate limiter, no assertion was weakened. **Scope note (flagged at verification):** the same commit also carries `uri_ui/` changes (M22.3's own ADMIN-gating UI courtesy in `connections_screen.dart`, correctly backed by real server-side enforcement rather than substituting for it, plus previously-pending M22.2 UI-parity work — role/tier display, device/session management, model status, memory category picker — and Flutter Windows desktop platform scaffolding) that exceed the M22.3 plan's original "`uri_ui/` — no UI code changes" boundary (§9) and its "zero diff" acceptance criterion (§18.10). All of it is covered by `uri_ui/test/m22_ui_parity_test.dart` and verified against the real `/auth/me` response shape; nothing insecure was found, but it is documented here as delivered scope broader than originally planned rather than silently absorbed into "M22.3 had zero UI diff." | **Operational consequence, not yet surfaced elsewhere:** `scripts/uri_server_ctl.ps1` (the persistent Task Scheduler launcher) invokes `run_uri_server.py` with no `--host` flag, so it now inherits the new loopback-only default — any existing LAN/phone access to a running persistent server instance stops working on next restart unless `--allow-insecure-bind`/TLS is explicitly configured. This is the plan's own accepted Decision 2 consequence (§19.1), not a defect, but had no tracker-visible callout before this entry. **Next: M22.4 CapabilityResolver/per-user capability grants.** M22.5 provider/secrets, Developer Mode, and the five deferred diagnostic-GET endpoints (Decision 1) remain deferred. |
| M22.4 | CapabilityResolver and per-user capability grants | **DONE, VERIFIED** | `ddbbb5e` | **Independently verified by Claude Code (third-layer review) 11 Sep 2026: 26/26 milestone tests passing, 106/106 Flutter tests passing, 1,241/1,241 Python regression tests passing. `orchestrator.py` maintained under line limit (5,461 lines). Authoritative check in `ApprovalGate.execute_tool`, end-to-end `PrincipalContext` propagation, anonymous caller fail-closed.** Plan: `docs/plans/M22.4_CAPABILITY_RESOLVER_PLAN.md`. | Introduces `CapabilityResolver` computing intersection of global registry and per-user grants; adds admin endpoints (`GET /admin/users`, `GET/PUT /admin/users/{user_id}/grants`) with mandatory audit trail; adds Flutter UI `AdminGrantsScreen`. | Superseded as baseline by M22.5. |
| M22.5 | Model provider registry, encrypted keys, and provider UI | **DONE, VERIFIED** | `69c8df3` | **Independently verified by Claude Code (third-layer review) 11 Sep 2026: 1,318/1,318 Python tests passing (0 skipped, 0 failures), 111/111 Flutter tests passing, `flutter analyze` clean (0 errors, 0 warnings). 6/6 key durability and security invariants verified from live storage behavior (Fernet + PBKDF2-HMAC-SHA256, write-only/no read-back, zero plaintext leakage). `orchestrator.py` untouched (5,461 lines).** Plan: `docs/plans/M22.5_PROVIDER_REGISTRY_PLAN.md`. | Introduces static `PROVIDER_CATALOGUE` with `ConfidenceValue` labeling, `ProviderKeyStore` with encrypted-at-rest keys via Fernet/PBKDF2-HMAC-SHA256 from `URI_PROVIDER_KEY_SECRET`, `ProviderConfigStore` for per-user base_url/model overrides, `OpenAICompatibleProvider` with `ProviderAuthenticationError` fail-closed semantics, USER endpoints (`GET /providers`, `POST /providers/keys`, `PUT /providers/config`), and Flutter `ProvidersScreen` with masked password inputs. Removes superseded legacy files (`hermes_service.py`, `semantic_interpreter.py`, `test_semantic_interpreter.py`, `test_credential_hygiene.py`). | Next: M22.6 model router and runtime provider selection. |
| M22.6 | ModelRouter, health-tracked fallback, and per-user principal threading | **DONE, VERIFIED** | `5b97e12` | **Independently verified by Claude Code across two remediation rounds (11 Sep 2026): 1,385/1,385 Python tests passing at final release, reproduced from scratch. `orchestrator.py` line-count invariant held (5,460 lines).** Plan: `docs/plans/M22.6_MODEL_ROUTER_PLAN.md`, state/evidence: `docs/plans/M22.6_STATE.md`. | Introduces `ModelRouter`/`ProviderHealthTracker` with health-cooldown fallback and a reserved (always-pass) budget pre-flight seam for M22.7; migrates all four M21 leaf modules from construction-time provider caching to per-call router resolution; threads the real per-user `PrincipalContext` through every production call chain, including office-noting/office-order drafting (found broken across two independent verification passes before being genuinely fixed). `ProviderAuthenticationError` always propagates uncaught. | Next: M22.7 usage metering and pre-flight budget enforcement. |
| M22.7 | Usage metering, budgets, and pre-flight ceiling enforcement | **DONE, VERIFIED** | *pending commit* | **Independently verified by Claude Code 11 Sep 2026: all 11 acceptance criteria traced directly against source and real test output (not reports). Targeted suite 91/91 passing. Full regression suite 1,433/1,433 Python tests passing, 29 subtests passing, 0 failures, reproduced from scratch after a bounded fix.** Plan: `docs/plans/M22.7_USAGE_METERING_PLAN.md`, state/evidence: `docs/plans/M22.7_STATE.md`. | Implements `ModelRouter._budget_ok()` as a real deterministic pre-flight monthly-token-ceiling check (`UsageCeilingStore`, default unlimited — zero behavior change until a User opts in); `UsageMeter` appends one observational `UsageRecord` per real `attempt()` outcome (never on auth failure) to a per-user monthly JSONL, with Windows-safe cross-process/cross-thread append locking; `usage_aggregator.aggregate_month()` folds it into a dashboard with zero model calls (AST-boundary enforced); `GET /usage`, `GET/PUT /usage/limits` (USER-tier, same-user-only, verified against an attempted cross-user impersonation). No prompt/response content is ever stored — verified against real serialized bytes, not just schema. Claude additionally found, root-caused, and fixed a pre-existing M22.6 test-isolation gap (a process-wide `ModelRouter` health cooldown leaking across test modules via `test_orchestrator_response_narrative.py`'s deliberately-broken-connectivity fixture) surfaced by this milestone's new tests but not caused by them. | Next: M22.8 — Modes and tiered UX (depends on M22.4 + M22.7, both complete). |
| M22.8 | Modes and tiered UX (office/diagnostic/admin capability filtering, BASIC-tier plain-language provider view, ceiling-reached flow) | **DONE, VERIFIED** | `35ac98b` | **Independently verified by Claude Code 11 Sep 2026 (Claude also completed the implementation itself under explicit one-instance User authorization after Codex exhausted its daily quota mid-implementation — see `docs/plans/M22.8_STATE.md` for the full defect list Claude found and fixed in the interrupted work). All 8 acceptance criteria traced against source. Full regression: 1,460/1,460 Python tests passing, 0 failures; Flutter: 0 analyze errors, 112/112 tests passing.** Plan: `docs/plans/M22.8_MODES_TIERED_UX_PLAN.md`, state/evidence: `docs/plans/M22.8_STATE.md`. | Adds `mode` (office/diagnostic/admin) as a real capability-filtering axis in `CapabilityResolver` (narrowing-only, `resolved = registry ∩ grants ∩ mode_allowlist`), self-scoped `GET/PUT /modes`; keeps `experience_tier` strictly presentation-only (verified never consulted by the new authorization logic); Flutter mode picker, BASIC-tier provider subtitle, ceiling-reached banner. | This is the recorded exception to standing AO-4 role separation for this one instance — see the M22.8 entry's own note; standing separation resumed with M22.9. |
| M22.9 | PWA/mobile client, branding, and durable session handling | **DONE — implementation-complete-pending-device-check** | `9c848fe` | **Independently self-audited by Claude Code 12 Sep 2026 (Claude implemented this milestone directly under explicit User authorization — Codex quota-exhausted and no Antigravity/Codex/Gemma session reachable from this Claude Code session; see `docs/plans/M22.9_STATE.md` for the full account, including a mid-implementation mistake caught by `flutter analyze` and corrected before commit). `flutter analyze`: 0 errors. `flutter test`: 118/118 passing (112 baseline + 6 new). APK built (`flutter build apk --debug`); static secret-scan of the built APK's assets: PASS, zero key-shaped literals. `git status`/`git diff` confirm zero `uri_core/` files touched.** Plan: `docs/plans/M22.9_PWA_MOBILE_CLIENT_PLAN.md`, state/evidence: `docs/plans/M22.9_STATE.md`. | Placeholder `applicationId` (`com.uriagent.dev`, explicitly non-publish-ready) and text-only "URI — AI COMPANION" wordmark (both User-resolved at ACCEPT, since neither is Claude's to invent); neutral placeholder launcher/web icons (no longer Flutter's default); proactive client-side session-expiry detection (`SessionStore`, `UriClient.validateSession()`) with an honest degrade-to-signed-out path — no server-side token refresh exists, so this stays detection-only, never invented refresh, per §5.3. | **Acceptance criterion 4 (a physical/emulator device sign-in walkthrough) is outstanding** — it requires the User's own hands-on confirmation and cannot be performed from a terminal session; this milestone is not claimed fully `VERIFIED` until that happens. This is also the second recorded instance of the Claude-implements-directly exception (see M22.9_STATE.md's own history log) — standing role separation resumed for M23. |

| M23 | URI-native Graph Intelligence foundation (structured entities, typed relationships, bounded query/path/explain/impact primitives, provenance) | **DONE, VERIFIED** | `dfee5a8` | **Independently self-audited by Claude Code 12 Sep 2026 (Claude implemented this milestone directly under explicit User authorization — no Antigravity/Codex/Gemma session reachable; see `docs/plans/M23_STATE.md` for the full account, including two design mistakes and one standing "orchestrator.py must never grow" rule violation this same session found and corrected before commit). Full regression: 1,401/1,401 tests run, the same single pre-existing, unrelated failure as the pre-M23 baseline (independently confirmed via `git stash` bisection), zero new failures — 91 net new tests (75 across 8 new graph-specific test files). `wc -l uri_core/core/orchestrator.py`: 5,460 before and after — exactly flat. `flutter analyze`/`flutter test`: zero diff (no `uri_ui/` file touched).** Plan: `docs/plans/M23_GRAPH_INTELLIGENCE_PLAN.md`, state/evidence: `docs/plans/M23_STATE.md`. | New per-user SQLite-backed `GraphStore` (nodes/edges, provenance, dedup, extensible type registry), bounded read-only traversal primitives (`graph_get_entity`/`graph_query`/`graph_neighbors`/`graph_path`/`graph_explain`/`graph_impact`), narrow deterministic ingestion from existing `VERIFIED` facts and consent-eligible memory only (no bulk extraction, no Gmail/Drive), one new optional `graph_context` section in `query_context.py` — proven, not merely documented, to be non-authoritative (new AST import-boundary test). Explicitly **M23**, not "M22.10" — see plan §0 for why that number stays reserved for the separate, still-unbuilt `M22_MEMORY_CONTEXT_RETRIEVAL_ARCHITECTURE.md` proposal. | Automatic entity extraction, entity resolution, contradiction detection, vector/embedding retrieval, Gmail/Drive ingestion, knowledge visualization, MCP exposure, and any write route exposed to a client are all explicitly deferred (plan §14/§19) — the design does not block any of them. `Fact.verify()`/`fact_manager.update_evidence_fact()` have no live caller in the current runtime, so `ingest_fact()`'s wiring is correct but currently dormant in production use — a pre-existing gap this milestone found and named, not caused or fixed (see M23_STATE.md). This is the third recorded instance of the Claude-implements-directly exception — standing role separation resumes for the next milestone. |
| M24–M33 | *(not backfilled into this table — see note above)* | — | — | Tracked in `docs/governance/URI_ACTIVE_MILESTONE.md` (the active per-milestone governance record from M30 onward: M30/M30.x, M31, M32, M33 planning). | — | M33 — External Capability Bridge and M33.1 — Real Integrations + Tools & Skills UI remain **NOT STARTED**; M32.1 — Execution Continuation Residual Hardening remains **NOT STARTED**. None block M34's closure below. |

**M33.1 closure correction, 2026-09-20:** the M24–M33 row above and prior
Batch-specific text are preserved as history. M33.1 is now **CLOSED / ACCEPTED**:
Batch 1 (`d78366d`/`0558a99`), Batch 2 (`dd4863a`), Batch 3 (`0fcdf29`), and
Batch 4 closure are all accepted. The final independent review recorded 35/35
isolated Batch 2–4 lifecycle/live tests passing, with the full-regression
classification and residual environment nondeterminism in the authoritative
plan §13.H. Firecrawl remains optional future Connected-Service work, not an
M33.1 closure requirement.
M33.2 Batch B.2 is **CLOSED / ACCEPTED** for Edge Perception Qualification
(Claude independent audit, 2026-09-20); Batch B.3 (Local Model Runtime &
Installation Lifecycle) is **ACCEPTED, planning-only**, awaiting
Antigravity-routed implementation, per a narrow, User-authorized amendment
to the canonical architecture's §13 runtime-installation exclusion. M33.3
is reserved for Unified URI Interaction & Capability UI; M33.4 is reserved
for Knowledge Fabric / Sources / Watches. No B.2 perception candidate is
promoted; no B.3 code has been implemented.

---

## Development Operations & Orchestration Milestones (AO Series)

| Milestone ID | Milestone Name | Status | Commit Hash | Verification / Test Status | Purpose (short) | Major Deferred Items |
|---|---|---|---|---|---|---|
| AO-1 | Multi-Agent Operating Architecture | DONE, VERIFIED | *Pending commit* | Verified against repository governance; authored `ORCHESTRATION.md` establishing roles, 12-step lifecycle, and 9-level document precedence hierarchy. | Establishes multi-agent development workflow separating User, Antigravity, Claude Code, Codex, and local review. | Local coordinator qualification deferred to AO-2. |
| AO-2 | Activate Qwen Coordination Loop | DONE, VERIFIED | *Pending commit* | Formally qualified via 8-part practical URI benchmark (score 4.55/5.0). Canonical contracts updated across `ORCHESTRATION.md`, `AGENTS.md`, `PROJECT_MEMORY.md`, `ARCHITECTURE.md`. | Activates Qwen 3 14B (Ollama) as canonical day-to-day coordinator (reasoning layer) and Antigravity as deterministic control surface. Defines 12-state model, structured input/output contracts, and negative-constraint injection mitigation. | Superseded by AO-4 (Qwen demoted to reserve/fallback). Automated CLI/driver hook remains deferred to AO-3 (not yet defined). |
| AO-4 | Claude-planned / Gemma-implemented / Antigravity-audited cycle | **DONE, VERIFIED** | *this commit* | User-directed workflow specification, incorporated into `ORCHESTRATION.md` §1, `AGENTS.md`, and `PROJECT_MEMORY.md` in this same commit. | Replaces AO-2's Qwen-coordinator loop with a fixed 7-step cycle: Claude plans each milestone from verified state → User accepts/modifies → Gemma 4 12B implements the accepted scope (backend + UI when required) → Antigravity independently audits the actual implementation and applies bounded fixes → Claude independently verifies → release (commit/push) only after Claude's `VERIFIED` → Claude drafts the next milestone's fresh plan. Adds a persistent, resumable state vocabulary (`DRAFT` … `COMPLETE`, plus `BLOCKED`/`WORKER_FAILED`/`WAITING_FOR_*`/`READY_TO_RESUME`) and explicit continuity rules so agent unavailability or quota exhaustion never causes a silent role substitution. Requires an explicit `UI IMPACT: NONE`/`REQUIRED` declaration on every milestone plan. Qwen 3 14B and Codex (CLI) move to explicit, User-invoked reserve/fallback only — never a default coordination step. | AO-3 remains a reserved, not-yet-defined number (an earlier AO-2-era note referenced it for a future "automated CLI/driver hook"); this document intentionally used AO-4 rather than collide with that reservation. |

---

## Verification method (for future updates)

1. Confirm working tree is clean and on the intended commit: `git status --short`, `git log -1 --format=%h`.
2. Identify the test files touched by the milestone's commit(s): `git show --stat <hash>`.
3. Run them directly with the repo's venv (tests use stdlib `unittest`, not pytest — pytest is not installed in `.venv`):
   `.venv/Scripts/python.exe -m unittest <test_module_1> <test_module_2> ... -v`
4. Record the pass count and date in the Verification column. Do not mark a milestone "verified" from commit-message claims alone.
