# Decision Record: Comprehensive Script Audit

<!-- SPECKIT_LEVEL: 3 -->
<!-- SPECKIT_TEMPLATE_SOURCE: decision-record | v2.2 -->

---

<!-- ANCHOR:adr-001 -->
## ADR-001: Shard-Based Audit Strategy

<!-- ANCHOR:adr-001-context -->
### Metadata

| Field | Value |
|-------|-------|
| **Status** | Accepted |
| **Date** | 2026-02-15 |
| **Deciders** | @speckit |

---

### Context

System-spec-kit contains ~50+ scripts across 3 directories (scripts/, shared/, mcp_server/) with complex interdependencies. A comprehensive audit requires systematic investigation that prevents scope creep while ensuring complete coverage. Previous audits have suffered from either incomplete coverage or scope expansion into implementation.

### Constraints
- Must exclude issues caused solely by ongoing node_modules relocation
- Cannot implement fixes (documentation only)
- Must compare against sk-code--opencode standards
- Time-bound investigation (15-24 hours estimated)
<!-- /ANCHOR:adr-001-context -->

---

<!-- ANCHOR:adr-001-decision -->
### Decision

**Summary**: Use 30 discrete investigation shards across 3 phases (Context, Build, Review) with explicit deliverables per shard.

**Details**:
- Phase 1 (Context): 10 shards for script discovery, dependency mapping, categorization
- Phase 2 (Build): 10 shards for execution testing, error validation, functionality assessment
- Phase 3 (Review): 10 shards for standards comparison, pattern analysis, alignment scoring
- Phase 4 (Synthesis): Aggregate findings, apply exclusion filters, create remediation roadmap

Each shard has bounded scope with specific deliverable (e.g., "enumerate scripts in scripts/", "test error handling paths").
<!-- /ANCHOR:adr-001-decision -->

---

<!-- ANCHOR:adr-001-alternatives -->
### Alternatives Considered

| Option | Pros | Cons | Score |
|--------|------|------|-------|
| **Shard-Based (30 shards)** | Systematic coverage, parallelizable, clear progress tracking, bounded scope | Shard management overhead | 9/10 |
| Full-Scan Approach | Comprehensive, less overhead | High risk of scope creep, hard to track progress, no parallelization | 4/10 |
| File-by-File Audit | Very granular, complete | Too granular (loses architectural context), ~100+ tasks, unmanageable | 3/10 |
| Directory-by-Directory | Simple structure | Misses cross-directory dependencies, no systematic methodology | 5/10 |

**Why Chosen**: Shard-based approach balances systematic coverage with manageable scope. 30 shards provide sufficient granularity without overwhelming task management. Three-phase structure (Context → Build → Review) ensures logical progression and enables early detection of patterns.
<!-- /ANCHOR:adr-001-alternatives -->

---

<!-- ANCHOR:adr-001-consequences -->
### Consequences

**Positive**:
- Systematic coverage prevents missed areas
- Bounded shard scope prevents scope creep
- Parallelizable shards (marked [P]) enable faster execution
- Clear progress tracking (10/30 shards complete)
- Synthesis shards (T010, T020, T030) provide phase checkpoints

**Negative**:
- Shard management overhead (36 total tasks) - Mitigation: Simple task.md checklist, no complex tooling required
- Risk of artificial boundaries between shards - Mitigation: Synthesis tasks aggregate cross-shard findings

**Risks**:
| Risk | Impact | Mitigation |
|------|--------|------------|
| Shard scope too narrow | M | Synthesis tasks aggregate findings |
| Shard scope too broad | M | Bounded deliverables prevent expansion |
| Findings duplication across shards | L | Synthesis deduplicates in Phase 4 |
<!-- /ANCHOR:adr-001-consequences -->

---

<!-- ANCHOR:adr-001-five-checks -->
### Five Checks Evaluation

| # | Check | Result | Evidence |
|---|-------|--------|----------|
| 1 | **Necessary?** | PASS | Systematic audit required to identify bugs/misalignments before remediation |
| 2 | **Beyond Local Maxima?** | PASS | Evaluated 4 alternatives (full-scan, file-by-file, directory-by-directory) |
| 3 | **Sufficient?** | PASS | 30 shards provide complete coverage without over-engineering |
| 4 | **Fits Goal?** | PASS | Directly supports audit goals (bug identification, standards comparison) |
| 5 | **Open Horizons?** | PASS | Remediation roadmap output enables future improvement work |

**Checks Summary**: 5/5 PASS
<!-- /ANCHOR:adr-001-five-checks -->

---

<!-- ANCHOR:adr-001-impl -->
### Implementation

**Affected Systems**:
- tasks.md: 36 tasks (30 shards + 6 synthesis)
- plan.md: 4-phase execution plan with dependency graph
- checklist.md: Phase-specific verification items

**Rollback**: If shard scope proves unworkable, consolidate to directory-by-directory approach (3 context + 3 build + 3 review = 9 tasks)
<!-- /ANCHOR:adr-001-impl -->

<!-- /ANCHOR:adr-001 -->

---

<!-- ANCHOR:adr-002 -->
## ADR-002: Node_modules Relocation Exclusion Protocol

<!-- ANCHOR:adr-002-context -->
### Metadata

| Field | Value |
|-------|-------|
| **Status** | Accepted |
| **Date** | 2026-02-15 |
| **Deciders** | User requirement |

---

### Context

System-spec-kit is undergoing active refactoring to relocate node_modules into mcp_server directory. This creates temporary broken imports and path errors that are not representative of actual script bugs.

### Constraints
- Must exclude issues SOLELY caused by relocation
- Cannot exclude legitimate bugs that happen to involve node_modules references
- Relocation scope not fully defined
<!-- /ANCHOR:adr-002-context -->

---

<!-- ANCHOR:adr-002-decision -->
### Decision

**Summary**: Implement explicit exclusion filter in Context Shard 8 (T008) and apply during Synthesis (T032).

**Details**:
- T008 identifies all node_modules references in scripts
- During Build shards (T011-T020), flag errors as "potential relocation issue"
- Synthesis task T032 applies exclusion filter based on pattern matching:
  - Exclude: "Cannot find module" errors pointing to node_modules paths
  - Exclude: Import path errors referencing old node_modules location
  - Include: Logic errors, runtime errors unrelated to module resolution
<!-- /ANCHOR:adr-002-decision -->

---

<!-- ANCHOR:adr-002-alternatives -->
### Alternatives Considered

| Option | Pros | Cons | Score |
|--------|------|------|-------|
| **Explicit Filter (T008 + T032)** | Clear methodology, auditable | Requires careful pattern matching | 8/10 |
| Ignore All Import Errors | Simple | Misses legitimate bugs | 2/10 |
| Manual Review Per Error | Accurate | Not scalable, subjective | 6/10 |

**Why Chosen**: Explicit filter provides auditable methodology while preventing false positives from relocation work.
<!-- /ANCHOR:adr-002-alternatives -->

---

<!-- ANCHOR:adr-002-consequences -->
### Consequences

**Positive**:
- Findings are actionable (not contaminated with in-progress work)
- Exclusion rationale is documented and auditable
- Can re-run audit post-relocation to verify exclusions were correct

**Negative**:
- Risk of excluding legitimate bugs - Mitigation: Conservative filter (when in doubt, include)
- Additional synthesis overhead - Mitigation: Automated pattern matching where possible

**Risks**:
| Risk | Impact | Mitigation |
|------|--------|------------|
| Exclude legitimate bugs | H | Conservative filter (include if ambiguous) |
| Miss relocation issues | L | Acceptable per requirements |
<!-- /ANCHOR:adr-002-consequences -->

---

<!-- ANCHOR:adr-002-five-checks -->
### Five Checks Evaluation

| # | Check | Result | Evidence |
|---|-------|--------|----------|
| 1 | **Necessary?** | PASS | Required by user (explicit requirement) |
| 2 | **Beyond Local Maxima?** | PASS | Evaluated ignore-all and manual-review alternatives |
| 3 | **Sufficient?** | PASS | Pattern-based filter balances accuracy and effort |
| 4 | **Fits Goal?** | PASS | Ensures findings represent actual bugs, not WIP |
| 5 | **Open Horizons?** | PASS | Methodology is reusable post-relocation |

**Checks Summary**: 5/5 PASS
<!-- /ANCHOR:adr-002-five-checks -->

---

<!-- ANCHOR:adr-002-impl -->
### Implementation

**Affected Systems**:
- tasks.md: T008 (identification), T032 (filtering)
- checklist.md: CHK-120 to CHK-123 (exclusion protocol verification)
- Synthesis output: Separate section for excluded issues

**Rollback**: If exclusion criteria unclear, escalate to user with examples for classification guidance
<!-- /ANCHOR:adr-002-impl -->

<!-- /ANCHOR:adr-002 -->

---

---

<!-- ANCHOR:adr-003 -->
## ADR-003: Audit Synthesis and Remediation Prioritization

<!-- ANCHOR:adr-003-context -->
### Metadata

| Field | Value |
|-------|-------|
| **Status** | Accepted |
| **Date** | 2026-02-15 |
| **Deciders** | @review, @speckit |

---

### Context

Ten independent review agents (review-agent-01 through review-agent-10) evaluated context and build verification artifacts across all audit shards. Findings include confirmed issues, false positives, severity adjustments, and coverage gaps. A consolidated remediation roadmap is required to prioritize fixes and exclude issues caused by ongoing node_modules relocation.

### Constraints
- Must aggregate findings from 10 review reports with varying formats
- Must apply node_modules relocation exclusion filter
- Must distinguish P0/P1/P2 priorities for remediation planning
- Must document uncertainties where review reports conflict or have coverage gaps
<!-- /ANCHOR:adr-003-context -->

---

<!-- ANCHOR:adr-003-decision -->
### Decision

**Summary**: Aggregate all confirmed findings into a prioritized remediation backlog with explicit exclusion of node_modules relocation issues and documented uncertainties for traceability conflicts.

**Details**:
- **P0 (Blockers)**: 7 findings across error handling, memory indexing, and data contracts
- **P1 (Required)**: 16 findings across all shards requiring fixes before system is production-ready
- **P2 (Suggestions)**: 26+ findings for quality improvements and maintainability

**Node_modules Relocation Exclusion**: Per ADR-002, issues SOLELY caused by the in-progress relocation are excluded. No findings in the current audit were attributed exclusively to relocation; all confirmed issues represent actual script bugs or misalignments.

**Uncertainties Documented**:
- Review-agent-01: File count mismatch (27 vs 18 divider-style files, 391+ fallback patterns unverified)
- Review-agent-02: Partial coverage (~10-14 reads remaining for full caller-trace)
- Review-agent-04: 43% false-positive rate (3/7 findings disproven)
- Review-agent-07: Coverage gap (C07-002/003 IVectorStore contract drift not in context report)
- Review-agent-09: Cross-platform path claims untested/theoretical
- Review-agent-10: 85-finding count discrepancy (only 5 substantiated in C10, 2 confirmed by build)
<!-- /ANCHOR:adr-003-decision -->

---

<!-- ANCHOR:adr-003-alternatives -->
### Prioritized Remediation

#### P0 — Blockers (7)

| ID | Finding | Shard | Impact |
|----|---------|-------|--------|
| C08-F001 | Swallowed errors in cleanup-orphaned-vectors.ts | Error Handling | Silent cleanup failures; data integrity unknown |
| C08-F008 | Null DB returns `true` in session-manager.ts | Error Handling | Deduplication silently disabled; duplicate memories |
| C08-F003 | Degraded operations continue without metrics | Error Handling | System runs in degraded state with no visibility |
| C08-F010 | UPDATE matching 0 rows reports success | Error Handling | FSRS tracking broken; caller believes PE succeeded |
| C09-001 | DB marker path contract can silently diverge | Memory/Indexing | Stale data served indefinitely; no error surfaced |
| C04-F003 | Constitutional files falsely flagged (FALSE POSITIVE) | Root Orchestration | Disproven by build verification; RETRACTED |
| C04-F004 | Path uniformity overclaimed at 100% confidence (FALSE POSITIVE) | Root Orchestration | Disproven by build verification; RETRACTED |

**Note**: 2 of 7 originally reported P0s were false positives; actual P0 count is **5 confirmed**.

#### P1 — Required Fixes (16)

| ID | Finding | Shard | Build Status |
|----|---------|-------|--------------|
| C01-002 | Async boundary missing try/catch (severity overstated) | JS/TS Scripts | CONFIRMED (impact adjusted) |
| C02-F004 | Doc-drift in score/similarity interfaces | Shared Utilities | Not verified by build |
| C03-F001 | Unknown-tool dispatch diagnostics are generic | MCP Server | CONFIRMED |
| C03-F003 | Embedding readiness race on cold start (lazy mode) | MCP Server | LIKELY |
| C03-F008 | Startup remediation references non-existent script | MCP Server | CONFIRMED |
| C04-F002 | Policy interpretation classified as HIGH (severity inflated) | Root Orchestration | Downgrade to MEDIUM |
| C06-02 | Zero-file anchor validation false pass | Validation/Quality | CONFIRMED |
| C06-04 | Case-insensitive + non-exact section matching | Validation/Quality | CONFIRMED |
| C07-002 | IVectorStore.search signature divergence | Data Contracts | CONFIRMED (missing from context) |
| C07-003 | IVectorStore id/lifecycle signature divergence | Data Contracts | CONFIRMED (missing from context) |
| C08-F002 | Inconsistent error levels across session-manager.ts | Error Handling | CONFIRMED |
| C08-F004 | Missing exit(1) in CLI script error paths | Error Handling | PARTIAL (valid for CLI only) |
| C08-F006 | stderr not used for warnings | Error Handling | CONFIRMED |
| C08-F007 | No retry logic for transient errors | Error Handling | CONFIRMED |
| C08-F011 | Exit code taxonomy absent | Error Handling | CONFIRMED |
| C10-F002 | Save-then-query not guaranteed (deferred indexing) | Memory/Indexing | CONFIRMED |

#### P2 — Suggestions (26+)

*(Sample of highest-value P2 items; full list in implementation-summary.md)*

| ID | Finding | Shard | Build Status |
|----|---------|-------|--------------|
| C01-008 | File counts don't match (27 vs 18) | JS/TS Scripts | CONFIRMED discrepancy |
| C02-F002 | Contract confusion (no active root imports) | Shared Utilities | CONFIRMED |
| C03-F006 | Auto-surface failure is silent to clients | MCP Server | CONFIRMED |
| C06-01 | Backtick placeholder handling is brittle | Validation/Quality | PARTIAL (risk shape changed) |
| C08-F012 | Deferred indexing with no timeout | Error Handling | CONFIRMED |
| C08-F014 | Vector search failure returns empty array | Error Handling | CONFIRMED |
| C08-F018 | Inconsistent return types (IndexResult vs boolean) | Error Handling | CONFIRMED |
<!-- /ANCHOR:adr-003-alternatives -->

---

<!-- ANCHOR:adr-003-consequences -->
### Alternatives Considered

| Option | Pros | Cons | Score |
|--------|------|------|-------|
| **Prioritized Remediation (P0/P1/P2)** | Clear urgency, actionable, aligns with gate model | Requires manual triage of 49+ findings | 9/10 |
| Fix All Findings (no prioritization) | Comprehensive | Time-prohibitive, includes false positives | 3/10 |
| Fix Only P0 | Fast | Leaves 42 issues unaddressed, no quality improvement | 5/10 |

**Why Chosen**: Prioritized remediation enables incremental improvement with clear gates (P0 = unblock, P1 = production-ready, P2 = quality enhancement).

---

### Consequences

**Positive**:
- 5 confirmed P0 blockers identified with specific remediation paths
- False positives explicitly retracted (2 findings, 43% false-positive rate in C04 shard)
- Uncertainties documented for traceability

**Negative**:
- 26+ P2 findings create a long tail of maintenance work
- Coverage gaps remain (partial verification in C02, C09, C10)
- Numeric discrepancies not fully resolved (C01-008, C10 85-finding count)

**Risks**:
| Risk | Impact | Mitigation |
|------|--------|------------|
| False negatives (missed issues) | M | Partial coverage acknowledged; follow-up audit after node_modules relocation |
| Over-prioritization of P2 items | L | Clear P0/P1/P2 taxonomy enforced |
<!-- /ANCHOR:adr-003-consequences -->

---

<!-- ANCHOR:adr-003-five-checks -->
### Five Checks Evaluation

| # | Check | Result | Evidence |
|---|-------|--------|----------|
| 1 | **Necessary?** | PASS | Synthesis required to produce actionable remediation plan |
| 2 | **Beyond Local Maxima?** | PASS | Evaluated fix-all vs fix-none vs prioritized approaches |
| 3 | **Sufficient?** | PASS | P0/P1/P2 taxonomy provides clear decision gates |
| 4 | **Fits Goal?** | PASS | Directly supports audit goal (actionable remediation roadmap) |
| 5 | **Open Horizons?** | PASS | P2 backlog enables incremental quality improvement post-P0/P1 |

**Checks Summary**: 5/5 PASS
<!-- /ANCHOR:adr-003-five-checks -->

---

<!-- ANCHOR:adr-003-impl -->
### Implementation

**Affected Systems**:
- implementation-summary.md: Full findings list with remediation actions
- checklist.md: Phase-specific verification items for P0/P1/P2 fixes
- tasks.md: Remediation task breakdown (T033-T036)

**Rollback**: If remediation effort exceeds capacity, defer all P2 items and focus on P0+P1 only (23 items vs 49+).
<!-- /ANCHOR:adr-003-impl -->

<!-- /ANCHOR:adr-003 -->

---

### P2 Remediation Backlog (Promoted from scratch/)

**Source**: Consolidated from `implementation-summary.md` P2 table and `scratch/review-agent-*.md` files.
**Rationale**: P2 findings were only in scratch/ (temporary) and implementation-summary.md. Per U20, these are at risk if scratch/ is cleaned. Promoted here for permanent traceability.

| ID | Finding | Component | Action | Effort |
|----|---------|-----------|--------|--------|
| C01-008 | File count mismatch (27 vs 18) | JS/TS Scripts | Re-verify divider-style file count; correct C01 report | 30min |
| C02-F002 | Contract confusion (no active root imports) | Shared Utilities | Add JSDoc note: "No current root consumers" | 15min |
| C03-F006 | Auto-surface failure is silent | MCP Server | Add `meta.autoSurface.status` flag on failure path | 1h |
| C06-01 | Backtick placeholder handling brittle | Validation/Quality | Replace `grep -v` with regex-based filter | 1h |
| C08-F005 | Timeout inconsistency (30s vs 5s) | Error Handling | Different operations — document expected timeouts | 30min |
| C08-F012 | Deferred indexing with no timeout | Error Handling | Add max retry count or TTL for deferred entries | 2h |
| C08-F014 | Vector search failure returns empty array | Error Handling | Distinguish "no results" from "search failed" | 1h |
| C08-F018 | Inconsistent return types | Error Handling | Standardize on `IndexResult` interface | 3h |
| C07-P1-01 | IVectorStore coverage gap in context report | Data Contracts | Add C07-002/003 as DCON-023/024 | 30min |
| C07-P1-02 | No traceability matrix (DCON ↔ C07) | Data Contracts | Add cross-reference table | 1h |
| C04-P2-01 | Confidence calibration drift | Root Orchestration | Cap unverified findings at 60% confidence | Policy |

**Remaining P2 items** (15+): Distributed across `scratch/review-agent-*.md` files. See individual review shard artifacts for component-specific suggestions.

**Total P2 Effort (top 11)**: ~12 hours

---

<!-- ANCHOR:adr-004 -->
## ADR-004: Uncertainty Resolution Results

<!-- ANCHOR:adr-004-context -->
### Metadata

| Field | Value |
|-------|-------|
| **Status** | Accepted |
| **Date** | 2026-02-15 |
| **Deciders** | @speckit (uncertainty analysis) |

---

### Context

During checklist verification (CHK-001 through CHK-143), 31 uncertainties were identified across the audit artifacts. These uncertainties ranged from unsubstantiated numeric claims (C10 "85 findings") to inflated quality scores (audit self-assessment 81/100) to phantom confidence in stub outputs (R09/R10 scoring 89/100 on 3-line files). Left unresolved, these uncertainties would undermine the reliability of the audit's remediation roadmap and priority assignments.

### Constraints
- Cannot re-run the full 30-shard audit (budget/time exhausted)
- Must preserve valid findings while correcting inflated claims
- High-complexity items (coverage gap analysis, cross-shard dedup) require dedicated investigation passes
<!-- /ANCHOR:adr-004-context -->

---

<!-- ANCHOR:adr-004-decision -->
### Decision

**Summary**: Resolved 10 uncertainties, partially resolved 8, deferred 3 (HIGH complexity), and accepted 10 (LOW priority / acceptable risk).

**Key Resolutions**:

| ID | Uncertainty | Resolution | Impact |
|----|------------|------------|--------|
| **U03** | C10 claims "85 findings" | **UNSUBSTANTIATED** — only 5 documented findings exist | All downstream P2 counts derived from C10 need recalculation |
| **U24** | R09/R10 review quality | **CONFIRMED STUBS** — 3-line outputs scored 89/100 | Tasks T029, T030 reverted to unchecked; review coverage reduced to 80% (8/10) |
| **U26** | Audit quality score 81/100 | **INFLATED** — independently verified at 55/100 | 26-point gap; self-assessment methodology unreliable |
| **U14** | C04 43% false-positive rate | **CONTAINED** — does not affect top 8 confirmed findings | P0/P1 remediation roadmap remains valid |
| **U20** | P2 findings only in scratch/ | **AT RISK** — scratch/ is temporary by policy | Need promotion to permanent location before cleanup |

**Deferred Items** (require dedicated investigation):
- **U07**: Coverage gap analysis — requires mapping all script functions to audit shard coverage
- **U27**: Cross-shard finding deduplication — potential duplicate findings across C08/C03/C10
- **U28**: Coverage completeness verification — C02, C09, C10 have partial build verification

**Accepted (LOW priority)**:
- U11-U13, U15-U18, U29-U31: Minor formatting inconsistencies, non-critical numeric imprecisions, and documentation style variations that do not affect remediation accuracy.
<!-- /ANCHOR:adr-004-decision -->

---

<!-- ANCHOR:adr-004-alternatives -->
### Alternatives Considered

| Option | Pros | Cons | Score |
|--------|------|------|-------|
| **Triage and Resolve (chosen)** | Addresses critical uncertainties, preserves valid work | 3 items deferred, 10 accepted | 8/10 |
| Full Re-Audit | Complete accuracy | Prohibitive cost (30+ shard re-runs) | 2/10 |
| Accept All Uncertainties | Zero effort | Undermines audit reliability | 3/10 |

**Why Chosen**: Triage approach resolves the highest-impact uncertainties (inflated scores, stub outputs, unsubstantiated claims) while deferring items that require dedicated investigation passes.
<!-- /ANCHOR:adr-004-alternatives -->

---

<!-- ANCHOR:adr-004-consequences -->
### Consequences

**Positive**:
- Audit quality score corrected from 81 to 55 (accurate self-assessment)
- 2 stub reviews (R09/R10) properly flagged instead of counted as complete
- C10 "85 findings" claim retracted, preventing inflated P2 counts in remediation planning
- Remediation roadmap for P0/P1 items remains valid (U14 confirms C04 FP rate is contained)

**Negative**:
- 3 deferred items (U07, U27, U28) remain open — may affect remediation effort estimates
- Audit coverage reduced from claimed 100% to actual 80% for review phase

**Risks**:
| Risk | Impact | Mitigation |
|------|--------|------------|
| Deferred items reveal more issues | M | Track in tasks.md; address in follow-up |
| P2 findings lost from scratch/ | H | Promote to permanent location before scratch cleanup |
<!-- /ANCHOR:adr-004-consequences -->

---

<!-- ANCHOR:adr-004-five-checks -->
### Five Checks Evaluation

| # | Check | Result | Evidence |
|---|-------|--------|----------|
| 1 | **Necessary?** | PASS | 31 uncertainties threatened audit reliability; resolution required |
| 2 | **Beyond Local Maxima?** | PASS | Evaluated full re-audit vs accept-all vs triage approaches |
| 3 | **Sufficient?** | PASS | 10 resolved + 8 partial covers all HIGH/CRITICAL uncertainties |
| 4 | **Fits Goal?** | PASS | Directly improves audit accuracy for remediation planning |
| 5 | **Open Horizons?** | PASS | Deferred items tracked; methodology reusable for future audits |

**Checks Summary**: 5/5 PASS
<!-- /ANCHOR:adr-004-five-checks -->

---

<!-- ANCHOR:adr-004-impl -->
### Implementation

**Affected Systems**:
- checklist.md: Verification summary corrected (34/34 → 33/54)
- tasks.md: T029, T030 reverted; orphan files W01-W03 tracked; completion criteria updated
- implementation-summary.md: Quality score corrected; review coverage updated; uncertainty section added

**Rollback**: N/A — corrections are factual accuracy fixes, not reversible design decisions
<!-- /ANCHOR:adr-004-impl -->

<!-- /ANCHOR:adr-004 -->

### Scoring Methodology Note

All confidence/quality scores in this audit are SELF-ASSESSED by individual agents without a standardized rubric. Scores are:
- Not comparable across agents (an 89 from a 3-line stub ≠ 89 from a 119-line analysis)
- Subjective and unverified unless independently confirmed
- Should be treated as directional indicators, not precise measurements

Recommendation: Future audits should establish a scoring rubric BEFORE agent dispatch, with objective criteria (e.g., citations per finding, evidence density, file:line coverage).

---

<!--
Level 3 Decision Record
Document significant technical decisions
One ADR per major decision
-->
