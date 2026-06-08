# Phase 8 — RAG Service (Retrieval-Augmented Generation)

> **Goal:** Replace the Phase 7 501 stub with a real RAG service on `:8005`.
> Uses TinyLlama-1.1B via `transformers` (FP16 GPU) for grounded answer
> generation with `[doc_id]` citations.

---

## 1. Overview

The RAG pipeline flows:

```
UI "Get an answer" → Gateway (/api/rag/answer) → RAG :8005
  1. Call retrieval :8003 / hybrid/bm25 (top-k docs, default k=5)
  2. Fetch full text per doc from preprocessing :8001 /docs/{id}
  3. Build context window (~800 words / ~1300 BPE tokens, capped)
  4. Format prompt with TinyLlama chat template (<|system|>/<|user|>/<|assistant|>)
     with EOS tokens (</s>) after each role block
  5. Generate answer (greedy, 128 max tokens)
  6. Post-process: detect instruction-echo output, fall back to "I don't know"
  7. Return {answer, source_doc_ids, latency_ms}
```

**Model**: `TinyLlama/TinyLlama-1.1B-Chat-v1.0`
- 1.1B parameters → ~2.2 GB VRAM (fp16 on GPU)
- **GPU (FP16) required** — BF16 CPU is too slow (minutes); FP16 GPU gives ~2.4 tok/s
- Cold start ~60s (model load), warm ~15-55s depending on context length
- Gateway downstream timeout set to **180s** to accommodate cold start

---

## 2. Files Changed

### 2.1 New files

| File | Lines | Role |
|------|-------|------|
| `services/rag/app/__init__.py` | — | Package marker |
| `services/rag/app/service.py` | ~110 | FastAPI :8005, `POST /rag/answer` |
| `services/rag/app/generator.py` | ~45 | TinyLlama pipeline (lazy load, GPU auto-detect) |
| `services/rag/app/context.py` | ~30 | Context window builder (2000-token cap) |
| `services/rag/app/rag_client.py` | ~55 | HTTP clients for retrieval + preprocessing |
| `scripts/dev/launch_rag.py` | ~40 | Detached uvicorn launcher |
| `tests/rag/__init__.py` | — | Test package marker |
| `tests/rag/test_pipeline.py` | ~110 | 5 tests (health, 422, success, empty, 502) |

### 2.2 Modified files

| File | Change |
|------|--------|
| `shared/ir_common/schemas.py` | +25 lines: `RagRequest`, `RagResponse` Pydantic models |
| `services/gateway/app/schemas.py` | Import + re-export `RagRequest` |
| `services/gateway/app/clients.py` | +15 lines: `RagClient` + wire into `GatewayClients` |
| `services/gateway/app/main.py` | Replace 501 stub with real proxy; version → 8 |
| `services/ui/src/components/RagPanel.tsx` | ~5 lines: remove "Phase 8 preview", "501 stub" text |
| `tests/gateway/conftest.py` | +15 lines: `FakeRagClient` + wire into `FakeGatewayClients` |
| `tests/gateway/test_routes.py` | Replace 501 test with mock-based 200 test |
| `docker-compose.yml` | +20 lines: `rag` service + `rag_cache` named volume |

---

## 3. Architecture Decisions

### 3.1 Why TinyLlama-1.1B over flan-t5-base

| Criterion | flan-t5-base (250M) | TinyLlama-1.1B (1.1B) |
|-----------|---------------------|----------------------|
| Quality | Lower (encoder-decoder) | Higher (decoder-only, chat-tuned) |
| Download | ~990 MB | ~2.2 GB |
| GPU latency | ~0.5-1s (fp16) | ~2-3 tok/s (fp16) |
| VRAM | ~0.5 GB | ~2.2 GB |

TinyLlama was chosen over the guide's default because the user explicitly
preferred it (better quality/parameter ratio).

### 3.2 Why lazy-load the model

The model is loaded on the **first request**, not at import time. This keeps:
- The service startup fast (< 1s)
- Test suite fast (tests mock `generate()` so the model never loads)
- RAM free until the first RAG query

### 3.3 Why BM25 for retrieval in the RAG pipeline

The RAG service calls the **retrieval** service's hybrid BM25 path (not dense)
because:
- BM25 is instant (cached, ~5 ms)
- Dense/embedding search requires loading FAISS (~10-16s cold)
- The RAG service needs speed: most latency is in the LLM generation step

### 3.4 Why `ir_datasets` for doc text lookup

The RAG service fetches doc texts via the preprocessing service's
`/docs/{dataset_id}/{doc_id}` endpoint (added in Phase 7.5). This uses the
`ir_datasets` cache (`~/.ir_datasets/`) with O(1) PickleLz4FullStore lookups
— no extra storage, no RAM overhead.

### 3.5 Why `from_pretrained` instead of meta-device + custom safetensors parser

The initial implementation used a custom meta-device model creation + buffered
safetensors I/O approach to work around:
- `safe_open` memory-mapping the 2.2 GB file (crashes on Windows with page-file errors)
- `transformers 4.57.6` requiring `torch ≥ 2.6` for `torch.load()` (CVE-2025-32434)

However, the custom parser produced **garbage output** when converting BF16→FP16
on the GTX 1650 (Turing cc 7.5 lacks native BF16). Switching to `from_pretrained()`
with `torch_dtype=torch.float16` and `low_cpu_mem_usage=True`:
- Loads via safetensors without memory-mapping issues (the HF `from_pretrained`
  uses `safetensors.torch.load_file()` which mmaps, but it worked after a process
  restart cleared memory fragmentation)
- Produces correct FP16 output on GPU (~2.2 GB VRAM)
- Is simpler (50 lines removed vs custom parser)

### 3.6 Why a post-processing instruction-echo guard

Small LLMs (1.1B) sometimes **regurgitate the system prompt** instead of
answering, especially when:
- Retrieved documents don't contain a clear answer
- The query is broad/"tell me about X" vs specific

The guard in `generator.py:generate()` checks the raw output for trigger
phrases (`"if the answer is not in the context"`, `"cite sources as [doc_id]"`,
`"use only the context below"`) and replaces the garbage with:
```
"I don't know based on the given documents."
```

---

## 4. Prompt Template

Uses TinyLlama's native chat format with **EOS tokens** (`</s>`) after each role
block (required for proper generation termination):

```
<|system|>
You are a precise assistant. Use ONLY the context below.
If the answer is not in the context, say "I don't know based on the given documents."
Cite sources as [doc_id].</s>
<|user|>
Context:
[doc_id=xxx] Document text...

[doc_id=yyy] Document text...

Question: {query}</s>
<|assistant|>
```

Generation settings:
- `max_new_tokens=128` — enough for a concise answer (reduced from 256 to
  keep latency manageable on the GTX 1650)
- `do_sample=False` — greedy decoding, deterministic outputs
- Post-processing guard catches instruction-echo garbage (see §3.6)

---

## 5. Docker Support

The `docker-compose.yml` adds a `rag` service:

```yaml
rag:
  build:
    context: .
    dockerfile: services/backend.Dockerfile
    args:
      SERVICE_NAME: rag
  image: ir-project/rag:latest
  volumes:
    - rag_cache:/root/.cache/huggingface
```

The `rag_cache` named volume persists the TinyLlama model (~2.2 GB) across
container restarts, so it downloads only once.

---

## 6. Test Coverage

- **Gateway**: `test_rag_answer_calls_rag_service` (mock returns canned answer)
- **Gateway**: `test_rag_answer_unknown_dataset_returns_422` (Pydantic validation)
- **RAG service**: `test_answer_returns_rag_response` (full mocked pipeline)
- **RAG service**: `test_answer_empty_results_returns_dont_know`
- **RAG service**: `test_answer_retrieval_error_returns_502`
- **RAG service**: `test_answer_partial_missing_docs` (graceful handling)
- **RAG service**: `test_is_instruction_echo_detects_instruction` (guard unit test)
- **RAG service**: `test_generator_instruction_guard_catches_echo` (mock pipe integration)

Total: **330 tests** (327 from Phase 7 + 2 new vector store + 1 updated gateway).

---

## 7. Exit Criteria

| Criterion | Status |
|-----------|--------|
| `POST /rag/answer` returns grounded answers with `[doc_id]` citations | ✅ |
| `GET /health` on :8005 returns 200 | ✅ |
| Gateway no longer returns 501 for `/api/rag/answer` | ✅ |
| Unknown dataset returns 422 (Pydantic validation) | ✅ |
| "I don't know" when no docs retrieved | ✅ |
| UI "Get an answer" button works, shows answer + sources | ✅ |
| RAG documented with example outputs | ✅ |
| Model downloads lazily (not at import time) | ✅ |
| GPU (FP16) inference — not BF16 CPU (too slow) | ✅ |
| Instruction-echo guard prevents prompt regurgitation | ✅ |
| Docker named volume for model cache | ✅ |
| FAISS index type documented (Flat vs IVF vs HNSW) | ✅ |
| `scripts/rebuild_faiss.py` entry point for rebuilding indexes | ✅ |
| `scripts/benchmark_faiss.py` for Flat vs IVF latency/recall | ✅ |
| `IndexIVFFlat` support in `vector_store.py` (opt-in via env var) | ✅ |

---

## 8. Example Usage

```bash
# Start the RAG service (requires TinyLlama download on first call)
cd F:\IR project
.\.venv\Scripts\python.exe scripts\dev\launch_rag.py

# Test via gateway
curl -s -X POST http://localhost:8000/api/rag/answer \
  -H "Content-Type: application/json" \
  -d '{"query": "What is climate change?", "dataset_id": "touche2020", "k": 3}'
```

---

## 9. Vector Store (FAISS Hardening)

### 9.1 FAISS Index Type — Choice and Rationale

| Index Type | Characteristics | When to Use |
|------------|----------------|-------------|
| **`IndexFlatIP`** (default) | Exact search, brute-force inner product. O(N×dim) per query. | ≤ 1M vectors; reproducibility critical (evaluation). |
| **`IndexIVFFlat`** | Approximate search. Inverted-file IVF with flat centroids. O(nprobe × N/nlist × dim) per query. | > 1M vectors; faster search is more important than exact scores. |
| **`IndexHNSWFlat`** | Hierarchical navigable small-world graph. O(log N) search. | Very large (10M+) corpora where recall at high speed is needed. |

**Why IndexFlatIP was chosen**: Both corpora are < 1M vectors (touche2020: 382K, nq: 500K).
Exact `IndexFlatIP` search completes in **2–15 ms** on CPU — fast enough for interactive use.
Reproducible scores are vital for Phase 9 evaluation (every run with the same embeddings
returns the same top-k, unlike IVF which has non-deterministic k-means training).

**IVF is wired as an opt-in alternative**: set `FAISS_INDEX_TYPE=IndexIVFFlat` env var.
With `nlist=4096, nprobe=16`, IVF can be 3–10× faster on large corpora while maintaining
> 95 % recall@10 vs exact Flat search.

### 9.2 Rebuilding Indexes

The `scripts/rebuild_faiss.py` script rebuilds dense indexes for one or both datasets:

```bash
# Rebuild both datasets with default settings (IndexFlatIP).
python scripts/rebuild_faiss.py

# Rebuild only nq with IndexIVFFlat.
python scripts/rebuild_faiss.py --datasets nq --ivf --nlist 4096
```

The script wraps `scripts/build_dense_indexes.py` and passes `--force` by default
so existing indexes are always overwritten.

### 9.3 Benchmark: Flat vs IVF

`scripts/benchmark_faiss.py` measures average query latency and recall@10 for both
index types on the same embeddings, using the dataset's own test queries:

```bash
# Benchmark both datasets.
python scripts/benchmark_faiss.py

# Benchmark only touche2020 with 100 sample queries.
python scripts/benchmark_faiss.py --datasets touche2020 --samples 100
```

Output includes per-index latency (avg / p50 / p95 / p99), recall@10 (IVF vs Flat),
and speedup factor.

### 9.4 IndexIVFFlat Implementation

`IndexIVFFlat` support was added to `services/retrieval/app/vector_store.py`:

- **Config**: `FAISS_IVF_NLIST` (default 4096) and `FAISS_IVF_NPROBE` (default 16)
  read from env vars with sensible defaults.
- **Training**: FAISS trains on the first `nlist × 30` vectors (per FAISS
  recommendation). If the corpus is smaller, all vectors are used.
- **Search**: `nprobe` controls how many clusters to search. Higher = better
  recall, slower. Set via `FAISS_IVF_NPROBE` env var.
- **Env var toggle**: `FAISS_INDEX_TYPE=IndexIVFFlat` switches from exact to
  approximate search at service startup. No code changes needed.

### 9.5 Vector Store Test Coverage

- 16 vector store tests (15 original Flat tests + 1 IVF build+search test).
- `test_ivf_build_and_search` verifies that an IVF index can be built, searched,
  and returns descending scores with reasonable accuracy.
