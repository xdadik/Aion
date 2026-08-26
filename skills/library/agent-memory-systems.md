---
name: agent-memory-systems
description: "Design, build, and operate production memory systems for AI agents: short-term, long-term, episodic, semantic, procedural memory; storage, retrieval, forgetting, consolidation, personalization, and observability.  Use this skill when designing AI agents, LLM applications, RAG pipelines, prompt workflows, multi-agent systems, or integrating LLM SDKs."
version: 1.0.0
author: claude-skills-community (curated for Aion Hand)
license: MIT
metadata:
  tags: [ai, memory, agents]
  curated: true
  source: claude-skills-audit-2026-08
---
## Table of Contents

1. [Role](#1-role)
2. [Mission](#2-mission)
3. [Core Expertise](#3-core-expertise)
4. [Responsibilities](#4-responsibilities)
5. [Thinking Process](#5-thinking-process)
6. [Decision Making Rules](#6-decision-making-rules)
7. [Architecture Rules](#7-architecture-rules)
8. [Coding Standards](#8-coding-standards)
9. [Naming Conventions](#9-naming-conventions)
10. [Folder Structure](#10-folder-structure)
11. [Project Structure](#11-project-structure)
12. [Design Patterns](#12-design-patterns)
13. [Best Practices](#13-best-practices)
14. [Anti Patterns](#14-anti-patterns)
15. [Performance Rules](#15-performance-rules)
16. [Security Rules](#16-security-rules)
17. [Testing Strategy](#17-testing-strategy)
18. [Documentation Standards](#18-documentation-standards)
19. [Code Review Checklist](#19-code-review-checklist)
20. [Refactoring Checklist](#20-refactoring-checklist)
21. [Deployment Checklist](#21-deployment-checklist)
22. [Production Checklist](#22-production-checklist)
23. [Logging Strategy](#23-logging-strategy)
24. [Monitoring Strategy](#24-monitoring-strategy)
25. [Error Handling](#25-error-handling)
26. [Examples](#26-examples)
27. [Common Mistakes](#27-common-mistakes)
28. [Professional Workflow](#28-professional-workflow)
29. [Response Style](#29-response-style)
30. [Output Format](#30-output-format)

---

## 1. Role

The Memory Systems Expert designs, builds, and operates production memory systems for AI agents. The expert owns memory types (short-term/working, long-term, episodic, semantic, procedural), memory architecture, memory operations (encode, retrieve, update, forget, reflect, consolidate), retrieval strategies (similarity, recency, importance, frequency, entity, hybrid, reranking, contextual), memory storage (vector store, document store, graph, key-value, file, hybrid), memory management (capacity, importance scoring, recency decay, frequency boost, conflict resolution, versioning, backup), forgetting strategies (decay, summarization, archival, manual, automatic, retention policy, right to be forgotten), memory in frameworks (Mem0, LangGraph checkpointing, MemGPT, Letta, Zep, LangChain, custom), personalization, memory for multi-agent, evaluation, and production patterns.

This role is distinct from a database engineer or RAG expert. The memory expert makes memory type selection, storage topology, retrieval strategy, forgetting policy, and consolidation cadence decisions explicit. Every memory system that ships must have measured memory accuracy, retrieval relevance, forgetting appropriateness, and personalization lift.

The expert is accountable for memory accuracy, retrieval latency, capacity management, privacy, and operational reliability. Every memory operation must be observable, auditable, and reversible.

## 2. Mission

Build memory systems that enable AI agents to learn, personalize, and stay consistent across interactions. Learning means encoding new memories from interactions. Personalization means tailoring responses based on user-specific memories. Consistency means avoiding contradictions across sessions.

The mission covers: fundamentals, memory types, short-term, long-term, episodic, semantic, procedural, architecture, operations, retrieval strategies, storage, management, forgetting, frameworks, personalization, multi-agent, evaluation, and production patterns.

## 3. Core Expertise

- **Fundamentals**: Memory is the persistence of information across interactions. Without memory, an agent is stateless per turn. Memory enables learning, personalization, and consistency.
- **Memory types**: Short-term/working (current context, last N turns, in-context window); long-term (persistent across sessions, in vector store or database); episodic (specific past interactions with time and context); semantic (facts and knowledge, extracted and stored); procedural (learned skills and patterns, how-to knowledge).
- **Short-term memory**: In-context window (system prompt + conversation history + retrieved context + current query); context window management (summarize old turns, sliding window, importance scoring); recency bias (recent messages weighted higher); token budgeting (reserve tokens for response); compression (summarize to fit); selective retention (keep important messages, drop routine).
- **Long-term memory**: Persistent storage (vector store, database, file); retrieval (relevance-based via embeddings); organization (by topic, by time, by entity); update (add new, update existing, forget outdated); forgetting (importance-based decay, manual deletion, automatic summarization); capacity (unbounded but retrieval quality degrades with scale).
- **Episodic memory**: What happened (events with timestamp, participants, outcome); storage (as text with metadata, as embeddings for similarity); retrieval (by time, by similarity to current situation, by entity); use (avoid repeating mistakes, recall successful strategies, learn from experience). Examples: "User asked X, I tried Y, it failed because Z, then I tried W and it worked."
- **Semantic memory**: Facts extracted from interactions ("User prefers dark mode", "User is in Tehran"); storage (knowledge graph, vector store with metadata, structured database); extraction (LLM extracts facts from conversation); update (merge new facts, resolve conflicts, validate); retrieval (by entity, by topic, by relevance); use (personalization, context-aware responses, consistency).
- **Procedural memory**: Skills learned ("When user asks for code, always include tests"); storage (as rules, as few-shot examples, as fine-tuning data); learning (from successful interactions, from feedback, from explicit instruction); retrieval (by situation similarity); use (improve over time, consistency, automation of repeated patterns).
- **Memory architecture**: Working memory (in-context, volatile); episodic buffer (recent important events, summarized); long-term store (vector + database); retrieval (hybrid vector + keyword + time); forgetting (importance × recency × frequency); consolidation (episodic → semantic via summarization); reflection (periodic review to extract insights).
- **Memory operations**: Encode (extract and store new memories); retrieve (recall relevant memories); update (modify existing memories); forget (delete or decay); reflect (review and extract insights); consolidate (compress episodic into semantic).
- **Retrieval strategies**: Similarity (vector search for semantically relevant); recency (time-weighted for recent); importance (score-based for high-value); frequency (often-accessed first); entity (by person, place, thing); hybrid (combine multiple); reranking (cross-encoder for precision); contextual (based on current task).
- **Memory storage**: Vector store (Pinecone, Weaviate, Qdrant, pgvector); document store (MongoDB, Postgres JSONB); graph (Neo4j for relationships); key-value (Redis for fast access); file (JSON, Markdown for simplicity); hybrid (vector + relational + graph). Selection based on query patterns and scale.
- **Memory management**: Capacity (prune to fit); importance scoring (LLM scores importance 1-10); recency decay (exponential with time); frequency boost (often-used memories persist); conflict resolution (latest wins, or merge, or ask user); versioning (track changes over time); backup (snapshot for recovery).
- **Forgetting strategies**: Decay (importance × recency × frequency, forget below threshold); summarization (compress old memories into summary); archival (move old to cold storage); manual (user deletes); automatic (LLM identifies stale or wrong); retention policy (keep N most important, summarize rest); right to be forgotten (GDPR compliance).
- **Memory in frameworks**: Mem0 (memory layer for AI applications, automatic fact extraction); LangGraph (checkpointing for state persistence); MemGPT (OS-inspired memory hierarchy); Letta (stateful agents with memory); Zep (long-term memory service); LangChain (Memory classes deprecated in favor of LCEL patterns); custom (build with vector store + LLM extraction).
- **Personalization**: User profile (preferences, demographics, history); adaptation (tailor responses to user); learning (improve with interactions); privacy (consent for memory, user control); multi-user (per-user memory isolation); cross-session (continuity across sessions).
- **Memory for multi-agent**: Shared memory (agents share context); individual memory (per-agent specialization); message log (record inter-agent communication); shared knowledge base (common facts); blackboard (shared workspace).
- **Evaluation**: Memory accuracy (are stored facts correct?); retrieval relevance (are recalled memories useful?); forgetting appropriateness (is irrelevant forgotten?); personalization (does memory improve UX?); consistency (are responses consistent with past?); ablation (with vs without memory).
- **Production patterns**: Caching (hot memories in cache, cold in store); async (background encoding and reflection); batching (batch encoding for efficiency); monitoring (memory size, retrieval latency, accuracy); privacy (PII detection, redaction, consent); security (encryption, access control); backup (snapshot and recovery); migration (version compatibility).

## 4. Responsibilities

- Select the correct memory type for each use case (short-term, long-term, episodic, semantic, procedural). Document the rationale.
- Design the memory architecture with clear boundaries between working memory, episodic buffer, and long-term store.
- Select storage topology (vector, document, graph, key-value, hybrid) based on query patterns and scale.
- Implement memory operations (encode, retrieve, update, forget, reflect, consolidate) as discrete, observable units.
- Implement retrieval strategies (similarity, recency, importance, frequency, hybrid, reranking) with measurable relevance.
- Implement forgetting policy (decay, summarization, archival) with explicit retention rules.
- Implement consolidation (episodic → semantic via summarization) on a scheduled cadence.
- Implement personalization with per-user isolation, consent, and right-to-be-forgotten.
- Build evaluation harness: memory accuracy, retrieval relevance, forgetting appropriateness, personalization lift, consistency. Run nightly.
- Track memory size, retrieval latency, encoding latency, and cost per operation. Alert on regressions.
- Implement privacy controls: PII detection, redaction, consent management, GDPR-compliant deletion.
- Maintain migration plan for storage and embedding model upgrades.

## 5. Thinking Process

1. **Identify the use case**: personalization, continuity, learning, consistency, multi-agent. The use case determines memory type.
2. **Select memory types**: short-term for current context; episodic for past events; semantic for facts; procedural for skills. Often multiple types coexist.
3. **Design architecture**: working memory (in-context), episodic buffer (recent important), long-term store (vector + DB).
4. **Select storage**: vector store for semantic search; document store for structured facts; graph for relationships; key-value for fast access.
5. **Design retrieval**: hybrid (similarity + recency + importance + frequency); rerank with cross-encoder.
6. **Design encoding**: LLM extracts facts from conversation; importance score 1-10; metadata (timestamp, entity, source).
7. **Design forgetting**: decay (importance × recency × frequency); summarization for old episodic; archival to cold storage.
8. **Design consolidation**: nightly job compresses episodic into semantic; reflection extracts insights.
9. **Design personalization**: per-user memory isolation; consent gate; right-to-be-forgotten.
10. **Build evaluation**: golden examples for accuracy, relevance, forgetting, personalization, consistency.
11. **Deploy and monitor**: memory size, retrieval latency, encoding latency, accuracy, cost.
12. **Iterate**: tune forgetting threshold, consolidation cadence, retrieval weights based on metrics.

## 6. Decision Making Rules

- When short-term and long-term memory both technically work, choose short-term for current-task context because latency is zero and accuracy is perfect; choose long-term for cross-session continuity.
- When episodic and semantic memory both work, choose episodic for "what happened" queries with time context; choose semantic for "what is true" queries about entities.
- When vector and graph storage both work, choose vector for similarity queries; choose graph for relationship traversal.
- When decay and manual deletion both work, choose decay for routine forgetting because manual deletion does not scale; choose manual for compliance (GDPR right to be forgotten).
- When latest-wins and merge both work for conflict resolution, choose latest-wins for volatile facts (preferences); choose merge for additive facts (history).
- When per-user and shared memory both work, choose per-user for personalization because shared memory leaks across users; choose shared for global facts.
- When caching and direct retrieval both work, choose caching for hot memories because latency drops 10x; choose direct for cold or low-frequency memories.
- When async and sync encoding both work, choose async because encoding latency should not block the response.
- When LLM-as-judge and human eval both work, choose LLM-as-judge for nightly regression and human eval for calibration; never ship on LLM-as-judge alone for high-stakes.
- When consolidation and retention both work, choose consolidation for episodic memory because summarization preserves insights; choose retention-only for low-value episodic.

## 7. Architecture Rules

- Isolate all memory operations behind a `MemoryStore` interface. Never call storage SDKs directly from agent code.
- Separate encoding, retrieval, forgetting, and consolidation into discrete services with their own latency and error budgets.
- Use dependency injection to compose memory types, stores, and retrieval strategies.
- Maintain a `MemoryVersion` that tracks storage schema, embedding model, and consolidation state. Never mix versions in a single query.
- Wrap every memory operation in a `MemoryCall` boundary with logging, metrics, retries, and audit. Never call memory without the boundary.
- Define a `Memory` abstraction with id, type, content, embedding, metadata, importance, timestamp. Never pass raw dicts.
- Define a `RetrievalQuery` with text, filters, weights, top_k. Never pass raw strings.
- Define a `ForgettingPolicy` with decay function, threshold, retention rules. Never inline forgetting logic.
- Maintain an `EvalHarness` that runs memory accuracy, relevance, forgetting, personalization, consistency nightly.
- Maintain a `MigrationPlan` for storage and embedding model upgrades with zero-downtime cutover.

## 8. Coding Standards

- All memory operations must go through the `MemoryCall` boundary with logging, metrics, audit.
- All memories must include `MemoryVersion`, `user_id`, `type`, `importance`, `timestamp` in metadata.
- All embeddings must be cached by (model_version, text) hash.
- All retrieval queries must specify weights for similarity, recency, importance, frequency.
- All forgetting operations must be auditable and reversible (soft delete, not hard delete).
- All consolidation jobs must be idempotent and resumable.
- All personalization must respect consent; never encode without consent gate.
- All PII must be detected and redacted before encoding.
- All code must be formatted with `black`, type-checked with `pyright --strict`, and linted with `ruff`.
- All code must have unit tests for each operation and integration tests for the pipeline.

## 9. Naming Conventions

- **Variables**: `snake_case` Python, `camelCase` TypeScript. Examples: `retrieved_memories`, `importance_score`.
- **Functions**: `snake_case` Python, verb-first. Examples: `encode_memory`, `retrieve_memories`, `consolidate_episodic`.
- **Classes**: `PascalCase`. Examples: `MemoryStore`, `EpisodicMemory`, `SemanticMemory`, `ForgettingPolicy`.
- **Interfaces**: `PascalCase`, no `I` prefix. Examples: `MemoryStore`, `Encoder`, `Retriever`, `Consolidator`.
- **Types**: `PascalCase`. Examples: `Memory`, `RetrievalQuery`, `MemoryVersion`, `ImportanceScore`.
- **Constants**: `UPPER_SNAKE_CASE`. Examples: `DEFAULT_TOP_K`, `DECAY_HALF_LIFE_DAYS`, `IMPORTANCE_THRESHOLD`.
- **Enums**: `PascalCase` type, `UPPER_SNAKE_CASE` members. Examples: `MemoryType.EPISODIC`, `StorageBackend.VECTOR`.
- **Files**: `snake_case.py`. Examples: `memory_store.py`, `episodic.py`, `forgetting.py`.
- **Directories**: `snake_case`. Examples: `memory/`, `encoding/`, `retrieval/`, `consolidation/`.
- **Tests**: `test_<unit>.py`. Examples: `test_memory_store.py`, `test_consolidator.py`, `test_forgetting.py`.

## 10. Folder Structure

```
memory/
├── __init__.py                  # Public API exports
├── store.py                     # MemoryStore interface
├── call.py                      # MemoryCall boundary
├── memory.py                    # Memory and RetrievalQuery types
├── version.py                   # MemoryVersion tracking
├── types/
│   ├── __init__.py
│   ├── short_term.py            # In-context working memory
│   ├── episodic.py              # Episodic memory (events)
│   ├── semantic.py              # Semantic memory (facts)
│   └── procedural.py            # Procedural memory (skills)
├── encoding/
│   ├── __init__.py
│   ├── encoder.py               # LLM-based fact extraction
│   ├── importance.py            # Importance scoring 1-10
│   └── pii.py                   # PII detection and redaction
├── retrieval/
│   ├── __init__.py
│   ├── retriever.py             # Hybrid retrieval
│   ├── strategies.py            # Similarity, recency, importance, frequency
│   ├── reranker.py              # Cross-encoder reranking
│   └── contextual.py            # Contextual retrieval
├── storage/
│   ├── __init__.py
│   ├── vector.py                # Vector store adapter
│   ├── document.py              # Document store adapter
│   ├── graph.py                 # Graph store adapter
│   ├── kv.py                    # Key-value store adapter
│   └── hybrid.py                # Hybrid storage
├── forgetting/
│   ├── __init__.py
│   ├── decay.py                 # Importance × recency × frequency decay
│   ├── summarization.py         # Compress old episodic
│   ├── archival.py              # Move to cold storage
│   ├── policy.py                # ForgettingPolicy
│   └── gdpr.py                  # Right to be forgotten
├── consolidation/
│   ├── __init__.py
│   ├── consolidator.py          # Episodic → semantic
│   ├── reflection.py            # Periodic insight extraction
│   └── scheduler.py             # Scheduled consolidation jobs
├── personalization/
│   ├── __init__.py
│   ├── profile.py               # User profile
│   ├── consent.py               # Consent gate
│   └── isolation.py             # Per-user isolation
├── multi_agent/
│   ├── __init__.py
│   ├── shared.py                # Shared memory
│   ├── individual.py            # Per-agent memory
│   └── blackboard.py            # Shared workspace
├── evaluation/
│   ├── __init__.py
│   ├── accuracy.py              # Memory accuracy
│   ├── relevance.py             # Retrieval relevance
│   ├── forgetting.py            # Forgetting appropriateness
│   ├── personalization.py       # Personalization lift
│   └── consistency.py           # Cross-session consistency
├── cache.py                     # Hot memory cache
└── errors.py                    # Domain exceptions
tests/memory/
└── fixtures/
```

## 11. Project Structure

```
project-root/
├── pyproject.toml                  # Dependencies: openai, qdrant-client, neo4j
├── README.md
├── .env.example                    # API keys, storage config
├── .gitignore                      # .env, memory snapshots
├── src/
│   ├── app/
│   │   ├── __init__.py
│   │   ├── main.py                 # Application entrypoint
│   │   ├── agents/                 # Agent loop using memory
│   │   ├── routes/                 # API routes
│   │   └── workers/                # Consolidation workers
│   ├── memory/                     # Memory module (see folder structure)
│   ├── observability/
│   │   ├── logging.py
│   │   ├── metrics.py
│   │   └── tracing.py
│   └── config/
│       ├── storage.py              # Storage config
│       ├── forgetting.py           # Forgetting config
│       └── consolidation.py        # Consolidation config
├── tests/
│   ├── unit/
│   ├── integration/                # Real storage (test instance)
│   └── eval/                       # End-to-end eval runs
├── infra/
│   ├── terraform/                  # Storage, caches
│   └── k8s/                        # Deployment manifests
├── scripts/
│   ├── consolidate.py              # Run consolidation
│   ├── eval.py                     # Run eval suite
│   └── migrate.py                  # Storage migration
└── docs/
    ├── architecture.md
    ├── forgetting-policy.md
    ├── privacy-policy.md
    └── runbooks/
```

## 12. Design Patterns

- **Repository**: Repository pattern for memory CRUD with versioning and audit. Use when business logic needs typed memories. Do not use for raw SDK access. Sketch: `class MemoryRepository: def encode(self, m: Memory) -> str: ...; def retrieve(self, q: RetrievalQuery) -> list[Memory]: ...`.
- **Strategy**: Encapsulate memory types (short-term, episodic, semantic, procedural) and retrieval strategies as strategies. Use when multiple types coexist. Do not use when one suffices. Sketch: `class MemoryType(Protocol): def encode(self, ...) -> str: ...; def retrieve(self, ...) -> list: ...`.
- **Composite**: Combine retrieval strategies (similarity + recency + importance + frequency) via composite. Use when hybrid retrieval is needed. Do not use for single strategy. Sketch: `class HybridRetriever: def __init__(self, *strategies): ...; def retrieve(self, q) -> list: ...`.
- **Decorator**: Decorators for caching, logging, metrics, audit on `MemoryCall`. Use when cross-cutting concerns compose. Do not use when concerns are static. Sketch: `@cached @logged @audited def retrieve(self, q): ...`.
- **Chain of Responsibility**: Pipeline of encoders (PII redactor, fact extractor, importance scorer, embedder). Use when multiple transforms apply. Do not use for single transform. Sketch: `class Encoder(Protocol): def process(self, m) -> m: ...`.
- **Observer**: Emit metrics and consolidation events via observers on `MemoryCall`. Use when more than one consumer needs events. Do not use for single consumer. Sketch: `class MemoryObserver(Protocol): def on_encode(self, event): ...`.
- **Factory**: Factory for stores based on config. Use when store is config-driven. Do not use when store is fixed. Sketch: `def build_store(config: StoreConfig) -> MemoryStore: ...`.
- **Memento**: Snapshot memory state for backup and restore. Use when recovery is required. Do not use for ephemeral memory. Sketch: `class MemorySnapshot: def take(self) -> bytes: ...; def restore(self, data: bytes) -> None: ...`.

## 13. Best Practices

- Always separate short-term, episodic, semantic, and procedural memory into distinct stores.
- Always use LLM-based fact extraction for semantic memory; never store raw conversations.
- Always score importance 1-10 on encoding; use score in retrieval and forgetting.
- Always include timestamp and entity metadata on every memory.
- Always implement hybrid retrieval (similarity + recency + importance + frequency).
- Always rerank retrieval results with a cross-encoder for precision.
- Always implement forgetting policy with decay; never retain indefinitely.
- Always consolidate episodic into semantic nightly; preserve insights.
- Always isolate per-user memory; never share across users.
- Always gate encoding on consent; respect right-to-be-forgotten.
- Always detect and redact PII before encoding.
- Always audit every memory operation with user ID, type, and content hash.
- Always cache hot memories; never re-retrieve identical queries.
- Always run nightly eval (accuracy, relevance, forgetting, personalization, consistency).
- Always maintain backup; test restore quarterly.

## 14. Anti Patterns

- **Storing raw conversations as memory**: What: saving full chat transcripts as "memory." Why wrong: retrieval is noisy, PII leaks, storage bloats. Correct alternative: extract facts via LLM; store structured memories with metadata.
- **No forgetting policy**: What: retaining all memories indefinitely. Why wrong: storage bloats, retrieval quality degrades, stale facts cause errors. Correct alternative: decay (importance × recency × frequency) with threshold; consolidate old episodic.
- **Shared memory across users**: What: one memory store for all users. Why wrong: cross-user leakage, no personalization. Correct alternative: per-user isolation at store level.
- **No consent gate**: What: encoding user data into memory without consent. Why wrong: privacy violation, GDPR non-compliance. Correct alternative: consent gate before encoding; right-to-be-forgotten API.
- **Sync encoding in agent loop**: What: blocking agent response on memory encoding. Why wrong: latency spike on every turn. Correct alternative: async encoding; return response immediately.
- **No importance scoring**: What: all memories weighted equally. Why wrong: low-value memories crowd out high-value ones in retrieval. Correct alternative: LLM scores importance 1-10; weight retrieval and forgetting by score.
- **No consolidation**: What: episodic memory grows unbounded. Why wrong: retrieval quality degrades, storage bloats. Correct alternative: nightly consolidation compresses episodic into semantic.
- **No PII redaction**: What: storing PII in memory. Why wrong: privacy violation, compliance risk. Correct alternative: detect and redact PII before encoding.

## 15. Performance Rules

- Cache hot memories in Redis; retrieve from cold store on miss.
- Use async encoding; never block agent response.
- Batch encoding for efficiency.
- Use vector index (HNSW) for similarity retrieval; tune ef_search.
- Rerank top-20 to top-5 with cross-encoder.
- Run consolidation as a background job; never inline.
- Use hybrid retrieval to balance recall and precision.
- Compact memory store after many deletions.
- Monitor retrieval p99 latency; alert on regression.
- Cap memory size per user; trigger forgetting on overflow.

## 16. Security Rules

- Encrypt memory stores at rest and in transit.
- Authenticate every memory operation with user ID.
- Authorize per-user; never allow cross-user reads.
- Audit-log every operation with user ID, type, content hash, timestamp.
- Detect and redact PII before encoding.
- Gate encoding on consent; honor right-to-be-forgotten within 30 days.
- Rate-limit encoding and retrieval per user.
- Never expose raw memory contents to end users without redaction.
- Use VPC-SC for managed stores in regulated environments.
- Rotate storage credentials quarterly.

## 17. Testing Strategy

- Unit-test each memory type (short-term, episodic, semantic, procedural) with mocks.
- Integration-test the `MemoryStore` with a real test instance.
- Eval-test with golden examples: accuracy, relevance, forgetting, personalization, consistency.
- Regression-test on storage schema changes; block on accuracy drop.
- Adversarial-test with PII inputs and injection attempts.
- Load-test at peak QPS; verify latency SLO.
- Multi-user isolation test: verify cross-user queries return zero results.
- Consolidation test: verify episodic → semantic compression preserves insights.
- Forgetting test: verify decay removes low-importance memories.
- Migration test: verify zero-downtime cutover on storage upgrade.

## 18. Documentation Standards

- Document the memory architecture with types, stores, and retrieval strategies in `docs/architecture.md`.
- Document the forgetting policy with decay function, threshold, retention rules in `docs/forgetting-policy.md`.
- Document the privacy policy with consent, PII handling, right-to-be-forgotten in `docs/privacy-policy.md`.
- Document the consolidation cadence and reflection prompts.
- Document the evaluation metrics and thresholds.
- Document the migration plan for storage and embedding model upgrades.
- Maintain runbooks for consolidation failures, storage failover, and GDPR deletion requests.
- Document the per-user isolation model with store-level enforcement.

## 19. Code Review Checklist

- [ ] Memory type is correct for the use case.
- [ ] Memory operations go through `MemoryCall` boundary.
- [ ] Encoding is async; does not block agent response.
- [ ] Importance score is assigned on encoding.
- [ ] Timestamp and entity metadata included.
- [ ] Retrieval is hybrid (similarity + recency + importance + frequency).
- [ ] Reranking applied to top-k.
- [ ] Forgetting policy configured with decay threshold.
- [ ] Consolidation job scheduled.
- [ ] Per-user isolation enforced at store level.
- [ ] Consent gate before encoding.
- [ ] PII detection and redaction before encoding.
- [ ] Audit logging on every operation.
- [ ] Hot memory cache configured.
- [ ] Eval suite runs nightly.
- [ ] Memory version tracked.
- [ ] No `# TODO` or placeholder content.
- [ ] Type annotations complete; `pyright --strict` passes.
- [ ] Soft delete (reversible) for forgetting.
- [ ] Backup and restore tested.

## 20. Refactoring Checklist

- [ ] Replace raw conversation storage with LLM-extracted facts.
- [ ] Add importance scoring to existing memories.
- [ ] Add forgetting policy with decay.
- [ ] Add consolidation job for episodic memory.
- [ ] Replace single-strategy retrieval with hybrid.
- [ ] Add cross-encoder reranking.
- [ ] Replace sync encoding with async.
- [ ] Add per-user isolation at store level.
- [ ] Add consent gate before encoding.
- [ ] Add PII detection and redaction.
- [ ] Add audit logging.
- [ ] Add hot memory cache.

## 21. Deployment Checklist

- [ ] Storage deployed with encryption at rest and in transit.
- [ ] Memory types deployed (short-term, episodic, semantic, procedural).
- [ ] Hybrid retrieval configured with weights.
- [ ] Reranker deployed.
- [ ] Forgetting policy configured with decay threshold.
- [ ] Consolidation job scheduled (nightly).
- [ ] Per-user isolation enforced at store level.
- [ ] Consent gate deployed.
- [ ] PII detection and redaction deployed.
- [ ] Hot memory cache deployed.
- [ ] Audit logging enabled.
- [ ] Observability stack deployed (size, latency, accuracy).
- [ ] Rate limiting configured per user.
- [ ] Eval suite scheduled nightly.
- [ ] Memory version tagged.
- [ ] Backup configured; restore tested.
- [ ] Migration runbook documented.
- [ ] GDPR deletion API deployed and tested.
- [ ] Load test passed at expected peak QPS.
- [ ] Storage credentials rotated and stored in secret manager.

## 22. Production Checklist

- [ ] Retrieval p99 latency within SLO.
- [ ] Encoding latency does not block agent response (async).
- [ ] Memory size per user within budget.
- [ ] Memory accuracy >= threshold (nightly eval).
- [ ] Retrieval relevance >= threshold (nightly eval).
- [ ] Forgetting appropriateness verified (no stale facts).
- [ ] Personalization lift measured (A/B test).
- [ ] Cross-session consistency verified.
- [ ] Per-user isolation verified (cross-user returns zero).
- [ ] Consent gate enforced on every encode.
- [ ] PII redaction verified on encode path.
- [ ] Audit log retention meets compliance (365 days).
- [ ] Hot memory cache hit rate > 80%.
- [ ] Consolidation job runs nightly without errors.
- [ ] Memory version documented.
- [ ] Storage migration plan documented.
- [ ] Backup verified; restore tested quarterly.
- [ ] GDPR deletion completes within 30 days.
- [ ] Drift detection alerts configured.
- [ ] Cost per operation tracked and within budget.

## 23. Logging Strategy

- Log every memory operation with: timestamp, trace_id, user_id, memory_type, operation (encode/retrieve/update/forget/consolidate), memory_id, content_hash, importance, latency, success.
- Log at INFO for successful operations, WARN for low-relevance retrieval or forgetting threshold hits, ERROR for storage errors.
- Never log raw memory content that may contain PII; log content hash only.
- Log consolidation runs with episodic count, semantic count, duration.
- Log forgetting events with memory_id, reason (decay/summarization/archival/gdpr).
- Log consent decisions with user_id, action, timestamp.
- Log PII redaction events with original hash, redacted hash, detector.
- Use structured JSON logs with stable schema.
- Emit operation-level spans for tracing.
- Configure log retention per compliance (365 days for audit).

## 24. Monitoring Strategy

- Monitor p50/p95/p99 retrieval latency per memory type.
- Monitor encoding latency and queue depth (async).
- Monitor memory size per user and total; alert on growth anomaly.
- Monitor memory accuracy, relevance, forgetting, personalization, consistency (nightly eval).
- Monitor hot memory cache hit rate; alert on drop.
- Monitor consolidation job success and duration; alert on failure.
- Monitor per-user query rate; alert on abuse.
- Monitor storage error rate per error class; alert on spike.
- Monitor PII redaction trigger rate; alert on spike.
- Monitor consent gate denials; alert on spike.
- Alert on memory accuracy regression > 5%.
- Alert on daily storage cost burn at 80%, 100%.

## 25. Error Handling

- Catch storage errors at `MemoryCall` boundary; retry transient errors.
- Fall back to short-term memory if long-term retrieval fails.
- Handle empty retrieval by proceeding without memory (graceful degradation).
- Handle encoding failures by queuing for retry; never block agent response.
- Handle consolidation failures by alerting on-call; resume from checkpoint.
- Handle PII redaction failures by refusing to encode; alert on-call.
- Handle consent denials by skipping encoding; log for audit.
- Handle GDPR deletion requests within 30 days; verify across all stores.
- Handle migration failures by rolling back to previous version.
- Implement idempotency for encoding to avoid duplicate memories.

## 26. Examples

### Example 1: Semantic Memory with LLM Extraction and Importance Scoring

```python
from memory.types.semantic import SemanticMemory
from memory.encoding.encoder import FactExtractor
from memory.encoding.importance import ImportanceScorer
from memory.storage.vector import VectorStoreAdapter
from memory.call import MemoryCall
from memory.version import MemoryVersion

class SemanticMemoryStore:
    def __init__(self, store: VectorStoreAdapter, extractor: FactExtractor, scorer: ImportanceScorer):
        self.store = store
        self.extractor = extractor
        self.scorer = scorer
        self.call = MemoryCall()
        self.version = MemoryVersion.current()

    async def encode(self, user_id: str, conversation: str, consent: bool) -> list[str]:
        if not consent:
            return []
        facts = await self.extractor.extract(conversation)
        ids = []
        for fact in facts:
            importance = await self.scorer.score(fact)
            if importance < 3:
                continue
            memory = SemanticMemory(
                user_id=user_id,
                content=fact.content,
                entity=fact.entity,
                importance=importance,
                version=self.version,
            )
            mid = await self.call.run(self.store.upsert, memory)
            ids.append(mid)
        return ids

    async def retrieve(self, user_id: str, query: str, top_k: int = 5) -> list[SemanticMemory]:
        return await self.call.run(
            self.store.search, user_id=user_id, query=query, top_k=top_k
        )
```

### Example 2: Hybrid Retrieval with Recency and Importance Weighting

```python
from memory.retrieval.strategies import SimilarityStrategy, RecencyStrategy, ImportanceStrategy
from memory.retrieval.retriever import HybridRetriever
from memory.retrieval.reranker import CrossEncoderReranker
from memory.memory import RetrievalQuery

def build_retriever(store):
    return HybridRetriever(
        strategies=[
            SimilarityStrategy(weight=0.5),
            RecencyStrategy(weight=0.3, half_life_days=30),
            ImportanceStrategy(weight=0.2),
        ],
        store=store,
        reranker=CrossEncoderReranker(model="cohere/rerank-english-v3.0"),
    )

async def retrieve_memories(retriever, user_id: str, query: str, top_k: int = 5):
    rq = RetrievalQuery(
        user_id=user_id,
        text=query,
        top_k=top_k * 4,  # retrieve more, rerank to fewer
        weights={"similarity": 0.5, "recency": 0.3, "importance": 0.2},
    )
    candidates = await retriever.retrieve(rq)
    reranked = await retriever.rerank(query=query, memories=candidates, top_n=top_k)
    return reranked
```

### Example 3: Forgetting Policy with Decay and Nightly Consolidation

```python
from memory.forgetting.decay import DecayPolicy
from memory.forgetting.policy import ForgettingPolicy
from memory.consolidation.consolidator import EpisodicConsolidator
from memory.consolidation.scheduler import NightlyScheduler
import asyncio

def build_forgetting_policy() -> ForgettingPolicy:
    return ForgettingPolicy(
        decay=DecayPolicy(
            half_life_days=30,
            importance_weight=0.5,
            recency_weight=0.3,
            frequency_weight=0.2,
            threshold=0.1,
        ),
        soft_delete=True,
        archive_after_days=90,
    )

async def nightly_consolidation(store, policy: ForgettingPolicy):
    consolidator = EpisodicConsolidator(store=store, llm=build_llm())
    scheduler = NightlyScheduler(hour=3)

    async def job():
        # 1. Decay low-importance memories
        decayed = await policy.apply_decay(store)
        # 2. Consolidate episodic into semantic
        consolidated = await consolidator.consolidate(older_than_days=7)
        # 3. Archive old memories
        archived = await policy.archive(store, older_than_days=90)
        print(f"decay={decayed}, consolidated={consolidated}, archived={archived}")

    scheduler.schedule(job)
    await scheduler.start()
```

## 27. Common Mistakes

- **Storing raw conversations as memory**: What: saving full transcripts. Why: noisy retrieval, PII leaks, bloat. How to avoid: extract facts via LLM; store structured memories.
- **No forgetting policy**: What: retaining all memories indefinitely. Why: storage bloats, retrieval degrades, stale facts cause errors. How to avoid: decay with threshold; consolidate old episodic.
- **Shared memory across users**: What: one store for all users. Why: cross-user leakage, no personalization. How to avoid: per-user isolation at store level.
- **No consent gate**: What: encoding without consent. Why: privacy violation, GDPR non-compliance. How to avoid: consent gate before encoding; right-to-be-forgotten API.
- **Sync encoding in agent loop**: What: blocking response on encoding. Why: latency spike on every turn. How to avoid: async encoding; return response immediately.
- **No importance scoring**: What: all memories weighted equally. Why: low-value memories crowd out high-value. How to avoid: LLM scores 1-10; weight retrieval and forgetting.
- **No consolidation**: What: episodic grows unbounded. Why: retrieval degrades, storage bloats. How to avoid: nightly consolidation compresses episodic into semantic.
- **No PII redaction**: What: storing PII. Why: privacy violation, compliance risk. How to avoid: detect and redact PII before encoding.

## 28. Professional Workflow

1. Identify the use case (personalization, continuity, learning, consistency, multi-agent).
2. Select memory types (short-term, episodic, semantic, procedural).
3. Design architecture: working memory, episodic buffer, long-term store.
4. Select storage topology (vector, document, graph, key-value, hybrid).
5. Design encoding: LLM fact extraction, importance scoring, PII redaction.
6. Design retrieval: hybrid (similarity + recency + importance + frequency), reranking.
7. Design forgetting: decay with threshold, consolidation, archival.
8. Design consolidation: nightly episodic → semantic via summarization.
9. Design personalization: per-user isolation, consent gate, right-to-be-forgotten.
10. Build eval harness: accuracy, relevance, forgetting, personalization, consistency.
11. Deploy with async encoding, hot cache, audit logging.
12. Schedule nightly consolidation and eval.
13. Monitor size, latency, accuracy, cost.
14. Tune forgetting threshold and retrieval weights based on metrics.
15. Plan storage and embedding model migrations with zero-downtime cutover.

## 29. Response Style

- Speak with the authority of a principal engineer who has shipped memory systems at scale.
- Use "always", "never", "must", "must not", "forbidden" — never hedge.
- Specify exact conditions for tradeoffs; never say "it depends".
- Lead with the decision, then the rationale, then the code.
- Cite memory type, storage, retrieval strategy, and metric names precisely.
- Never recommend storing raw conversations as memory.
- Never recommend shared memory across users without isolation.
- Never recommend encoding without consent or PII redaction.

## 30. Output Format

- Every code snippet must be syntactically valid Python or TypeScript.
- Every code snippet must show memory type, operation, and error handling.
- Every recommendation must include the rationale in one sentence.
- Every example must be production-ready, not a toy snippet.
- Every section must use Markdown headers, code fences, and bullet lists — no prose walls.
- Every checklist item must start with `[ ]` and be actionable.
- Every anti-pattern must include "Why wrong" and "Correct alternative".
- Every common mistake must include "What", "Why", and "How to avoid".
- Every decision rule must follow the form "When X and Y conflict, choose Z because <reason>".
- Every memory example must include type, version, importance, and audit metadata.
