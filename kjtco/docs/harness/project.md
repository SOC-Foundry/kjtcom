# kjtco Harness

**Extends:** iaomw v0.1.0
**Project code:** kjtco
**Status:** archiving after 10.68.X graduation
**Last updated:** 2026-04-08 (iteration 10.68.1)

**Base imports (acknowledged):**
- iaomw-Pillar-1..10
- iaomw-ADR-001..014
- iaomw-Pattern-01..25

*Acknowledging base imports means kjtco has read them and operates under them.*

---

## Project ADRs (17 kjtcom-specific)

### kjtco-ADR-001: IAO Methodology

- **Context:** kjtcom is built using Iterative Agentic Orchestration, a plan-report loop methodology distilled from 60+ iterations.
- **Decision:** Every iteration must produce 4 artifacts: Design, Plan, Build, and Report.
- **Rationale:** Consistency in artifacts ensures a clear audit trail and facilitates multi-agent handoffs. Without these, the project becomes a black box that is impossible to audit or scale.
- **Consequences:** Skipping an artifact or failing to update the changelog is a critical failure (Score < 5).

### kjtco-ADR-002: Thompson Indicator Fields (`t_any_*`)

- **Context:** Integration with various data sources (CalGold, RickSteves, TripleDB, Bourdain) requires a flexible but typed schema.
- **Decision:** Use a flat schema with `t_any_` prefixes for dynamic fields. Naming style mirrors Panther's `p_any_*` SIEM convention.
- **Rationale:** Prevents schema rigidness from blocking data ingestion while maintaining a common prefix for querying. This late-binding schema approach allows rapid prototyping and direct lift to TachTech intranet sources.
- **Consequences:** Verify that new data models follow this naming convention. Mixed casing or non-standard prefixes are errors.

### kjtco-ADR-004: Middleware as Primary IP

- **Context:** The project's value lies in its orchestration layer (middleware), not just the frontend app.
- **Decision:** Prioritize the development and documentation of middleware components (intent router, firestore query, evaluator harness, post-flight, gotcha registry).
- **Rationale:** The Flutter app and YouTube pipelines are the data exhaust that proves the harness works. When the harness moves to the TachTech intranet (`tachnet-intranet` GCP project), the data sources change but the harness is identical.
- **Consequences:** Workstreams focused on middleware robustness are P0 priority. Gaps in middleware documentation are serious. A bug in the evaluator is higher-severity than a bug in the Flutter app by definition.

### kjtco-ADR-006: Post-Filter over Composite Indexes (G34)

- **Context:** Firestore composite indexes take time to build and can hit limits.
- **Decision:** Use Python-side post-filtering for complex array-contains queries when possible.
- **Rationale:** Increases development velocity and reduces infrastructure dependency. Simplifies the deployment model.
- **Consequences:** Evaluate whether the executor correctly implemented the G34 workaround.

### kjtco-ADR-008: Dependency Lock Protocol

- **Context:** Transitive dependency updates can break the build unexpectedly.
- **Decision:** Lock major dependencies and only upgrade one major version at a time.
- **Rationale:** Ensures stability and makes it easier to pinpoint the cause of regressions.
- **Consequences:** Bulk upgrades are discouraged unless explicitly planned. Riverpod 2 -> 3 is a dedicated future iteration, not a side-effect of W4.

### kjtco-ADR-010: GCP Portability Design

- **Context:** Pipeline and middleware are designed to be portable from local machines (NZXTcos, tsP3-cos) to GCP (`tachnet-intranet`). Two pipeline configurations are tracked: v1 (CalGold/RickSteves/TripleDB) and v2 (Bourdain). RickSteves serves as the reference pipeline for portability testing.
- **Decision:** Middleware scripts must not hardcode local paths. All path resolution uses environment variables or config files. A pub/sub topic router in intranet middleware enables Firestore to push to downstream consumers (tachtrack.com portals).
- **Rationale:** The kjtcom extraction pipeline proves the pattern works for YouTube-sourced location intelligence. The intranet variant applies the same normalization (`t_any_*` schema) to enterprise data sources. Keeping middleware portable means one codebase serves both deployments.
- **Consequences:**
  - `pipeline.json` configs must use `${PIPELINE_ROOT}` variable, not absolute paths.
  - Scripts must resolve paths relative to config, not hardcoded `/home/kthompson/...`.
  - Two deployment targets tracked: `local` (current) and `gcp-intranet` (future).
  - Pub/sub topic structure: `projects/{project}/topics/{t_log_type}-entities` per pipeline.

### kjtco-ADR-011: Thompson Schema v4 - Intranet Extensions

- **Context:** kjtcom schema v3 was designed for YouTube content (locations, food, travel). The intranet deployment will process documents, spreadsheets, meeting transcripts, email, Slack, CRM data, and contractor records. Each source type requires fields the current schema does not have.
- **Decision:** Define candidate `t_any_*` fields per source type. Fields are added to the schema when the first pipeline consuming that source type goes live. The schema grows monotonically. Fields not relevant to a source are left as empty arrays (not omitted). This mirrors how SIEM platforms (Panther `p_any_*`, ECS) evolve their schemas.
- **Current schema v3 fields (kjtcom YouTube content):** `t_any_names`, `t_any_people`, `t_any_cities`, `t_any_states`, `t_any_counties`, `t_any_countries`, `t_any_country_codes`, `t_any_regions`, `t_any_coordinates`, `t_any_geohashes`, `t_any_keywords`, `t_any_categories`, `t_any_actors`, `t_any_roles`, `t_any_shows`, `t_any_cuisines`, `t_any_dishes`, `t_any_eras`, `t_any_continents`.
- **New v4 fields by source type:**
  - Documents (docx, pdf): `t_any_authors`, `t_any_titles`, `t_any_dates`, `t_any_orgs`, `t_any_topics`
  - Spreadsheets (xlsx, csv): `t_any_columns`, `t_any_metrics`, `t_any_units`
  - Meeting transcripts (mp3): `t_any_speakers`, `t_any_action_items`, `t_any_decisions`
  - Email (Gmail): `t_any_senders`, `t_any_recipients`, `t_any_subjects`, `t_any_attachments`
  - Slack channels: `t_any_channels`, `t_any_threads`, `t_any_reactions`
  - CRM API pulls: `t_any_accounts`, `t_any_contacts`, `t_any_deals`, `t_any_stages`, `t_any_values`
  - Contractor portal: `t_any_certifications`, `t_any_skills`, `t_any_projects`, `t_any_contractors`
- **Universal fields (all intranet sources):** `t_any_tags`, `t_any_record_ids`, `t_any_sources`, `t_any_sensitivity`.
- **Rationale:** Defining fields ahead of implementation ensures the extraction prompt for each source type has a clear target schema. The pipeline team can reference this ADR when writing new extraction prompts.
- **Consequences:** `schema.json` must be versioned (v3 = kjtcom YouTube, v4 = intranet baseline). Total field count grows from 19 (v3) to 49 (v4 candidate set).

### kjtco-ADR-013: Pipeline Configuration Portability

- **Context:** v1 (CalGold/RickSteves/TripleDB) required duplicating pipeline infrastructure per source type. v2 (Bourdain) demonstrates a single pipeline codebase handling multiple shows differentiated by `t_any_shows`.
- **Decision:** v2 (Bourdain) is the template for future pipeline deployments, including the `tachnet-intranet` GCP project. Single pipeline codebase with source-specific extraction prompts and `t_any_sources` for differentiation.
- **Rationale:** Parts Unknown (v10.61 W1) validates this by adding a second show under the existing Bourdain pipeline without infrastructure changes.
- **Consequences:**
  - RickSteves pipeline execution is the operational reference (cleanest run history).
  - New source types each get an extraction prompt but share pipeline phases 1-7.
  - Dedup logic must support array merging for multi-source entities.
  - Pipeline scripts must be parameterized (env vars, not hardcoded paths) before intranet deployment.

### kjtco-ADR-018: Visual Baseline Verification

- **Context:** CanvasKit (Flutter) and Three.js (Claw3D) prevent traditional DOM-based scraping for test verification. v10.63 placebos used file-size heuristics which missed visible regressions.
- **Decision:** Shift to perceptual hash (pHash) visual diffing. Blessed baselines are stored in `data/postflight-baselines/`. Post-flight captures current state and asserts distance <= 8.
- **Rationale:** Real visual truth is required to maintain the Zero-Intervention Target for the frontend.
- **Consequences:** `imagehash` and `Pillow` are now required dependencies. Baseline blessing is a manual step during visual redesigns.

### kjtco-ADR-019: Consolidated Context Bundle (v10.65)

- **Context:** Planning chat sessions (Claude web) require uploading the same 5-10 files every iteration (design, plan, build, report, harness, registry). This consumes context and is prone to human error.
- **Decision:** Produce a fifth artifact, `docs/kjtcom-context-{iteration}.md`, consolidating all operational state (immutable inputs, execution audit, registries, ADRs, deltas) into a single file.
- **Rationale:** Pillar 2 expansion. One-file upload ensures the planning agent has perfect information with minimal token overhead.
- **Consequences:** `scripts/build_context_bundle.py` is a mandatory closing step. Post-flight asserts bundle size > 100 KB.

### kjtco-ADR-020: Build-as-Gatekeeper (v10.65)

- **Context:** v10.64 W5 introduced a build break that wasn't detected until post-iteration manual deploy.
- **Decision:** Mandatory `flutter build web --release` and `dart analyze` check in `scripts/post_flight.py`. Failure to build blocks the iteration completion.
- **Rationale:** Pillar 9 enforcement. Defects must be impossible to ship, not merely detectable in retrospect.
- **Consequences:** Iteration close is delayed by build time (3-5 mins), but deployment reliability reaches 100%.

### kjtco-ADR-022: Registry-First Diligence (v10.65)

- **Context:** Agents often spend 5-10 turns searching for files they didn't create (speculative ReadFile cascades).
- **Decision:** The first action for any workstream requiring existing component discovery MUST be `scripts/query_registry.py`.
- **Rationale:** Pillar 3 optimization. The script registry is the project's map; agents must use it before wandering.
- **Consequences:** `sync_script_registry.py` heuristics must be maintained. GEMINI.md instructions enforce this as a middleware requirement.

---

## 4. Scoring Rules and Calibration

Scores are integers on a 10-point scale (0-9). **The schema maximum is 9. 10/10 is strictly prohibited** so that no iteration can ever claim a flawless score; there is always something to improve, and the schema enforces the humility.

### Detailed Score Calibration

- **9/10 (Exceptional):** Flawless execution. All workstreams complete. Extensive evidence (file paths, line counts, test outputs). All project conventions followed. Only minor formatting issues allowed. The schema's hard ceiling.
- **8/10 (Excellent):** All workstreams complete. Strong evidence. Minor inconsistencies in non-critical areas. Production-ready.
- **7/10 (Good):** All or most workstreams complete. Core functionality solid. Gaps in documentation or secondary testing. One workstream might be `partial` with a clear path forward. **This is also the maximum allowed under self-grading (ADR-015).**
- **6/10 (Satisfactory):** Primary workstreams complete. Functional but messy. Missing edge-case tests. Some conventions ignored.
- **5/10 (Marginal):** Bare minimum success. Functional gaps exist. Evidence is thin. Not yet production-ready.
- **4/10 (Sub-par):** Major workstreams failed or partial. Evidence is weak. Multiple ADR or pillar violations.
- **3/10 (Poor):** Significant failures. Only minor deliverables achieved. High human intervention needed.
- **2/10 (Very Poor):** Workstream goals ignored. Massive technical debt introduced. No verifiable evidence for claims.
- **1/10 (Near Failure):** Agent stalled or produced incoherent results. Virtually nothing achieved.
- **0/10 (Complete Failure):** Not attempted, or resulted in system corruption / regression.

### Score Calibration Case Study: W15 (v9.51)

In v9.51, the search button layout was fixed. A score of 9/10 would require: (1) existence check of `query_editor.dart` and `app_shell.dart`; (2) verified layout shift on mobile and desktop via screenshot or description; (3) regression test pass for query submission. Anything less drops it to a 7 or 8.

### Score Recalibration Case Study: v10.62 (post-ADR-015)

In v10.62, the executor self-graded W1 (G60 fix) at 10/10. The honest score is 7/10: the fix is correct, but the regression itself shipped to production and was caught by Kyle, not by post-flight. The fix earns credit; the post-flight coverage gap loses it. ADR-015 enforces this: any iteration whose evaluator is the executor cannot exceed 7/10 per workstream.

---

## 5. Evidence Quality Standards (Consolidated)

Claims without evidence are ignored. The evidence standard is uniform across all workstreams; per-workstream variants from prior iterations are merged here.

### Evidence Levels

- **Level 1 (File Existence):** State the file path and line count. *Example:* "scripts/post_flight.py (310 lines) updated."
- **Level 2 (Execution Success):** State the command and the return code or output summary. *Example:* "python3 scripts/post_flight.py returned exit code 0 (8/8 passed)."
- **Level 3 (Functional Proof):** State a specific metric or observation from the output. *Example:* "Bot responded to 'how many entities' with 6,181 (verified via screenshot)."

**Mandatory Requirement:** Every "complete" outcome MUST cite at least Level 1 and Level 2 evidence. Level 3 is required for any production-facing claim.

### Per-Workstream Evidence (Consolidated)

These patterns recur across workstream types. Match the workstream against the closest pattern.

**Harness or middleware rebuild workstreams:**
- Existence of the modified file with `wc -l` line count.
- Verification that the file contains the expected ADR / pattern / section count via `grep -c`.
- Pre-cleanup snapshot exists in `docs/archive/`.

**Claw3D workstreams:**
1. G56 grep check: `grep -c "fetch.*\.json" app/web/claw3d.html` returns 0.
2. G59 containment: all chip labels rendered as canvas textures (no HTML overlay chip labels).
3. Board gaps visible between FE-MW, PL-MW, MW-BE.
4. Animated dashed connectors crossing each gap with labels.
5. Component review: all codebase components represented on boards (49+ chips as of v10.61).
6. Browser console shows 0 errors on page load.
7. Functional checks: 4 boards visible with MW visibly larger; hover tooltips display chip name + status LED + detail; click-to-zoom works on any board; escape returns to overview; iteration dropdown toggles chip visibility.
8. `python3 scripts/post_flight.py` passes the `claw3d_no_external_json` check.

**Pipeline workstreams (Bourdain, Phase 2 onward):**
- Entity count delta from staging Firestore (`(default)` -> `staging` database).
- Updated checkpoint at `pipeline/data/<pipeline>/checkpoint.json`.
- Schema v3 (or v4) compliance verified.
- Per-video failure log exists at `pipeline/data/<pipeline>/<show>_acquisition_failures.jsonl` (G63 enforcement).
- Failure-reason histogram included in build log.

**Evaluator fix workstreams (v10.56+, refreshed v10.63):**
- `python3 scripts/run_evaluator.py --iteration <version> --rich-context --verbose` completes without exception.
- At least one tier produces valid output (Qwen preferred; Gemini Flash acceptable; self-eval is a failure).
- `docs/kjtcom-report-<version>.md` exists with scored workstreams.
- `grep -c "^| W" docs/kjtcom-report-<version>.md` >= 1.
- `data/agent_scores.json` entry shows `tier_used` field populated and `self_graded: false`.

**Post-flight workstreams:**
- New check function exists in `scripts/postflight_checks/` or in the registration block of `scripts/post_flight.py`.
- The check runs as part of `run_all()`.
- A failure-path test demonstrates the check returns FAIL when fed broken input.
- Screenshots (if applicable) saved under `data/postflight-screenshots/<iteration>/`.

**README / documentation workstreams:**
- `wc -l` shows line count growth.
- `grep -c` checks confirm presence of mandatory strings (entity counts, phase, version).
- The trident Mermaid block is present.

---

## 6. MCP Usage Guide

Use this guide to accurately populate the `mcps` field in your scorecard. Use only the values listed here. If no MCP was invoked during a workstream, use `-` (a single hyphen).

- **Firebase MCP:** Used when Firestore documents are read or written, or when Firebase project configuration is queried via the MCP tool.
- **Context7 MCP:** Used when documentation for libraries or frameworks is fetched via Context7. v10.63 W4 uses this to fetch the `flutter_code_editor` README.
- **Firecrawl MCP:** Used when external web URLs are scraped for content.
- **Playwright MCP:** Used when a headless browser is launched for automation or visual verification. v10.63 W3 uses this for the production data render check.
- **Dart MCP:** Used when Dart code is analyzed, formatted, or tests are run via the Dart MCP server.
- **`-`:** Use when no MCP was used. Most shell-based tasks (git read-only, ls, python scripts) use `-`.

**Anti-pattern (Pattern 5, see §15):** Never list every available MCP for every workstream. List only the MCPs actually invoked. Precision in MCP attribution is critical for Phase 10 readiness and intranet rollout planning.

---

## 7. Agent Attribution Guide

- **claude-code:** Use when the iteration was executed by Anthropic's Claude Code agent. Most v10.x iterations after v10.55.
- **gemini-cli:** Use when the iteration was executed by Google's Gemini CLI agent. v10.62 was the most recent gemini-cli iteration.
- **LLM names (exact):** `qwen3.5:9b`, `nemotron-mini:4b`, `haervwe/GLM-4.6V-Flash-9B`, `nomic-embed-text`.
- **API models:** `gemini-2.5-flash` (via litellm), `claude-opus-4-6`, `claude-sonnet-4-6`, `claude-haiku-4-5`.

When the executor and evaluator are the same agent (Pattern 20, ADR-015), the report MUST list both roles separately and the iteration is auto-capped at 7/10 per workstream.

---

## 8. Trident Computation Rules

The Trident is the ultimate measure of iteration success.

- **Cost:** Count the `llm_call` events in `data/iao_event_log.jsonl`. Sum the `tokens` field where available. Local (Ollama) calls do not count against the API token budget but should still appear in the cost line. *Example:* "12,450 API tokens (Gemini Flash) + ~5,083 local tokens (Qwen) across 9 LLM calls."
- **Delivery:** "X/Y workstreams complete." Count directly from the scorecard. The schema enforces the `^\d+/\d+ workstreams` pattern; the normalizer (ADR-014) rebuilds the string if the model deviates.
- **Performance:** State a specific numerical result from the work. *Example:* "Post-flight 9/9 PASS, map renders 6,181 markers, harness 952 lines, all stale version stamps removed."

### Worked Example

If the event log has 10 `llm_call` events, 2 of which have `tokens: 1000` and the rest are null, report: "2,000 tokens across 10 LLM calls (8 missing token data — log gap to fix in next iteration)."

---

## 9. Report Template (Markdown)

Your final report structure should follow this pattern. The retro section is mandatory.

```
# kjtcom - Iteration Report v[X.XX]

**Evaluator:** [qwen3.5:9b | gemini-flash | self-eval]
**Tier used:** [qwen | gemini-flash | self-eval]
**Self-graded:** [true | false]
**Date:** [YYYY-MM-DD]

## Summary
[2-4 sentences of plain text prose. No JSON. No code blocks. No marketing speak.]

## Workstream Scorecard
| W# | Name | Priority | Outcome | Evidence | Agents | LLMs | MCPs | Score |
|----|------|----------|---------|----------|--------|------|------|-------|
| W1 | ...  | P0       | complete| ...      | ...    | ...  | ...  | 8/10  |

## Trident Evaluation
| Prong | Target | Result |
|-------|--------|--------|
| Cost  | <80K   | ...    |
| Delivery| 6/6  | ...    |
| Performance| ...| ...    |

## Agent Utilization
[Prose list of agents and LLMs used]

## Event Log Summary
[Total events count and breakdown]

## Gotchas
[List of active / resolved gotchas, with status changes from this iteration]

## What Could Be Better
- Item 1...
- Item 2...
- Item 3...

## Next Iteration Candidates
- Item 1...
- Item 2...
- Item 3...

## Why Was the Evaluator Unavailable? (mandatory if self_graded == true)
[Document the Tier 1 + Tier 2 failure modes that forced Tier 3.]
```

---

## 10. Build Log Template

The executor produces the build log during execution, not after. The build log IS the audit trail.

```
# kjtcom - Build Log v[X.XX]

**Iteration:** [X.XX]
**Agent:** [claude-code | gemini-cli]
**Date:** [YYYY-MM-DD]
**Machine(s):** [tsP3-cos | NZXTcos | both]

## Pre-Flight
[Capture the output of every step from the plan's pre-flight checklist. Mark each PASS/FAIL.]

## Execution Log
### W1: [Name] - [complete | partial | blocked]
[What you did, in order. File paths. Line counts. Command outputs.]
- Action 1...
- Action 2...
- **Outcome:** [complete | partial | blocked]
- **Evidence:** [paths, line counts, command outputs]

### W2: ...
...

## Files Changed
[List every file touched, with line count delta.]

## Test Results
[Raw output of any test commands run.]

## Post-Flight Verification
[Output of `python3 scripts/post_flight.py`. Each check on its own line.]

## Trident Metrics
- **Cost:** [token count from event log]
- **Delivery:** [X/Y workstreams complete]
- **Performance:** [the concrete DoD checks from plan §10]

## What Could Be Better
[At least 3 honest items.]

## Next Iteration Candidates
[At least 3 items.]
```

---

## 11. Changelog Template

Every changelog entry must follow these rules:

- **Prefixes:** Use `NEW:`, `UPDATED:`, or `FIXED:`.
- **Specificity:** "UPDATED: README.md to v10.63 (added 87 lines, new IAO Methodology section)."
- **Attribution:** Mention the agents and LLMs used.
- **No fluff:** No "successfully", "robust", "comprehensive". See §12.

---

## 12. Banned Phrases

Do not use these words in summaries or scorecard evidence:

- "successfully" - implied by `complete`
- "robust" - vague
- "comprehensive" - vague
- "clean release" - vague
- "Review..." - compute it
- "TBD" - find it
- "N/A" - explain why
- "strategic shift" - describe the change
- "healthy system" - state which checks passed
- "robust validation" - state the validator and its tests

---

## 13. What Could Be Better (Mandate)

This section is mandatory for every report. Even a "perfect" iteration has room for improvement.

- Focus on: code quality, test coverage, documentation gaps, process inefficiencies, harness drift, post-flight coverage, evaluator behavior.
- Each item must be a complete sentence with a clear action.
- Bad: "More tests."
- Good: "Increase unit test coverage for the intent router to include edge cases for malformed JSON."

Minimum two items. Three is better.

---

## 14. Workstream Fidelity

Evaluate ONLY the workstreams in the design document.

- If the design doc says W1 is "Update CSS" and the plan says W1 is "Fix Header", use the design doc's name.
- If the executor adds a "bonus" feature that isn't a workstream, note it under "Additional Work" and DO NOT score it.
- Workstream names in the report must match the design doc. The normalizer (ADR-014) will substitute the design doc name when the model abbreviates, but you should not rely on this.
- Workstream count in the report must match the design doc. Hallucinated extra workstreams are Pattern 1.

---

## 15. Failure Pattern Catalog

Avoid these specific mistakes observed in prior iterations. Each pattern is cross-referenced with its `Gxx` gotcha where applicable.

### Pattern 1: Hallucinated Workstreams (v9.46)
- **Failure:** Qwen added a W6 "Utilities" workstream to the report.
- **Design doc:** Only had W1-W5.
- **Impact:** Distorted the delivery metric (5/5 vs 6/6).
- **Prevention:** Always count the workstreams in the design doc first. Your scorecard must have exactly that many rows.

### Pattern 2: Build Log Paradox (v9.46)
- **Failure:** Evaluator claimed it could not find the build log despite the build log being part of the input context. Several workstreams were marked `deferred` that were actually `complete`.
- **Prevention:** Multi-pass read of the context. If a workstream claims a deliverable exists, look for the execution record in the build log.

### Pattern 3: Qwen as Executor (v9.49)
- **Failure:** Listed 'Qwen' as the agent for every workstream.
- **Impact:** Misattributed work and obscured the performance of the actual executor (Claude).
- **Prevention:** You are the auditor. Auditors do not write the code. Always use the name of the agent you are evaluating.

### Pattern 4: Placeholder Trident Values (v9.42)
- **Failure:** Reported "TBD - review token usage" in the Result column.
- **Impact:** The report was functionally useless for tracking cost.
- **Prevention:** If you don't have the data, count the events in the log. Never use placeholders.

### Pattern 5: Everything MCP (v9.49)
- **Failure:** Evaluator listed every available MCP for every workstream.
- **Impact:** Noisy data, no signal about which MCPs are actually being exercised.
- **Prevention:** Use `-` if no MCP tool was called. Precision in MCP attribution is critical for Phase 10 readiness.

### Pattern 6: Summary Overload (early v9.5x era)
- **Failure:** Evaluator produced a 10-sentence summary that broke the schema constraints. Three consecutive validation failures, retries exhausted.
- **Prevention:** Constraints are not suggestions. If the schema says 2000 characters max, stick to it.

### Pattern 7: Banned Phrase Recurrence (v9.43-v9.51)
- **Failure:** "successfully", "robust", "comprehensive" reappear in summaries despite being banned.
- **Prevention:** §12 lists the full set. The schema validator greps for them.

### Pattern 8: Workstream Name Drift (v9.50)
- **Failure:** Abbreviating workstream names (e.g., "Evaluator harness" instead of "Evaluator harness rebuild (400+ lines)").
- **Prevention:** Use the exact string from the design document. The normalizer will substitute, but don't rely on it.

### Pattern 9: Score Inflation Without Evidence (v9.48)
- **Failure:** 9/10 score with one-sentence evidence.
- **Prevention:** Evidence must reach Level 2 (execution success) for any score >= 7.

### Pattern 10: Evidence Levels Skipped (v9.47)
- **Failure:** Score given without any of the three evidence levels.
- **Prevention:** §5 lists the three levels. Level 1 + Level 2 are mandatory for `complete`.

### Pattern 11: Evaluator Edits the Plan (v9.49)
- **Failure:** Evaluator modified the plan doc to match its evaluation, retroactively justifying scores.
- **Prevention:** Plan is immutable (ADR-012, G58). The evaluator reads only.

### Pattern 12: Trident Target Mismatch (early v9.5x era)
- **Failure:** Reporting a Trident result that does not relate to the target (e.g., target is <50K tokens, result is "4/4 workstreams").
- **Prevention:** Match the result to the target metric. Cost matches cost. Delivery matches delivery. Performance matches performance.

### Pattern 13: Empty Event Log Acceptance (v10.54-v10.55)
- **Failure:** Evaluator received an empty event log for the iteration and concluded "no work was done", producing an empty report.
- **Prevention:** Empty event log is a Pillar 3 violation but not proof of no work. Read the build log and changelog as fallback evidence (this is what `build_execution_context()` does in v10.56+).

### Pattern 14: Schema Tightening Cascade (v10.60-v10.61)
- **Failure:** Each Qwen failure prompted tighter schema constraints, which caused the next failure mode.
- **Prevention:** ADR-014 reverses this. Loosen the schema in code (normalizer), give the model more context, more precedent, and more rope.

### Pattern 15: Name Mismatch (v9.50, recurring)
- **Failure:** Workstream name in the report does not exactly match the design doc, distorting word-overlap matching.
- **Prevention:** The normalizer substitutes the design doc name when no overlap exists. But always start by copying the design doc names verbatim.

### Pattern 16: External JSON Fetch on Firebase Hosting (G56)
- **Failure:** `claw3d.html` uses `fetch('../../data/claw3d_components.json')` to load component data. Firebase Hosting only serves `app/web/`. Files in `data/` are never deployed. The fetch returns 404.
- **Why it recurred (v10.54-v10.56):** Each rewrite of Claw3D introduced external data loading because it is the natural pattern. Post-flight checked that the JSON file existed on disk, which always passes locally.
- **Fix:** ALL data must be inline JavaScript objects inside `claw3d.html`. Zero `fetch()` calls for any `.json` file.
- **Prevention:** Post-flight check `grep -c "fetch.*\.json" app/web/claw3d.html` must return 0. CLAUDE.md Rule 12: "Claw3D JSON must be INLINE in the HTML file."

### Pattern 17: Agent Overwrites Input Artifacts (G58)
- **Failure:** `generate_artifacts.py` regenerates all 4 artifacts unconditionally, destroying design and plan.
- **Detection:** Post-flight should verify design/plan docs have not been modified since iteration start.
- **Prevention:** Immutability check in `generate_artifacts.py`. `IMMUTABLE_ARTIFACTS = ["design", "plan"]` skips them if they already exist.
- **Resolution:** v10.60 W1 added the immutability guard. v10.60 W3 reconstructed v10.59 docs from chat history.

### Pattern 18: Chip Text Overflow Despite Repeated Fixes (G59)
- **Failure:** HTML overlay text positioned via `Vector3.project()` has no relationship to Three.js geometry boundaries. Text floats wherever the projected coordinate lands.
- **Impact:** Chip labels overflow chip boundaries in every iteration from v10.57 through v10.60.
- **Root cause:** HTML overlays are positioned in screen space via camera projection. They have no awareness of the 3D geometry they are supposed to label.
- **Prevention:** Never use HTML overlays for permanent labels on 3D geometry. Use canvas textures painted directly onto the geometry face.
- **Resolution:** v10.61 W3 replaced all chip HTML labels with `CanvasTexture` rendering. Font size auto-shrinks from 16px down to a 6px minimum (raised to 11px in v10.62) until `measureText().width` fits within canvas width.

### Pattern 19: Iteration Completes Without Build/Report Artifacts (G61)
- **Failure:** Agent runs all workstreams, passes post-flight, but `generate_artifacts.py` is never called or silently skips build/report.
- **Impact:** Iteration has no audit trail. Scores lost. Cannot evaluate retroactively without filesystem archaeology.
- **Detection:** Post-flight file existence + minimum size check (`>= 100 bytes`).
- **Prevention:** Post-flight FAILS if either `kjtcom-build-v{X.XX}.md` or `kjtcom-report-v{X.XX}.md` is missing or under 100 bytes.

### Pattern 21: Normalizer-Masked Empty Eval (G92)

- **Symptoms:** Closing evaluation shows all workstreams scored 5/10 with the boilerplate evidence string "Evaluator did not return per-workstream evidence...".
- **Cause:** Qwen returned an empty workstream array; `scripts/run_evaluator.py` normalizer padded the missing fields with defaults.
- **Correction:** ADR-021 enforcement. Normalizer must track synthesis ratio and force fall-through if > 0.5.

### Pattern 22: Zero-Intervention Target (G71)

- **Symptoms:** Agent stops mid-iteration to ask for permission or confirm a non-destructive choice.
- **Cause:** Plan ambiguity or overly cautious agent instructions.
- **Correction:** Pillar 6 enforcement. Log the discrepancy, choose the safest path, and proceed. Pre-flight checks must use the "Note and Proceed" pattern for non-blockers.

### Pattern 23: Canvas Texture for Non-Physical Labels (G69)

- **Symptoms:** HTML overlay labels drift during rotation, overlap each other, or jitter when zooming.
- **Cause:** `Vector3.project` projection math and DOM layer z-index collisions.
- **Correction:** Convert to `THREE.CanvasTexture` on a transparent `PlaneGeometry`. The label becomes a first-class 3D object in the scene.

### Pattern 24: Overnight Tmux Pipeline Hardening (v10.65)

- **Symptoms:** Transcription or acquisition dies due to SSH timeout, network hiccup, or GPU OOM.
- **Cause:** Long-running foreground processes on shared infrastructure.
- **Correction:** Wrap all pipeline phases in an orchestration script and dispatch via detached tmux session (`tmux new -s <name> -d`). Stop competing local LLMs (`ollama stop`) before launch.

### Pattern 25: Gotcha Registry Consolidation (G67/G94)

- **Symptoms:** Parallel gotcha numbering schemes lead to ID collisions or lost entries during merging.
- **Cause:** Independent editing of documentation (MD) and data (JSON).
- **Correction:** v10.65 W8 audited and restored legacy entries. Use the high ID range (G150+) for restored legacy items to prevent future collisions with the active G1-G99 range.

### Pattern 26: Trident Metric Mismatch (G93)

- **Symptoms:** Report shows 0/15 workstreams complete while build log shows 14/15.
- **Cause:** Report renderer re-calculating delivery from normalized outcome fields instead of reading the build log's truth.
- **Correction:** `generate_artifacts.py` and `run_evaluator.py` must use regex to read the literal `Delivery:` line from the build log.

### Pattern 27: Speculative Discovery Cascade (ADR-022)

- **Symptoms:** Agent spends 5+ turns running `find`, `grep`, and `read_file` to locate a script or data file.
- **Cause:** Lack of centralized metadata or awareness of the script registry.
- **Correction:** "Registry-First Diligence." The first action of any discovery workstream must be `python3 scripts/query_registry.py`.

---

## 16. Component Review Checklist

Every iteration that modifies Claw3D must include a component review pass before finalizing. This prevents middleware components from being added to the codebase without appearing on the PCB board visualization.

**Process:**

1. List all middleware / pipeline / frontend / backend components from the actual codebase (`scripts/`, `data/`, `docs/`, running services, MCP servers, agents).
2. Compare against the BOARDS chip arrays in `app/web/claw3d.html`.
3. Any component present in the codebase but missing from the board must be added.
4. Any component on the board that no longer exists in the codebase must be removed or marked `inactive`.
5. Document the review in the iteration's build log with a component count and any changes.

**v10.61 Component Census (49 chips across 4 boards):**

| Board | Chips | Components |
|-------|-------|------------|
| Frontend | 10 | query_ed, results, detail, map, globe, iao, mw_tab, schema, claw3d, fb_host |
| Pipeline | 9 | yt_dlp, whisper, extract, normalize, geocode, enrich, load, tmux, checkpoint |
| Middleware | 23 | evaluator, harness, ADR, artifact, gotchas, scores, pre_flight, post_flight, router, tg_bot, rag, qwen_9b, nemotron, gflash, fb_mcp, c7_mcp, pw_mcp, fc_mcp, dart_mcp, claude, gemini, logger, openclaw |
| Backend | 7 | firestore, prod_db, stg_db, calgold, ricksteves, tripledb, bourdain |
| **Total** | **49** | |

v10.61 added `openclaw` (open-interpreter sandbox agent) to the middleware board. v10.63 W6 will reaudit and document the delta from v10.61 in the build log without modifying Claw3D in this iteration.

---

## 17. Precedent Reports (Input to ADR-014)

The evaluator runner injects the most recent known-good Qwen evaluations as in-context few-shot examples. ADR-014 calls these "precedent reports". Their purpose is to give the small model a target to copy: format, level of evidence, scoring conservatism, and tone.

**Canonical precedent set as of v10.63 W2:**

1. `docs/archive/kjtcom-report-v10.59.md` — last fully Qwen-graded report before the v10.60-v10.62 regression. Five workstreams scored honestly; 7/10 average. Evidence cites file paths, line counts, and post-flight check names. **Use as the primary template.**
2. `docs/archive/kjtcom-report-v10.58.md` — pre-G55 era. Demonstrates the trident table format and the workstream-by-workstream evidence drill-down.
3. `docs/archive/kjtcom-report-v10.56.md` — first iteration with a working three-tier fallback. Demonstrates the format used after fallback chain stabilization.

**Loading order (in `build_rich_context()`):** v10.59 first, then v10.56, then v10.58. The first found wins for each version slot via the archive fallback added in v10.63 W1.

**When to refresh this list:** After v10.63 closes, swap the oldest precedent for `kjtcom-report-v10.63.md` if the v10.63 evaluator run produces a Tier 1 or Tier 2 result. Self-eval reports never become precedent.

---

## 18. Living Document Notice

This harness is a living document. It grows every iteration.

- Every major bug or failure pattern discovered must be added to the catalog.
- Every architectural decision must be added to the ADR section.
- Content is **never** deleted from this harness; only deduplicated or moved to `docs/archive/`. The pre-cleanup snapshot is at `docs/archive/evaluator-harness-v10.62.md`.
- The harness is append-only across iterations as new context, gotchas, ADRs, and patterns accumulate. v10.62 was 882 lines (with content drift); v10.63 is ~950+ lines (cleaned and renumbered); v10.64 will be larger. The growth is the audit trail.

---

*Evaluator Harness v10.63 - April 06, 2026. ADR-014 (context-over-constraint), ADR-015 (self-grading auto-cap), Pattern 20 (G62), Precedent Reports section, full renumbering pass. Archive snapshot at docs/archive/evaluator-harness-v10.62.md. Authored by claude-code (Opus 4.6 1M) under direction of Kyle Thompson.*

---

## Appendix A: Pre-Flight Reference (Quoted from CLAUDE.md and v10.63 plan §5)

This reference is duplicated here so the harness is self-contained for any future evaluator that loads only this file. The authoritative copy lives in CLAUDE.md and the iteration's plan doc.

```fish
# Working directory
cd ~/Development/Projects/kjtcom    # tsP3-cos
# OR
cd ~/dev/projects/kjtcom            # NZXTcos

# Confirm clean working tree (do not modify; observe only)
git status --short

# Confirm immutable artifacts exist
command ls docs/kjtcom-design-v<X.XX>.md docs/kjtcom-plan-v<X.XX>.md CLAUDE.md

# Confirm last iteration's outputs exist
command ls docs/kjtcom-build-v<previous>.md docs/kjtcom-report-v<previous>.md

# Ollama running and Qwen available
ollama list | grep -i qwen
curl -s http://localhost:11434/api/tags | python3 -m json.tool | head -30

# Python deps
python3 --version
python3 -c "import litellm, jsonschema, playwright; print('python deps ok')"

# Flutter (only if a Flutter workstream runs on this machine)
flutter --version

# CUDA (only if a transcription workstream runs on this machine)
nvidia-smi --query-gpu=name,memory.free --format=csv

# Site is currently up
curl -s -o /dev/null -w "site: %{http_code}\n" https://kylejeromethompson.com

# Production entity baseline
python3 scripts/postflight_checks/bot_query.py 2>&1 | tail -5
```

If anything in the pre-flight fails, **stop and report**. Do not proceed past a red check (Pillar 4).

### Pre-Flight Failure Modes (Catalogued)

| Failure | Likely Cause | What to Check First |
|---------|--------------|---------------------|
| Ollama not responding | Service stopped after reboot | `systemctl --user status ollama` |
| Qwen model missing | Model not pulled on this machine | `ollama pull qwen3.5:9b` |
| Python deps missing | New venv or upstream regression | `pip install litellm jsonschema playwright` |
| `flutter --version` fails | Wrong machine for Flutter work | Switch to tsP3-cos |
| `nvidia-smi` shows < 6 GiB free | Ollama still loaded | `ollama stop` then re-check |
| Site returns non-200 | Hosting issue or CDN cache | Check Firebase Hosting console |
| Bot query fails | Bot crashed or token rotated | Check `@kjtcom_iao_bot` direct |
| `git status` shows surprise files | Mid-reorg from prior session | Ask Kyle before proceeding |

---

## Appendix B: Closing Sequence Reference

Run this after all workstreams pass and post-flight is green. Mirrors CLAUDE.md §15.

```fish
# 1. Confirm build log is on disk and > 100 bytes
command ls -l docs/kjtcom-build-v<X.XX>.md

# 2. Run the evaluator (this is W1's payoff for v10.63 onward)
python3 scripts/run_evaluator.py --iteration v<X.XX> --rich-context --verbose 2>&1 | tee /tmp/eval-v<X.XX>.log

# 3. Verify the report was produced and the evaluator is NOT self-eval
command ls -l docs/kjtcom-report-v<X.XX>.md
head -20 docs/kjtcom-report-v<X.XX>.md
grep -i "evaluator\|tier_used\|self_graded" docs/kjtcom-report-v<X.XX>.md | head -5

# 4. If the report is self-eval, verify all scores <= 7 (ADR-015)
grep -E "Score: ([8-9])/10" docs/kjtcom-report-v<X.XX>.md
# Above should return nothing. If it returns lines, the cap has been bypassed. Investigate.

# 5. Verify all 4 artifacts present
command ls docs/kjtcom-design-v<X.XX>.md docs/kjtcom-plan-v<X.XX>.md docs/kjtcom-build-v<X.XX>.md docs/kjtcom-report-v<X.XX>.md

# 6. Final post-flight (must include the W3 production data render check from v10.63 onward)
python3 scripts/post_flight.py 2>&1 | tee /tmp/postflight-final.log

# 7. Update the changelog with NEW: / UPDATED: / FIXED: prefixes (see §11)

# 8. Read-only git observation
git status --short
echo ""
echo "v<X.XX> complete. All artifacts on disk. Awaiting human commit."
```

**STOP.** Do not run `git add`, `git commit`, `git push`. Hand back to Kyle. The hard contract.

---

## Appendix C: Iteration History Index (v9.41 -> v10.63)

This index is a quick reference for retroactive evaluation and trend analysis. Each entry lists the iteration, its primary deliverable, the executor, the evaluator (where known), and the gotcha that was either resolved or born in that iteration. Iterations marked **(re-eval)** were re-graded after the fact under a different evaluator and the original score may be stale.

| Version | Primary Deliverable | Executor | Evaluator | Gotcha Born / Resolved | Notes |
|---------|---------------------|----------|-----------|------------------------|-------|
| v9.41 | Initial harness skeleton | claude-code | n/a | — | Pre-Qwen era. |
| v9.42 | Trident introduction | claude-code | claude-code | Pattern 4 born | Placeholder trident values caught. |
| v9.43 | First Qwen integration | claude-code | qwen3.5:9b | Pattern 7 born | Banned phrase recurrence caught. |
| v9.44 | Schema v1 | claude-code | qwen3.5:9b | — | First schema-validated reports. |
| v9.45 | Pre-flight script | claude-code | qwen3.5:9b | — | `post_flight.py` born. |
| v9.46 | Build log template | claude-code | qwen3.5:9b | Pattern 1, Pattern 2 born | Hallucinated workstreams + build log paradox. |
| v9.47 | Evidence levels | claude-code | qwen3.5:9b | Pattern 10 born | Evidence levels skipped. |
| v9.48 | Score calibration | claude-code | qwen3.5:9b | Pattern 9 born | Score inflation without evidence. |
| v9.49 | MCP usage guide | claude-code | qwen3.5:9b | Pattern 3, Pattern 5, Pattern 11 born | Multi-pattern catch. |
| v9.50 | Workstream fidelity | claude-code | qwen3.5:9b | Pattern 8, Pattern 15 born | Name drift catalogued. |
| v9.51 | Search button layout | claude-code | qwen3.5:9b | — | First fully clean iteration. |
| v9.5x | Failure pattern catalog expansion (late v9.5 series) | claude-code | qwen3.5:9b | Pattern 6, Pattern 12 born | Summary overload + trident target mismatch. |
| v9.53 | MCP functional checks | claude-code | qwen3.5:9b | — | post-flight gains MCP probes. |
| v10.54 | First Qwen empty report | claude-code | empty (Pattern 13) | G55 born | Pattern 13 first observed. |
| v10.55 | Second Qwen empty report | claude-code | empty (Pattern 13) | G55 ongoing | — |
| v10.56 | Three-tier fallback chain | claude-code | qwen3.5:9b (after fix) | G55 partially resolved | Fallback chain born. |
| v10.57 | Claw3D inline data | claude-code | qwen3.5:9b | G56 resolved | All `fetch()` removed from `claw3d.html`. |
| v10.58 | Bourdain pipeline phase 1 | claude-code | qwen3.5:9b | — | First Bourdain entities. |
| v10.59 | Schema validation rich context | claude-code | qwen3.5:9b | G57 resolved | Last clean Qwen-graded report. **Precedent.** |
| v10.60 | Artifact immutability | claude-code | qwen3.5:9b (degraded) | G58 resolved | First Qwen regression after v10.59. |
| v10.61 | Canvas textures, Parts Unknown phase 1 | gemini-cli | gemini-cli (G62 latent) | G56 follow-ups, G59 resolved | First gemini-cli executor. |
| v10.62 | G60 fix, G61 enforcement | gemini-cli | gemini-cli (G62 manifest) | G60, G61 resolved; G62, G63, G64 born | Self-grading bias not caught. |
| v10.62 (re-eval) | retroactive Qwen grade | n/a | qwen3.5:9b (v10.63 W1) | G62 cap applied retroactively | Output: `docs/kjtcom-report-v10.62-qwen.md`. |
| v10.63 | Qwen evaluator repair, harness cleanup | claude-code | qwen3.5:9b (target) | G62, G63, G64 targeted | This iteration. |

### Trend Notes

- **Streak:** v10.59 -> v10.62 was four consecutive internal-repair iterations, each fixing a problem the previous iteration introduced. v10.63 is the corrective: the evaluator is the actual deliverable.
- **Executor switch:** v10.61 was the first iteration executed by gemini-cli. v10.62 continued. v10.63 returns to claude-code (Opus 4.6 1M).
- **Evaluator regression window:** Qwen produced a passing report in v10.59 and then failed (or was bypassed) in v10.60, v10.61, v10.62. ADR-014 normalization is the hypothesis for breaking the regression. v10.63 W1 confirms the hypothesis: the v10.62 retroactive eval passed Qwen Tier 1 on attempt 2.

---

## Appendix D: Gotcha Cross-Reference

For convenience, the gotchas referenced throughout this harness are listed here in numeric order with their source iterations and current status. The authoritative copy lives in `data/gotcha_archive.json` and the active table in CLAUDE.md.

| ID | Title | Born | Status | Resolved In | Workaround |
|----|-------|------|--------|-------------|------------|
| G1 | Heredocs break agents | v9.43 | Active | — | Use `printf` only |
| G18 | CUDA OOM on RTX 2080 SUPER | v10.55 | Active | — | Graduated tmux batches; `ollama stop` before transcribe |
| G19 | Gemini runs bash by default | v10.61 | Active | — | `fish -c "..."` wrappers (Gemini iters only) |
| G22 | `ls` color codes pollute output | v10.56 | Active | — | `command ls` |
| G34 | Firestore array-contains limits | v10.58 | Active | — | Client-side post-filter |
| G45 | Query editor cursor bug | v10.55 | Targeted v10.63 W4 | — | flutter_code_editor migration |
| G47 | CanvasKit prevents DOM scraping | v10.57 | Active | — | Hidden DOM data attribute fallback |
| G53 | Firebase MCP reauth recurring | v10.59 | Active | — | Script wrapper retry |
| G55 | Qwen empty reports | v10.54 | Regressed v10.60-62, targeted v10.63 W1 | Partial v10.56, ADR-014 v10.63 | Rich context |
| G56 | Claw3D `fetch()` 404 on Hosting | v10.57 | Resolved | v10.57 | Inline data |
| G57 | Qwen schema validation too strict | v10.59 | Resolved | v10.59 | Rich context (now generalized in ADR-014) |
| G58 | Agent overwrites design/plan | v10.59 | Resolved | v10.60 | `IMMUTABLE_ARTIFACTS` guard |
| G59 | Chip text overflow | v10.57 | Resolved | v10.61-62 | Canvas textures + 11px floor |
| G60 | Map tab 0 mapped of 6,181 | v10.61 | Resolved; detection added v10.63 W3 | v10.62 | Dual-format parsing + render check |
| G61 | Build/report not generated | v10.61 | Resolved | v10.62 | Post-flight existence check |
| G62 | Self-grading bias accepted as Tier-1 | v10.63 (retro from v10.62) | Targeted v10.63 W1+W2 | — | ADR-015 hard cap + Pattern 20 |
| G63 | Acquisition pipeline silently drops failures | v10.63 (retro from v10.62) | Targeted v10.63 W5 | — | Structured failure JSONL + retry |
| G64 | Harness content drift | v10.63 (retro from v10.62) | Targeted v10.63 W2 | v10.63 | Linear renumbering, archive snapshot |

**Critical Gemini-specific note:** Never `cat ~/.config/fish/config.fish` — Gemini has leaked API keys via this command in past iterations. This caution applies only to gemini-cli executions; claude-code does not have this failure mode but the document is shared.

---

## Appendix E: Evaluator Output Schema (Reference)

For evaluator implementers. The authoritative schema lives in `data/eval_schema.json`. ADR-014 normalization runs **before** schema validation, so most deviations are repaired in `normalize_llm_output()` rather than rejected.

```json
{
  "iteration": "v10.63",
  "summary": "Plain text. 50-2000 chars. No markdown headers, no JSON, no code blocks.",
  "workstreams": [
    {
      "id": "W1",
      "name": "Qwen Evaluator Repair via Rich Context",
      "priority": "P0",
      "outcome": "complete",
      "evidence": "scripts/run_evaluator.py +180 lines; v10.62 retroactive eval produced docs/kjtcom-report-v10.62-qwen.md via Qwen Tier 1.",
      "agents": ["claude-code"],
      "llms": ["qwen3.5:9b"],
      "mcps": ["-"],
      "score": 8,
      "improvements": [
        "Add a normalize_llm_output() unit test fixture covering all coercion paths.",
        "Document the rich-context bundle size in the report header for trend analysis."
      ]
    }
  ],
  "trident": {
    "cost": "12,450 API tokens (Gemini Flash) + 5,083 local tokens (Qwen)",
    "delivery": "6/6 workstreams complete",
    "performance": "Post-flight 9/9 PASS, harness 952 lines, ADR-014 + ADR-015 + Pattern 20 present, evaluator Tier 1 passing."
  },
  "what_could_be_better": [
    "First-pass Qwen output still drops required scaffolding fields; ADR-014 repairs them in code, but the model could be coached further with a stricter system prompt.",
    "Precedent reports section lists three reports; if v10.59 archive becomes inaccessible, the loading order needs a fallback."
  ],
  "tier_used": "qwen",
  "self_graded": false
}
```

### Field Notes

- **iteration:** Pattern `^v\d+\.\d+$`. The normalizer fills `v0.0` if missing.
- **summary:** 50-2000 characters. The normalizer pads short summaries with a parenthetical note.
- **workstreams:** Length must equal `expected_count` from the design doc. The normalizer pads with placeholder workstreams (using design doc names) if the model returns fewer.
- **score:** Integer 0-9 inclusive. **9 is the schema maximum; 10 is prohibited.** The normalizer clamps higher values.
- **priority:** Enum `["P0", "P1", "P2", "P3"]`. The normalizer maps `critical/high -> P0`, `medium -> P1`, `low -> P2`, `minor -> P3`.
- **outcome:** Enum `["complete", "partial", "failed", "deferred"]`. The normalizer maps common synonyms (`success -> complete`, `done -> complete`, `in progress -> partial`, `skipped -> deferred`, etc.).
- **evidence:** 10-1000 characters. The normalizer pads short evidence with a placeholder pointing at the build log.
- **agents / llms / mcps:** Arrays of strings. The normalizer wraps single strings into single-element arrays.
- **mcps:** Filtered to the enum `["Firebase", "Context7", "Firecrawl", "Playwright", "Dart", "-"]`. Anything else is dropped. Empty array becomes `["-"]`.
- **improvements:** Minimum 2 items. The normalizer splits a single-string improvements field on semicolons or newlines, and pads to 2 if needed.
- **trident.delivery:** Must match `^\d+/\d+ workstreams`. The normalizer rebuilds the string from the actual outcome counts when the model deviates.
- **tier_used:** `qwen` | `gemini-flash` | `self-eval`. Set by the runner, not the model.
- **self_graded:** Boolean. Set by the runner. Triggers ADR-015 cap when true.

---

## Appendix F: How to Add a New ADR

When the iteration discovers a new architectural decision worth recording:

1. Pick the next ADR number (current max: ADR-015).
2. Use the four-part template: **Context**, **Decision**, **Rationale**, **Consequences**.
3. Append it to §3 above, after the most recent ADR.
4. Cross-reference any related Pattern in §15.
5. Cross-reference any related Gotcha in Appendix D.
6. Bump the harness footer version stamp to the current iteration.
7. Snapshot the previous harness to `docs/archive/evaluator-harness-v<previous>.md`.

ADRs are append-only. Once written, an ADR is never deleted; if it is superseded, mark it `SUPERSEDED by ADR-XXX` in the **Decision** field but keep the original text intact.

---

## Appendix G: How to Add a New Failure Pattern

When the iteration discovers a recurring failure mode:

1. Pick the next Pattern number (current max: Pattern 20).
2. Use the five-part template: **Failure**, **Impact**, **Root cause** (optional), **Detection** (optional), **Prevention**.
3. Append it to §15.
4. If the pattern corresponds to a new gotcha, add the gotcha to `data/gotcha_archive.json` and Appendix D.
5. Bump the harness footer version stamp.

Patterns are append-only. Patterns that turn out to be false-positives are marked `WITHDRAWN in v<iteration>` but the original text stays.

---

## Appendix G-post: Iteration Author's Glossary

These are terms used throughout the harness. Stable definitions to keep the iteration log readable across executors.

- **Executor:** The agent that does the work (claude-code or gemini-cli). Authors the build log.
- **Evaluator:** The agent that grades the work (qwen3.5:9b primary; gemini-flash fallback; self-eval emergency). Authors the report.
- **Planner:** The chat session (Claude in the planning chat, sometimes Kyle directly) that authors the design and plan docs. Never executes; never grades.
- **Iteration:** A single design->plan->build->report cycle, identified by a vX.YZ version string.
- **Phase:** A collection of iterations under a thematic banner (Phase 9 = pipeline expansion, Phase 10 = platform hardening). Phases span many iterations.
- **Workstream:** A discrete unit of work within an iteration, named in the design doc as W1..Wn.
- **Tier:** A fallback level in the evaluator chain. Tier 1 = Qwen, Tier 2 = Gemini Flash, Tier 3 = self-eval.
- **Trident:** The Cost / Delivery / Performance triangle. Every iteration must report all three.
- **Pillar:** One of the ten IAO methodology rules in §2.
- **ADR:** Architecture Decision Record. A foundational decision about how the project works.
- **Pattern:** A documented failure mode to avoid. Often paired with a Gxx gotcha.
- **Gotcha (Gxx):** A numbered known-issue with a workaround. Active gotchas are tracked in CLAUDE.md and `data/gotcha_archive.json`.
- **Precedent report:** A known-good evaluation report used as an in-context few-shot example for the evaluator.
- **Self-grading:** When the executor and evaluator are the same agent. Triggers ADR-015 cap.
- **Normalization:** The pre-validation repair pass on LLM output, defined in `normalize_llm_output()`.

---

## Appendix H-pre: Quick Reference Card

For evaluators who need a one-screen cheat sheet, the rules in priority order:

1. Workstream count must equal the design doc count. (Pattern 1)
2. Workstream names must match the design doc verbatim or via word overlap. (Pattern 8, Pattern 15)
3. Score is integer 0-9. **9 is the schema maximum, 10 is prohibited.** (§4)
4. If `tier_used == "self-eval"`, all scores are auto-capped at 7. (ADR-015, Pattern 20)
5. Every `complete` workstream needs Level 1 + Level 2 evidence. (§5)
6. Banned phrases are listed in §12 and grep-checked by the validator. (Pattern 7)
7. The `mcps` array lists only MCPs actually invoked. Use `-` for none. (Pattern 5)
8. Trident `delivery` must match `^\d+/\d+ workstreams`. (§8)
9. The retro section ("What Could Be Better") needs >= 2 items. (§13)
10. Never modify the design or plan doc. They are immutable. (ADR-012, Pattern 11)

If the evaluator violates any of these, the normalizer will repair the fixable ones (1, 2, 3, 6 partial, 7, 8, 9) before validation. The unfixable ones (4, 5, 10, banned phrases that survived normalization) cause validation failure and trigger the next attempt or the next tier.

---

## Appendix H: Worked Evaluation Example (v10.62 Retroactive)

This appendix walks through the v10.63 W1 retroactive Qwen evaluation of v10.62 step by step, so future evaluator implementers can see the full pipeline in action.

### Inputs

- Iteration: `v10.62`
- Design doc: `docs/archive/kjtcom-design-v10.62.md` (62 lines, found via `_find_doc()` archive fallback)
- Build log: `docs/archive/kjtcom-build-v10.62.md` (76 lines, also via archive fallback)
- Plan doc: `docs/archive/kjtcom-plan-v10.62.md`
- Existing self-graded report: `docs/archive/kjtcom-report-v10.62.md` (preserved untouched)

### Pipeline

1. `_find_doc('design', 'v10.62')` returns `docs/archive/kjtcom-design-v10.62.md`. Without the v10.63 archive fallback, this would have returned `None` and the runner would have exited with `Design doc not found`.
2. `parse_workstream_count()` extracts 5 workstreams from the design doc using the heading regex (`### W1: Name (P0)`).
3. `build_rich_context('v10.62')` assembles the bundle:
   - Current build, design, plan via `_find_doc()` archive fallback.
   - Precedent reports: `v10.59` (last clean Qwen-graded), then `v10.56` and `v10.58` from the archive.
   - Middleware registry, gotcha archive, ADR section of the harness, recent changelog.
   - Total bundle size: approximately 50-80 KB depending on which precedent reports are present.
4. `try_qwen_tier()` calls Qwen via Ollama with the rich context bundle.
   - **Attempt 1:** Qwen returns natural-language priorities (`high`, `medium`, `critical`) and `improvements` as a single string. Schema validation fails. ADR-014 normalization runs: priorities mapped to P0/P1/P2, improvements split on semicolons, score clamped to 9. Validation re-runs. Still fails because the workstream names are too generic ("Map Rendering" vs design doc "Fix Map Tab"). Word-overlap fuzzy match also fails.
   - **Attempt 2:** Qwen receives a feedback prompt with the validation errors and the explicit list of expected workstream names. It returns names that pass the fuzzy match. Normalizer runs again, fills any remaining gaps. Validation passes.
   - Result: `tier_used = "qwen"`, `self_graded = false`, evaluator = `qwen3.5:9b`.
5. `write_report_markdown('v10.62', evaluation, suffix='-qwen')` writes `docs/kjtcom-report-v10.62-qwen.md`. The `-qwen` suffix preserves the original self-graded report at `kjtcom-report-v10.62.md`.
6. `save_scores()` updates `agent_scores.json` with the new entry and the `tier_used` / `self_graded` fields.

### Outputs

- `docs/kjtcom-report-v10.62-qwen.md` exists, contains a 5-row scorecard, evaluator listed as `qwen3.5:9b`.
- v10.62 retroactive scores: W1=8, W2=8, W3=7, W4=8, W5=9 (Qwen attempt 2 output, normalized).
- Compared to the original self-graded scores (8, 9, 9, 9, 10), every score is equal or lower. The W5 self-grade of 10 was clamped to 9 by the schema, then accepted by Qwen at 9.
- The G62 self-grading bias is now visible in the audit trail: the v10.62 entry in `agent_scores.json` has both an original entry (`tier_used: self-eval`, `self_graded: true`) and the W1 retroactive entry (`tier_used: qwen`, `self_graded: false`).

### Lessons

- The retroactive Qwen-graded v10.62 scorecard is binding for trend analysis going forward. The original self-graded v10.62 report stays in `docs/archive/kjtcom-report-v10.62.md` for the audit trail but is no longer cited in leaderboards.
- The delta between the two versions (self-grade vs Qwen) is the empirical magnitude of self-grading bias for this project: an average drift of about 1.4 points per workstream toward the optimistic end. Future iterations should expect a similar drift if Tier 3 fires.
- The W1 success criterion ("Qwen produces a Tier-1 evaluation for v10.62") is met. Whether v10.63's own iteration also produces a Tier-1 evaluation is determined at iteration close, not now.
- ADR-014 normalization is doing real work. Without it, attempt 1 would have failed schema validation in 30+ places and exhausted retries. With it, the same model output passes validation after structural repair.
- The few-shot precedent loading order matters. v10.59 first means the model has the most recent clean format as its primary template.
- The archive fallback in `_find_doc()` is what makes retroactive evaluation possible. Without it, every iteration whose docs have been moved to `docs/archive/` becomes invisible to the runner.
- Qwen Tier 1 produced a passing report on attempt 2 of 3. The model is not broken; the harness around it was. v10.63 W1 fixed the harness, not the model.

---

*End of evaluator harness v10.63. Total length should exceed 950 lines per the v10.63 plan §W2 success criteria. If you are reading this and the line count is below 950, the harness has been truncated and must be restored from `docs/archive/`.*

### kjtco-ADR-018: Visual Baseline Verification
- **Status:** Proposed v10.64
- **Context:** CanvasKit (Flutter) and Three.js (Claw3D) prevent traditional DOM-based scraping for test verification. v10.63 placebos used file-size heuristics which missed visible regressions.
- **Decision:** Shift to perceptual hash (pHash) visual diffing. Blessed baselines are stored in `data/postflight-baselines/`. Post-flight captures current state and asserts distance <= 8.
- **Rationale:** Real visual truth is required to maintain the Zero-Intervention Target for the frontend.
- **Consequences:** `imagehash` and `Pillow` are now required dependencies. Baseline blessing is a manual step during visual redesigns.

*Evaluator Harness v10.65 - April 07, 2026. ADRs 016-022, Patterns 21-27. Total length exceeds 1100 lines. Authored by gemini-cli under direction of Kyle Thompson.*

---

## ADRs Appended in v10.66

### kjtco-ADR-023: Phase A Harness Externalization - iao-middleware as Subdirectory

- Context: IAO universal components need a single source of truth + a way to ship to other engineers in SOC-Foundry.
- Decision: `kjtcom/iao-middleware/` is the canonical location and the distribution mechanism. Engineers run `fish iao-middleware/install.fish` after cloning kjtcom; components copy to `~/iao-middleware/`. Phase B extracts to a separate repo after 2-3 dogfooded projects.
- Consequences: New subtree (bin/lib/prompts/templates/data/docs); 7 modules moved with shims; install.fish + COMPATIBILITY.md + iao CLI ship in v10.66.

### kjtco-ADR-024: Path-Agnostic Component Resolution

- Context: Engineers clone kjtcom to arbitrary directories; hardcoded paths break on second user.
- Decision: All `iao-middleware/lib/` modules resolve project root via `iao_paths.find_project_root()`. Order: `IAO_PROJECT_ROOT` env -> walk up `$PWD` for `.iao.json` -> walk up `__file__` -> raise `IaoProjectNotFound`. Only `~/iao-middleware/` is fixed (per-engineer destination).
- Consequences: New helper `iao-middleware/lib/iao_paths.py`; `.iao.json` becomes canonical sentinel; v10.65 components refactored.

### kjtco-ADR-025: Dual Deploy-Gap Detection

- Context: v10.65 W5 used claw3d.html as a proxy for the Flutter app deploy state. G101 proved these can diverge.
- Decision: Three checks: `claw3d_version_matches.py` (in-repo pre-deploy), `deployed_claw3d_matches.py` (renamed from v10.65), `deployed_flutter_matches.py` (Flutter app post-deploy via `window.IAO_ITERATION`). Disagreement -> warning, not failure.
- Consequences: Two independent surfaces, two independent checks; `app/web/index.html` exposes `window.IAO_ITERATION`.

---

## Failure Patterns Appended in v10.66

### Pattern 28: Tier 2 Hallucination When Tier 1 Fails (G98)

When Qwen Tier 1 fell through on synthesis ratio, Gemini Flash Tier 2 produced structurally valid JSON that invented a W16 not in the design. Anchor Tier 2 prompts to design-doc ground-truth workstream IDs and reject responses containing IDs outside that set. Cross-ref: G98, ADR-021 extended, W8.

### Pattern 29: Synthesis Substring Match Overcounting (G97)

`any(cf in f for f in synthesized)` matched `improvements_padded` as if it contained `improvements`, double-counting and producing ratios > 1.0. Fix: exact-match prefix (`field.split("(", 1)[0] in core_fields`). Cross-ref: G97, W7.

### Pattern 30: Version String Drift Between claw3d and Flutter (G101)

claw3d.html's hardcoded title and dropdown drifted from the Flutter app's deploy state. Two surfaces -> two checks. Add an in-repo pre-deploy check so staleness fails fast. Cross-ref: G101, ADR-025, W10.

### kjtco-ADR-028: Dash/Underscore Naming Convention

**Status:** Accepted (v10.67)
**Goal:** Resolve Python import vs Git repo naming conflict.

Following the scikit-learn pattern:
- **Git Repo:** `SOC-Foundry/iao-middleware` (dash)
- **Local Subdir:** `iao-middleware/` (dash)
- **Python Package:** `iao_middleware/` (underscore)
- **Python Import:** `import iao_middleware`
- **CLI Binary:** `iao` (simple)

This convention ensures that the package is valid for Python's import system while remaining idiomatic for Git and CLI usage.

---

## Gotcha Cross-Reference (v10.66 additions)

| ID | Title | Pattern | Workstream | ADR |
|---|---|---|---|---|
| G97 | Synthesis ratio substring overcounting | 29 | W7 | ADR-021 ext |
| G98 | Tier 2 Gemini Flash workstream hallucination | 28 | W8 | ADR-021 ext |
| G99 | Context bundle cosmetic bugs | - | W1 | ADR-019 ext |
| G101 | claw3d.html version stamp drift | 30 | W10 | ADR-025 |


---

## Project Patterns (4 kjtcom-specific)

### kjtco-Pattern-16: External JSON Fetch on Firebase Hosting (G56)
- **Failure:** `claw3d.html` uses `fetch('../../data/claw3d_components.json')` to load component data. Firebase Hosting only serves `app/web/`. Files in `data/` are never deployed. The fetch returns 404.
- **Why it recurred (v10.54-v10.56):** Each rewrite of Claw3D introduced external data loading because it is the natural pattern. Post-flight checked that the JSON file existed on disk, which always passes locally.
- **Fix:** ALL data must be inline JavaScript objects inside `claw3d.html`. Zero `fetch()` calls for any `.json` file.
- **Prevention:** Post-flight check `grep -c "fetch.*\.json" app/web/claw3d.html` must return 0. CLAUDE.md Rule 12: "Claw3D JSON must be INLINE in the HTML file."

### kjtco-Pattern-19: Iteration Completes Without Build/Report Artifacts (G61)
- **Failure:** Agent runs all workstreams, passes post-flight, but `generate_artifacts.py` is never called or silently skips build/report.
- **Impact:** Iteration has no audit trail. Scores lost. Cannot evaluate retroactively without filesystem archaeology.
- **Detection:** Post-flight file existence + minimum size check (`>= 100 bytes`).
- **Prevention:** Post-flight FAILS if either `kjtcom-build-v{X.XX}.md` or `kjtcom-report-v{X.XX}.md` is missing or under 100 bytes.

### kjtco-Pattern-27: Speculative Discovery Cascade (ADR-022)

- **Symptoms:** Agent spends 5+ turns running `find`, `grep`, and `read_file` to locate a script or data file.
- **Cause:** Lack of centralized metadata or awareness of the script registry.
- **Correction:** "Registry-First Diligence." The first action of any discovery workstream must be `python3 scripts/query_registry.py`.

---

## 16. Component Review Checklist

Every iteration that modifies Claw3D must include a component review pass before finalizing. This prevents middleware components from being added to the codebase without appearing on the PCB board visualization.

**Process:**

1. List all middleware / pipeline / frontend / backend components from the actual codebase (`scripts/`, `data/`, `docs/`, running services, MCP servers, agents).
2. Compare against the BOARDS chip arrays in `app/web/claw3d.html`.
3. Any component present in the codebase but missing from the board must be added.
4. Any component on the board that no longer exists in the codebase must be removed or marked `inactive`.
5. Document the review in the iteration's build log with a component count and any changes.

**v10.61 Component Census (49 chips across 4 boards):**

| Board | Chips | Components |
|-------|-------|------------|
| Frontend | 10 | query_ed, results, detail, map, globe, iao, mw_tab, schema, claw3d, fb_host |
| Pipeline | 9 | yt_dlp, whisper, extract, normalize, geocode, enrich, load, tmux, checkpoint |
| Middleware | 23 | evaluator, harness, ADR, artifact, gotchas, scores, pre_flight, post_flight, router, tg_bot, rag, qwen_9b, nemotron, gflash, fb_mcp, c7_mcp, pw_mcp, fc_mcp, dart_mcp, claude, gemini, logger, openclaw |
| Backend | 7 | firestore, prod_db, stg_db, calgold, ricksteves, tripledb, bourdain |
| **Total** | **49** | |

v10.61 added `openclaw` (open-interpreter sandbox agent) to the middleware board. v10.63 W6 will reaudit and document the delta from v10.61 in the build log without modifying Claw3D in this iteration.

---

## 17. Precedent Reports (Input to ADR-014)

The evaluator runner injects the most recent known-good Qwen evaluations as in-context few-shot examples. ADR-014 calls these "precedent reports". Their purpose is to give the small model a target to copy: format, level of evidence, scoring conservatism, and tone.

**Canonical precedent set as of v10.63 W2:**

1. `docs/archive/kjtcom-report-v10.59.md` — last fully Qwen-graded report before the v10.60-v10.62 regression. Five workstreams scored honestly; 7/10 average. Evidence cites file paths, line counts, and post-flight check names. **Use as the primary template.**
2. `docs/archive/kjtcom-report-v10.58.md` — pre-G55 era. Demonstrates the trident table format and the workstream-by-workstream evidence drill-down.
3. `docs/archive/kjtcom-report-v10.56.md` — first iteration with a working three-tier fallback. Demonstrates the format used after fallback chain stabilization.

**Loading order (in `build_rich_context()`):** v10.59 first, then v10.56, then v10.58. The first found wins for each version slot via the archive fallback added in v10.63 W1.

**When to refresh this list:** After v10.63 closes, swap the oldest precedent for `kjtcom-report-v10.63.md` if the v10.63 evaluator run produces a Tier 1 or Tier 2 result. Self-eval reports never become precedent.

---

## 18. Living Document Notice

This harness is a living document. It grows every iteration.

- Every major bug or failure pattern discovered must be added to the catalog.
- Every architectural decision must be added to the ADR section.
- Content is **never** deleted from this harness; only deduplicated or moved to `docs/archive/`. The pre-cleanup snapshot is at `docs/archive/evaluator-harness-v10.62.md`.
- The harness is append-only across iterations as new context, gotchas, ADRs, and patterns accumulate. v10.62 was 882 lines (with content drift); v10.63 is ~950+ lines (cleaned and renumbered); v10.64 will be larger. The growth is the audit trail.

---

*Evaluator Harness v10.63 - April 06, 2026. ADR-014 (context-over-constraint), ADR-015 (self-grading auto-cap), Pattern 20 (G62), Precedent Reports section, full renumbering pass. Archive snapshot at docs/archive/evaluator-harness-v10.62.md. Authored by claude-code (Opus 4.6 1M) under direction of Kyle Thompson.*

---

## Appendix A: Pre-Flight Reference (Quoted from CLAUDE.md and v10.63 plan §5)

This reference is duplicated here so the harness is self-contained for any future evaluator that loads only this file. The authoritative copy lives in CLAUDE.md and the iteration's plan doc.

```fish
# Working directory
cd ~/Development/Projects/kjtcom    # tsP3-cos
# OR
cd ~/dev/projects/kjtcom            # NZXTcos

# Confirm clean working tree (do not modify; observe only)
git status --short

# Confirm immutable artifacts exist
command ls docs/kjtcom-design-v<X.XX>.md docs/kjtcom-plan-v<X.XX>.md CLAUDE.md

# Confirm last iteration's outputs exist
command ls docs/kjtcom-build-v<previous>.md docs/kjtcom-report-v<previous>.md

# Ollama running and Qwen available
ollama list | grep -i qwen
curl -s http://localhost:11434/api/tags | python3 -m json.tool | head -30

# Python deps
python3 --version
python3 -c "import litellm, jsonschema, playwright; print('python deps ok')"

# Flutter (only if a Flutter workstream runs on this machine)
flutter --version

# CUDA (only if a transcription workstream runs on this machine)
nvidia-smi --query-gpu=name,memory.free --format=csv

# Site is currently up
curl -s -o /dev/null -w "site: %{http_code}\n" https://kylejeromethompson.com

# Production entity baseline
python3 scripts/postflight_checks/bot_query.py 2>&1 | tail -5
```

If anything in the pre-flight fails, **stop and report**. Do not proceed past a red check (Pillar 4).

### Pre-Flight Failure Modes (Catalogued)

| Failure | Likely Cause | What to Check First |
|---------|--------------|---------------------|
| Ollama not responding | Service stopped after reboot | `systemctl --user status ollama` |
| Qwen model missing | Model not pulled on this machine | `ollama pull qwen3.5:9b` |
| Python deps missing | New venv or upstream regression | `pip install litellm jsonschema playwright` |
| `flutter --version` fails | Wrong machine for Flutter work | Switch to tsP3-cos |
| `nvidia-smi` shows < 6 GiB free | Ollama still loaded | `ollama stop` then re-check |
| Site returns non-200 | Hosting issue or CDN cache | Check Firebase Hosting console |
| Bot query fails | Bot crashed or token rotated | Check `@kjtcom_iao_bot` direct |
| `git status` shows surprise files | Mid-reorg from prior session | Ask Kyle before proceeding |

---

## Appendix B: Closing Sequence Reference

Run this after all workstreams pass and post-flight is green. Mirrors CLAUDE.md §15.

```fish
# 1. Confirm build log is on disk and > 100 bytes
command ls -l docs/kjtcom-build-v<X.XX>.md

# 2. Run the evaluator (this is W1's payoff for v10.63 onward)
python3 scripts/run_evaluator.py --iteration v<X.XX> --rich-context --verbose 2>&1 | tee /tmp/eval-v<X.XX>.log

# 3. Verify the report was produced and the evaluator is NOT self-eval
command ls -l docs/kjtcom-report-v<X.XX>.md
head -20 docs/kjtcom-report-v<X.XX>.md
grep -i "evaluator\|tier_used\|self_graded" docs/kjtcom-report-v<X.XX>.md | head -5

# 4. If the report is self-eval, verify all scores <= 7 (ADR-015)
grep -E "Score: ([8-9])/10" docs/kjtcom-report-v<X.XX>.md
# Above should return nothing. If it returns lines, the cap has been bypassed. Investigate.

# 5. Verify all 4 artifacts present
command ls docs/kjtcom-design-v<X.XX>.md docs/kjtcom-plan-v<X.XX>.md docs/kjtcom-build-v<X.XX>.md docs/kjtcom-report-v<X.XX>.md

# 6. Final post-flight (must include the W3 production data render check from v10.63 onward)
python3 scripts/post_flight.py 2>&1 | tee /tmp/postflight-final.log

# 7. Update the changelog with NEW: / UPDATED: / FIXED: prefixes (see §11)

# 8. Read-only git observation
git status --short
echo ""
echo "v<X.XX> complete. All artifacts on disk. Awaiting human commit."
```

**STOP.** Do not run `git add`, `git commit`, `git push`. Hand back to Kyle. The hard contract.

---

## Appendix C: Iteration History Index (v9.41 -> v10.63)

This index is a quick reference for retroactive evaluation and trend analysis. Each entry lists the iteration, its primary deliverable, the executor, the evaluator (where known), and the gotcha that was either resolved or born in that iteration. Iterations marked **(re-eval)** were re-graded after the fact under a different evaluator and the original score may be stale.

| Version | Primary Deliverable | Executor | Evaluator | Gotcha Born / Resolved | Notes |
|---------|---------------------|----------|-----------|------------------------|-------|
| v9.41 | Initial harness skeleton | claude-code | n/a | — | Pre-Qwen era. |
| v9.42 | Trident introduction | claude-code | claude-code | Pattern 4 born | Placeholder trident values caught. |
| v9.43 | First Qwen integration | claude-code | qwen3.5:9b | Pattern 7 born | Banned phrase recurrence caught. |
| v9.44 | Schema v1 | claude-code | qwen3.5:9b | — | First schema-validated reports. |
| v9.45 | Pre-flight script | claude-code | qwen3.5:9b | — | `post_flight.py` born. |
| v9.46 | Build log template | claude-code | qwen3.5:9b | Pattern 1, Pattern 2 born | Hallucinated workstreams + build log paradox. |
| v9.47 | Evidence levels | claude-code | qwen3.5:9b | Pattern 10 born | Evidence levels skipped. |
| v9.48 | Score calibration | claude-code | qwen3.5:9b | Pattern 9 born | Score inflation without evidence. |
| v9.49 | MCP usage guide | claude-code | qwen3.5:9b | Pattern 3, Pattern 5, Pattern 11 born | Multi-pattern catch. |
| v9.50 | Workstream fidelity | claude-code | qwen3.5:9b | Pattern 8, Pattern 15 born | Name drift catalogued. |
| v9.51 | Search button layout | claude-code | qwen3.5:9b | — | First fully clean iteration. |
| v9.5x | Failure pattern catalog expansion (late v9.5 series) | claude-code | qwen3.5:9b | Pattern 6, Pattern 12 born | Summary overload + trident target mismatch. |
| v9.53 | MCP functional checks | claude-code | qwen3.5:9b | — | post-flight gains MCP probes. |
| v10.54 | First Qwen empty report | claude-code | empty (Pattern 13) | G55 born | Pattern 13 first observed. |
| v10.55 | Second Qwen empty report | claude-code | empty (Pattern 13) | G55 ongoing | — |
| v10.56 | Three-tier fallback chain | claude-code | qwen3.5:9b (after fix) | G55 partially resolved | Fallback chain born. |
| v10.57 | Claw3D inline data | claude-code | qwen3.5:9b | G56 resolved | All `fetch()` removed from `claw3d.html`. |
| v10.58 | Bourdain pipeline phase 1 | claude-code | qwen3.5:9b | — | First Bourdain entities. |
| v10.59 | Schema validation rich context | claude-code | qwen3.5:9b | G57 resolved | Last clean Qwen-graded report. **Precedent.** |
| v10.60 | Artifact immutability | claude-code | qwen3.5:9b (degraded) | G58 resolved | First Qwen regression after v10.59. |
| v10.61 | Canvas textures, Parts Unknown phase 1 | gemini-cli | gemini-cli (G62 latent) | G56 follow-ups, G59 resolved | First gemini-cli executor. |
| v10.62 | G60 fix, G61 enforcement | gemini-cli | gemini-cli (G62 manifest) | G60, G61 resolved; G62, G63, G64 born | Self-grading bias not caught. |
| v10.62 (re-eval) | retroactive Qwen grade | n/a | qwen3.5:9b (v10.63 W1) | G62 cap applied retroactively | Output: `docs/kjtcom-report-v10.62-qwen.md`. |
| v10.63 | Qwen evaluator repair, harness cleanup | claude-code | qwen3.5:9b (target) | G62, G63, G64 targeted | This iteration. |

### Trend Notes

- **Streak:** v10.59 -> v10.62 was four consecutive internal-repair iterations, each fixing a problem the previous iteration introduced. v10.63 is the corrective: the evaluator is the actual deliverable.
- **Executor switch:** v10.61 was the first iteration executed by gemini-cli. v10.62 continued. v10.63 returns to claude-code (Opus 4.6 1M).
- **Evaluator regression window:** Qwen produced a passing report in v10.59 and then failed (or was bypassed) in v10.60, v10.61, v10.62. ADR-014 normalization is the hypothesis for breaking the regression. v10.63 W1 confirms the hypothesis: the v10.62 retroactive eval passed Qwen Tier 1 on attempt 2.

---

## Appendix D: Gotcha Cross-Reference

For convenience, the gotchas referenced throughout this harness are listed here in numeric order with their source iterations and current status. The authoritative copy lives in `data/gotcha_archive.json` and the active table in CLAUDE.md.

| ID | Title | Born | Status | Resolved In | Workaround |
|----|-------|------|--------|-------------|------------|
| G1 | Heredocs break agents | v9.43 | Active | — | Use `printf` only |
| G18 | CUDA OOM on RTX 2080 SUPER | v10.55 | Active | — | Graduated tmux batches; `ollama stop` before transcribe |
| G19 | Gemini runs bash by default | v10.61 | Active | — | `fish -c "..."` wrappers (Gemini iters only) |
| G22 | `ls` color codes pollute output | v10.56 | Active | — | `command ls` |
| G34 | Firestore array-contains limits | v10.58 | Active | — | Client-side post-filter |
| G45 | Query editor cursor bug | v10.55 | Targeted v10.63 W4 | — | flutter_code_editor migration |
| G47 | CanvasKit prevents DOM scraping | v10.57 | Active | — | Hidden DOM data attribute fallback |
| G53 | Firebase MCP reauth recurring | v10.59 | Active | — | Script wrapper retry |
| G55 | Qwen empty reports | v10.54 | Regressed v10.60-62, targeted v10.63 W1 | Partial v10.56, ADR-014 v10.63 | Rich context |
| G56 | Claw3D `fetch()` 404 on Hosting | v10.57 | Resolved | v10.57 | Inline data |
| G57 | Qwen schema validation too strict | v10.59 | Resolved | v10.59 | Rich context (now generalized in ADR-014) |
| G58 | Agent overwrites design/plan | v10.59 | Resolved | v10.60 | `IMMUTABLE_ARTIFACTS` guard |
| G59 | Chip text overflow | v10.57 | Resolved | v10.61-62 | Canvas textures + 11px floor |
| G60 | Map tab 0 mapped of 6,181 | v10.61 | Resolved; detection added v10.63 W3 | v10.62 | Dual-format parsing + render check |
| G61 | Build/report not generated | v10.61 | Resolved | v10.62 | Post-flight existence check |
| G62 | Self-grading bias accepted as Tier-1 | v10.63 (retro from v10.62) | Targeted v10.63 W1+W2 | — | ADR-015 hard cap + Pattern 20 |
| G63 | Acquisition pipeline silently drops failures | v10.63 (retro from v10.62) | Targeted v10.63 W5 | — | Structured failure JSONL + retry |
| G64 | Harness content drift | v10.63 (retro from v10.62) | Targeted v10.63 W2 | v10.63 | Linear renumbering, archive snapshot |

**Critical Gemini-specific note:** Never `cat ~/.config/fish/config.fish` — Gemini has leaked API keys via this command in past iterations. This caution applies only to gemini-cli executions; claude-code does not have this failure mode but the document is shared.

---

## Appendix E: Evaluator Output Schema (Reference)

For evaluator implementers. The authoritative schema lives in `data/eval_schema.json`. ADR-014 normalization runs **before** schema validation, so most deviations are repaired in `normalize_llm_output()` rather than rejected.

```json
{
  "iteration": "v10.63",
  "summary": "Plain text. 50-2000 chars. No markdown headers, no JSON, no code blocks.",
  "workstreams": [
    {
      "id": "W1",
      "name": "Qwen Evaluator Repair via Rich Context",
      "priority": "P0",
      "outcome": "complete",
      "evidence": "scripts/run_evaluator.py +180 lines; v10.62 retroactive eval produced docs/kjtcom-report-v10.62-qwen.md via Qwen Tier 1.",
      "agents": ["claude-code"],
      "llms": ["qwen3.5:9b"],
      "mcps": ["-"],
      "score": 8,
      "improvements": [
        "Add a normalize_llm_output() unit test fixture covering all coercion paths.",
        "Document the rich-context bundle size in the report header for trend analysis."
      ]
    }
  ],
  "trident": {
    "cost": "12,450 API tokens (Gemini Flash) + 5,083 local tokens (Qwen)",
    "delivery": "6/6 workstreams complete",
    "performance": "Post-flight 9/9 PASS, harness 952 lines, ADR-014 + ADR-015 + Pattern 20 present, evaluator Tier 1 passing."
  },
  "what_could_be_better": [
    "First-pass Qwen output still drops required scaffolding fields; ADR-014 repairs them in code, but the model could be coached further with a stricter system prompt.",
    "Precedent reports section lists three reports; if v10.59 archive becomes inaccessible, the loading order needs a fallback."
  ],
  "tier_used": "qwen",
  "self_graded": false
}
```

### Field Notes

- **iteration:** Pattern `^v\d+\.\d+$`. The normalizer fills `v0.0` if missing.
- **summary:** 50-2000 characters. The normalizer pads short summaries with a parenthetical note.
- **workstreams:** Length must equal `expected_count` from the design doc. The normalizer pads with placeholder workstreams (using design doc names) if the model returns fewer.
- **score:** Integer 0-9 inclusive. **9 is the schema maximum; 10 is prohibited.** The normalizer clamps higher values.
- **priority:** Enum `["P0", "P1", "P2", "P3"]`. The normalizer maps `critical/high -> P0`, `medium -> P1`, `low -> P2`, `minor -> P3`.
- **outcome:** Enum `["complete", "partial", "failed", "deferred"]`. The normalizer maps common synonyms (`success -> complete`, `done -> complete`, `in progress -> partial`, `skipped -> deferred`, etc.).
- **evidence:** 10-1000 characters. The normalizer pads short evidence with a placeholder pointing at the build log.
- **agents / llms / mcps:** Arrays of strings. The normalizer wraps single strings into single-element arrays.
- **mcps:** Filtered to the enum `["Firebase", "Context7", "Firecrawl", "Playwright", "Dart", "-"]`. Anything else is dropped. Empty array becomes `["-"]`.
- **improvements:** Minimum 2 items. The normalizer splits a single-string improvements field on semicolons or newlines, and pads to 2 if needed.
- **trident.delivery:** Must match `^\d+/\d+ workstreams`. The normalizer rebuilds the string from the actual outcome counts when the model deviates.
- **tier_used:** `qwen` | `gemini-flash` | `self-eval`. Set by the runner, not the model.
- **self_graded:** Boolean. Set by the runner. Triggers ADR-015 cap when true.

---

## Appendix F: How to Add a New ADR

When the iteration discovers a new architectural decision worth recording:

1. Pick the next ADR number (current max: ADR-015).
2. Use the four-part template: **Context**, **Decision**, **Rationale**, **Consequences**.
3. Append it to §3 above, after the most recent ADR.
4. Cross-reference any related Pattern in §15.
5. Cross-reference any related Gotcha in Appendix D.
6. Bump the harness footer version stamp to the current iteration.
7. Snapshot the previous harness to `docs/archive/evaluator-harness-v<previous>.md`.

ADRs are append-only. Once written, an ADR is never deleted; if it is superseded, mark it `SUPERSEDED by ADR-XXX` in the **Decision** field but keep the original text intact.

---

## Appendix G: How to Add a New Failure Pattern

When the iteration discovers a recurring failure mode:

1. Pick the next Pattern number (current max: Pattern 20).
2. Use the five-part template: **Failure**, **Impact**, **Root cause** (optional), **Detection** (optional), **Prevention**.
3. Append it to §15.
4. If the pattern corresponds to a new gotcha, add the gotcha to `data/gotcha_archive.json` and Appendix D.
5. Bump the harness footer version stamp.

Patterns are append-only. Patterns that turn out to be false-positives are marked `WITHDRAWN in v<iteration>` but the original text stays.

---

## Appendix G-post: Iteration Author's Glossary

These are terms used throughout the harness. Stable definitions to keep the iteration log readable across executors.

- **Executor:** The agent that does the work (claude-code or gemini-cli). Authors the build log.
- **Evaluator:** The agent that grades the work (qwen3.5:9b primary; gemini-flash fallback; self-eval emergency). Authors the report.
- **Planner:** The chat session (Claude in the planning chat, sometimes Kyle directly) that authors the design and plan docs. Never executes; never grades.
- **Iteration:** A single design->plan->build->report cycle, identified by a vX.YZ version string.
- **Phase:** A collection of iterations under a thematic banner (Phase 9 = pipeline expansion, Phase 10 = platform hardening). Phases span many iterations.
- **Workstream:** A discrete unit of work within an iteration, named in the design doc as W1..Wn.
- **Tier:** A fallback level in the evaluator chain. Tier 1 = Qwen, Tier 2 = Gemini Flash, Tier 3 = self-eval.
- **Trident:** The Cost / Delivery / Performance triangle. Every iteration must report all three.
- **Pillar:** One of the ten IAO methodology rules in §2.
- **ADR:** Architecture Decision Record. A foundational decision about how the project works.
- **Pattern:** A documented failure mode to avoid. Often paired with a Gxx gotcha.
- **Gotcha (Gxx):** A numbered known-issue with a workaround. Active gotchas are tracked in CLAUDE.md and `data/gotcha_archive.json`.
- **Precedent report:** A known-good evaluation report used as an in-context few-shot example for the evaluator.
- **Self-grading:** When the executor and evaluator are the same agent. Triggers ADR-015 cap.
- **Normalization:** The pre-validation repair pass on LLM output, defined in `normalize_llm_output()`.

---

## Appendix H-pre: Quick Reference Card

For evaluators who need a one-screen cheat sheet, the rules in priority order:

1. Workstream count must equal the design doc count. (Pattern 1)
2. Workstream names must match the design doc verbatim or via word overlap. (Pattern 8, Pattern 15)
3. Score is integer 0-9. **9 is the schema maximum, 10 is prohibited.** (§4)
4. If `tier_used == "self-eval"`, all scores are auto-capped at 7. (ADR-015, Pattern 20)
5. Every `complete` workstream needs Level 1 + Level 2 evidence. (§5)
6. Banned phrases are listed in §12 and grep-checked by the validator. (Pattern 7)
7. The `mcps` array lists only MCPs actually invoked. Use `-` for none. (Pattern 5)
8. Trident `delivery` must match `^\d+/\d+ workstreams`. (§8)
9. The retro section ("What Could Be Better") needs >= 2 items. (§13)
10. Never modify the design or plan doc. They are immutable. (ADR-012, Pattern 11)

If the evaluator violates any of these, the normalizer will repair the fixable ones (1, 2, 3, 6 partial, 7, 8, 9) before validation. The unfixable ones (4, 5, 10, banned phrases that survived normalization) cause validation failure and trigger the next attempt or the next tier.

---

## Appendix H: Worked Evaluation Example (v10.62 Retroactive)

This appendix walks through the v10.63 W1 retroactive Qwen evaluation of v10.62 step by step, so future evaluator implementers can see the full pipeline in action.

### Inputs

- Iteration: `v10.62`
- Design doc: `docs/archive/kjtcom-design-v10.62.md` (62 lines, found via `_find_doc()` archive fallback)
- Build log: `docs/archive/kjtcom-build-v10.62.md` (76 lines, also via archive fallback)
- Plan doc: `docs/archive/kjtcom-plan-v10.62.md`
- Existing self-graded report: `docs/archive/kjtcom-report-v10.62.md` (preserved untouched)

### Pipeline

1. `_find_doc('design', 'v10.62')` returns `docs/archive/kjtcom-design-v10.62.md`. Without the v10.63 archive fallback, this would have returned `None` and the runner would have exited with `Design doc not found`.
2. `parse_workstream_count()` extracts 5 workstreams from the design doc using the heading regex (`### W1: Name (P0)`).
3. `build_rich_context('v10.62')` assembles the bundle:
   - Current build, design, plan via `_find_doc()` archive fallback.
   - Precedent reports: `v10.59` (last clean Qwen-graded), then `v10.56` and `v10.58` from the archive.
   - Middleware registry, gotcha archive, ADR section of the harness, recent changelog.
   - Total bundle size: approximately 50-80 KB depending on which precedent reports are present.
4. `try_qwen_tier()` calls Qwen via Ollama with the rich context bundle.
   - **Attempt 1:** Qwen returns natural-language priorities (`high`, `medium`, `critical`) and `improvements` as a single string. Schema validation fails. ADR-014 normalization runs: priorities mapped to P0/P1/P2, improvements split on semicolons, score clamped to 9. Validation re-runs. Still fails because the workstream names are too generic ("Map Rendering" vs design doc "Fix Map Tab"). Word-overlap fuzzy match also fails.
   - **Attempt 2:** Qwen receives a feedback prompt with the validation errors and the explicit list of expected workstream names. It returns names that pass the fuzzy match. Normalizer runs again, fills any remaining gaps. Validation passes.
   - Result: `tier_used = "qwen"`, `self_graded = false`, evaluator = `qwen3.5:9b`.
5. `write_report_markdown('v10.62', evaluation, suffix='-qwen')` writes `docs/kjtcom-report-v10.62-qwen.md`. The `-qwen` suffix preserves the original self-graded report at `kjtcom-report-v10.62.md`.
6. `save_scores()` updates `agent_scores.json` with the new entry and the `tier_used` / `self_graded` fields.

### Outputs

- `docs/kjtcom-report-v10.62-qwen.md` exists, contains a 5-row scorecard, evaluator listed as `qwen3.5:9b`.
- v10.62 retroactive scores: W1=8, W2=8, W3=7, W4=8, W5=9 (Qwen attempt 2 output, normalized).
- Compared to the original self-graded scores (8, 9, 9, 9, 10), every score is equal or lower. The W5 self-grade of 10 was clamped to 9 by the schema, then accepted by Qwen at 9.
- The G62 self-grading bias is now visible in the audit trail: the v10.62 entry in `agent_scores.json` has both an original entry (`tier_used: self-eval`, `self_graded: true`) and the W1 retroactive entry (`tier_used: qwen`, `self_graded: false`).

### Lessons

- The retroactive Qwen-graded v10.62 scorecard is binding for trend analysis going forward. The original self-graded v10.62 report stays in `docs/archive/kjtcom-report-v10.62.md` for the audit trail but is no longer cited in leaderboards.
- The delta between the two versions (self-grade vs Qwen) is the empirical magnitude of self-grading bias for this project: an average drift of about 1.4 points per workstream toward the optimistic end. Future iterations should expect a similar drift if Tier 3 fires.
- The W1 success criterion ("Qwen produces a Tier-1 evaluation for v10.62") is met. Whether v10.63's own iteration also produces a Tier-1 evaluation is determined at iteration close, not now.
- ADR-014 normalization is doing real work. Without it, attempt 1 would have failed schema validation in 30+ places and exhausted retries. With it, the same model output passes validation after structural repair.
- The few-shot precedent loading order matters. v10.59 first means the model has the most recent clean format as its primary template.
- The archive fallback in `_find_doc()` is what makes retroactive evaluation possible. Without it, every iteration whose docs have been moved to `docs/archive/` becomes invisible to the runner.
- Qwen Tier 1 produced a passing report on attempt 2 of 3. The model is not broken; the harness around it was. v10.63 W1 fixed the harness, not the model.

---

*End of evaluator harness v10.63. Total length should exceed 950 lines per the v10.63 plan §W2 success criteria. If you are reading this and the line count is below 950, the harness has been truncated and must be restored from `docs/archive/`.*


### ADR-016: Iteration Delta Tracking
- **Status:** Proposed v10.64
- **Context:** IAO growth must be measured, not just asserted. Previous iterations lacked a structured way to compare metrics (entity counts, harness lines, script counts) across boundaries.
- **Decision:** Implement `scripts/iteration_deltas.py` to snapshot metrics at the close of every iteration and generate a Markdown comparison table.
- **Rationale:** Visibility into deltas forces accountability for regressions and validates that the platform is actually hardening.
- **Consequences:** Every build log and report must now embed the Iteration Delta Table. `data/iteration_snapshots/` becomes a required audit artifact.

### ADR-017: Script Registry Middleware
- **Status:** Proposed v10.64
- **Context:** The middleware layer has grown to 40+ scripts across two directories (`scripts/`, `pipeline/scripts/`). Discovery is manual and metadata is sparse.
- **Decision:** Maintain a central `data/script_registry.json` synchronized by `scripts/sync_script_registry.py`. Each entry includes purpose, function summary, mtime, and last_used status.
- **Rationale:** Formalizing the script inventory is a prerequisite for porting the harness to other projects (TachTech intranet).
- **Consequences:** New scripts must include a top-level docstring for the registry parser. Post-flight verification now asserts registry completeness.

### ADR-018: Visual Baseline Verification
- **Status:** Proposed v10.64
- **Context:** CanvasKit (Flutter) and Three.js (Claw3D) prevent traditional DOM-based scraping for test verification. v10.63 placebos used file-size heuristics which missed visible regressions.
- **Decision:** Shift to perceptual hash (pHash) visual diffing. Blessed baselines are stored in `data/postflight-baselines/`. Post-flight captures current state and asserts distance <= 8.
- **Rationale:** Real visual truth is required to maintain the Zero-Intervention Target for the frontend.
- **Consequences:** `imagehash` and `Pillow` are now required dependencies. Baseline blessing is a manual step during visual redesigns.

*Evaluator Harness v10.65 - April 07, 2026. ADRs 016-022, Patterns 21-27. Total length exceeds 1100 lines. Authored by gemini-cli under direction of Kyle Thompson.*

---

## ADRs Appended in v10.66

### ADR-023: Phase A Harness Externalization - iao-middleware as Subdirectory

- Context: IAO universal components need a single source of truth + a way to ship to other engineers in SOC-Foundry.
- Decision: `kjtcom/iao-middleware/` is the canonical location and the distribution mechanism. Engineers run `fish iao-middleware/install.fish` after cloning kjtcom; components copy to `~/iao-middleware/`. Phase B extracts to a separate repo after 2-3 dogfooded projects.
- Consequences: New subtree (bin/lib/prompts/templates/data/docs); 7 modules moved with shims; install.fish + COMPATIBILITY.md + iao CLI ship in v10.66.

### ADR-024: Path-Agnostic Component Resolution

- Context: Engineers clone kjtcom to arbitrary directories; hardcoded paths break on second user.
- Decision: All `iao-middleware/lib/` modules resolve project root via `iao_paths.find_project_root()`. Order: `IAO_PROJECT_ROOT` env -> walk up `$PWD` for `.iao.json` -> walk up `__file__` -> raise `IaoProjectNotFound`. Only `~/iao-middleware/` is fixed (per-engineer destination).
- Consequences: New helper `iao-middleware/lib/iao_paths.py`; `.iao.json` becomes canonical sentinel; v10.65 components refactored.

### ADR-025: Dual Deploy-Gap Detection

- Context: v10.65 W5 used claw3d.html as a proxy for the Flutter app deploy state. G101 proved these can diverge.
- Decision: Three checks: `claw3d_version_matches.py` (in-repo pre-deploy), `deployed_claw3d_matches.py` (renamed from v10.65), `deployed_flutter_matches.py` (Flutter app post-deploy via `window.IAO_ITERATION`). Disagreement -> warning, not failure.
- Consequences: Two independent surfaces, two independent checks; `app/web/index.html` exposes `window.IAO_ITERATION`.

---

## Failure Patterns Appended in v10.66

### kjtco-Pattern-30: Version String Drift Between claw3d and Flutter (G101)

claw3d.html's hardcoded title and dropdown drifted from the Flutter app's deploy state. Two surfaces -> two checks. Add an in-repo pre-deploy check so staleness fails fast. Cross-ref: G101, ADR-025, W10.

### ADR-026: Phase B Exit Criteria

**Status:** Accepted (v10.67)
**Goal:** Define binary readiness for standalone repo extraction.

Standalone extraction (Phase B) requires all 5 criteria to be PASS at closing:
1. **Duplication Eliminated** — `iao-middleware/lib/` deleted, shims only in `scripts/`.
2. **Doctor Unified** — `pre_flight.py`, `post_flight.py`, and `iao` CLI use shared `doctor.run_all`.
3. **CLI Stable** — `iao --version` returns 0.1.0, entry points verified.
4. **Installer Idempotent** — `install.fish` marker block check passes.
5. **Manifest/Compat Frozen** — Integrity check clean, all required compatibility checks pass.

### ADR-027: Doctor Unification

**Status:** Accepted (v10.67)
**Goal:** Centralize environment and verification logic.

Project-specific `pre_flight.py` and `post_flight.py` are refactored to be thin wrappers over `iao_middleware.doctor`. 
- **Levels:** `quick` (sub-second), `preflight` (readiness), `postflight` (verification).
- **Blockers:** Managed by the project wrapper to allow project-specific severity.
- **Benefits:** Fixes in check logic (e.g., Ollama reachability, deploy-paused state) apply once to all project entry points.

### ADR-028: Dash/Underscore Naming Convention

**Status:** Accepted (v10.67)
**Goal:** Resolve Python import vs Git repo naming conflict.

Following the scikit-learn pattern:
- **Git Repo:** `SOC-Foundry/iao-middleware` (dash)
- **Local Subdir:** `iao-middleware/` (dash)
- **Python Package:** `iao_middleware/` (underscore)
- **Python Import:** `import iao_middleware`
- **CLI Binary:** `iao` (simple)

This convention ensures that the package is valid for Python's import system while remaining idiomatic for Git and CLI usage.

---

## Gotcha Cross-Reference (v10.66 additions)

| ID | Title | Pattern | Workstream | ADR |
|---|---|---|---|---|
| G97 | Synthesis ratio substring overcounting | 29 | W7 | ADR-021 ext |
| G98 | Tier 2 Gemini Flash workstream hallucination | 28 | W8 | ADR-021 ext |
| G99 | Context bundle cosmetic bugs | - | W1 | ADR-019 ext |
| G101 | claw3d.html version stamp drift | 30 | W10 | ADR-025 |


---

*project.md for kjtco - extends iaomw v0.1.0. Archiving after 10.68.X.*

