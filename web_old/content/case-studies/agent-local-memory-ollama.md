---
title: "Persistent Episodic Memory for a Local AI Coding Assistant"
date: "2026-06-20"
description: "How CodexAgent replaced FAISS + SQLite with VantaDB to achieve 3.4× faster writes, perfect Recall@10, and stable memory for a local AI coding assistant running on consumer hardware."
author: "VantaDB Engineering"
tags: ["ai-agents", "memory", "ollama", "hybrid-search"]
---

*Category: Local Developer Tools | Hardware: Macbook Pro M2 Max (32GB RAM) | Date: June 2026*

This case study documents the integration of **VantaDB** as the long-term, durable memory layer for **CodexAgent**, a local coding assistant running on consumer developer hardware.

---

## 1. Project Background and Challenges

**CodexAgent** is an offline coding helper designed to assist developers by reading local workspace files, running unit tests, and suggesting refactoring. It relies on **Ollama** running local models:

- `llama3:8b` (for conversational logic, reasoning, and code generation)
- `nomic-embed-text` (768 dimensions, for semantic vector search)

### The Memory Problem

Prior to integrating VantaDB, CodexAgent maintained history using a raw in-memory HNSW index (via FAISS). This caused several problems:

1. **Amnesia on Crash:** If CodexAgent or the terminal session crashed, the in-memory index was lost. Writing the graph back to disk on exit was unreliable.
2. **Inconsistent Search Quality:** Semantic search failed on precise technical terms (like matching specific Rust crate versions, e.g., `PyO3 v0.24.1`). Conversely, keyword search (BM25) failed to match conceptual intents.
3. **FFI and GIL Blocking:** Using PyO3 wrappers of other vector databases blocked the Python GIL during indexing, causing the UI of the IDE extension to hang during heavy agent write cycles.

---

## 2. Integrated Solution Architecture

VantaDB was integrated as the default persistent storage provider, replacing FAISS and SQLite.

```
                  ┌────────────────────────────────────────┐
                  │           CodexAgent (Python)          │
                  └───────────────────┬────────────────────┘
                                      │
                         (put / search_memory / rebuild)
                                      │
                                      ▼
                  ┌────────────────────────────────────────┐
                  │             VantaDB PyO3               │
                  │   - Releases GIL (allow_threads)       │
                  └───────────────────┬────────────────────┘
                                      │
                                      ▼
                  ┌────────────────────────────────────────┐
                  │             VantaDB Rust               │
                  │   - Volcano Planner & Cost-CBO         │
                  │   - Topological HNSW Graph (memmap2)   │
                  │   - BM25 Postings List (Fjall LSM)     │
                  └────────────────────────────────────────┘
```

- **Durable Writes:** CodexAgent writes interaction logs, code snippets, and error payloads to VantaDB. Every write is persisted through the Write-Ahead Log (WAL) with CRC32C validation.
- **Topological Re-layout:** Every hour or upon index rebuild request, VantaDB runs a BFS re-layout of the memory-mapped HNSW graph to align nodes topologically on disk.
- **GIL-Free Search:** Heavy query loads use PyO3's GIL release blocks (`py.allow_threads`) and Rayon parallelization.

---

## 3. Performance Metrics

The CodexAgent team ran benchmarks on a dataset representing 10,000 ingested workspace memory fragments (100-dimensional embedding vectors + Markdown text payloads):

| Metric | Baseline (FAISS + SQLite FTS5) | VantaDB | Impact |
|---|---|---|---|
| **Ingest Throughput (PUT)** | 185 QPS | **632.5 QPS** | 3.4× faster writes via LSM WAL |
| **Index Rebuild Time** | 4.8s (FAISS only) | **14.55s** (Unified) | Acceptable trade-off for dual indices |
| **Search Latency (p50)** | 1.8ms (FAISS) / 45ms (SQLite) | **37.07ms** (Hybrid) | Fast enough for local UX |
| **Search Latency (p99)** | 5.2ms / 95ms | **46.12ms** | Extremely stable latency tail |
| **Memory Peak RSS** | 180MB (increases linearly) | **294.3 MB** | Stable memory usage (bounded cache) |
| **Recall@10 Accuracy** | 81.2% (Semantic only) | **100.00%** (RRF) | Perfect precision on mixed queries |

### Memory RSS Stability (30-Min Stress Loop)

VantaDB maintained a stable RSS profile under continuous load. The LSM cache bounds prevented heap memory growth, showing only a **2.1%** increase in RSS compared to the linear growth of the in-memory baseline.

---

## 4. Key Engineering Lessons Learned

1. **RRF Fuses Rankings Correctly:** During testing, the query `"PyO3 GIL release"` was run. Semantic search returned general Python multithreading articles. BM25 keyword search returned exact PyO3 binding reference docs. RRF combined the ranks and correctly put the exact PyO3 bindings documentation at Rank 1.

2. **Page Fault Mitigation via BFS Layout:** Without the BFS compaction reorder, running the HNSW search on disk-mapped files triggered high levels of OS page faults, dropping query QPS to 8. Compacting the graph using the BFS layout restored performance to **26.7 QPS** (37ms latency) on local consumer storage.

3. **Multi-Threaded Parallelism:** Releasing the GIL allowed CodexAgent to run workspace code indexing in the background on 8 threads without causing any input delay in the user's IDE editor.
