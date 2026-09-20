## Contracts and Runtime

- [x] Add monitoring contracts and export them from `kun/src/contracts/index.ts`.
- [x] Add SQLite repositories and authenticated engineering project/dataset/run routes.
- [x] Implement CSV/XLSX normalization, mapping, quality findings, deterministic analysis, and citation/manifest persistence.
- [x] Add chart, DOCX/PDF report, XLSX evidence, artifact validation, cancellation, resume, idempotency, and revision-conflict behavior.

## Integrations and UI

- [x] Add namespaced RailWise tool adapters while preserving existing tool IDs and agent-pack source metadata.
- [x] Add the classic Engineering workbench route, project/import/quality/analysis/deliverable/review views, and WorkbenchRegistry lazy loading as a compatibility surface.
- [x] Add the reusable monitoring-report Flow template using the same Runtime endpoints.

## AI-first Engineering redesign

- [x] Add additive `domain`/`projectId` thread metadata to the contract, file/SQLite index, Runtime list/create/update routes, and renderer mapper; preserve unknown legacy records.
- [x] Add Engineering thread selection and restoration actions to `ChatState`; opening Engineering must select/create one project thread, and route switching must preserve Code/Write/Design/Engineering timelines independently.
- [x] Replace `EngineeringAiCommandCenter` localStorage/provider/SSE shim with a real session shell that renders existing message blocks, attachments, queued sends, approvals, and runtime errors.
- [x] Add `EngineeringContextService` for bounded context snapshots, project/dataset/citation revisions, provenance, and Watch drafts; no raw 500k-row payloads are sent to the model.
- [x] Add `EngineeringAiOrchestrator` for typed plan parsing/validation, approval tokens, idempotency, revision conflicts, TaskRun submission, event projection, cancel, resume, and stale-plan handling.
- [x] Route approved Engineering steps through `TaskController`/`AgentLoop` and RailWise tool provider; remove direct AI completion/cancel/resume writes from `engineering_runs` while keeping deterministic service records compatible.
- [x] Add AI routes/events, evidence-card reads, and renderer cards for plans, approvals, findings, metrics, trends, citations, artifacts, and model/tool unavailable recovery.
- [ ] Add packaged UI acceptance for Engineering thread isolation, AI-first entry, classic fallback, loading/empty/partial/error/stale states, light/dark themes, narrow windows, keyboard/a11y, and a real CSV/XLSX-to-DOCX/PDF/XLSX/manifest run.

## D-04 product naming compatibility

- [x] Apply the WorkWise / Survey / RAILWISE Survey naming boundary to new user-visible workbench and project-thread labels; preserve package, bundle, updater, API, route, storage, and `domain: "engineering"` compatibility identifiers with regression coverage.

## Canonical survey adjustment

- [x] Add canonical metre/radian unit metadata to adjustment results, per-observation residuals, closures, UI and DOCX/PDF/XLSX evidence, including non-destructive legacy-read compatibility.
- [x] Extract the single canonical matrix/WLS kernel with rank, condition, covariance, residual, precision, convergence and dimension-limit diagnostics.
- [x] Implement and verify independent leveling/height-control and ordered traverse strategies, including route-length/variance weights and angular/coordinate closures.
- [x] Implement and verify independent iterative plane-control and angle-network triangulation strategies; reject distance-only triangulation and malformed angle geometry.
- [x] Implement and verify CPIII free-station/resection with fixed-target geometry, station orientation parameters, slope/zenith processing and height evidence.
- [x] Implement and verify GNSS vector-baseline/covariance/fixed-datum adjustment, with stable blockers for incomplete scalar or covariance-free data.
- [x] Implement and verify coordinate transformation strategies for 2-D similarity, 3-D seven-parameter estimation/application, Gauss-Kruger conversion and height fitting without identity fallback.
- [x] Implement deformation epoch comparison for dX/dY/dH, settlement, horizontal displacement, tilt, convergence, rate and trend from immutable deterministic results.
- [x] Replace generic multi-network fixtures with independent golden and negative fixtures for every supported strategy and record the approved reference calculation/source.

## Verification

- [x] Add unit, Runtime integration, Flow, renderer, artifact, and migration tests.
- [x] Complete pinned-commit, file-hash, redistribution-license, script, dependency, network, credential and real-scenario audit for every bundled specialist Skill; exclude blocked assets without touching user copies.
- [x] Close the remaining 0.3.3 and specialist-skill acceptance tasks without modifying user data.
- [ ] Run typecheck, lint, full tests, build, strict OpenSpec validation, packaged GUI acceptance, and private 0.5.0-rc evidence collection.

## Professional survey source formats

- [x] Add versioned source-file, format-detection, raw-record anchor, parser/converter provenance, diagnostics, and import-disposition contracts; persist them without rewriting existing networks.
- [x] Implement the bounded `SurveyFormatRegistry`, content-signature conflict handling, canonical-unit contracts, and safe archive-only/blocking dispositions without promoting an unverified vendor format to adjustment-ready.
- [x] Implement and independently validate native Leica GSI-8/GSI-16/HeXML, Trimble JobXML/JXL/M5/DAT, TDS/Carlson RAW/RW5, Sokkia SDR2x/SDR33, and LandXML drivers against licensed or synthetic golden fixtures before any format can become adjustment-ready.
- [x] Implement and independently validate GNSS RINEX 2/3/4, compressed/Hatanaka wrapper, SINEX, NMEA, RTCM 2/3, SP3/IONEX/ANTEX, u-blox UBX, NovAtel OEM, Septentrio SBF, BINEX, Javad JPS, Topcon TPS, South STH, Hi-Target ZHD, CHCNAV HCN, and ComNav CNB inspection/import states; require datum-bound baseline vectors and covariance before GNSS adjustment.
- [x] Complete the deterministic local-converter chain for Trimble T01/T02/T04/JOB, Leica DBX/MDB, and Survey Pro databases: accept only locally user-supplied, allowlisted sandboxed converters; retain both source hashes and provenance; do not bundle vendor binaries or reverse-engineer opaque formats; and apply normal parser, semantics, units, datum, topology, closure, precision, and traceability gates to converted output without a manufacturer-authorization requirement.
- [x] Add the professional import preflight UI, format/readiness filters, raw-record and diagnostic views, accessible recovery actions, and replace the CSV/XLSX/JSON-only survey copy and file picker.
- [ ] Add redistributable or synthetic format fixtures for every advertised vendor/receiver family, parser golden/negative tests, decompression-bomb and malformed-record limits, Runtime/UI/artifact provenance tests, and real-project production acceptance: at least two P0 measurement formats must run import -> preflight -> deterministic adjustment -> DOCX/PDF/XLSX/manifest in the packaged candidate, with closure/precision comparison evidence. Do not treat a source as accepted merely because its vendor family is named.

## RAILWISE AI / Survey convergence baseline (2026-09-19)

The user-provided consolidated plan supersedes the earlier D-04 platform naming and AI-only first-screen design. Historical checkmarks above describe the earlier scope, not completion of this baseline.

- [x] Complete six typed engineering jobs, non-destructive legacy mapping, editable task context (datum, grade, standard version/clause), and migration integration tests.
- [ ] Complete four production stages, persistent AI conversation, stage tools, localized summary and readiness-driven actions; never label preview files reviewed.
- [ ] Verify ordinary questions, modification confirmation cards, typed execution approvals, evidence-to-record navigation and model-offline manual operation.
- [ ] Centralize RAILWISE AI / RAILWISE Survey display naming, migrate menus/settings/startup/about/candidate display and brand assets; retain technical identifiers and record the migration matrix.
- [ ] Complete Survey English/Chinese locale validation, theme/window/accessibility acceptance in the exact packaged candidate.
- [x] Complete current-head desktop and Runtime tests, lint, typecheck, build and strict specification validation with separate command evidence.
- [ ] Complete candidate signing/notarization, isolated install, two P0 format GUI delivery runs, restart and real private updater round trip; obtain human UI/professional confirmation.
- [ ] P1 professional credibility: versioned standards and GB/T 24356-2023 quality chain, residual-to-record navigation, replay/signatures, advanced adjustment methods and second-batch format admission.
- [ ] P2 after P0 acceptance: GeoCOM, coordinate/engineering expansion, DXF/point clouds/3D, outward MCP, audited binary converters, Survey/Write/Design/Flow collaboration.
- [ ] Record measured production metrics (traceable projects, first-result time, import success, 30-minute leveling workflow, reproducibility, provenance and one-click evidence questions).

## Review and execution boundary follow-through

- [x] Show concrete parameters, predecessor bindings, expected outputs and reversibility in Typed Plan review; retain incomplete and legacy plans as non-executable drafts.
- [x] Enforce approved arguments, project ownership, dependency success and idempotency in the actual RailWise tool executor, with both Survey and monitoring export integration tests.
- [x] Preserve selected operations during replanning and bind result reads to the exact approved predecessor adjustment.
- [x] Add durable project modification suggestions with before/after cards, UI-only confirmation credentials, reject/apply decisions, stale-context protection and mutation-free model proposal tests.

These code and automated-test items do not close task 39: a successful real-model session and exact packaged GUI acceptance of these new controls remain required.

## P1 XY error ellipse increment

- [x] Add explicit solver-indexed XY covariance, standard ellipse axes/orientation/variance basis for plane, traverse, triangulation, CPIII and GNSS; preserve ellipse-free algorithm-6 replay without rewriting old results.
- [x] Carry ellipse values and interpretation through bilingual point views, DOCX/PDF/XLSX and manifests; validate analytic rotated/diagonal/degenerate cases, real service covariance, export and legacy replay.
- [ ] Verify the new ellipse and parser diagnostic increment in its exact signed candidate and obtain professional interpretation/UI acceptance; this does not close the broader advanced-adjustment task.

## P1 deliverable verification increment

- [x] Add a project-scoped read-only check for persisted manifests, output hashes/sizes, current input bindings, exact Survey recomputation and source provenance; retain original review status.
- [x] Expose authenticated Runtime route and desktop IPC plus bilingual review controls; reject cross-project, tampered and stale evidence; clear stale UI results on retries/offline transitions.
- [x] Verify the new control in its exact signed packaged candidate. This does not complete digital signing, professional review or standards compliance. Evidence: `docs/qa/evidence/railwise-convergence-94f1550a7946/README.md` (Chinese light pass, English dark tamper rejection and restored pass).

## Packaged sidebar creation regression

- [x] Replace persistent create-request effect replay with one event-driven creation and an in-flight guard; verify duplicate, selection/locale/reconnect and failure/retry cases against the old failure.
- [x] Recheck sidebar creation in a fresh signed candidate, including stable project counts after navigation and restart; 69e9728 remains a failed candidate.

## P1 advanced numerical kernels

- [x] Add a versioned fixed-linear generalized-w diagnostic with explicitly declared known absolute covariance, complete residual covariance and detectability/numerical boundaries; verify independent exact correlated models and extreme-scale counterexamples without changing formal observations or decisions.
- [x] Add a versioned fixed-linear VCE trial for independent disjoint variance groups, preserving initial values, every candidate and explicit nonpositive/identifiability/numerical stops; verify exact and high-precision independent cases without replacing formal weights.
- [x] Bind both advanced trials to immutable project-scoped input evidence, authenticated Runtime/IPC, strict replay, bounded history and bilingual manual UI; keep declared experimental models separate from validated production covariance.
- [ ] Verify the advanced-trial integration in its exact signed private candidate, including damaged/stale records, restart, themes and keyboard access; obtain required human UI and professional confirmation before treating the broader advanced-adjustment task as complete.

## P1 statistical-family and Huber increment

- [x] Add explicitly declared normal/t/chi-square statistical families with complete-family Bonferroni correction, numerical boundaries and independent high-precision replay; do not silently use approximate upstream statistics as exact inputs.
- [x] Add fixed-external-scale Huber QR/IRLS trials with retained observations, weights, objective/score history and explicit stopping/uniqueness limits; verify independent exact and high-precision cases.
- [x] Extend immutable advanced-trial Runtime/IPC/history and bilingual UI for both kinds, preserving legacy records, raw bytes, bounded replay, exact distribution parameters and full critical interval display; verify independent service/client/DOM probes.
- [ ] Verify these two new kinds in their exact signed candidate, including native export, restart, damaged records, themes/window sizes and required human confirmation; previous generalized-w/VCE package evidence does not cover them.

## P1 declared two-epoch reference datum

- [x] Add the bounded 1D complete-covariance reference-definition pure kernel with explicit mapping/dependence, GLS/equal method boundaries and independent exact/high-precision/negative fixtures; do not infer stable points.
- [x] Bind the reference trial to immutable project evidence, authenticated Runtime/IPC and bilingual results with complete covariance, preserved numerical qualification and no method fallback; independently verify replay, scope, native-export payload and maximum history bounds.
- [x] Verify the reference workspace in its exact signed package. The 6ff82c8 installed GUI covered GLS, singular refusal, explicit equal weighting and original-ID restart replay; three actual stored records passed independent arithmetic checks. Overall human acceptance remains separate.

## P1 declared inspection scoring

- [x] Implement the source-bound plane/height-control exact-rational scoring kernel for declared accuracy, defects, explicit layered scope, overview, samples and the two batch stages; independently verify strict thresholds, vetoes, missing evidence and unsupported branches without claiming full standard conformity.
- [x] Bind declared scoring to immutable project records, authenticated APIs and bilingual quality controls; independently verify exact fractions, scope, replay, corruption rejection, capacity and late project changes.
- [x] Verify declared scoring in its exact signed package. The 6ff82c8 installed GUI covered four declared outcomes, restart, single-byte corruption rejection, healthy history and restoration, with independent read-only verification; evidence authenticity and human approval remain explicit separate responsibilities.

## P1 static independent-observation append

- [x] Add a bounded fixed-model, known-prior-variance Givens append kernel with a declared baseline fingerprint, every row trace and independent full Householder batch comparison; independently replay exact/high-precision models and boundary failures.
- [x] Bind static append to immutable advanced-trial records, Runtime/IPC and bilingual results with base/append/total counts, prior covariance, full-batch comparison and bounded history; preserve old-kind limits and hashes.
- [ ] Verify static append in its exact signed package, including stale baseline, full parameter/covariance/row displays, export, restart and supported themes/window sizes.

The 6ff82c8 package already passed normal/stale/maximum GUI cases, maximum native export, original-ID restart and independent checks of all 128 maximum-case prefixes. Complete visual coverage of the large parameter/covariance surfaces remains open.

## P1 declared quality linkage assessment

- [x] Bind a draft deliverable, retained-material head, complete first-round sample and explicit per-unit scoring records in a separate immutable assessment service; preserve coverage and vetoes as separate results, replay dependencies twice, enforce bounded source reads and leave deliverable review status unchanged.
- [x] Expose authenticated Runtime/IPC, a role-validated client and bilingual review UI; independently verify source changes, corruption isolation, strict score replay, late response cancellation and clearing stale conclusions.
- [ ] Verify the linkage assessment in its exact signed package, including full and incomplete coverage, changed sources, native export, restart and themes/window sizes. This does not complete professional review, signing or production approval.

The 281dc87 signed package passed actual GUI creation of full/missing/veto-with-missing cases, native export cancellation and save, original-ID restart, source-change rejection and same-plan recovery, plus wrong-unit rejection. Independent read-only checks passed for three scores, four assessments, export and unchanged engineering baseline. Chinese light/dark compact and wide layouts, English light/dark wide layouts and limited keyboard focus were observed. Complete language/theme/window coverage, measured native minimum bounds and full accessibility remain open; this aggregate task is not checked off. See `docs/qa/evidence/railwise-convergence-281dc8767250/README.md`.

## Import measurement and converter follow-through

- [x] Record additive import started/committed/finished events, preserve rejected and incomplete attempts, bind commit receipts to the network transaction and report first-observed file-key subsets separately from unavailable production-wide KPIs.
- [x] Verify converter timeout/cancellation and process-group cleanup with real isolated processes; reject oversized stdout/stderr by bytes and bounded regular-file output, while preserving input and existing converter admission rules.
- [x] Enforce and test COSA NET resource limits and OU1 comparison dimension bounds without admitting historical references as formal input.

Source validation is recorded in `docs/qa/evidence/railwise-import-converter-followthrough/README.md`. These tasks do not close the aggregate production KPI, proprietary-converter acceptance or packaged UI gates.

## P1 exact standards reference catalog

- [x] Add an immutable, bounded GB/T 24356-2023 catalog for existing first-round sampling and declared scoring, with exact rule/catalog/algorithm versions, source hash, applicable profiles and verified clause/table/page references; reject unsupported or mismatched references without granting professional trust.
- [x] Expose authenticated read-only Runtime and desktop IPC/client access, and bilingual keyboard-accessible source details from existing sampling/scoring results; retain historical bytes and distinguish citation resolution from standards conformity.
- [ ] Verify exact-reference mapping, mismatch refusal, current/legacy result handling, authorization and stale UI states; record independent review and exact-package UI acceptance separately.

Source-level checks and independent probes passed after correcting the unit-score formula clause; see `docs/qa/evidence/railwise-standard-basis-20260920/README.md`. Exact packaged UI acceptance remains separate and pending.

## Public product documentation follow-through

- [x] Merge reviewed bilingual README, product introduction and Chinese light candidate screenshots independently of application changes; preserve published 0.5.0 download metadata and clearly label the candidate scope.
- [x] Render the exact website source with official PHP/templates, inspect desktop/mobile views, deploy the reviewed content and verify public content/image hashes and unchanged downloads; retain failures and rollback evidence.

PR #29 and source `bea9a04` were merged and deployed successfully; exact remote preview, browser observations and immutable-download checks are recorded in `docs/qa/evidence/railwise-website-20260920/README.md`. No new application candidate was publicly released.

## P0 scoped state and exact evidence navigation follow-through

- [x] Isolate project-list, overview and Survey-summary reads by request generation and project/workspace/Runtime scope; reject late successes and failures, clear prior-project presentation immediately and preserve already loaded draft evidence during Runtime disconnection.
- [x] Apply the same scope boundary to asynchronous create/save/import/check/analysis/chart/preview/finalization responses, follow-up requests and busy-state cleanup; invalidate pre-save overview reads and pre-create project-list reads, and verify delayed mutations cannot replace the newly selected project's data or outputs.
- [x] Hide adjustment actions for sources without current admission and validated network status; prepare missing-data questions with the exact selected source/network evidence without replacing existing question text, sending a message or executing a calculation.
- [x] Add read-only, one-shot navigation from literal plan inputs, exact evidence-card identities and explicitly selected Survey evidence to the corresponding network, run, finding, observation, source anchor, point, diagnostic or artifact; re-read Survey bindings before locating, reject stale/ambiguous/unresolved targets, retain the mounted conversation and respect subsequent manual navigation.

Source verification: four focused renderer test files, 92 tests passed; focused ESLint and web TypeScript passed. The final integration run including the standards-profile page refinement and creation/list race fix passed 2,752 desktop tests with 2 skipped (327 files passed, 2 skipped). That full run predates two added profile-link DOM cases; a subsequent 15-case targeted DOM run includes them and is not pooled into the full-run count. Final desktop/Runtime typechecks, strict OpenSpec 11/11 and related-file lint passed; earlier full lint reported 0 errors and 1 existing Workbench Hook warning. Independent review found the delayed-mutation and repeated-navigation regressions; both were fixed and covered before its final review reported no unresolved definite defect. A later creation/list regression reproduced an older list response reselecting the previous project before the fix and passed after invalidation was added. The tests cover source behavior, not installed UI acceptance or real-model success. Existing 17 unchecked aggregate tasks remain unchecked; no historical package is declared to contain this increment. Source hashes, retained logs and explicitly labeled session summaries are in `docs/qa/evidence/railwise-navigation-audit-followthrough/README.md`.

## Durable verification lifecycle measurement follow-through

- [x] Independently persist verification starts, atomically bind finished receipts to unchanged terminal audit records, preserve interruptions and audit failures, and add read-only start-cohort metrics with strict cutoff, legacy-terminal separation and corruption rejection; verify transaction failures, immutable storage, real subprocess SIGKILL and historical compatibility without backfilling events or changing review status.

Focused verification: Runtime audit 14 tests and Python measurement 37 tests passed. This adds measurable recorded service attempts, not complete production denominators, fresh file verification, authenticated professional signatures or evidence that production KPI targets have been met. The production-metrics aggregate remains open; method and limitations are recorded in `docs/qa/RAILWISE_SURVEY_PRODUCTION_METRICS.md`.

## Model identity and actual execution follow-through

- [x] Preserve provider/model identity across duplicate model menus, preferences, queued sends, Turn/Task persistence, Review, UI actions and child requests; pin new default selections, retain legacy model priority, reject missing explicit providers and resume the original Task through a validated internal continuation identity.
- [x] Preserve Survey reasoning effort in workspace/project-scoped session drafts, snapshot provider/model/effort before asynchronous approval, forward typed start/resume choices, and document additive migration and unchanged historical configuration.
- [x] Refresh authoritative project and Survey data once an execution settles, isolate late responses by project/thread, preserve drafts and manual network selections, and localize structured stale-plan errors and Markdown table controls.
- [x] Verify modification approval, stale suggestion/plan refusal, replan approval reset and a real model-driven four-tool run in the exact fbb88ea signed package; independently verify deterministic results, three output files, restart persistence and temporary relay cleanup without claiming final manifest approval or acceptance of subsequent source changes.

Source integration: desktop 2780 passed/2 skipped; Runtime 2795 passed/22 skipped, with the first-run assertion failure retained separately. Typechecks, build and strict OpenSpec passed; lint has 0 errors and 1 existing Hook warning. Exact fbb evidence is in `docs/qa/evidence/railwise-convergence-fbb88ea71557/README.md`; source migration and validation are in `docs/qa/RAILWISE_SURVEY_MODEL_FOLLOWTHROUGH.md`. New provider, effort, localization and refresh changes require their own signed candidate. The 17 unchecked aggregate tasks are not closed by these narrow checks.
