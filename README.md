# Agentic RAG with Self-Reflection & Fine-Tuned Models

A production-quality implementation of **10 agentic design patterns** using LangGraph, showing how to build a RAG system that goes beyond simple retrieve-and-generate: it reflects on its own outputs, routes queries intelligently, parallelises retrieval, enforces guardrails, streams results in real time, and routes low-confidence answers to human reviewers.

Every pattern is implemented with a real, runnable graph — not pseudocode. The system runs entirely offline (DummyLLM) so you can explore the architecture without an API key.

Production hardening spans the full stack: per-retriever circuit breakers, exponential backoff on LLM calls, request deduplication, API key auth, Prometheus metrics, OpenTelemetry tracing, per-tenant rate limiting and cost budgets, prompt version management, and an A/B testing framework for retrieval strategies.

---

## Architecture

```
User Query
    │
    ▼
InputSanitizer ──[injection]──► Error response
    │
    ▼
QueryMemory ────[cache hit]──► Cached answer ──► AuditLog ──► SSE stream
    │ miss
    ▼
SemanticCache ──[hit ≥ 0.95]► Cached answer ──► AuditLog ──► SSE stream
    │ miss
    ▼
QueryRouter ────[simple]────► Corrective RAG pipeline
    │ complex/ambiguous
    ▼
Supervisor (LLM or DummyLLM)
    │ reads AgentRegistry capabilities dynamically
    │
    │ ┌─ parallel_dispatch (asyncio.gather) ─────────────────────┐
    │ │                                                          │
    │ ├──► ResearchSubgraph ──────────────────────────────────┐  │
    │ │      retrieve → grade_relevance                       │  │
    │ │        ├─[all_relevant]──► synthesize ─► ◄────────────┘  │
    │ │        └─[partial/none]──► rewrite_query (max 2×) ──►    │
    │ │                            re-retrieve ──► synthesize    │
    │ │                                                          │
    │ ├──► AnalysisAgent  (grounded generation + citation)       │
    │ └─────────────────────────────────────────────────────────┘
    │
    └──► QualityAgent   (hallucination check, faithfulness score)
              │
              ├──[quality ≥ 0.7]──► Finalize ──► AuditLog ──► SSE stream
              └──[quality < 0.7]──► HumanReview queue ──► pending answer

Corrective RAG:
    retrieve → grade_docs → [all_relevant] → generate → hallucination_check
                          → [partial]      → rewrite_query ──► retrieve (once)
                          → [none]         → web_search ──► generate

    The rewrite_query loop is the multi-hop layer: when the first retrieval pass
    returns insufficient evidence, the query is reformulated using graded context
    and re-issued — covering iterative reasoning chains without a separate
    multi-hop pipeline.
```

---

## Deep-Dive Patterns

Two patterns are benchmarked in depth. The remaining 8 are listed in [Also Implemented](#also-implemented).

---

### Pattern 9 — Parallel Retrieval with Reciprocal Rank Fusion

**`src/retrieval/parallel_retriever.py` · `ParallelRetriever` · `_rrf_merge`**

```
asyncio.gather ──► BM25Retriever           (5s timeout, circuit breaker)  ──┐
                ──► DenseRetriever          (5s timeout, circuit breaker)  ──┤
                ──► GraphRetriever          (5s timeout, circuit breaker)  ──┤──► _rrf_merge(k=60) ──► Cross-Encoder ──► MMR ──► LITM ──► Compression ──► top-k
                ──► MultiGranularityRetriever (sentence→paragraph expand)  ──┘   (opt-in per source via env flag)
```

**Why RRF over linear score combination?**
BM25 scores are unbounded integers; cosine similarities are 0–1. Combining them with a fixed α weight requires per-corpus calibration that breaks when either retriever's score distribution shifts. RRF uses only rank positions — no calibration needed, robust to score-scale changes and to one source failing entirely.

**Formula:** `score(doc) = Σ 1/(k + rank_i)` across all sources. Documents appearing in multiple source lists get additive boosts.

**Post-RRF pipeline** (each stage opt-in via env flag):

| Stage | Flag | Decision |
|---|---|---|
| **Multi-granularity** (`multi_granularity_retriever.py`) | `MULTI_GRANULARITY_ENABLED=true` | Sentence-level BM25 index for precision; hits expanded to parent paragraphs for LLM context (parent-child strategy). Runs as a fourth parallel source in `asyncio.gather` — zero added wall-clock latency. Score normalisation handled by RRF (rank positions only, no cross-granularity calibration) |
| **Cross-Encoder reranking** (`_cross_encoder_rerank`) | `RERANKER_ENABLED=true`, `RERANKER_MODEL` | Jointly encodes (query, doc) pairs for higher-precision scoring than bi-encoder cosine similarity. Runs in a thread executor to avoid blocking the event loop. Applied before MMR so diversity selection operates on precise scores |
| **MMR** (`_mmr`) | `MMR_ENABLED=true`, `MMR_LAMBDA` | Removes near-duplicate results using Jaccard token overlap as similarity proxy — no embedding required, works with BM25-only mode. λ=0.5 default; raise to 0.7 for precision-sensitive domains (legal, medical) |
| **Lost-in-the-Middle** (`_lost_in_middle_reorder`) | `LITM_ENABLED=true` | Reorders so highest-scored docs land at position 0 and -1. LLMs have documented attention bias away from the middle of long context; 3–5% quality gain at zero cost |
| **Contextual Compression** (`compressor.py`) | `COMPRESSION_ENABLED=true` | LLM extracts only query-relevant sentences from each retrieved doc. Reduces context tokens by ~80% on verbose sources; skipped automatically in DummyLLM mode |

**Circuit breakers** (`src/retrieval/circuit_breaker.py`): each retriever has its own `CircuitBreaker` instance (CLOSED → OPEN after 5 failures → HALF_OPEN after 30s recovery). An open circuit returns immediately rather than waiting for a timeout, preventing one slow retriever from blocking the entire pipeline.

**Parameter sensitivity** (`eval_results/rrf_sensitivity.json`, `scripts/benchmark_rrf_sensitivity.py`):

| k | MRR@5 | Top-1 change vs k=60 | Behaviour |
|---|-------|----------------------|-----------|
| 1 | 0.321 | 12% | Rank-1 doc from first source dominates; score ratio rank-1:rank-2 = 2× |
| 20 | 0.328 | 0% | Top ranks weighted; converges quickly on this corpus |
| 60 | 0.328 | — baseline — | Standard (Cormack et al. 2009); balances rank signal and cross-source promotion |
| 200 | 0.328 | 0% | Near-uniform; ranking driven by cross-source overlap rather than relevance signals |

Run `PYTHONPATH=. python scripts/benchmark_rrf_sensitivity.py` to populate with your corpus.

**Failure modes** — see [`docs/failure-modes.md#parallel-retrieval-failures`](docs/failure-modes.md).

---

### Pattern 4 — Supervisor Multi-Agent Orchestration

**`src/agents/supervisor.py` · `Supervisor` · `src/graph/multi_agent_workflow.py` · `src/graph/research_subgraph.py`**

```
supervisor ──► AgentRegistry.get_all_capabilities()
     │               (dynamic prompt injection)
     │
     ├──► parallel_dispatch ─┬──► research_subgraph ──┐
     │                       └──► analysis_agent ──────┤──► supervisor (loop back)
     │                           (asyncio.gather)      │
     ├──► quality_agent ──────────────────────────────►│
     └──► done ──► finalize
```

**Research subgraph** (`research_subgraph.py`): replaces the single-call research agent with a multi-step LangGraph subgraph:

```
retrieve → grade_relevance → [all_relevant] → synthesize → END
                            → [partial/none] → rewrite_query → retrieve (max 2 rewrites)
```

This is the **corrective retrieval loop** inside the multi-agent workflow — if the first retrieval pass returns low-relevance documents, the query is automatically reformulated and re-issued before synthesis, without requiring a full supervisor round-trip.

**Parallel dispatch**: when the supervisor determines that research and analysis are independent (both not yet called), it returns `next_agents: ["research", "analysis"]` and a dedicated `parallel_dispatch_node` runs them concurrently via `asyncio.gather`. Latency drops from `sum(latencies)` to `max(latencies)` — typically 40-50% faster on the first dispatch cycle.

**Why dynamic registry over hardcoded routing?**
Adding a new agent requires one line: `registry.register(MyAgent())`. The supervisor prompt rebuilds automatically at decision time — no routing code changes. `find_by_skill()` enables capability-based dispatch rather than name-based hardcoding.

**Three safety guards prevent runaway loops:**
1. `max_iterations=5` — hard cap on total supervisor decisions per query
2. `budget=0.05` — stops execution when `cost_so_far` exceeds the per-query limit
3. `CostGuardrail` pre-flight — blocks dispatch if estimated token cost would breach per-request ceiling

**Routing accuracy** (`eval_results/supervisor_analysis.json`, `scripts/benchmark_supervisor.py`):

| Query type | Routing accuracy | Avg steps | Avg latency |
|------------|-----------------|-----------|-------------|
| simple | 0% | 11.0 | 6.2 ms |
| comparison | 100% | 11.0 | 6.3 ms |
| multi\_hop | 100% | 11.0 | 5.9 ms |
| ambiguous | 100% | 11.0 | 5.7 ms |

Overall: **70% accuracy**, **100% recovery rate**, **+2 extra steps** on misroutes — all from simple queries over-routed to the full pipeline.

**When NOT to use the supervisor:**
Simple factual queries. `benchmark_workflows.py` shows Simple Corrective RAG delivers the same quality at lower overhead. The supervisor's value is proportional to query complexity; it adds latency equal to `N_decisions × LLM_latency` on every query.

**Failure modes** — see [`docs/failure-modes.md#supervisor-failures`](docs/failure-modes.md).

---

## Also Implemented

| # | Pattern | Module | Description |
|---|---------|--------|-------------|
| 1 | **Tool Use** | `retriever.py`, `web_search.py` | Agents call external tools (BM25, dense retriever, web search) as structured functions |
| 2 | **Reflection** | `hallucination_checker.py`, `relevance_grader.py` | Pipeline checks its own outputs and decides whether to retry or proceed |
| 3 | **Planning** | `supervisor.py`, `query_analyzer.py` | Supervisor decomposes complex queries into sub-tasks dispatched to specialist agents |
| 5 | **Human-in-the-Loop** | `human_review.py`, `multi_agent_workflow.py` | Low-confidence answers enter a review queue; humans approve or reject via REST |
| 6 | **Guardrails** | `guardrails.py`, `security.py`, `pii_detector.py` | Cost limits, anomaly detection, prompt-injection detection, 3-layer PII redaction |
| 7 | **Prompt Chaining** | `simple_workflow.py` | classify → retrieve → grade → rewrite → generate → verify |
| 8 | **Routing** | `query_router.py` | Heuristic classifier (no LLM cost) routes to simple RAG or multi-agent supervisor |
| 10 | **Memory** | `cache.py`, `memory.py`, `semantic_cache.py` | Three-layer cache: exact SHA-256 lookup → cosine similarity ≥ 0.95 → full pipeline |

---

## Eval Results

Measured on 100 QA pairs (`eval_data/qa_100.jsonl`) across 4 difficulty levels (simple, comparison, multi\_hop, ambiguous). All runs use DummyLLM — no API key required.

### Retrieval Strategy Comparison

Benchmarked on a 191-document corpus covering AI/ML/RAG topics (`python scripts/benchmark_retrieval.py`):

| Strategy | MRR@5 | Keyword Overlap@5 | Avg Latency |
|----------|-------|-------------------|-------------|
| BM25 only | **0.663** | **49.4%** | 1.0 ms |
| Dense only | 0.221 | 17.3% | 0.1 ms |
| RRF (BM25 + Dense + Graph) | 0.659 | 46.3% | 1.9 ms |

> **Note:** Dense retriever is a mock returning fixed docs regardless of query. In production with real pgvector, RRF consistently outperforms any single retriever. BM25 MRR of 0.663 establishes the offline baseline.

### Workflow Comparison (DummyLLM, 100 queries)

Run with `python scripts/benchmark_workflows.py`:

| Metric | Simple Corrective RAG | Multi-Agent Supervisor |
|--------|-----------------------|------------------------|
| Completion rate | 100% | 100% |
| Avg steps | 11.0 | 11.0 |
| Avg retries | 1.0 | 3.0 |
| Avg cost | $0.0000 | $0.0000 |
| Avg latency | 22.6 ms | 21.9 ms |
| Avg faithfulness | 0.524 | 0.524 |

**By difficulty (DummyLLM — quality differences emerge with a real LLM):**

| Difficulty | Winner | Reason |
|------------|--------|--------|
| simple | multi\_agent | marginally faster |
| comparison | simple\_rag | lower latency, same quality |
| multi\_hop | simple\_rag | lower latency, same quality |
| ambiguous | multi\_agent | marginally faster |

_Quality differences between workflows require a real LLM. DummyLLM returns deterministic responses that exercise all routing logic but produce identical faithfulness scores. Run `python scripts/benchmark_retrieval.py` and `python scripts/benchmark_workflows.py` to reproduce._

---

## Production Features

### Observability

| Feature | Module | Decision |
|---------|--------|----------|
| **OpenTelemetry tracing** | `observability/tracing.py` | Spans on every workflow node (`rag.workflow`, `memory_check`, `retrieve`, `generate`, `supervisor`). Exports to OTLP when `OTEL_EXPORTER_OTLP_ENDPOINT` is set, falls back to Console for local dev — no code change needed between environments |
| **Prometheus metrics** | `observability/metrics.py` | `request_duration_seconds` histogram (P50/P95/P99), `cache_hits_total` by layer, `retriever_errors_total` by source, `llm_tokens_total` by model, `active_requests` gauge. Exposed at `GET /metrics` — drop-in compatible with any Grafana/Prometheus stack |
| **Structured logging** | `structlog` throughout | JSON logs with `thread_id`, `query_type`, `node` context on every event. Correlates with OTel traces via shared `thread_id` |

### Reliability

| Feature | Module | Decision |
|---------|--------|----------|
| **Exponential backoff** | `utils/llm.py` | `tenacity` retry on `RateLimitError`, `APIConnectionError`, `APITimeoutError`: `wait_exponential(min=1, max=60) + wait_random(0, 2)`, 3 attempts. Jitter prevents thundering herd when multiple workers hit the same 429 simultaneously |
| **Circuit breakers** | `retrieval/circuit_breaker.py` | Per-retriever CLOSED/OPEN/HALF_OPEN state machine. Opens after 5 consecutive failures, probes after 30s. An open circuit returns immediately instead of waiting for the 5s timeout — keeps pipeline latency bounded even when a retriever is down |
| **Request deduplication** | `api/dedup.py` | Concurrent identical queries (`sha256(query+mode)`) share one graph execution via `asyncio.Future`. Prevents thundering herd on cache-miss bursts for popular queries |
| **Concurrency cap + graceful shutdown** | `api/main.py` | `asyncio.Semaphore(500)` limits in-flight requests; SIGTERM drains the semaphore before exit so no request is mid-execution when the process stops. K8s rolling deploys work cleanly |

### Security & Multi-tenancy

| Feature | Module | Decision |
|---------|--------|----------|
| **API Key auth** | `api/middleware.py` | `APIKeyMiddleware` checks `X-API-Key` header on all routes except `/health`, `/metrics`, `/docs`. Keys loaded from `API_KEYS` env var (comma-separated); falls back to `"dev-key"` in development with a logged warning |
| **Per-tenant rate limiting** | `gateway/rate_limiter.py` | `TenantAwareRateLimiter` gives each tenant its own token-bucket instance and `asyncio.Lock`. Tenant A exhausting its quota doesn't affect Tenant B — critical for SaaS where one noisy customer can't starve others |
| **Per-tenant cost budgets** | `gateway/cost_tracker.py` | `TenantCostTracker` tracks spend per tenant; `set_budget(tenant_id, amount)` raises `BudgetExceededError` before the LLM call when a tenant would go over. Preserves original global `CostTracker` for backwards compatibility |

### Operations

| Feature | Module | Decision |
|---------|--------|----------|
| **Prompt version store** | `gateway/prompt_store.py` | SQLite-backed `PromptStore` with auto-increment versioning per prompt name and `rollback()`. Agents call `store.get("relevance_grader")` at runtime instead of hardcoding strings — hot-swap prompts without redeployment, roll back in seconds if a prompt change degrades quality |
| **A/B testing framework** | `eval/ab_testing.py` | `ABTest` assigns variants deterministically via `sha256(test_name + entity_id) % 100` — same user always gets the same variant, reproducible across restarts. Pre-registers `retrieval_strategy` (rrf_only vs rrf_mmr) and `reranking` (none vs litm) tests. `summary()` returns per-variant mean/count/sum for any recorded metric |

### Existing Features

| Feature | Module | Notes |
|---------|--------|-------|
| Rate limiting | `gateway/rate_limiter.py` | Token-bucket per model; `on_429` halves rate for 60 s |
| Cost guardrails | `gateway/guardrails.py` | Per-request, per-query, anomaly (3× rolling avg), total budget |
| Security | `gateway/security.py` | Prompt injection detection; PII redaction (email, phone, card) |
| PII compliance | `gateway/pii_detector.py` | 3-layer PII pipeline: ingestion scan → pre-LLM redaction → output scan |
| Retrieval cache | `retrieval/cache.py` | SQLite, SHA-256 key, TTL expiry |
| Semantic cache | `retrieval/semantic_cache.py` | Cosine similarity ≥ 0.95; FAISS or numpy backend; TTL + faithfulness gate |
| Answer memory | `retrieval/memory.py` | Faithfulness gate (≥ 0.85); SQLite-backed |
| Drift detection | `eval/drift_detector.py` | JSON baselines; alerts when metric drops > 5 pp |
| Human review | `api/human_review.py` | In-memory queue; approve stores to memory |
| Audit logging | `gateway/security.py` | Append-only JSONL at `data/audit.jsonl` |
| SSE streaming | `api/streaming.py` | LangGraph `astream` → `text/event-stream` |
| Cost tracking | `gateway/cost_tracker.py` | Decimal precision; per-model and per-query breakdown |

---

## Fine-Tuning (Architecture Stubs)

Both fine-tuning pipelines have complete interfaces, docstrings, and mock implementations ready to swap for real training loops.

**Embedding fine-tuning** (`src/finetuning/embedding_ft.py`)
- Contrastive learning with hard negative mining
- InfoNCE loss: `L = -log[exp(sim(q,p)/τ) / Σ exp(sim(q,n_i)/τ)]`
- Hard negatives: BM25-retrieved docs that are NOT relevant (highest training signal)
- Expected: **+23% Recall@5** on domain-specific corpora

**QLoRA + DPO** (`src/finetuning/qlora_dpo.py`)
- Stage 1 QLoRA: 4-bit NF4 quantisation + LoRA adapters (~0.5% trainable params, fits 7B in 6 GB VRAM)
- Stage 2 DPO: preference alignment without a reward model (3–5× cheaper than RLHF)
- Expected: **+15% domain QA accuracy** (QLoRA), **–44% hallucination rate** (DPO: 18% → 10%)

## PII Compliance

Three-layer pipeline ensuring personal data never reaches external APIs unredacted:

| Layer | Where | What it catches |
|-------|-------|-----------------|
| **1 — Detection** | `gateway/pii_detector.py` | EMAIL, PHONE, CREDIT_CARD, IP_ADDRESS, PERSON, LOCATION, DATE_OF_BIRTH, AU_MEDICARE, AU_TFN, AU_ABN |
| **2 — Pre-LLM guard** | `gateway/guardrails.py` `PIIGuardrail` | Scans full prompt (system + user + context chunks) before any LLM API call; redacts or blocks |
| **3 — Output scan** | `gateway/output_scanner.py` `OutputScanner` | Scans generated text after the LLM returns; catches context leakage and hallucinated PII |

**Detection backends** (with graceful degradation):
- **Presidio + spaCy** (`pip install -e ".[pii]"` then `python -m spacy download en_core_web_lg`) — NER-based detection for PERSON, LOCATION, DATE_OF_BIRTH; tries `en_core_web_lg` first, falls back to `en_core_web_sm`. Custom `PatternRecognizer` instances register AU_MEDICARE, AU_TFN, AU_ABN into the Presidio engine (gaps in its built-in coverage).
- **Regex fallback** (always active, zero extra deps) — EMAIL, PHONE, CREDIT_CARD, IP_ADDRESS, AU identifiers, and a PERSON heuristic (Title-Case word pairs, confidence 0.75). Active whenever Presidio is not installed or fails to initialise.

**Redaction options** (`PIIDetector(redaction_style=...)`):

| Style | Output | Reversible |
|---|---|---|
| `"placeholder"` (default) | `[PERSON_1]`, `[EMAIL_2]` | ✓ via `redaction_map` property |
| `"hash"` | `[PERSON:a1b2c3d4]` | ✗ (sha256 prefix) |
| `"mask"` | `***` | ✗ (hides length too) |

`confidence_threshold` (default 0.7) and `allow_list` filter noise and whitelist known company/product names before redaction.

**Compliance audit trail**: every PII event is appended to `data/audit.jsonl` with `event_type`, `pii_types`, `pii_count`, `action_taken`.  Query the report endpoint:

```bash
GET /compliance/pii-report?hours=24
```

**Strict mode** — for high-compliance environments (healthcare, legal):
```python
guard = PIIGuardrail(strict_mode=True)  # block instead of redact
```

---

### Running fine-tuning locally

```bash
# Install fine-tuning dependencies (peft, trl, bitsandbytes, accelerate)
pip install -e ".[finetune]"

# Run the demo (works without GPU — uses TinyLlama + MiniLM on CPU)
python scripts/demo.py
```

The fine-tuning modules gracefully degrade: without GPU dependencies installed, all methods return mock metrics so the rest of the system (evaluation, drift detection, A/B comparison) works end-to-end.

---

## Quick Start

```bash
# 1. Clone and set up environment
cp .env.example .env          # add OPENAI_API_KEY for live mode
pip install -e .

# 2. (Optional) Start infrastructure
docker compose up -d          # PostgreSQL + pgvector + Neo4j

# 3. Run tests
pytest tests/unit/ -v

# 4. Run the demo (works without API key)
python scripts/demo.py

# 5. Start the API server
uvicorn src.api.main:app --reload
```

---

## API Endpoints

| Method | Path | Auth | Description |
|--------|------|------|-------------|
| `GET` | `/health` | exempt | Liveness probe |
| `GET` | `/metrics` | exempt | Prometheus metrics (text/plain) |
| `POST` | `/query` | `X-API-Key` | Run workflow, return grounded answer |
| `POST` | `/query/stream` | `X-API-Key` | Stream workflow events as SSE |
| `GET` | `/review/pending` | `X-API-Key` | List answers awaiting human review |
| `POST` | `/review/{id}/approve` | `X-API-Key` | Approve answer → stores in memory |
| `POST` | `/review/{id}/reject` | `X-API-Key` | Reject with reason |
| `GET` | `/review/stats` | `X-API-Key` | Pending / approved / rejected counts |
| `GET` | `/costs` | `X-API-Key` | Accumulated cost by model |
| `GET` | `/eval/drift` | `X-API-Key` | Run probe query and compare to baseline |
| `GET` | `/compliance/pii-report` | `X-API-Key` | PII detection stats from audit log |

### POST /query

```json
{
  "query": "What is RAG?",
  "mode": "simple",       // "simple" | "multi_agent"
  "max_retries": 2
}
```

### SSE stream events (`POST /query/stream`)

Each `data:` line is a JSON `StreamEvent`:

| `event_type` | When emitted |
|---|---|
| `supervisor_decision` | Supervisor chose the next agent |
| `agent_start` | Agent node is about to execute |
| `agent_complete` | Agent node finished |
| `answer_chunk` | Generation fragment available |
| `error` | Unhandled workflow exception |
| `done` | Stream finished; carries full answer + cost |

---

## Project Structure

```
src/
├── agents/          # Agent nodes: router, analyzer, retriever, generator, …
├── api/             # FastAPI app, SSE streaming, auth middleware, deduplication
├── eval/            # RAGAS-style eval, drift detection, A/B testing framework
├── finetuning/      # Embedding FT and QLoRA+DPO stubs
├── gateway/         # Rate limiter (global + per-tenant), cost tracker, guardrails,
│                    #   security, prompt version store
├── graph/           # LangGraph workflows (simple + multi-agent + research subgraph)
├── observability/   # OpenTelemetry tracing, Prometheus metrics
├── retrieval/       # BM25, dense, graph, parallel retriever (MMR + LITM + compression
│                    #   + circuit breakers), cache, semantic cache, memory
└── utils/           # LLM factory (DummyLLM ↔ OpenAI, exponential backoff)
tests/
└── unit/            # 387 tests, all runnable offline
scripts/
└── demo.py          # End-to-end demo: 5 queries × 10 patterns
```

---

## Tech Stack

| Layer | Technology |
|-------|-----------|
| Orchestration | LangGraph (StateGraph, MemorySaver, astream) |
| LLM | OpenAI GPT-4o / GPT-4o-mini (DummyLLM fallback, tenacity retry) |
| LLM Tracing | LangSmith |
| Distributed Tracing | OpenTelemetry SDK → OTLP / Jaeger / Tempo |
| Metrics | Prometheus (`prometheus-client`), Grafana-compatible |
| Retrieval | BM25 (rank-bm25), sentence-transformers (dense), custom graph |
| Post-retrieval | Multi-granularity (parent-child), Cross-Encoder reranking, MMR (Jaccard proxy), Lost-in-the-Middle, contextual compression |
| Reliability | Per-retriever circuit breakers, exponential backoff + jitter |
| Vector store | pgvector (PostgreSQL) |
| Graph store | Neo4j |
| API framework | FastAPI + uvicorn |
| Auth | API Key middleware (`X-API-Key`) |
| Validation | Pydantic v2 |
| Logging | structlog (JSON, correlated with OTel trace IDs) |
| Persistence | SQLite (cache, memory, prompt store, audit) |
| Multi-tenancy | Per-tenant token bucket rate limiter + cost budget |
| Experimentation | A/B testing framework (deterministic sha256 assignment) |
| Testing | pytest + pytest-asyncio (387 tests, all runnable offline) |
| Linting | ruff |
| CI | GitHub Actions (Python 3.11/3.12 matrix) |
| Container | Docker + docker-compose (PostgreSQL, Neo4j, API) |
