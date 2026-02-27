// ---------------------------------------------------------------
// MODULE: Ground Truth Data
// T007: Synthetic query-relevance dataset for retrieval evaluation.
//
// DISTRIBUTION SUMMARY (as of 2026-02-27):
// ─────────────────────────────────────────────────────────────
//   Total queries:        110
//
//   By source:
//     seed              :  21  (queries from T000d, ids 1-21)
//     pattern_derived   :  35  (from T007b agent consumption patterns)
//     trigger_derived   :  14  (from memory trigger phrases)
//     manual            :  40  (curated natural-language, NOT from triggers)
//
//   By intent type:
//     understand        :  18
//     find_decision     :  17
//     fix_bug           :  16
//     add_feature       :  16
//     find_spec         :  16
//     refactor          :  14
//     security_audit    :  13
//
//   By complexity tier:
//     simple            :  32
//     moderate          :  46
//     complex           :  32
//
//   By category:
//     factual           :  22
//     cross_document    :  22
//     graph_relationship:  21
//     temporal          :  20
//     hard_negative     :  14
//     anchor_based      :   7
//     scope_filtered    :   4
//
//   Hard negatives:       14  (≥3 required)
//   Manual queries:       40  (≥30 required)
// ─────────────────────────────────────────────────────────────
// ---------------------------------------------------------------

/* ---------------------------------------------------------------
   1. TYPES
--------------------------------------------------------------- */

export type IntentType =
  | 'add_feature'
  | 'fix_bug'
  | 'refactor'
  | 'security_audit'
  | 'understand'
  | 'find_spec'
  | 'find_decision';

export type ComplexityTier = 'simple' | 'moderate' | 'complex';

export type QueryCategory =
  | 'factual'
  | 'temporal'
  | 'graph_relationship'
  | 'cross_document'
  | 'hard_negative'
  | 'anchor_based'
  | 'scope_filtered';

export type QuerySource = 'manual' | 'trigger_derived' | 'pattern_derived' | 'seed';

export interface GroundTruthQuery {
  id: number;
  query: string;
  intentType: IntentType;
  complexityTier: ComplexityTier;
  category: QueryCategory;
  source: QuerySource;
  expectedResultDescription: string;
  notes?: string;
}

export interface GroundTruthRelevance {
  queryId: number;
  memoryId: number;
  relevance: 0 | 1 | 2 | 3; // 0=not relevant, 1=partial, 2=relevant, 3=highly relevant
}

/* ---------------------------------------------------------------
   2. QUERY DATASET
   Sections:
     A. Seed queries (ids 1-21) — from T000d, converted to camelCase
     B. Pattern-derived queries (ids 22-56) — from T007b consumption patterns
     C. Trigger-derived queries (ids 57-70) — from known trigger phrases
     D. Manual queries (ids 71-110) — curated, NOT trigger-derived
--------------------------------------------------------------- */

// ─── SECTION A: Seed queries from T000d (21 queries) ─────────

const SEED_QUERIES: GroundTruthQuery[] = [
  {
    id: 1,
    query: 'what does maxTriggersPerMemory control in the search pipeline',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'seed',
    expectedResultDescription:
      'Memory or spec covering search-weights.json and the MAX_TRIGGERS_PER_MEMORY constant in vector-index-impl.ts. Should surface the T000c audit or related sprint-0 documentation.',
    notes: 'Direct factual lookup — tests whether a specific technical constant is retrievable by natural-language description of its purpose.',
  },
  {
    id: 2,
    query: 'why was SHA256 dedup introduced for memory indexing',
    intentType: 'find_decision',
    complexityTier: 'simple',
    category: 'graph_relationship',
    source: 'seed',
    expectedResultDescription:
      'Decision record or memory explaining T054 / T003 (content hash dedup) rationale. Should reference Wave 1 bug fixes and duplicate prevention.',
    notes: 'Tests causal-edge graph retrieval — the decision to add SHA256 should be linked to prior duplicates observed.',
  },
  {
    id: 3,
    query: 'how does intent classification affect search result ranking',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'seed',
    expectedResultDescription:
      'Should surface memories about adaptive-fusion.ts (7 intent profiles), intent-classifier.ts, and memory_context intent routing. Cross-document because the behavior spans multiple modules.',
    notes: 'Tests whether multi-hop conceptual retrieval works — the answer requires understanding intent-classifier + adaptive-fusion + memory-context handler together.',
  },
  {
    id: 4,
    query: 'what decisions led to using RRF instead of a weighted linear combination for search fusion',
    intentType: 'find_decision',
    complexityTier: 'complex',
    category: 'graph_relationship',
    source: 'seed',
    expectedResultDescription:
      'Decision records from hybrid-rag-fusion spec (spec 139) about fusion strategy selection. Should surface rationale for RRF over linear weighted sum.',
    notes: 'Graph-relationship query tracing decision lineage. Tests causal traversal in the decision graph.',
  },
  {
    id: 5,
    query: 'SPECKIT_ADAPTIVE_FUSION flag is not working when set to false',
    intentType: 'fix_bug',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'seed',
    expectedResultDescription:
      'Should surface adaptive-fusion.ts (FEATURE_FLAG constant, isFeatureEnabled check), search-flags.ts, and rollout-policy.ts. Tests understanding the opt-out semantics.',
    notes: 'Bug-intent query matching a specific flag. Tests whether bug-type queries get boosted keyword weighting for technical terms.',
  },
  {
    id: 6,
    query: 'what was recently discussed about the graph channel hit rate being zero',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'temporal',
    source: 'seed',
    expectedResultDescription:
      'Should surface sprint-0 baseline measurement (T000a) which records graphHitRate=0, and any related spec memories about graph channel initialization or telemetry gaps.',
    notes: "Temporal query — 'recently discussed' should surface content from the last 7 days of memory creation. Tests recency boost in fix_bug / understand intent modes.",
  },
  {
    id: 7,
    query: 'how do I add a new feature flag to the SPECKIT system',
    intentType: 'add_feature',
    complexityTier: 'simple',
    category: 'factual',
    source: 'seed',
    expectedResultDescription:
      'Should surface the T000b feature flag governance document, rollout-policy.ts, and any SKILL.md sections about flag naming conventions.',
    notes: 'Add-feature intent for a procedural question. Tests whether governance documentation is surfaced for implementation guidance.',
  },
  {
    id: 8,
    query: 'what is the relationship between the working memory system and event decay',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'seed',
    expectedResultDescription:
      'Should surface memories about SPECKIT_WORKING_MEMORY, SPECKIT_EVENT_DECAY, working-memory.ts, and archival-manager.ts. The relationship is that event decay reduces attention scores over time.',
    notes: 'Cross-document query spanning multiple cognitive subsystems. Tests ability to retrieve conceptually related content without exact term matching.',
  },
  {
    id: 9,
    query: 'memory_context returns wrong results when token pressure is high',
    intentType: 'fix_bug',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'seed',
    expectedResultDescription:
      'Should surface memory-context.ts SPECKIT_PRESSURE_POLICY handling, the getPressureLevel function, and any spec/memory about pressure policy design decisions.',
    notes: 'Bug-intent query with specific symptom. Tests whether bug-type queries get boosted keyword weighting for technical terms.',
  },
  {
    id: 10,
    query: 'what decisions shaped the architecture of the 7-layer MCP tool hierarchy',
    intentType: 'find_decision',
    complexityTier: 'complex',
    category: 'graph_relationship',
    source: 'seed',
    expectedResultDescription:
      'Should surface system-spec-kit spec documents and memories about the L1/L2/L3/L4/L5/L6/L7 layer design, token budgets per layer, and original design rationale.',
    notes: 'Graph-relationship query about architectural lineage. Tests find_decision intent routing with high graph weight (0.50 per adaptive-fusion profile).',
  },
  {
    id: 11,
    query: 'how should I structure a new spec folder for a multi-phase feature',
    intentType: 'add_feature',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'seed',
    expectedResultDescription:
      'Should surface system-spec-kit SKILL.md section on spec folder structure, phase system documentation (spec 138), and the create.sh --phase command details.',
    notes: 'Add-feature procedural query. Tests retrieval of how-to content for a workflow the user wants to follow.',
  },
  {
    id: 12,
    query: 'which spec documents were added during the hybrid RAG fusion sprint',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'temporal',
    source: 'seed',
    expectedResultDescription:
      'Should surface memories in spec folder 003-system-spec-kit/139-hybrid-rag-fusion (89 memories) and 140-hybrid-rag-fusion-refinement. Lists spec documents created in those sprints.',
    notes: 'Find-spec intent with temporal/scope framing. Tests specFolder-aware retrieval.',
  },
  {
    id: 13,
    query: 'what is the current test coverage gap for the eval logging system',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'temporal',
    source: 'seed',
    expectedResultDescription:
      'Should surface T000a baseline (19 skipped tests, deferred DB fixture tests) and T005 eval-logger.ts module. May surface spec tasks.md identifying coverage gaps.',
    notes: 'Temporal query about current state. Tests whether the baseline measurement document surfaces for "current state" queries.',
  },
  {
    id: 14,
    query: 'smartRanking config weights in search-weights.json are inconsistent with the code fallback values',
    intentType: 'fix_bug',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'seed',
    expectedResultDescription:
      'Should surface T000c audit document which explicitly documents the relevanceWeight 0.2 vs 0.5 discrepancy, plus vector-index-impl.ts lines 2802-2804.',
    notes: 'Bug-intent query for a specific discrepancy found during this audit. Tests whether newly created scratch documents are retrieved when they contain the answer.',
  },
  {
    id: 15,
    query: 'what spec folder documents are required for a level 2 spec',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'factual',
    source: 'seed',
    expectedResultDescription:
      'Should surface CLAUDE.md or system-spec-kit SKILL.md table showing Level 2 requires: spec.md, plan.md, tasks.md, implementation-summary.md, checklist.md.',
    notes: 'Find-spec direct factual lookup. Tests whether constitutional or critical-tier memories (CLAUDE.md rules) are prioritized in retrieval.',
  },
  {
    id: 16,
    query: 'what was decided about removing the cross-encoder configuration from search-weights.json',
    intentType: 'find_decision',
    complexityTier: 'complex',
    category: 'graph_relationship',
    source: 'seed',
    expectedResultDescription:
      'Should surface the T000c audit finding that the crossEncoder section is dead config per agent-14 audit on 2026-02-08. May also surface spec 139 decisions.',
    notes: 'Find-decision query about a specific configuration removal decision. Tests whether recent audit documents are correctly linked to their decision context.',
  },
  {
    id: 17,
    query: 'python unit tests for the billing module',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'hard_negative',
    source: 'seed',
    expectedResultDescription:
      'Should return NO relevant results. This codebase has no Python code, no billing module, and no pytest setup. A high-quality retrieval system returns empty or near-empty results.',
    notes: 'Hard negative — completely out-of-domain query. Tests the system\'s ability to not hallucinate false matches on irrelevant queries.',
  },
  {
    id: 18,
    query: 'React component library Storybook configuration',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'hard_negative',
    source: 'seed',
    expectedResultDescription:
      'Should return NO relevant results. No React, no Storybook, no frontend component system exists in this codebase.',
    notes: 'Hard negative — completely wrong domain (frontend UI). Tests false positive rate.',
  },
  {
    id: 19,
    query: 'Kubernetes deployment manifest for the MCP server',
    intentType: 'find_spec',
    complexityTier: 'moderate',
    category: 'hard_negative',
    source: 'seed',
    expectedResultDescription:
      'Should return NO relevant results. The MCP server is a Node.js local process; there is no Kubernetes or containerization setup.',
    notes: "Hard negative — plausible-sounding query (it IS an MCP server!) but the deployment context does not exist. Tests whether surface-level term matches ('MCP server') cause false positives.",
  },
  {
    id: 20,
    query: 'OAuth 2.0 token refresh endpoint implementation',
    intentType: 'add_feature',
    complexityTier: 'moderate',
    category: 'hard_negative',
    source: 'seed',
    expectedResultDescription:
      'Should return NO relevant results. There is no OAuth, no HTTP server endpoints, no token auth in this system. API key validation is the only auth mechanism.',
    notes: 'Hard negative — auth-adjacent query that sounds plausible but targets a completely absent subsystem. Note: SPECKIT_SKIP_API_VALIDATION exists but is for internal testing bypass, not OAuth.',
  },
  {
    id: 21,
    query: 'GraphQL schema definition for the memory index API',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'hard_negative',
    source: 'seed',
    expectedResultDescription:
      'Should return NO relevant results. The API is MCP (Model Context Protocol) over JSON-RPC, not GraphQL. No schema definition language files exist.',
    notes: "Hard negative — tests whether mentions of 'memory index' cause false matches when the query context (GraphQL) is entirely wrong.",
  },
];

// ─── SECTION B: Pattern-derived queries from T007b (35 queries) ──

const PATTERN_DERIVED_QUERIES: GroundTruthQuery[] = [
  // Pattern 1 — Gate 1 trigger-style short queries (terse, verbatim-looking)
  {
    id: 22,
    query: 'fix the memory context handler',
    intentType: 'fix_bug',
    complexityTier: 'simple',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Gate 1 style terse query. Should surface memory-context.ts handler and related memories about known handler bugs or pressure policy issues.',
    notes: 'From T007b §5a: Gate 1 passes raw user messages verbatim; terse commands should still match.',
  },
  {
    id: 23,
    query: 'session state',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'temporal',
    source: 'pattern_derived',
    expectedResultDescription:
      'Resume-style fixed query. Should surface the most recent session state memory with next-steps anchor content.',
    notes: 'From T007b Pattern 2: session resume always uses "session state" as the input string.',
  },
  {
    id: 24,
    query: 'what was being worked on in the sprint-0 measurement foundation',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'temporal',
    source: 'pattern_derived',
    expectedResultDescription:
      'Topic-scoped resume query. Should surface spec folder 001-sprint-0-measurement-foundation memories with state/next-steps anchors.',
    notes: 'From T007b Pattern 2: variant of session resume scoped to a specific sprint/spec folder.',
  },
  {
    id: 25,
    query: 'implement ground truth generator for retrieval evaluation',
    intentType: 'add_feature',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Pre-implementation context load. Should surface existing eval-db.ts schema, eval-metrics.ts types, and any prior decisions about eval framework design.',
    notes: 'From T007b Pattern 3: feature description passed to memory_context before implementation.',
  },
  {
    id: 26,
    query: 'why was focused mode chosen over deep mode for fix_bug intent',
    intentType: 'find_decision',
    complexityTier: 'moderate',
    category: 'graph_relationship',
    source: 'pattern_derived',
    expectedResultDescription:
      'Decision archaeology query. Should surface adaptive-fusion.ts intent profiles and any decision record about mode selection heuristics.',
    notes: "From T007b Pattern 4: decision archaeology with anchors=['decisions', 'rationale'].",
  },
  {
    id: 27,
    query: 'what rationale drove the token budget assignments per MCP layer',
    intentType: 'find_decision',
    complexityTier: 'complex',
    category: 'graph_relationship',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface system-spec-kit SKILL.md section on L1-L7 token budgets (2000, 1500, 800, 500, 600, 1200, 1000) and any decision record explaining their sizing.',
    notes: 'From T007b Pattern 4: decision archaeology seeking rationale for architectural numbers.',
  },
  {
    id: 28,
    query: 'adaptive fusion search pipeline architecture',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Deep investigation query. Should surface adaptive-fusion.ts, hybrid-search.ts, rrf-fusion.ts, and related spec memories spanning the search stack.',
    notes: 'From T007b Pattern 5: deep investigation with mode=deep, cross-document retrieval.',
  },
  {
    id: 29,
    query: 'how does the @context agent coordinate sub-agent search strategies',
    intentType: 'understand',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface .opencode/agent/context.md and any spec memories about the @context agent\'s Layer 1/2/3 retrieval strategy and sub-agent dispatch.',
    notes: 'From T007b Pattern 5: @context agent deep investigation workflow.',
  },
  {
    id: 30,
    query: 'list all memories in the hybrid RAG fusion spec folder',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'scope_filtered',
    source: 'pattern_derived',
    expectedResultDescription:
      'Spec-scoped browse. Should surface memory titles and tiers from spec folder 003-system-spec-kit/139-hybrid-rag-fusion or 140-hybrid-rag-fusion-refinement.',
    notes: 'From T007b Pattern 6: architecture discovery using specFolder filter.',
  },
  {
    id: 31,
    query: 'what are all the spec documents in sprint 0 measurement foundation',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'scope_filtered',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface spec.md, plan.md, tasks.md, checklist.md from 001-sprint-0-measurement-foundation spec folder.',
    notes: 'From T007b Pattern 6: enumeration of what exists in a specific spec folder.',
  },
  {
    id: 32,
    query: 'constitutional memory rules',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Constitutional enforcement query. Should always surface constitutional-tier memories (CLAUDE.md rules, Four Laws of Agent Safety) at the top of results regardless of other content.',
    notes: 'From T007b Pattern 7: constitutional memories surface unconditionally on every query.',
  },
  {
    id: 33,
    query: 'relationship between causal edges and memory decision lineage',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'AND-search style query. Should surface causal-edges.ts, memory_causal_link tool schema, and any memories about the causal graph design.',
    notes: "From T007b Pattern 8: concept AND search for 'causal edges' AND 'decision lineage'.",
  },
  {
    id: 34,
    query: 'git workflow branch strategy',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'scope_filtered',
    source: 'pattern_derived',
    expectedResultDescription:
      'Git context recovery query. Should surface sk-git skill documentation and any spec memories about branch naming conventions or git workflow choices.',
    notes: 'From T007b Pattern 9: sk-git skill session recovery with domain-specific phrase.',
  },
  {
    id: 35,
    query: 'checklist verification status for T006 eval metrics implementation',
    intentType: 'find_spec',
    complexityTier: 'moderate',
    category: 'anchor_based',
    source: 'pattern_derived',
    expectedResultDescription:
      'Completion verification query. Should surface the sprint-0 checklist.md with T006 line items marked or unmarked, and any state anchor from recent sessions.',
    notes: "From T007b Pattern 10: completion verification using anchors=['state', 'checklist'].",
  },
  {
    id: 36,
    query: 'what tasks remain in the sprint 0 measurement foundation',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'anchor_based',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface the tasks.md from 001-sprint-0-measurement-foundation with incomplete tasks listed, and any session state memory with next-steps anchor.',
    notes: 'From T007b §6 rec 3: include queries about what remains to be done — maps to state anchor extraction.',
  },
  {
    id: 37,
    query: 'SPECKIT_BM25 environment variable controls what behavior',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface bm25-index.ts isBm25Enabled() function and any documentation about the BM25 feature flag.',
    notes: 'From T007b §6 rec 7: vary query length — this is a short, targeted factual query about a specific env var.',
  },
  {
    id: 38,
    query: 'how does multi-query expansion work in deep mode retrieval',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface query-expander.ts, memory-context.ts deep mode branch, and any spec about domain vocabulary expansion.',
    notes: 'From T007b §1 step 3: multi-query expansion is specific to deep mode — cross-document query.',
  },
  {
    id: 39,
    query: 'how should I refactor the eval-logger to support per-channel metrics',
    intentType: 'refactor',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface eval-logger.ts, eval-db.ts schema (eval_channel_results table), and any spec decisions about the eval framework design.',
    notes: 'Refactor-intent query — tests that refactor intent routes to deep mode (T007b §1 step 1).',
  },
  {
    id: 40,
    query: 'add a new intent type to the adaptive fusion scoring profiles',
    intentType: 'add_feature',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface adaptive-fusion.ts intent profiles, intent-classifier.ts enum, and eval-metrics.ts intentMultipliers. Cross-document because the change touches 3+ files.',
    notes: 'From T007b §5b: mode selection driven by intent classifier — add_feature routes to deep mode.',
  },
  {
    id: 41,
    query: 'security audit of the API key validation bypass flag',
    intentType: 'security_audit',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface SPECKIT_SKIP_API_VALIDATION documentation, api-key-validation.ts, and any memories about the conditions under which this flag is safe to use.',
    notes: 'Security audit intent — tests that security_audit intent routes to deep mode and surfaces relevant security content.',
  },
  {
    id: 42,
    query: 'the memory_search tool returns stale results after index rebuild',
    intentType: 'fix_bug',
    complexityTier: 'moderate',
    category: 'temporal',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface incremental-index.ts, index-refresh.ts, and any spec memories about stale cache behavior after indexing operations.',
    notes: 'Bug-intent with temporal aspect ("after index rebuild") — tests recency boosting for fix_bug intent.',
  },
  {
    id: 43,
    query: 'what is the difference between memory_context and memory_search for context retrieval',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface both memory_context (L1 unified entry) and memory_search (L2 core) tool schemas and any documentation comparing their use cases.',
    notes: 'From T007b §2: comparing two closely related tools — requires cross-document retrieval.',
  },
  {
    id: 44,
    query: 'refactor session deduplication to use a sliding window instead of session-scoped set',
    intentType: 'refactor',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface session-manager.ts, integration-session-dedup.vitest.ts, and any spec decisions about the deduplication design.',
    notes: 'Complex refactor query requiring understanding of current design before proposing change.',
  },
  {
    id: 45,
    query: 'find the spec that defines the SPECKIT_CAUSAL_BOOST feature flag',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'scope_filtered',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface causal-boost.ts, search-flags.ts, and any spec memory that introduced SPECKIT_CAUSAL_BOOST.',
    notes: 'Find-spec intent for a specific flag — tests feature flag governance retrieval.',
  },
  {
    id: 46,
    query: 'how does RRF fusion combine vector and BM25 channel scores',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface rrf-fusion.ts, adaptive-fusion.ts channel weights, and the T000a baseline note about graphHitRate=0.',
    notes: 'Cross-document query spanning fusion implementation and channel weight configuration.',
  },
  {
    id: 47,
    query: 'decision record for introducing the five-factor scoring system',
    intentType: 'find_decision',
    complexityTier: 'complex',
    category: 'graph_relationship',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface five-factor-scoring.vitest.ts, composite-scoring.ts, and any decision record about why five factors were chosen over a simpler scoring approach.',
    notes: 'Decision archaeology for a specific design choice — tests causal graph traversal.',
  },
  {
    id: 48,
    query: 'what security considerations exist for the memory save pipeline',
    intentType: 'security_audit',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface redaction-gate.ts, path-security.ts, preflight.ts, and any spec memories about data sanitization or access control in the save flow.',
    notes: 'Security audit of the save pipeline — requires cross-document retrieval of security-adjacent modules.',
  },
  {
    id: 49,
    query: 'what changed in the memory indexing pipeline after the T054 content hash fix',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'temporal',
    source: 'pattern_derived',
    expectedResultDescription:
      'Temporal query about a specific task milestone. Should surface memories created after T054 that reference the content hash dedup feature.',
    notes: 'From T007b §5a: temporal queries with task-reference framing.',
  },
  {
    id: 50,
    query: 'add FSRS spaced repetition scheduling to the memory attention score update',
    intentType: 'add_feature',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface fsrs-scheduler.ts, fsrs.ts, working-memory.ts, and any spec about the cognitive memory system integration.',
    notes: 'Complex add_feature query spanning multiple cognitive subsystem files.',
  },
  {
    id: 51,
    query: 'can the trigger matcher handle multi-word phrases with stop words',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface trigger-matcher.ts, trigger-extractor.vitest.ts, and any spec about trigger phrase normalization.',
    notes: 'Factual query about a specific capability of the trigger matcher module.',
  },
  {
    id: 52,
    query: 'find the decision that established the WARM tier as the minimum search state',
    intentType: 'find_decision',
    complexityTier: 'moderate',
    category: 'graph_relationship',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface importance-tiers.ts, tier-classifier.ts, and any decision record explaining why WARM (not COLD) is the default minState.',
    notes: 'Decision tracing for a specific default value in the search configuration.',
  },
  {
    id: 53,
    query: 'how does the prediction error gate integrate with the cognitive memory pipeline',
    intentType: 'understand',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface prediction-error-gate.ts, co-activation.ts, working-memory.ts, and any spec about the cognitive architecture integration points.',
    notes: 'Complex cross-document query about a niche cognitive subsystem component.',
  },
  {
    id: 54,
    query: 'refactor the importance tier scoring to use a lookup table instead of conditional chain',
    intentType: 'refactor',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface importance-tiers.ts, scoring.vitest.ts, and any spec about importance tier weight assignments.',
    notes: 'Refactor intent with a specific implementation suggestion — tests refactor routing to deep mode.',
  },
  {
    id: 55,
    query: 'what are the exact MCP tool names exposed by the spec kit memory server',
    intentType: 'find_spec',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface tool-schemas.ts or SKILL.md section listing all 20+ memory_* tool names and their layer classification.',
    notes: 'Factual find_spec query about the public API surface of the MCP server.',
  },
  {
    id: 56,
    query: 'security review of the path traversal prevention in memory file loading',
    intentType: 'security_audit',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'pattern_derived',
    expectedResultDescription:
      'Should surface path-security.ts, canonical-path.ts, and any spec memories about path traversal attack prevention.',
    notes: 'Security audit query targeting a specific attack surface in the file loading pipeline.',
  },
];

// ─── SECTION C: Trigger-derived queries (14 queries) ─────────

const TRIGGER_DERIVED_QUERIES: GroundTruthQuery[] = [
  {
    id: 57,
    query: 'memory deduplication content hash',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface memories with trigger phrases matching "content hash" or "deduplication". Likely surfaces T054-related memories about SHA256 dedup implementation.',
    notes: 'Derived from known trigger phrases in the memory system related to content hash dedup.',
  },
  {
    id: 58,
    query: 'constitutional memory tier enforcement',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface constitutional-tier memories (CLAUDE.md rules) which are injected unconditionally at the top of every result.',
    notes: 'Trigger phrase derived from constitutional tier documentation.',
  },
  {
    id: 59,
    query: 'SPECKIT_SESSION_BOOST working memory attention',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface session-boost.ts, working-memory.ts, and memories with trigger phrases about session boost or attention scoring.',
    notes: 'Derived from env var name which appears as a trigger phrase in session boost documentation.',
  },
  {
    id: 60,
    query: 'vector index embedding generation pipeline',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface vector-index.ts, embeddings.ts, and any spec memories about embedding model selection or the indexing pipeline.',
    notes: 'Trigger-phrase-style query about the vector indexing subsystem.',
  },
  {
    id: 61,
    query: 'RRF reciprocal rank fusion channel weights',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface rrf-fusion.ts, adaptive-fusion.ts, and spec memories about channel weight configuration.',
    notes: 'Derived from "reciprocal rank fusion" trigger phrase in the hybrid search documentation.',
  },
  {
    id: 62,
    query: 'spec kit memory MCP server initialization',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface server initialization documentation, SKILL.md sections about MCP server startup, and any init-related spec memories.',
    notes: 'Direct trigger phrase derived from the system name and initialization context.',
  },
  {
    id: 63,
    query: 'memory state lifecycle HOT WARM COLD DORMANT ARCHIVED',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface importance-tiers.ts, tier-classifier.ts, archival-manager.ts, and any spec memories about the 5-tier state machine.',
    notes: 'Trigger derived from tier names — tests whether explicit state name enumeration retrieves the right docs.',
  },
  {
    id: 64,
    query: 'generate context script memory save workflow',
    intentType: 'add_feature',
    complexityTier: 'simple',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface the generate-context.js script documentation and CLAUDE.md Memory Save Rule about using the script instead of the Write tool.',
    notes: 'Derived from "generate-context" trigger phrase in the memory save workflow documentation.',
  },
  {
    id: 65,
    query: 'attention decay cognitive memory scores',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface attention-decay.ts, working-memory.ts, and any spec memories about cognitive decay models applied to attention scores.',
    notes: 'Derived from "attention decay" trigger phrase in the cognitive subsystem.',
  },
  {
    id: 66,
    query: 'BM25 tokenization stemming',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface bm25-index.ts tokenize() and simpleStem() functions and any spec documentation about the text normalization approach.',
    notes: 'Derived from "BM25" and "stemming" trigger phrases in the BM25 index module.',
  },
  {
    id: 67,
    query: 'causal edge graph traversal memory relationships',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'graph_relationship',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface causal-edges.ts, causal-boost.ts, memory_drift_why tool schema, and spec memories about the causal relationship graph.',
    notes: 'Derived from "causal edge" and "graph traversal" trigger phrases.',
  },
  {
    id: 68,
    query: 'spec folder level 3 decision record requirement',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface CLAUDE.md documentation levels table showing Level 3 requires decision-record.md for ≥500 LOC changes.',
    notes: 'Derived from "decision record" and "level 3" trigger phrases in spec kit documentation.',
  },
  {
    id: 69,
    query: 'MMR maximal marginal relevance reranker diversity',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface mmr-reranker.ts and any spec memories about diversity-aware reranking in the search pipeline.',
    notes: 'Derived from "maximal marginal relevance" or "MMR" trigger phrases.',
  },
  {
    id: 70,
    query: 'SPECKIT_PRESSURE_POLICY token budget downgrade',
    intentType: 'fix_bug',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'trigger_derived',
    expectedResultDescription:
      'Should surface pressure-monitor.ts, memory-context.ts pressure handling, and any spec about the pressure policy design decisions.',
    notes: 'Derived from SPECKIT_PRESSURE_POLICY env var trigger phrase — overlaps with seed query 9 but phrased differently.',
  },
];

// ─── SECTION D: Manual queries (40 queries, NOT trigger-derived) ──

const MANUAL_QUERIES: GroundTruthQuery[] = [
  // --- understand intent (manual) ---
  {
    id: 71,
    query: 'I want to understand how the memory system decides when to archive a memory',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface archival-manager.ts, tier-classifier.ts, and any spec about the archival lifecycle conditions.',
    notes: 'Manual conversational phrasing — "I want to understand how" mimics natural user language.',
  },
  {
    id: 72,
    query: 'explain the difference between a spec folder and a memory folder in the spec kit',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface SKILL.md documentation distinguishing spec/ directories (governance docs) from memory/ directories (AI context storage).',
    notes: 'Manual clarification-seeking query using "explain the difference between".',
  },
  {
    id: 73,
    query: 'when should I use memory_search versus memory_context',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface tool comparison documentation in SKILL.md or tool-schemas.ts explaining L1 vs L2 routing.',
    notes: 'Manual decision-guidance query — realistic user confusion about which tool to use.',
  },
  {
    id: 74,
    query: 'why does my query return constitutional memories even when they are not relevant',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface the constitutional memory injection behavior described in SKILL.md §3 and T007b Pattern 7.',
    notes: 'Manual query expressing user frustration — tests whether the system surfaces the design rationale.',
  },
  {
    id: 75,
    query: 'how does the system know which memories are most important',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface importance-tiers.ts, composite-scoring.ts, five-factor-scoring documentation, and any spec about the importance weight assignment.',
    notes: 'Vague natural language query — tests whether broad semantic retrieval surfaces the right subsystems.',
  },
  {
    id: 76,
    query: 'what happens if two memories have the same content',
    intentType: 'understand',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface content hash dedup implementation in the save pipeline and the UNIQUE constraint in the memory schema.',
    notes: 'Manual conversational phrasing of the content dedup behavior.',
  },
  // --- find_decision intent (manual) ---
  {
    id: 77,
    query: 'why did the team choose SQLite over a dedicated vector database for memory storage',
    intentType: 'find_decision',
    complexityTier: 'complex',
    category: 'graph_relationship',
    source: 'manual',
    expectedResultDescription:
      'Should surface decision records or spec memories explaining the choice of SQLite + FTS5 + custom vector storage over alternatives like Pinecone or Chroma.',
    notes: 'High-level architectural decision query — tests whether foundational design choices are preserved in memory.',
  },
  {
    id: 78,
    query: 'what was the original reason for creating the spec kit memory system',
    intentType: 'find_decision',
    complexityTier: 'complex',
    category: 'graph_relationship',
    source: 'manual',
    expectedResultDescription:
      'Should surface early spec folder memories or constitutional documentation about why persistent AI memory was needed for the Claude Code / OpenCode workflow.',
    notes: 'Origin-story decision query — tests deep historical retrieval.',
  },
  {
    id: 79,
    query: 'how was the 7-intent taxonomy for memory retrieval originally justified',
    intentType: 'find_decision',
    complexityTier: 'moderate',
    category: 'graph_relationship',
    source: 'manual',
    expectedResultDescription:
      'Should surface intent-classifier.ts comments and any decision record explaining why exactly 7 intent types were chosen.',
    notes: 'Manual query about a specific count/taxonomy decision.',
  },
  {
    id: 80,
    query: 'was there ever a decision to deprecate the cross-encoder reranker',
    intentType: 'find_decision',
    complexityTier: 'moderate',
    category: 'temporal',
    source: 'manual',
    expectedResultDescription:
      'Should surface cross-encoder.ts and the T000c audit note that crossEncoder section is dead config, plus any decision record about its planned removal.',
    notes: 'Manual past-tense decision query — "was there ever a decision" pattern.',
  },
  // --- fix_bug intent (manual) ---
  {
    id: 81,
    query: 'the memory list tool is not returning chunk children even when I set includeChunks true',
    intentType: 'fix_bug',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface memory_list handler code and any spec about the includeChunks parameter behavior.',
    notes: 'Manual bug report phrasing — realistic user-facing issue description.',
  },
  {
    id: 82,
    query: 'causal graph traversal is returning empty results for all my queries',
    intentType: 'fix_bug',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface graph-search-fn.ts, causal-edges.ts, and the T000a baseline note about graphHitRate=0 being expected until the graph is populated.',
    notes: 'Manual bug report for the graph channel — relates to known T000a baseline finding.',
  },
  {
    id: 83,
    query: 'why is my new memory not appearing in search results after saving',
    intentType: 'fix_bug',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface incremental-index.ts, index-refresh.ts, and any spec about the indexing latency after save operations.',
    notes: 'Manual bug query about indexing lag — realistic user confusion about save vs. search consistency.',
  },
  {
    id: 84,
    query: 'memory_save keeps failing with duplicate content hash error',
    intentType: 'fix_bug',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface the content hash dedup logic in the save pipeline and explain that this is expected behavior when saving identical content.',
    notes: 'Manual error-message-style bug query.',
  },
  {
    id: 85,
    query: 'the tier classifier is promoting memories to constitutional tier incorrectly',
    intentType: 'fix_bug',
    complexityTier: 'complex',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface tier-classifier.ts, the constitutional tier qualification criteria, and any test coverage in tier-classifier.vitest.ts.',
    notes: 'Manual bug report about tier promotion logic — a sensitive path given constitutional tier has special behavior.',
  },
  // --- add_feature intent (manual) ---
  {
    id: 86,
    query: 'I want to add telemetry tracking to the hybrid search pipeline',
    intentType: 'add_feature',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface retrieval-telemetry.ts, trace-schema.ts, and any spec about the eval logging framework (T005).',
    notes: 'Manual add_feature intent with "I want to" phrasing — conversational but maps to implementation guidance.',
  },
  {
    id: 87,
    query: 'how can I extend the ground truth evaluation framework with a new metric',
    intentType: 'add_feature',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface eval-metrics.ts (existing metric functions), eval-db.ts schema, and spec tasks.md for the sprint-0 eval framework.',
    notes: 'Manual extensibility query about adding new eval metrics.',
  },
  {
    id: 88,
    query: 'what would be involved in adding a PostgreSQL backend option for the memory database',
    intentType: 'add_feature',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface the vector-store.ts interface, eval-db.ts, and the decision record about choosing SQLite. May surface the architecture layer definitions.',
    notes: 'Manual complex add_feature question — tests retrieval of interface contracts and architecture decisions together.',
  },
  {
    id: 89,
    query: 'add pagination support to the memory_list tool',
    intentType: 'add_feature',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface the memory_list handler code (offset/limit parameters that already exist) and the tool schema definition.',
    notes: 'Manual add_feature request that may already be partially implemented — tests whether the system surfaces the existing API.',
  },
  // --- find_spec intent (manual) ---
  {
    id: 90,
    query: 'where is the documentation for the sk-git skill',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface .opencode/skill/sk-git/SKILL.md and any spec memories about the sk-git skill functionality.',
    notes: 'Manual "where is" documentation query — tests file location retrieval.',
  },
  {
    id: 91,
    query: 'show me the checklist for the sprint 0 hybrid RAG fusion refinement',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'anchor_based',
    source: 'manual',
    expectedResultDescription:
      'Should surface checklist.md from the 001-sprint-0-measurement-foundation spec folder with P0/P1/P2 items.',
    notes: 'Manual "show me" retrieval query for a specific spec document.',
  },
  {
    id: 92,
    query: 'is there a research document for the hybrid RAG fusion approach',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface research.md from the 139-hybrid-rag-fusion or 140-hybrid-rag-fusion-refinement spec folder if it exists.',
    notes: 'Manual existence-check query for a specific spec document type.',
  },
  {
    id: 93,
    query: 'what is the task breakdown for the T008 BM25 baseline measurement task',
    intentType: 'find_spec',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface the tasks.md entry for T008 in 001-sprint-0-measurement-foundation with its sub-tasks and acceptance criteria.',
    notes: 'Manual task-lookup query for a specific task within the sprint.',
  },
  {
    id: 94,
    query: 'find the implementation summary for the eval metrics module',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface implementation-summary.md from the sprint-0 spec folder if it covers the eval metrics work (T006).',
    notes: 'Manual search for a specific document type about a completed implementation.',
  },
  // --- refactor intent (manual) ---
  {
    id: 95,
    query: 'the eval-db module has too many responsibilities and should be split up',
    intentType: 'refactor',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface eval-db.ts (5 tables, DDL, singleton pattern) and any spec decisions about the eval framework architecture.',
    notes: 'Manual refactor opinion expressed as a statement — tests whether refactor intent surfaces current architecture docs.',
  },
  {
    id: 96,
    query: 'can the trigger matching and vector search be unified into a single query path',
    intentType: 'refactor',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface trigger-matcher.ts, vector-index.ts, hybrid-search.ts, and any architectural decision about keeping the two paths separate.',
    notes: 'Manual architectural refactor question about system unification.',
  },
  {
    id: 97,
    query: 'the scoring module has duplicated weight normalization logic across several files',
    intentType: 'refactor',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface composite-scoring.ts, folder-scoring.ts, adaptive-fusion.ts, and any spec about the scoring module design.',
    notes: 'Manual DRY-violation observation driving a refactor request.',
  },
  {
    id: 98,
    query: 'refactor the memory parser to use a streaming approach for large files',
    intentType: 'refactor',
    complexityTier: 'complex',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface memory-parser.ts, chunking/anchor-chunker.ts, and any spec about large file handling or chunking strategies.',
    notes: 'Manual performance-motivated refactor request — may surface chunking design decisions.',
  },
  // --- security_audit intent (manual) ---
  {
    id: 99,
    query: 'what prevents a user from saving a memory with arbitrary filesystem paths',
    intentType: 'security_audit',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface path-security.ts, canonical-path.ts, preflight.ts validation, and the memory save handler input validation.',
    notes: 'Manual security question about path traversal prevention — specific attack surface.',
  },
  {
    id: 100,
    query: 'are there any secrets or credentials that could be accidentally saved to memory',
    intentType: 'security_audit',
    complexityTier: 'moderate',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface redaction-gate.ts, memory-parser.ts (redaction handling), and any spec about sensitive data handling in the memory pipeline.',
    notes: 'Manual security concern about data leakage — tests redaction-related content retrieval.',
  },
  {
    id: 101,
    query: 'can the eval logging system be used to exfiltrate search query content',
    intentType: 'security_audit',
    complexityTier: 'complex',
    category: 'cross_document',
    source: 'manual',
    expectedResultDescription:
      'Should surface eval-logger.ts (SPECKIT_EVAL_LOGGING flag, fail-safe design), eval-db.ts (local SQLite only), and any spec about the eval framework security model.',
    notes: 'Manual adversarial security query about the eval logging system — tests whether the security design is documented.',
  },
  {
    id: 102,
    query: 'how is access to the memory database restricted in production',
    intentType: 'security_audit',
    complexityTier: 'simple',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface database path resolution logic, api-key-validation.ts, and any spec about the production security model.',
    notes: 'Manual security question about database access control.',
  },
  // --- hard negatives (manual) ---
  {
    id: 103,
    query: 'how do I configure Redis cache invalidation for the memory store',
    intentType: 'fix_bug',
    complexityTier: 'simple',
    category: 'hard_negative',
    source: 'manual',
    expectedResultDescription:
      'Should return NO relevant results. There is no Redis cache; caching is implemented with a local in-memory tool-cache.ts module only.',
    notes: "Hard negative — Redis is plausible for a 'store' but does not exist in this system.",
  },
  {
    id: 104,
    query: 'Docker compose configuration for the spec kit memory MCP server',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'hard_negative',
    source: 'manual',
    expectedResultDescription:
      'Should return NO relevant results. There is no Docker, no containerization, no compose files for this project.',
    notes: 'Hard negative — Docker is common infrastructure but absent here. "MCP server" surface match is a false positive risk.',
  },
  {
    id: 105,
    query: 'SQL injection prevention in the memory search query parameter',
    intentType: 'security_audit',
    complexityTier: 'moderate',
    category: 'hard_negative',
    source: 'manual',
    expectedResultDescription:
      'Should return NO relevant results in the sense of documented SQL injection mitigations — while SQLite is used, the queries use parameterized statements and there is no documented injection audit.',
    notes: 'Hard negative — sounds plausible (SQLite IS used) but the specific security audit content does not exist.',
  },
  {
    id: 106,
    query: 'Java Spring Boot microservice integration with the memory API',
    intentType: 'add_feature',
    complexityTier: 'moderate',
    category: 'hard_negative',
    source: 'manual',
    expectedResultDescription:
      'Should return NO relevant results. The system is TypeScript/Node.js only; no Java, no Spring Boot, no microservice architecture.',
    notes: 'Hard negative — completely wrong technology stack.',
  },
  {
    id: 107,
    query: 'machine learning model training pipeline for embedding fine-tuning',
    intentType: 'add_feature',
    complexityTier: 'complex',
    category: 'hard_negative',
    source: 'manual',
    expectedResultDescription:
      'Should return NO relevant results. Embeddings are consumed from an external provider (Anthropic API); there is no training pipeline or model fine-tuning in this codebase.',
    notes: 'Hard negative — "embedding" exists but "training pipeline" context is completely absent.',
  },
  {
    id: 108,
    query: 'Terraform infrastructure provisioning scripts for the database',
    intentType: 'find_spec',
    complexityTier: 'simple',
    category: 'hard_negative',
    source: 'manual',
    expectedResultDescription:
      'Should return NO relevant results. The database is a local SQLite file; no infrastructure as code, no cloud provisioning.',
    notes: 'Hard negative — infrastructure tooling that does not exist.',
  },
  // --- additional coverage queries (to ensure all gates pass) ---
  {
    id: 109,
    query: 'how does the memory_bulk_delete tool decide which tier to clean up first',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface memory_bulk_delete tool schema (tier parameter, confirm safety gate), the bulk delete handler, and any spec about tier-based cleanup strategies.',
    notes: 'Manual query about a specific administrative tool behavior — L4 Mutation layer.',
  },
  {
    id: 110,
    query: 'what is the learning index formula used in task preflight and postflight scoring',
    intentType: 'understand',
    complexityTier: 'moderate',
    category: 'factual',
    source: 'manual',
    expectedResultDescription:
      'Should surface the Learning Index formula (LI = KnowledgeDelta×0.4 + UncertaintyReduction×0.35 + ContextImprovement×0.25) from CLAUDE.md or memory_task_preflight tool documentation.',
    notes: 'Manual query targeting a specific quantitative formula documented in the system — tests factual precision retrieval.',
  },
];

/* ---------------------------------------------------------------
   3. COMBINED EXPORT
--------------------------------------------------------------- */

/** Full ground truth query dataset (110 queries). */
export const GROUND_TRUTH_QUERIES: GroundTruthQuery[] = [
  ...SEED_QUERIES,
  ...PATTERN_DERIVED_QUERIES,
  ...TRIGGER_DERIVED_QUERIES,
  ...MANUAL_QUERIES,
];

/** Query distribution summary for reporting. */
export const QUERY_DISTRIBUTION = {
  total: GROUND_TRUTH_QUERIES.length,
  bySource: {
    seed: SEED_QUERIES.length,
    pattern_derived: PATTERN_DERIVED_QUERIES.length,
    trigger_derived: TRIGGER_DERIVED_QUERIES.length,
    manual: MANUAL_QUERIES.length,
  },
  byIntentType: computeDistribution('intentType'),
  byComplexityTier: computeDistribution('complexityTier'),
  byCategory: computeDistribution('category'),
  hardNegativeCount: GROUND_TRUTH_QUERIES.filter(q => q.category === 'hard_negative').length,
  manualQueryCount: GROUND_TRUTH_QUERIES.filter(q => q.source === 'manual').length,
} as const;

/** Compute distribution counts over a string key of GroundTruthQuery. */
function computeDistribution(
  key: keyof Pick<GroundTruthQuery, 'intentType' | 'complexityTier' | 'category'>,
): Record<string, number> {
  const counts: Record<string, number> = {};
  for (const q of GROUND_TRUTH_QUERIES) {
    const val = q[key] as string;
    counts[val] = (counts[val] ?? 0) + 1;
  }
  return counts;
}
