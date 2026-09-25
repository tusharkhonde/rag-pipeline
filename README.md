# RAG Document Q&A

A retrieval-augmented generation (RAG) service: upload PDF, Markdown or text documents, then ask
questions and get answers grounded in those documents, with inline citations back to the exact
source sections. It runs entirely locally (one `docker compose up`) with multi-tenant auth,
caching, metrics and an evaluation harness.

```
question ─► embed ─┬─► pgvector HNSW search ──┐
                   └─► Postgres full-text ────┴─► RRF fusion ─► prompt with numbered sources ─► LLM ─► answer [1][2]
```

**Stack:** TypeScript/Fastify API · Python/FastAPI ingestion service · PostgreSQL 17 + pgvector ·
Redis · Ollama (`qwen2.5:7b` for answers, `nomic-embed-text` for embeddings) · Docker Compose

## Highlights

- **Hybrid retrieval:** HNSW vector search and weighted full-text search run concurrently and
  are fused with Reciprocal Rank Fusion, so both paraphrases and exact identifiers are found.
- **Grounded answers with verified citations:** numbered, delimited sources; a fixed refusal
  when the answer isn't in the documents; citation markers are mapped back to chunks and
  hallucinated source numbers are detected.
- **Token-aware, structure-aware chunking:** chunks follow headings/pages (one citation
  location each), carry a context header, and can never be silently truncated by the model.
- **OAuth2 client credentials → RS256 JWTs** with JWKS, scopes, argon2id secret hashing, rate
  limiting, and **Postgres row-level security** as a second tenancy layer.
- **Caching that invalidates itself:** query embeddings and answers in Redis, keyed on tenant,
  collection version, models and prompt version.
- **Streaming:** answers stream over Server-Sent Events; client disconnects abort generation.
- **Observability:** Prometheus metrics per pipeline stage, token usage, cache and retrieval
  hit-rates; structured logs with request ids; liveness vs readiness probes.
- **Evaluation harness:** precision@k, recall@k (hit@k), MRR per retrieval mode, answer quality
  (key-fact coverage, citation accuracy, LLM-as-judge), refusal accuracy and latency percentiles.

## Quickstart

Requirements: Docker with **≥ 10 GB of memory** assigned (Docker Desktop → Settings → Resources).

```bash
docker compose up --build -d     # first run pulls ~5 GB of models (qwen2.5:7b, nomic-embed-text)
curl localhost:3000/ready        # {"status":"ready", ...} once every dependency is up
scripts/demo.sh                  # client → token → upload samples → search → streamed answers
```

> **Performance note:** Docker on macOS can't use the GPU, so the 7B model runs on CPU
> (~2–3 tokens/s, 30–100 s per answer; the first request also loads the model). Answers
> stream, and repeated questions are served from cache in milliseconds. For faster demos set
> `LLM_MODEL=qwen2.5:3b`, or point `LLM_BASE_URL` at any OpenAI-compatible hosted API.

## Using the API

```bash
# 1. Register a client (prints client_id and client_secret once)
docker compose exec api node dist/cli/create-client.js --name my-app --scopes "documents:write query"

# 2. Get an access token (OAuth2 client credentials, HTTP Basic auth)
TOKEN=$(curl -s -u "$CLIENT_ID:$CLIENT_SECRET" -d grant_type=client_credentials \
  localhost:3000/oauth/token | jq -r .access_token)

# 3. Create a collection and upload documents
COLLECTION=$(curl -s -H "authorization: Bearer $TOKEN" -H 'content-type: application/json' \
  -d '{"name":"handbook"}' localhost:3000/collections | jq -r .id)
curl -H "authorization: Bearer $TOKEN" -F file=@samples/docs/nimbus-queue-runbook.md \
  localhost:3000/collections/$COLLECTION/documents

# 4. Ask (add "stream": true for Server-Sent Events)
curl -H "authorization: Bearer $TOKEN" -H 'content-type: application/json' \
  -d '{"question":"How long does the message broker keep messages?"}' \
  localhost:3000/collections/$COLLECTION/query
```

| Endpoint | Scope | Purpose |
|---|---|---|
| `POST /oauth/token` | – | Client-credentials grant → 15-min RS256 access token |
| `GET /.well-known/jwks.json` | – | Public signing keys |
| `POST /collections` · `GET /collections` | `documents:write` · `query` | Manage collections |
| `POST /collections/:id/documents` | `documents:write` | Upload PDF / Markdown / text (idempotent by content hash) |
| `GET /collections/:id/documents` | `query` | List documents and chunk counts |
| `POST /collections/:id/search` | `query` | Retrieval only (`mode`: hybrid / vector / keyword) |
| `POST /collections/:id/query` | `query` | Grounded answer with citations; `stream: true` for SSE |
| `GET /health` · `GET /ready` · `GET /metrics` | – | Liveness, readiness, Prometheus metrics |

A real response (qwen2.5:7b on CPU; the question never says "Nimbus", semantic retrieval found it):

```json
{
  "answer": "By default, messages are retained for 72 hours. However, the `telemetry.raw` topic keeps messages for 7 days because reprocessing jobs replay it after decoder upgrades. [1]",
  "citations": [{ "index": 1, "label": "nimbus-queue-runbook.md › Architecture", "chunkId": "90a985d1-…" }],
  "invalidCitations": [],
  "refused": false,
  "cached": false,
  "model": "qwen2.5:7b",
  "usage": { "promptTokens": 818, "completionTokens": 41 },
  "retrieval": { "mode": "hybrid", "topVectorScore": 0.695, "embeddingCached": false },
  "timings": { "embed": 50.9, "vector_search": 5.2, "keyword_search": 8.4, "ttft": 52726.7, "generate": 61728.7, "total": 61803 }
}
```

Timings are in milliseconds: retrieval takes ~60 ms, generation on CPU takes the rest.

## Architecture

```
            ┌───────────────────── Docker Compose network ──────────────────────┐
 client ──► │ api  (TypeScript, Fastify) :3000   ← the only published port      │
   JWT      │   auth · tenancy · caching · retrieval · prompting · SSE · metrics │
            │      │ HTTP           │ SQL (RLS)        │ RESP       │ HTTP       │
            │      ▼                ▼                  ▼            ▼            │
            │  ml (Python)     postgres+pgvector     redis       ollama          │
            │  parse · chunk    chunks, vectors,     embedding   qwen2.5:7b      │
            │  embed · /embed   full-text, tenants   & answer    nomic-embed-    │
            │      └──── writes chunks (RLS) ─┘      caches      text            │
            └────────────────────────────────────────────────────────────────────┘
```

- **api** owns the HTTP edge: OAuth2 token issuance, JWT verification, per-route scopes,
  tenant-scoped data access, hybrid retrieval, prompt construction, streaming, caching, metrics.
- **ml** owns document processing: parsing (pypdf, heading-aware Markdown), chunking, and
  embedding (via Ollama), plus query embedding for the API so both sides use the same model.
  It isn't reachable from outside the compose network, and its writes also run under RLS.
- **postgres** holds tenants, collections, documents and chunks (`vector(768)` + HNSW index,
  generated weighted `tsvector` + GIN index), with row-level security policies.
- **redis** caches query embeddings and answers (LRU, memory-capped, fail-safe).
- **ollama** serves both models; one-shot compose jobs pull them on first start.

### Request flow for `POST /collections/:id/query`

1. `onRequest`: verify the bearer JWT (RS256 pinned, issuer, audience, expiry) *before* the body is read; `preHandler` checks the route's scope.
2. Load the collection under RLS for this tenant (another tenant's id → 404).
3. Answer cache lookup (tenant + collection version + normalized question + models + params).
4. Embed the query (Redis-cached), then run **vector** and **keyword** search concurrently, 20 candidates each; fuse with RRF; keep the top 5.
5. No chunks → refuse without calling the LLM. Otherwise build the prompt: numbered `<source>` blocks within a token budget, grounding and refusal rules, document text treated as untrusted.
6. Stream tokens from the LLM (SSE: `sources` → `delta`… → `done`); parse `[n]` citations; flag invalid ones; cache the result; record metrics and one structured log line.

## Design decisions

Each has a short decision record in [`docs/adr/`](docs/adr/) with the alternatives considered.

| Decision | Choice | Main tradeoff |
|---|---|---|
| [Vector store](docs/adr/0001-postgres-pgvector.md) | PostgreSQL + pgvector, HNSW | One transactional store with SQL filtering and RLS, vs. a dedicated vector DB's scale-out |
| [Chunking](docs/adr/0002-chunking.md) | Section-bounded, 600/800 tokens, 80 overlap, context headers | Precise citations and no silent truncation, vs. some small chunks |
| [Inference](docs/adr/0003-local-inference-ollama.md) | Ollama in Docker, OpenAI-compatible APIs | Private, free, one command, vs. CPU-only speed on macOS |
| [Retrieval](docs/adr/0004-hybrid-retrieval.md) | Vector + full-text, Reciprocal Rank Fusion | Robust to paraphrase *and* identifiers without score tuning, vs. a cross-encoder's precision |
| [Auth & tenancy](docs/adr/0005-auth-and-tenancy.md) | Client credentials, RS256 JWT, scopes, RLS | Stateless verification, vs. revocation only by expiry |
| [Caching](docs/adr/0006-caching.md) | Versioned keys in Redis | Self-invalidating, tenant-safe, vs. no semantic (similar-question) hits |

## Evaluation

`scripts/eval.sh` runs the harness in a container on the compose network against
[`eval/dataset.jsonl`](eval/dataset.jsonl): 20 answerable questions (each with the expected
source document and key phrases) and 5 unanswerable ones. A retrieved chunk counts as relevant
if it comes from the expected document **and** contains an expected phrase.

```bash
scripts/eval.sh                       # retrieval: all modes, all questions (~10 s)
scripts/eval.sh --generate --limit 5  # plus answer quality on 5 + 5 questions (slow on CPU)
```

Retrieval on the sample corpus (k = 5):

| mode | precision@5 | hit@5 (= recall@5) | MRR |
|---|---|---|---|
| hybrid | 0.200 | 1.000 | 0.942 |
| vector | 0.200 | 1.000 | 0.871 |
| keyword | 0.200 | 1.000 | 0.950 |

Reading the numbers:
- **precision@5 = 0.2** is the ceiling here: each question has one answer-bearing chunk. That's
  why it's reported together with hit@k and MRR.
- **Keyword ≈ hybrid > vector on MRR.** The questions were written from the documents and share
  their vocabulary, which favours keyword search. Hybrid keeps its advantage on paraphrased
  questions ("message broker" → Nimbus Queue).
- **Retrieval confidence overlaps:** unanswerable questions reach a top cosine similarity of 0.70,
  while some answerable ones score 0.56. No similarity threshold separates them, so the refusal
  decision is left to the grounded prompt rather than a score cutoff.

Generation, `--generate --limit 3` (3 answerable + 3 unanswerable questions, qwen2.5:7b on CPU):

| metric | value |
|---|---|
| key-fact coverage (answerable) | 1.00 |
| citation accuracy (cites the expected document) | 1.00 |
| answer ↔ reference similarity (cosine) | 0.83 |
| LLM-as-judge (1–5) | 4.67 |
| correct refusals (unanswerable) / false refusals (answerable) | 1.00 / 0.00 |
| hallucinated citation markers | 0 |
| latency p50 / p95 · time to first token p50 / p95 | 45 s / 106 s · 36 s / 95 s |

The sample is small (CPU inference makes each answer take ~1 minute), and the judge is the same
model as the generator, which biases it upward. Treat these as a smoke test, not a benchmark.

## Observability

- `GET /metrics` (Prometheus): `rag_stage_duration_seconds{stage}` (embed, vector_search,
  keyword_search, ttft, generate, total), `rag_llm_tokens_total{type}`,
  `rag_cache_requests_total{cache,result}`, `rag_retrieval_queries_total{mode,outcome}`,
  `rag_retrieval_top_vector_score`, `rag_answers_total{outcome,cached}`,
  `rag_invalid_citations_total`, HTTP latency by route template, plus process metrics.
- **Retrieval hit-rate** = hits / queries, where a hit means the best cosine similarity is at
  least `RETRIEVAL_HIT_THRESHOLD` (keyword mode: any result).
- `GET /health` is liveness (process only); `GET /ready` checks Postgres, Redis, ml and the LLM in parallel with timeouts.
- Logs are structured JSON (pino) with a request id (`X-Request-Id` honoured and echoed). Each question produces one `rag_query` line with timings, tokens, cache and retrieval confidence, never the question text.

## Tests

```bash
# API (TypeScript): unit tests with fakes, then integration tests against compose Postgres
cd services/api && npm test && npm run test:integration

# ml service (Python), in a container
docker build --target test -t rag-ml-test services/ml && docker run --rm rag-ml-test

# evaluation metric functions
docker run --rm -v "$PWD/eval":/eval -w /eval python:3.12-slim python -m unittest
```

Coverage highlights: chunk boundaries/overlap/limits, parsers (heading paths, PDF pages),
RRF, SQL retrieval on seeded vectors (including cross-collection isolation and the
double-stemming regression), prompt construction and injection escaping, citation parsing,
cache keys (tenant, version), SSE, token forgery (expired, wrong audience/issuer/key,
`alg: none`, HS256 key confusion, tampering), OAuth errors and rate limiting, and RLS.

## Configuration

Every setting has a default; see [`.env.example`](.env.example).

| Variable | Default | Purpose |
|---|---|---|
| `LLM_BASE_URL` / `LLM_MODEL` / `LLM_API_KEY` | Ollama / `qwen2.5:7b` / – | Any OpenAI-compatible chat endpoint |
| `EMBEDDINGS_PROVIDER` / `EMBEDDING_MODEL` | `ollama` / `nomic-embed-text` | Or `openai` / `text-embedding-3-small` (re-ingest after switching) |
| `RETRIEVAL_MODE` / `RETRIEVAL_TOP_K` | `hybrid` / `5` | Retriever and chunks per prompt |
| `RETRIEVAL_HIT_THRESHOLD` | `0.6` | Hit-rate metric threshold |
| `METRICS_TOKEN` | unset | Protect `/metrics` with a bearer token |

## Project layout

```
db/migrations/        001 schema + HNSW · 002 weighted full-text · 003 row-level security
services/api/src/     auth/ cache/ db/ generation/ ml/ observability/ retrieval/ routes/ cli/
services/ml/app/      parsers · chunker · embedder · pipeline · store · main (FastAPI)
eval/                 dataset.jsonl · run_eval.py · metrics.py · reports/
samples/              docs/ (fictional handbook, runbook, FAQ) · queries.md
scripts/              demo.sh · eval.sh
docs/adr/             architecture decision records
```

## Production next steps

- **Async ingestion:** queue uploads (status `processing` already exists in the schema) so large PDFs don't hold a request open.
- **GPU inference** or a hosted LLM; keep Ollama for local development.
- **Reranking:** a cross-encoder second stage where model sources allow it.
- **Key management:** signing key from a KMS or secret manager with scheduled rotation (the JWKS already supports several keys by `kid`).
- **Tracing:** OpenTelemetry spans across api → ml → Postgres → LLM instead of per-stage timings only.
- **Online evaluation:** sample production answers for LLM-judge scoring; track refusal and citation rates over time.
- **Scale:** partition chunks by tenant or move to a dedicated vector store past tens of millions of vectors.
