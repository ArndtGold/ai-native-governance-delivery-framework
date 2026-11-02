# TP: Reliable Codex MCP inspection — final native qualification

Status: draft
Gate: TP
Gate approval: open
Based on: SD
Date: 2026-10-25
Owner: Arndt Gold
Traceability contract: criteria-chain-v1
Planning Decisions contract: tp-decisions-v1

This plan derives from exact approved PRD sha256:bbfa5c7931f9b6617489d90c4ec4bc26a85c3bd5fd5b6b3239c5152a259249c0 and SD sha256:76847b3b3dc81bc8250b2c11a5b86b1e711a7a6d40ee5df76477b970e631acb6. The retained post-UR Brownfield Review is sha256:9f9c261dd8db0c9dca12cb119538eea8c9b3fb158dcfacb338914f2d2f8e5118. The deliberately confirmed TP source revision f2e43645-4e34-46bd-adbf-1ca5039b3783 was applied at Run revision 22. UR, PRD, SD and the exact current post-UR analysis remain retained; prior TP-bound preparation/quality fulfillment is reassessed. Acceptance remains solely in PRD.

The original two real sessions are consumed and immutable. They ran before the paired-target guidance correction: session 1 completed the intended UR approval with five MCP calls and one SDK rejection (target_source without primary_target); session 2 used four calls and zero errors. Both original/strict T7 predicates passed, but the separate PRD call/error criterion passed only 1/2. Their broad complete:true observations are not rewritten. The corrected current candidate has zero native sessions. This plan proposes exactly two additional fresh sessions, in one new cohort, only after a NEW deliberate Approval: TP. Authoring/recording/presentation launches no model and grants no execution approval.

Aliases are explicit planning inputs, never target or Run-selection authority:

- ROOT: /Users/arndtgold/Documents/GitHub/ai-native-governance-delivery-framework
- RUN: mcp-codex-guided-inspection-20261025-01
- RUN_DIR: ROOT/.agdf/control/artefacts/mcp-codex-guided-inspection-20261025-01
- E: RUN_DIR/evidence; P: E/pair-guidance; V: RUN_DIR/validation
- CANDIDATE: /private/tmp/agdf-guided-implementation-5cu6sw88/candidate
- NODE: /usr/local/Cellar/node@22/22.22.3/bin/node
- CODEX: /Users/arndtgold/.npm-global/bin/codex
- W: CANDIDATE/qualification-wrapper/pair-guidance-01 (new, not yet created)
- Q: E/qualification/pair-guidance-01 (new, not yet created)
- Prior consumed cohort: CANDIDATE/qualification-wrapper/renewed/ledger.json and E/qualification/renewed/native-summary.json; never reset, overwrite or reinterpret these slots.

All test/build routes use CANDIDATE and Node 22.22.3 first in child PATH. No global PATH, configuration, plugin, installed runtime or credential is changed. W and Q were absent during preparation; T-BASE must recheck that absence and the spent old ledger before creating new owned paths.

## 1. Task List

| task_id | Task | Owner | Dependencies |
|---|---|---|---|
| T-BASE | Fresh implementation-preparation Brownfield Analysis for this approved TP; verify current source/assembly/SDK/host bindings, baseline and protected data; produce new exact applicability assessment. | Codex using brownfield-analysis | NEW deliberate Approval: TP and canonical continuation |
| T-RET | Reverify selected retained prestudy, both original consumed sessions/ledger and all setup/guard failures; preserve original/copy hashes and label source cohorts. | Codex | T-BASE |
| T-CORE | Reassess the current two-owner Core implementation and explicit paired-target descriptions against exact current source; no new product or harness modification is planned. | Codex | T-BASE, T-RET |
| T-NAV | Reassess current pair-cli/protocol returned-call, scope, historical/current, refusal and advisory-failure evidence; rerun affected cases only if applicability fails. | Codex | T-CORE |
| T-SCHEMA | Reassess current 247,003 SDK comparisons, 160 frozen Core outcomes and original 24-input/15-error replay without redefining the baseline. | Codex | T-BASE, T-CORE |
| T-RENDER | Reassess the actual CLI 0.163.0 capture showing all fields/operations and paired comments; new loopback-only capture only if an input changes. | Codex | T-CORE, T-SCHEMA |
| T-GUARD | Reassess unchanged guard/entry/test fingerprints and actual OS mock/control/deadline cases in guard-integration-03; preserve the one-controller/one-profile boundary. | Codex | T-BASE, T-RET |
| T-BUILD | Reassess current normal build, source/assembly/profile/budget/performance and applicable complete SDK/Core suites. Prepare only contained new freeze/launcher/evidence paths and verify actual loaded source. | Codex | T-NAV, T-SCHEMA, T-RENDER, T-GUARD |
| T-NATIVE | Fresh final-source guarded zero-model preflight; reserve exactly two additional slots and launch one unchanged normal two-repetition T7 cohort; retain complete original evidence and all outcomes. | Codex | T-BUILD pass; guard/account/host/source prerequisites pass |
| T-REVIEW | Record actual CD+Tests; obtain current TP Review, Clean Implementation Review, Code Review and sole QA assessment through existing owners. | Existing AGDF review/QA owners | T-NATIVE or explicit preserved evidence gap; no fabricated success |
| T-CLOSE | Reconcile exact scope, foreign data, four-slot Run accounting and qualification limits for QA/handoff; present only the canonically ready human decision. | Codex and gate-check | Current evidence/review stage; later QA/UAT/OR follow their own approvals |

T-BASE through T-NATIVE are this renewal's implementation/evidence obligations. T-REVIEW/T-CLOSE are phase-bound lifecycle obligations: record completed review/reconciliation work honestly, keep later human decisions pending, and never claim future QA/UAT/OR already approved.

## 2. Verification Traceability

| criterion_id | design_decision_id | task_id | scenario_id | expected_result | evidence |
|---|---|---|---|---|---|
| AC-001 | SDD-001 | T-CORE | SCN-CONTRACT-VISIBILITY | Published field/operation inventory and meaningful selector guidance remain complete under the equivalent canonical projection. | P/checks/candidate-definition.json; E/checks/pair-cli-01.log; P/renderer/capture/signature.ts |
| AC-001 | SDD-006 | T-RENDER | SCN-HOST-TYPES | Actual installed Codex argument declaration contains all 14 fields and 11 operations without unknown intersections hiding them. | P/renderer/capture/signature.ts, requests.json and visibility.json |
| AC-002 | SDD-001 | T-SCHEMA | SCN-ACCEPTANCE | 247,003 matrix cases have zero SDK acceptance differences against the verified original schema. | P/checks/schema-parity.json; E/checks/pair-schema-01.log |
| AC-002 | SDD-006 | T-SCHEMA | SCN-CORE-REPLAY | The 160 accepted matrix cases preserve frozen Core outcomes; all 15 retained original SDK-invalid calls stay rejected and replay acceptance is unchanged. | E/baseline/core-expectations.json; P/checks/replay.json; pair-schema-01.log |
| AC-003 | SDD-002 | T-NAV | SCN-NAV-VALID | Explicit normal context yields only complete SDK-valid inspect calls from canonical descriptor/catalog owners, in sequential order. | E/checks/navigation.json; E/checks/pair-protocol-01.log |
| AC-003 | SDD-003 | T-NAV | SCN-NAV-FAULT | Unbound or unavailable advisory context yields no actionable hints and does not create an alternative authority. | E/checks/navigation.json; E/checks/pair-protocol-01.log |
| AC-003 | SDD-004 | T-NAV | SCN-NAV-PRECEDENCE | Catalog filter/completeness are visible; a valid exact known binding remains readable even when broader discovery is ambiguous, without substitution by a current-gate hint. | E/checks/navigation.json; E/checks/pair-protocol-01.log |
| AC-004 | SDD-004 | T-NAV | SCN-DOC-BINDINGS | Document arguments retain original revision while operation-contract arguments use current revision; ambiguous/invalid data creates no replacement presentation. | E/checks/historical.json; E/checks/pair-protocol-01.log |
| AC-004 | SDD-006 | T-NAV | SCN-DOC-STDIO | Actual SDK/STDIO document retrieval preserves bytes, order, cursor namespace and existing multipage behavior; invalid cursor/binding is rejected. | E/checks/mcp-server-01.log and run-command-flow-01.log; pair-protocol-01.log |
| AC-004 | SDD-008 | T-NAV | SCN-APPROVAL-REFUSAL | Stale revision and historical/foreign presentation approvals are rejected without approval or revision mutation. | E/checks/historical.json; run-command-flow-01.log; pair-protocol-01.log |
| AC-005 | SDD-006 | T-NATIVE | SCN-NATIVE-T7 | Both planned final-candidate sessions satisfy original and unchanged strict T7 predicates, with at most 4 MCP calls and zero SDK/other errors each. | Q/native/session-01 and session-02, original traces and Q/native-summary.json |
| AC-005 | SDD-008 | T-NATIVE | SCN-NATIVE-GUARD | Every executed session has the approved model/effort, complete trace, unchanged protected settings and no forbidden detour; original ROOT is write-protected during the cohort. | Q/native/controller/combined.sb, guard-controls.json, snapshots; Q/native/ledger.json and launches |
| AC-006 | SDD-007 | T-BUILD | SCN-BUDGET-LATENCY | Normal generated artifacts satisfy all unchanged size ceilings; the original fixed-fixture performance suite passes its existing metrics and thresholds. | P/checks/budget.json and performance.json; E/checks/pair-copilot-01.log and pair-performance-01.log |
| AC-007 | SDD-003 | T-NAV | SCN-LEGACY-FAULT | Injected advisory-only failure leaves the original valid/blocked report and presentation unchanged; original evaluator failure still fails. | E/checks/pair-cli-01.log and pair-protocol-01.log; retained exact-parity assertions |
| AC-007 | SDD-006 | T-BUILD | SCN-PROTOCOL-REGRESSION | Existing CLI/read-only/preview and modern/legacy MCP protocol suites pass without skipped or weakened behavioral assertions. | E/checks/pair-cli-01.log, pair-protocol-01.log and applicable complete mcp-server-01.log |
| AC-007 | SDD-008 | T-BUILD | SCN-WRITER-RECOVERY | Existing command, receipt, refusal and uncertainty/recovery tests pass; no writer or approval behavior is changed. | E/checks/run-command-flow-01.log and mcp-server-01.log; unchanged writer/recovery hashes |
| AC-008 | SDD-005 | T-RET | SCN-RETENTION | All selected original observations and manifests match their original bytes; positive and negative cohorts remain separately labeled. | E/prestudy/retention-index.json and original manifests; Q/retention-verification.json |
| AC-008 | SDD-006 | T-BUILD | SCN-CANDIDATE-PROVENANCE | CLI/tests and assembled MCP payload load the reviewed candidate Core files, not a stale copied workspace package. | P/build/source-bindings.json; Q/final-bindings.json, frozen-candidate.json and fresh preflight |
| AC-008 | SDD-007 | T-BUILD | SCN-DERIVED-SOURCE | Canonical generation/assembly/profile outputs map to the exact reviewed source; any deterministic compatibility refresh preserves historical inputs. | P/build/derived-review.json, final-source-scope.json; E/checks/pair-normal-build-01.log |
| AC-008 | SDD-008 | T-CLOSE | SCN-SCOPE-PRESERVATION | Original Git entries, foreign files, protected settings and prior Run bytes are preserved; only reviewed product/test/derived paths and this Run's authorized control/evidence change. | E/baseline/preservation.json; Q/native/controller/root-before.json and root-after.json; Q/final-scope.json |
| AC-005 | SDD-009 | T-GUARD | SCN-GUARD-INHERITANCE | One OS application covers setup, MCP and both mock Codex descendants; Root/config existing-file append opens and all settings replacement probes fail, owned candidate/temp writes succeed. | E/checks/guard-integration-03.log; unchanged guard/test hashes; Q/preflight/controller/guard-controls.json |
| AC-005 | SDD-009 | T-GUARD | SCN-GUARD-FAIL-CLOSED | Direct unguarded worker, flag-only, wrong binding/digest and failed controls stop before account/MCP/model; guard application is distinct from executed auth failure. | E/checks/guard-integration-03.log: direct flag, tamper, weaker profile, positive-control and application cases |
| AC-008 | SDD-009 | T-GUARD | SCN-GUARD-DEADLINE | A short fixture deadline covers setup/model/teardown and kills only the owned process group; an unrelated sentinel survives; no real model. | E/checks/guard-integration-03.log: setup/worker/teardown deadlines and unrelated sentinel; Q lifecycle result |
| AC-008 | SDD-009 | T-NATIVE | SCN-GUARD-PREFLIGHT | Fresh final-source guarded preflight verifies actual controls, account/host and unchanged task/audit with zero model calls; old failures remain intact and do not independently determine readiness. | Q/preflight original observation, controller policy/controls/snapshots and Q/preflight-summary.json |

## 3. Test Plan

| criterion_id | scenario_id | test_route | environment | prerequisites_permissions | owner | expected_evidence | unavailable_action |
|---|---|---|---|---|---|---|---|
| AC-001 | SCN-CONTRACT-VISIBILITY | R-CLI: assess pair-cli-01 and actual current definition | Isolated candidate, Node 22.22.3 | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | P/checks/candidate-definition.json; E/checks/pair-cli-01.log; P/renderer/capture/signature.ts | Fix only the scoped source/setup or report a blocker; no reduced field inventory |
| AC-001 | SCN-HOST-TYPES | R-RENDER: assess pair-renderer-01; fresh loopback-only capture if host/definition changes | darwin x64; installed CLI 0.163.0; loopback only | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | P/renderer/capture/signature.ts, requests.json and visibility.json | Stop this obligation if the approved host/guard is unavailable; no guessed rendering success |
| AC-002 | SCN-ACCEPTANCE | R-SCHEMA: assess pair-schema-01; unchanged comparator on a new evidence tree if needed | Node 22.22.3; actual SDK 2.0.0 validator | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | P/checks/schema-parity.json; E/checks/pair-schema-01.log | Resolve the concrete mismatch; never redefine the baseline or relax the comparator |
| AC-002 | SCN-CORE-REPLAY | R-SCHEMA: same 160 frozen Core outcomes and 24 original inputs/15 rejections | Isolated candidate and retained source-bound inputs | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/baseline/core-expectations.json; P/checks/replay.json; pair-schema-01.log | Keep a missing/mismatching input as an evidence gap; no reconstruction by native rerun |
| AC-003 | SCN-NAV-VALID | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Actual modern/legacy SDK/STDIO fixture | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/navigation.json; E/checks/pair-protocol-01.log | Stop on invalid hint; repair its existing owner without bypassing SDK validation |
| AC-003 | SCN-NAV-FAULT | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Isolated deterministic fixtures | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/navigation.json; E/checks/pair-protocol-01.log | Block implementation qualification if optional observation breaks a valid read |
| AC-003 | SCN-NAV-PRECEDENCE | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Isolated current/historical fixtures | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/navigation.json; E/checks/pair-protocol-01.log | Correct the advisory boundary; do not infer a substitute document or new product rule |
| AC-004 | SCN-DOC-BINDINGS | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Isolated actual MCP runtime | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/historical.json; E/checks/pair-protocol-01.log | Preserve the failure and return to the design owner if revision meaning conflicts |
| AC-004 | SCN-DOC-STDIO | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Actual SDK/STDIO and existing multipage fixtures | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/mcp-server-01.log and run-command-flow-01.log; pair-protocol-01.log | Keep the obligation open; no short document substituted for required multipage proof |
| AC-004 | SCN-APPROVAL-REFUSAL | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Synthetic Runs only | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/historical.json; run-command-flow-01.log; pair-protocol-01.log | Stop if any unintended approval occurs; preserve trace and inspect the existing owner |
| AC-005 | SCN-NATIVE-T7 | R-NATIVE: one newly authorized two-repetition cohort defined below | macOS darwin x64, CLI 0.163.0, gpt-6.1-sol/low | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | Q/native/session-01 and session-02, original traces and Q/native-summary.json | Retain any failure; no third/additional/replacement session, resume or changed predicate |
| AC-005 | SCN-NATIVE-GUARD | R-NATIVE: existing one-profile controller, real controls and before/after comparison | Same native cohort | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | Q/native/controller/combined.sb, guard-controls.json, snapshots; Q/native/ledger.json and launches | Stop on unavailable guard or infrastructure violation; do not launch a replacement session |
| AC-006 | SCN-BUDGET-LATENCY | R-BUILD/BUDGET: assess current canonical build/profile and original fixed performance | Isolated fixed fixtures, no concurrent heavy tests | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | P/checks/budget.json and performance.json; E/checks/pair-copilot-01.log and pair-performance-01.log | Keep a size/timing failure visible; no threshold change, required-file exclusion or repeated sampling to select a pass |
| AC-007 | SCN-LEGACY-FAULT | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Existing test seams and actual read path | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/pair-cli-01.log and pair-protocol-01.log; retained exact-parity assertions | Repair failure isolation within SD; do not swallow the original failure |
| AC-007 | SCN-PROTOCOL-REGRESSION | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Existing registered suites, both supported protocol versions | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/pair-cli-01.log, pair-protocol-01.log and applicable complete mcp-server-01.log | Diagnose the failing case; no skipped test or weaker behavioral assertion |
| AC-007 | SCN-WRITER-RECOVERY | R-REGRESSION: assess current pair-cli/protocol and applicable full MCP/Core logs; rerun affected registered route only | Existing synthetic command/uncertainty fixtures | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/run-command-flow-01.log and mcp-server-01.log; unchanged writer/recovery hashes | Stop at the existing recovery owner if effects are uncertain; no speculative replay |
| AC-008 | SCN-RETENTION | R-RET: hash original and retained selected bytes; never rerun completed cases | Read-only original study directories | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/prestudy/retention-index.json and original manifests; Q/retention-verification.json | Missing/corrupt source is a blocker; never edit or recreate the original observation |
| AC-008 | SCN-CANDIDATE-PROVENANCE | R-BIND: actual Root/candidate/assembly/SDK/UI verification plus fresh guarded preflight | Isolated candidate and zero-model preflight | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | P/build/source-bindings.json; Q/final-bindings.json, frozen-candidate.json and fresh preflight | Fix a stale workspace resolution before qualification; no installed-runtime replacement |
| AC-008 | SCN-DERIVED-SOURCE | R-BUILD: assess pair-normal-build-01 and canonical compatibility/source closure | Candidate with canonical generated assets | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | P/build/derived-review.json, final-source-scope.json; E/checks/pair-normal-build-01.log | Preserve non-freshness failures as blockers; no automatic native evidence renewal |
| AC-008 | SCN-SCOPE-PRESERVATION | R-SCOPE: exact foreign/staging/settings/control/candidate comparisons before import | Original ROOT and isolated outputs | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/baseline/preservation.json; Q/native/controller/root-before.json and root-after.json; Q/final-scope.json | Preserve foreign changes; never reset/clean/restore them to make comparison pass |
| AC-005 | SCN-GUARD-INHERITANCE | R-GUARD: assess unchanged-source guard-integration-03; actual OS synthetic tests if needed | macOS, owned isolated Root/settings/fixtures | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/guard-integration-03.log; unchanged guard/test hashes; Q/preflight/controller/guard-controls.json | Stop if OS protection cannot be established; no mock result relabeled native |
| AC-005 | SCN-GUARD-FAIL-CLOSED | R-GUARD: same direct-worker/tamper/weak-profile/positive-control/application cases | Same synthetic fixtures | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/guard-integration-03.log: direct flag, tamper, weaker profile, positive-control and application cases | Fix guard owner or report blocker, no weaker fallback |
| AC-008 | SCN-GUARD-DEADLINE | R-GUARD: same setup/worker/teardown short deadlines with unrelated sentinel | Owned child process groups | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | E/checks/guard-integration-03.log: setup/worker/teardown deadlines and unrelated sentinel; Q lifecycle result | Stop if owned-tree termination cannot be proved; do not kill foreign processes |
| AC-008 | SCN-GUARD-PREFLIGHT | R-NATIVE --preflight-only: fresh exact-source integrated guarded preflight | Exact installed CLI/host/account and frozen candidate | New Approval: TP, fresh implementation preparation, exact source/evidence applicability; account/guard only for R-NATIVE | Codex | Q/preflight original observation, controller policy/controls/snapshots and Q/preflight-summary.json | Preserve failure and stop model-dependent work; scoped model-free correction/retest only |

### Current source bindings and execution boundary

Current product/test source is P/build/source-bindings.json, with exact loaded candidate Core and matching assembled Core. Bind and recheck these values in ROOT and CANDIDATE:

| Source | SHA-256 |
|---|---|
| packages/core/lib/control-inspect/contract.js | ef57f82385cd7ffb3805e8fb723318b874d62d8ec100308dd746a5dcdd2bb57e |
| packages/core/lib/control-inspect/service.js | 0e3e4557c0cabeee4706c6c6965ae356462c36d98df6e9b8807dbbe54ff05b2a |
| packages/cli/scripts/control-inspect-test.js | 1acb08aba3ccbbb16770e657e4c7ce53442f37b0baad723170d0a0c6f1644156 |
| packages/mcp-server/test/protocol.test.js | 16a2125d73b7a15b7d0ddf65057f3eb4fb28e6e8120fa70c9cfa2e0e6d3ab552 |
| scripts/native-probes/codex-host-e2e.mjs | 9ed63ea770cf9b92263389c984fd2a4fc542744584a00c195b4813ab749af001 |
| scripts/native-probes/lib/codex-command-guard.mjs | 947fc8568e3dc6b2f569613f255185031615c5b8280d96dddd39c16d113c4aec |
| scripts/native-probes/codex-command-task-test.mjs | 9bb38b89a60e696cbab733edcd3724e1f4ccd15dd8f369e90e3b1367d3ed9560 |
| evals/mcp-ergonomics/lib/native-run.js | 0241b7687a599cf64d646409466d6bcebdad0a08b51e0ebb1997d266edd67a1d |
| evals/mcp-ergonomics/lib/native-tasks.js | 1ed79fdfc59b6e67b6742e958a16a94a16dd06febcda2efb4f8d00b39c7bca84 |

The explicit target-field pairing adds one byte but no accepted input, selector, operation, task or validator rule. Keep all seven current product/test/guard files above unchanged in this qualification renewal. A source drift or newly found defect stops dependent qualification and returns to its existing owner; no repair or mixed source is allowed between repetitions. Unplanned product/harness/test/audit changes are not authorized by this TP. Run-local launcher/freeze/retention helpers may be adapted only for distinct paths, current bindings, applicability and faithful evidence/accounting; no new policy registry, outer sandbox or parser/predicate fork.

Baseline HEAD is 5046858826f3bca7922c14ef402b095feca8b6fb. Exact staged-entry SHA is 3e920896a1946dccf9df5fa9953e7b736f520508a4ee39c89080e12840ec16fb. Preserve all 14 known foreign staged files, five known foreign untracked files, 11,129 other-control files and any subsequently identified foreign work. Use git ls-files --stage -z, not raw index stat-cache bytes; do not stage/reset/clean/restore another owner's files. Original Root dist/dependency remnants stay untouched.

P/build/source-bindings.json binds actual SDK server/client 2.0.0 manifests, SDK runtime digest b863c5d6511cbdf1e29eddaf5e95e052b5f5c0d742d186f6665daaa9189994bb, lockfiles, current UI manifests/assets and unchanged original performance/baseline files. Verify actual resolved @agdf/core and assembled paths; version labels alone do not prove provenance.

### R-APPLICABILITY: required reassessment, not transferred fulfillment

After the NEW TP approval and fresh Brownfield Analysis, create Q/applicability.json. For every stable scenario, record exact retained file/log/metadata hashes, source/SDK/build/host inputs, coverage, current applicability, rationale and any fresh action. Prior source-revision archives remain historical. T-BASE must reassess current files against P/build/source-bindings.json, final-source-scope.json and derived-review.json rather than importing a pass label.

Current final-source evidence candidates are E/checks/pair-schema-01, pair-cli-01, pair-renderer-01, pair-protocol-01, pair-build-prepare-01, pair-compatibility-record-01, pair-normal-build-01, pair-source-bindings-01, pair-copilot-01 and pair-performance-01 (each JSON metadata and complete log), plus P/checks and P/renderer/capture. They cover the latest paired descriptions. The earlier full mcp-server-01 and run-command-flow-01 remain reusable only for reviewed unchanged subpaths; affected contract/render/protocol/build/budget/performance inputs were already rerun by the pair-* checks. Guard-integration-03 covers current guard/test source; current product guidance does not change that execution owner.

The current normal build passed, canonical compatibility evaluated 56 deterministic scenarios with zero unexpected failures, and historical/reported/native compatibility inputs were unchanged. Measured payload is Inspect 4,993 bytes and Copilot 397 files/3,509,461 bytes. The original fixed-fixture current performance passed once with 20 cold tools/list and 20 warm dispatch samples: p95 701.422/426.184 ms against 1,500/1,000 ms. These are retained measured results, not predicted fresh results. No unchanged repeat sampling merely to select a pass; rerun affected checks if inputs/failures/coverage actually require it.

Always fresh: selected-Run implementation preparation, current source/freeze/guard input, actual integrated preflight and both new native sessions. A former preflight, old-source success, synthetic mock or loopback renderer cannot fulfill these native obligations. The original two-session cohort remains qualified:false (PRD call/error acceptance 1/2); do not combine its one success with a new session.

### R-RET: immutable selected retention

Reverify all 626 entries in E/prestudy/retention-index.json against retained bytes and their explicit original sources; retain original manifests and the new selected index separately. Preserve projection-captures/supplement-index.json and its selected source relationships. Sources remain the original inspect-evaluation, inspect-agent-ab, inspect-projection studies and the two retained c2-native repetition input sets. No completed driver/case is rerun; no credential file/value or unrelated scratch tree is copied. Missing/corrupt evidence remains an explicit gap.

Verify E/qualification/renewed/native/session-01 and session-02 retention-manifest.json against both original observations/events/rollouts/effective-config/final-response bytes and the retained copies. Preserve original complete:true and strict results as their actual narrow outcomes; the separate PRD call/error result is decisive. Preserve all failed guard/setup/preflight observations and prior source-revision archives. New native evidence goes only under Q and W; no old file is cleaned or relabeled.

### R-SCHEMA, R-CLI, R-REGRESSION and R-RENDER

Assess current pair-schema-01: 247,003 SDK acceptance comparisons, 160 frozen Core outcomes and 24 original inputs with all 15 original SDK errors still rejected. Baseline schema raw SHA remains 38558b12d11eca3b1f7bf20f2d98097be6e62c9dfdb7deda2736b76442bbc4c4; baseline is never imported from the changed candidate. If genuinely needed, create Q/offline-evidence with exact hash-preserved baseline/baseline.json, baseline/core-expectations.json and prestudy/c2-native/repetition-01 and repetition-02 events/rollouts, then run the unchanged comparator with new output paths:

```text
NODE V/inspect-contract-checks.mjs --candidate CANDIDATE --evidence Q/offline-evidence
npm --prefix packages/cli run test:control-inspect
NODE packages/mcp-server/test/protocol.test.js
npm --prefix packages/cli run test:run-command-flow
npm --prefix packages/mcp-server test
```

Use only the affected routes after applicability assessment. No comparator/assertion/validator/task/audit change, skipped test or baseline redefinition. CLI and actual SDK/STDIO cases retain full report/presentation parity, current-gate scope, unique/ambiguous discovery, explicit known-binding precedence, original document/current contract revisions, stale/foreign refusal, cursor namespace/multipage checks, mutation snapshots and advisory-only versus evaluator failure.

Assess P/renderer/capture/signature.ts, requests.json, visibility.json and protocol.json against current definition/CLI. The actual declaration includes all 14 fields and 11 operations and both named pairing comments. If host/definition changes, run the existing model-free helper with a unique new output (for example Q/renderer-01):

```text
python3 V/codex-render-check.py --candidate CANDIDATE --output Q/renderer-01
```

This uses a deterministic loopback stub, fresh owned scratch CODEX_HOME, no account/API credential or real model, and denies external networking. Preserve request/IPC evidence; a string elsewhere in prose does not prove visible parameter types. Failure/unavailability is a concrete evidence gap, not permission to substitute structural or other-host claims.

### R-GUARD, R-BUILD, R-BIND and R-BUDGET

Reassess the exact current guard entry/helper/test fingerprints and full guard-integration-03 log. The existing registered test command, only if affected:

```text
NODE --test scripts/native-probes/codex-command-task-test.mjs
```

It uses owned synthetic Root/settings and mock hosts, verifies inherited Root/settings denial, allowed owned writes, direct flag/tamper/weaker-policy/positive-control/application failures before host use, and short setup/worker/teardown deadlines with an unrelated sentinel. Preserve all original two-fixture/account-home/API-exclusion assertions. Synthetic host exec counters are not real model invocations. Any unproved protection/lifecycle blocks native execution; no weaker fallback.

Current normal build/profile/provenance are reusable only after exact-input assessment. R-BIND rechecks actual ROOT/candidate source, canonical workspace Core resolution, assembled Core, SDK/locks, UI and profile inventory, then writes fresh Q/final-bindings.json and a full candidate manifest Q/frozen-candidate.json. Derive that manifest using canonical tracked files, current generated/runtime/dependency roots and the new guard helper; preserve symlink identities. Exclude only named owned qualification/probe outputs. Do not narrow the OS Root deny or use a source-free version label. Review any helper adaptation as output/binding-only; never overwrite old evidence.

If affected canonical routes need execution, use existing owners:

```text
npm run build:prepare
npm run build
npm --prefix packages/cli run test:copilot-profile
NODE scripts/payload-budget.js
NODE packages/mcp-server/test/performance.test.js
```

Only a diagnosed source_snapshot_changed permits build:prepare, compatibility:record, review of its new deterministic facts/content-addressed observation, compatibility:check and normal build again. Other freshness, evidence or historical-input errors remain blockers. Never overwrite historical observations, native sources, baseline/limit constants or foreign suffixed files. Root generated/dependency trees and installed runtimes are not repaired.

Limits remain Inspect 5,000; each command 8,192; five command and command/decision aggregate 24,576; input/output 65,536/1,048,576; Copilot 397 files/3,509,461 bytes. Existing measured command aggregate is 23,254 and command/decision aggregate 24,509. Keep all budget/profile checks active, never use --accept or remove required files. Copilot is currently exactly at its ceiling. The original fixed-performance route remains unmodified, 20 cold tools/list and 20 warm dispatch, p95 1,500/1,000 ms; run without concurrent heavy work only when justified by changed input/failure, never for favorable resampling.

### R-NATIVE: exactly two additional sessions, one new guarded cohort

The previous two real slots remain consumed. This NEW TP, after a new deliberate approval, permits at most two additional fresh sessions in one cohort under W, hence at most four real sessions in this Run across both explicitly approved cohorts. New local repetitions are still 1/2 as the unchanged harness expects; Run accounting links them to new global slots 3/4 without changing task/parser/audit semantics. Preserve every old ledger and event, even if a new cohort stops early. Never refill/reset a reserved slot or combine candidates.

Actual tuple: gpt-6.1-sol with Reasoning low, Codex CLI 0.163.0, Node 22.22.3, same darwin x64 OS 24.6.0 host, existing ChatGPT account. Reobserve actual host/model/effort; changed tuple is a stop. USD 0 additional API spend, no API/provider fallback, credential copy/login, usage reset, plugin install or protected global setting change. Preserve normal host-owned account/session persistence outside protected targets. No AGDF_AB_REPETITION, custom prompt, hidden retry/resume/replacement, other native task/mode, altered strict/original predicate or parser/audit.

Each model session retains 600,000 ms timeout; total new model allowance 1,200,000 ms. The unchanged controller enforces 1,500,000 ms for the whole setup/two-session/teardown window, reserving up to 5,000 ms inside it for forced termination/reap. Kill only owned worker/auxiliary process groups, not foreign processes. All child setup and teardown stay bounded. A normal task failure may be followed only by the other already planned repetition under unchanged original infrastructure semantics and the same frozen source. Infrastructure failure stops; missing second execution does not grant another cohort.

Only after TP approval and fresh implementation preparation, create a new bounded V/native-pair-cohort.py by reusing the previous Run launcher as subordinate input/result retention glue. It supplies W/Q/current metadata and exact frozen inputs to the existing T7 controller; it applies no sandbox and owns no independent policy/reservation. Adapt paths/prerequisite facts/accounting only, preserve real-session versus model-free labeling and original observations. Freeze its reviewed source/digest. Never execute/modify the spent old launcher ledger paths.

Q/final-bindings.json must bind the listed current sources plus unchanged task/audit/performance/baseline, actual assembly/SDK/UI, guard entry/helper/test, source revision, prior consumed ledger digest, new cohort identity/paths, Node/CLI/OS and launcher/snapshot method. Use fresh guard-input JSON under W with schema_version 1, canonical ROOT/candidate/existing personal CODEX_HOME, new output and W/ledger.json paths, exact source/assembly/candidate manifest, expected immutable-setting hashes and preflight reference. Those paths do not select an AGDF Run or grant human authority.

Start the unchanged T7 controller directly from CANDIDATE with child-only CODEX_BIN=CODEX, AGDF_T7_GUARD_INPUT pointing to the new bound input and Node first in child PATH. Remove API/provider overrides, AGDF_AB_REPETITION, NODE_TEST_CONTEXT, an inherited AGDF_T7_GUARD_WORKER and test-output redirections into Root. Do not add an outer sandbox or new allowlist. First run only:

```text
NODE scripts/native-probes/codex-host-e2e.mjs --command-task T7 --repetitions 2 --model gpt-6.1-sol --reasoning-effort low --preflight-only
```

Fresh preflight must prove current source/frozen manifest/policy binding, actual guarded-worker safe O_WRONLY|O_APPEND denial on existing Root/config without creation/truncation/data write, allowed owned temporary write/read/cleanup, actual host/account readiness and matching actual MCP discovery. Every immutable literal remains in the profile even if absent. One canonical macOS profile denies file-write* for the entire original ROOT subtree and the same config.toml, plugins/installed_plugins.json and plugins/known_marketplaces.json literals in existing personal CODEX_HOME; descendants inherit it. Direct flags alone never prove an active guard. Guard application/verification/account failures remain distinct. A preflight starts zero models and reserves zero slots; keep all outcomes and bounded model-free corrections, never a weaker fallback or deletion-based readiness.

Only a fresh successful matching preflight and unchanged final bindings permit the existing controller's exclusive write-ahead reservation of two new slots in W/ledger.json before one actual launch. Reusing an output/reservation, source/preflight drift or uncertain prior launch count blocks. Use exactly once without preflight-only:

```text
NODE scripts/native-probes/codex-host-e2e.mjs --command-task T7 --repetitions 2 --model gpt-6.1-sol --reasoning-effort low
```

The controller is the sole reservation/guard owner. Log reserved, attempted and executed separately; all model-related setup/MCP/Codex processes inherit its profile. Do not wrap the real cohort in the model-free run-check helper or record model_invocations:0 for it. Retain all controller/raw worker output outside Root under W throughout the protected comparison window. No selected-Run/control writes or evidence imports are made during that window.

After worker exit, compare original tracked/nonignored Root files plus complete control, exact staging/known foreign files/settings and the full frozen candidate before import. The OS denial always covers the entire Root, including ignored trees; bounded inventory does not weaken it. A mismatch is retained and reported without foreign repair/restore. Only after comparison retain exact originals under Q/native/session-01 and session-02, controller policy/controls/snapshots/lifecycle, new input, launch events/ledger, original events/rollouts/effective-config/final-response and raw hashes. Keep old Q namespaces and spent original results untouched.

For EACH of the two new final-source sessions require both original and strict predicates, exactly one intended fixture UR approval, trace complete, observed sole model/effort gpt-6.1-sol/low, no forbidden detour/shell, at most four MCP calls and zero SDK/invalid-argument/is-error/AGDF-failure results. Use existing parser/counters and faithful Run-level acceptance checks; do not change the original native observation when broad complete:true fails the separate call/error condition. No permission denial or incomplete error accounting can count as zero. Both must qualify on the same frozen source. Final preservation, policy/discovery/source and start-count checks are mandatory.

If either native result is failed/unavailable, source/guard/account/trace is uncertain, or the new allowance is spent without two successes, preserve evidence and stop at the existing owner. No third new session, substitute model, resume, changed prompt/predicate or automatic further TP renewal is authorized. This TP may not turn a failed result green or waive the PRD obligation.

### R-SCOPE, review and completion

Create Q/final-scope.json for actual authorized changed files, staged entries/foreign bytes, settings/control/candidate comparisons, prior and new ledger linkage, original/copy hashes and qualification limits. Preserve all earlier successful/failed evidence and completed studies; clean only newly owned transient fixtures through their existing lifecycle. No credential material or prior leftovers are handled.

Record actual CD+Tests with current-source applicability and actual native outcomes. Then current task-plan-review, clean-implementation-review and code-review provide their separate evidence dimensions; qa-gate alone decides pass/revise/block and cannot pass with missing native evidence or open applicable findings. Use normalized findings and the earliest existing owner where needed. Present only fresh canonically ready QA/UAT; later UAT/OR remain human-controlled. No commit/push/PR/merge/install/release/publication is authorized.

## Planning Decisions

| Decision | Source | Status | Resolution | Owner |
|---|---|---|---|---|
| Current task/scenario and retention mapping | SD: Detailed task/scenario mapping and retention inventory | resolved | All eleven stable tasks, 24 scenarios and exact current/past evidence routes remain mapped; Q/applicability.json rechecks current input/coverage and never transfers a pass label. Retain 626 prestudy entries, original two sessions and all failures. | Codex |
| Additional bounded final-candidate cohort | SD: Bounded real-agent execution plan | resolved | Confirmed TP-only source revision permits presenting a concrete renewal: exactly two additional new sessions only after NEW Approval: TP. Keep unchanged two-session cohort design, model/task/audit/guard, 600,000 ms each, 1,500,000 ms complete window and all restrictions. Old two slots stay spent; no mixed-candidate success transfer. | Codex |
| Current candidate and implementation scope | TP | resolved | Listed actual paired-guidance Core/guard/test hashes are fixed. This renewal performs applicability, contained helper binding/freeze and fresh qualification; no product/harness/test/audit changes are planned or authorized. Source drift routes to its owner. | Codex |
| New paths and one reservation owner | TP | resolved | W/Q are distinct absent new namespaces. Existing T7 entry owns one inherited policy and exclusive new ledger; Run launcher only supplies input/retains output. Link cohort-local 1/2 to Run slots 3/4 without rewriting old counts or native semantics. | Codex |
| Retained versus fresh obligations | TP | resolved | Exact current pair-* and unchanged guard/full-suite inputs may be reused after mandatory assessment. Fresh implementation preparation, full final binding/freeze, integrated preflight and both new native sessions are mandatory. No new model before TP approval. | Codex |
| Protection, error truth and stop rules | TP | resolved | Same complete Root and three-setting denial, real negative/positive controls and owned-tree deadline; original/strict success plus separate four-call/zero-error counters each session. Preserve broad original observations and true failures; no fallback/retry/resume/replacement. | Codex |
| Limits and account boundary | TP | resolved | Existing ChatGPT quota only, USD 0 extra API authority, same gpt-6.1-sol/low tuple, no login/auth copy/settings/install/reset. Every MCP/Copilot/performance ceiling unchanged; current Copilot payload equals its ceiling. | Codex |

No material product/design/planning question remains unresolved. Future host/account availability is an execution prerequisite with an explicit stop action, not consent to acquire access or waive proof. No Clarification Requests/Details sections apply. This resolved draft is still unapproved and non-authorizing until freshly presented and deliberately approved.

## 4. Brownfield Scope

Retain exact current post-UR Review; its writer-owned source is unchanged UR. Reperform TP-bound implementation-preparation Brownfield Analysis after the NEW TP approval because source revision clears its prior fulfillment. Inspect existing Core contract/service, target identity, command descriptors, presentation/approval/recovery owners, T7 controller/helper/test and canonical build/profile paths. Preserve their ownership; no UI/domain/state migration, transport policy, operation registry, async product authority or Context Graph node is introduced. Retained code/testing evidence is exact-source input for assessment, never an automatic implementation or native pass.

## 5. Out Of Scope

New product/harness/task/test/audit/parser/predicate changes, new tools/operations/selectors/state/UI, weaker validation or approval authority, concurrency architecture, additional real sessions beyond the new two, retries/resume/replacement or other model/host modes, credential/login/API/provider work, usage reset, global/plugin installation or upgrades, budget/baseline increases, old evidence/ledger rewriting, foreign-work cleanup and operative Git/release actions.

## 6. Risks And Blockers

- One original session needed an extra failed input call; clearer guidance is model-free verified but not yet proven by two final native sessions. Model variability remains; no success is promised or manufactured by further attempts.
- Current candidate has zero native sessions. Old-source 1/2 PRD acceptance and broad original/strict success cannot qualify it. A wrong tuple, extra/erroneous call, incomplete trace, forbidden detour or missing exact approval fails that session.
- Stale source/build/SDK/freeze, occupied new output/ledger, unclear launch count or protection/lifecycle failure blocks model start. Future account/quota loss stays unavailable evidence; no access acquisition or fallback.
- Copilot is exactly at 397 files/3,509,461 bytes. Any unauthorized growth or failing original performance/coverage check blocks quality; no limit adjustment, required-file removal or favorable resampling.
- Foreign/control/settings/candidate mismatches must stay visible and attributable. Do not restore or clean another owner's data to produce equality. Only new test-owned transient cleanup is allowed.
- Qualification is bounded to this exact normal T7 workflow/tuple; no other-host, human-viewing, installed-plugin, release or production claim follows. Missing evidence remains open and qa-gate retains sole decision authority.

## 7. Next Step

Review this renewed task and test plan and approve only with:

`Approval: TP`

The prior reply confirmed source-revision application; it does not approve this newly authored material. A new deliberate reply is required after its current canonical presentation. Then fresh implementation preparation, assessed model-free prerequisites, fresh guarded preflight and exactly the new two sessions may proceed through their existing owners. Stop at the next human gate or concrete blocker.

## AGDF Approval Summary (de; source=en)

- Ziel: Den korrigierten MCP-Kandidaten mit ausdrücklich sichtbarem Pflichtpaar target_source und primary_target abschließend mit echten Codex-Agenten qualifizieren. UR, PRD und SD bleiben unverändert freigegeben.
- Umfang und Stand: Der bisherige Schutzfehler ist behoben. Genau zwei frühere Sitzungen sind verbraucht und bleiben unverändert erhalten: einmal fünf Aufrufe mit einem SDK-Eingabefehler, einmal vier Aufrufe ohne Fehler. Die anschließende Eingabehilfe-Korrektur besteht die modellfreien Prüfungen, hat aber noch keine echte Kandidatenabnahme. Dieser Plan ändert keinen Produktcode, Harness, Prompt oder Prüfer; er bindet Nachweisbewertung, neue geschützte Ausgabepfade und Qualifikation.
- Echte Agenten: Genau zwei zusätzliche normale T7-Sitzungen in einem einzigen neuen Lauf am selben eingefrorenen Kandidaten, mit Codex CLI 0.163.0, gpt-6.1-sol und Reasoning low. Beide müssen ursprünglichen und strengen Prüfer bestehen, genau eine beabsichtigte UR-Freigabe erfassen, höchstens vier MCP-Aufrufe und null SDK- oder sonstige Fehler aufweisen. Alte Erfolge zählen nicht für den geänderten Kandidaten. Keine dritte neue Sitzung, Ersatzsitzung, kein Resume oder versteckter Wiederholungsversuch.
- Schutz, Zeit und Kosten: Der bestehende Test-Owner wendet genau eine geerbte macOS-Sandbox für Harness, MCP und Codex an; vollständiger Original-ROOT und dieselben drei globalen Einstellungsdateien bleiben gesperrt. Reale negative und positive Kontrollen sowie eine frische modellfreie Vorprüfung sind vor dem Start erforderlich. Zehn Minuten je Sitzung, zwanzig Minuten gesamte neue Modellzeit, fünfundzwanzig Minuten einschließlich Aufbau, Abbau und begrenztem Beenden ausschließlich eigener Prozesse. Nur bestehendes ChatGPT-Konto und Kontingent, keine zusätzlichen API-Ausgaben, Anmeldung, Zugangsdatenkopie, globale Änderung, Plugin-Installation oder Kontingent-Rücksetzung.
- Nachweise und Prüfungen: Alle elf bisherigen Aufgaben und 24 Szenarien bleiben zugeordnet. Nach erneuter Brownfield Analysis werden aktuelle Quellen, Pakete, SDK, Umgebung und Abdeckung geprüft. Bestandene 247.003 SDK-Vergleiche, 160 Core-Erwartungen, Fehlerwiedergabe, tatsächliche Typanzeige, Protokoll-, Build-, Profil-, Guard- und ursprüngliche Leistungstests dürfen nur nach genauer Gültigkeitsbewertung weiterverwendet werden; betroffene oder ungeklärte Prüfungen werden erneuert. Finale Bindung, Vorprüfung und beide echten Sitzungen sind zwingend frisch.
- Grenzen und Daten: Alle MCP-Limits und Copilot 397 Dateien/3.509.461 Byte bleiben unverändert; aktuell Inspect 4.993 Byte und Copilot exakt an seiner Grenze. Alte Reservierungen, Erfolge, Fehler, Originalspuren und frühere Runs bleiben erhalten. Die neue Reservierung trennt die zwei zusätzlichen Sitzungen von den zwei verbrauchten. Ergebnisse bleiben bis zum Vergleich von Originalbestand, Vormerkungen, Einstellungen und eingefrorenem Kandidaten außerhalb des Original-ROOT; fremde Dateien werden nicht bereinigt oder zurückgesetzt.
- Stoppregeln und nächster Schritt: Die Quellenrevision hat nur TP wieder geöffnet. Erst eine neue Approval: TP nach dieser Vorlage erlaubt Vorbereitung und die zwei zusätzlichen Sitzungen. Fehlende Schutz-, Quellen-, Konto-, Startzählungs- oder Trace-Nachweise sowie ein nicht bestandener Lauf bleiben offen; keine automatische Budgeterneuerung oder schwächere Abnahme. Danach folgen CD+Tests und TP-/Clean-/Code-Review; QA entscheidet allein pass, revise oder block. Spätere QA/UAT/OR-Entscheidungen sowie Git, Installation und Veröffentlichung werden hier nicht freigegeben.
