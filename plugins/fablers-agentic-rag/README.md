<div align="center">

# fablers-agentic-rag

**Ask your documents. Get a cited answer.**

A Claude Code plugin that runs an agentic RAG pipeline — query analysis, hybrid retrieval, evaluation with CRAG validation, and cited answer synthesis — all orchestrated by Claude agents. Supports PDF, plain text, and Markdown.

[![Claude Code Plugin](https://img.shields.io/badge/Claude_Code-Plugin-blueviolet?style=for-the-badge)](https://claude.ai)
[![Version](https://img.shields.io/badge/version-3.1.0-blue?style=for-the-badge)](#)
[![License: MIT](https://img.shields.io/badge/License-MIT-green?style=for-the-badge)](LICENSE)

[English](README.md) | [한국어](README.ko.md) | [日本語](README.ja.md)

</div>

---

## What is this?

You have documents. You have questions. But keyword search is fragile and LLMs hallucinate without sources.

**fablers-agentic-rag** bridges the gap: it chunks your document (PDF, TXT, or Markdown), indexes it with vector + BM25, and deploys a 3-agent pipeline that retrieves, validates, and synthesizes answers with page-level citations — all inside Claude Code.

---

## Why this exists

There are many ways to do RAG with Claude Code. You could wire up Obsidian + an MCP server + a vector DB + a separate AI for summarization. It works — but now you're managing four tools, each with its own setup, updates, and quirks.

Or you could just feed the whole PDF to Claude. But a 600-page book blows past the context window, and even if it fits, you'd burn tokens re-reading it with every question.

This plugin takes a different approach: **one tool, one workflow**. Ingest, search, validate, answer — all inside Claude Code. The only reason OpenAI is involved at all is that Claude doesn't offer an embedding API (yet). Everything else runs on the Claude you're already using.

### vs. Typical RAG MCP

| | Typical RAG MCP | This Plugin |
|---|---|---|
| **Workflow** | Obsidian / vector DB / external AI — multiple tools to manage | **Claude Code only** — ingest to answer in one place |
| **Brain** | External LLM API calls (OpenAI, etc.) for reasoning | **Claude Code agents ARE the brain** — no external LLM |
| **Architecture** | Single retrieve → paste | Multi-agent pipeline with validation |
| **Quality check** | None — returns whatever vector search finds | CRAG validation scores every passage, retries with rewritten queries |
| **Complex questions** | Same path for all queries | Complexity routing — 1 agent for simple, 3 for multi-part |
| **Citations** | Raw chunk dump or none | Every claim gets `[Source N]` inline + sources section |
| **Search method** | Vector-only (misses exact terms) | Hybrid vector + BM25 (catches both semantics and keywords) |
| **Infrastructure** | Often requires Docker, vector DB server | Zero infra — pure Python files + Claude agents |
| **Self-correction** | One-shot, no retry | CRAG loop rewrites queries up to 2x when results are poor |

### vs. Reading the whole PDF

| | Whole PDF in context | This Plugin |
|---|---|---|
| **~50 pages** | Works fine. Just read it. | Overkill |
| **~150+ pages** | Exceeds context window or costs explode | Index once, query cheaply forever |
| **Repeated questions** | Full re-read every time (10 questions = 10x cost) | One-time index, ~5K tokens per query |
| **Citation accuracy** | May hallucinate page numbers | Chunk metadata has exact pages/headings |

The only external API call is OpenAI `text-embedding-3-small` for query embedding. Everything else — query analysis, reranking, validation, answer synthesis — runs on Claude Code's own agent system. No extra LLM costs.

**TL;DR**: An MCP gives you search results. This plugin gives you a validated, cited answer — powered by the Claude you're already paying for. Put those tokens to good use.

### A small arc reactor, not a power grid

This plugin was born from a real need: ideating on game design theory from Jesse Schell's *The Art of Game Design* — a 600-page book full of interconnected concepts, lenses, and frameworks. The goal was never to index a million documents. It was to deeply understand one.

Think of it as a compact, self-contained reactor you drop into a project:

- A textbook you want to study with citations
- A technical manual you need to reference accurately
- Research papers you want to cross-examine
- Project documentation you want to query

numpy arrays + in-memory BM25 — no vector DB, no server, no Docker. If your data fits in a few files, this is all you need. For enterprise-scale knowledge bases with millions of records, use GraphRAG or a dedicated vector DB solution instead.

---

## What's new

### v3.1.0 — Pluggable embeddings (Gemini default)

OpenAI embeddings are no longer required. The pipeline now dispatches between providers via a single `embedding_provider` setting:

- **`gemini`** (new default) — `gemini-embedding-2-preview` (3072 dim). Uses `RETRIEVAL_DOCUMENT` / `RETRIEVAL_QUERY` task types for ingestion vs. query.
- **`openai`** — `text-embedding-3-small` (1536 dim). Existing behavior preserved.

Index layout changed to per-provider subdirectories so both can coexist:
```
{rag_data_path}/
├── chunks.json              # shared
├── bm25_corpus.json         # shared
└── embeddings/
    ├── gemini/{embeddings.npz, metadata.json, index.meta.json}
    └── openai/{embeddings.npz, metadata.json, index.meta.json}
```

**Migration from v3.0.x**: Existing `embeddings.npz` at the data root is no longer read. Re-run `/ingest` to rebuild under the new layout. The legacy file is left in place; delete it after verifying the new index works. Search will print a clear migration hint if it can't find the new layout.

### v3.0.0 — Command rename (breaking)

Commands have been renamed to avoid namespace collisions with other plugins in the marketplace:

- `/ask <question>` → `/rag-ask <question>`
- `/search <query>` → `/rag-search <query>`
- `/ingest` is unchanged

Update your usage accordingly if upgrading from v2.0.x.

### v2.0.0

- **Faster**: 3 agents instead of 5 — simple questions use only 1 agent call
- **Simpler structure**: repo root = plugin (no nested `plugin/` directory)
- **New commands**: `/rag-search` for direct search, `/ingest` for document indexing
- **Smarter routing**: complexity-based branching skips unnecessary agents

---

## How it works

```
/rag-ask How does the elemental tetrad relate to game mechanics?
```

**Simple questions** (1 agent call):
```
You ── /rag-ask ──▶ Skill generates 2 queries ──▶ search.py ──▶ Answer Synthesizer
                                                              │
                                                        Cited answer
                                                        with [Source N]
```

**Complex questions** (up to 3 agent calls):
```
You ── /rag-ask ──▶ Query Analyst ──▶ search.py ──▶ Evaluator ──▶ Answer Synthesizer
                  │                                │                │
             Decomposes into              Reranks + CRAG        Cited answer
             2-5 sub-queries              validation            with [Source N]
                                               │
                                         ┌─────┴──────┐
                                         │  RETRY?    │
                                         │  rewrite → │──▶ back to search.py
                                         │  (max 2x)  │
                                         └────────────┘
```

### The 3 Agents

| # | Agent | Role |
|---|-------|------|
| 1 | **Query Analyst** | Decomposes complex questions into 2-5 concrete search queries. Skipped for simple questions. |
| 2 | **Evaluator** | Reranks retrieved passages by relevance (top 5) + CRAG validation. Can trigger query rewrites (max 2x). |
| 3 | **Answer Synthesizer** | Produces the final answer with inline `[Source N]` citations and a sources section. |

---

## Quick Start

### 1. Install the plugin

In Claude Code, add the marketplace and install:
```
/plugin marketplace add flashwade03/fablers-claude-plugins
/plugin install fablers-agentic-rag@fablers
```

### 2. Prepare your data

Install dependencies. Pick the SDK for whichever embedding provider you want — you only need one:

```bash
# Always required
pip install pdfplumber numpy rank_bm25

# Provider-specific (install whichever you'll use)
pip install google-genai   # for embedding_provider: gemini  (default)
pip install openai         # for embedding_provider: openai
```

Then run the ingestion pipeline:

```bash
cd scripts && python3 ingest.py --document /path/to/your/document.pdf --output-dir ../data
```

Or use the `/ingest` command after installing the plugin.

Supports `.pdf`, `.txt`, and `.md` files. Use `--skip-embeddings` to test chunking only.

### 3. Configure

On first session start, the plugin creates `.claude/fablers-agentic-rag.local.md`. Edit it:

```yaml
rag_data_path: /absolute/path/to/data
embedding_provider: gemini       # or "openai"
gemini_api_key: AIza...           # required if provider = gemini
openai_api_key: sk-...            # required if provider = openai
```

You only need the API key for the provider you select. To compare providers, ingest the same document with both — embeddings are stored per-provider and `chunks.json`/`bm25_corpus.json` are reused.

### 4. Ask

```
/rag-ask What are the key concepts in chapter 3?
/rag-ask How does the author define the main framework, and what tools help evaluate each element?
```

### Other commands

```
/rag-search What is game design?    # Direct hybrid search, raw results
/ingest /path/to/new-document.pdf   # Index a new document
```

---

## Project Structure

```
fablers-agentic-rag/                  ← plugin root
├── .claude-plugin/
│   └── plugin.json                   # Plugin manifest (v3.1.0)
├── agents/
│   ├── query-analyst.md              # Query decomposition
│   ├── evaluator.md                  # Reranking + CRAG validation
│   └── answer-synthesizer.md         # Cited answer generation
├── commands/
│   ├── rag-ask.md                    # /rag-ask command
│   ├── rag-search.md                 # /rag-search command
│   └── ingest.md                     # /ingest command
├── skills/
│   └── ask/SKILL.md                  # Pipeline orchestration
├── scripts/
│   ├── search.py                     # Hybrid search (provider-aware)
│   ├── ingest.py                     # Document ingestion (provider-aware)
│   ├── chunker.py                    # Auto-detect chunking strategy
│   ├── embedder.py                   # Provider dispatcher (openai + gemini)
│   ├── config.py                     # Provider/model registry, path helpers
│   └── session-start.sh              # Session initialization
├── hooks/
│   └── hooks.json                    # Event hooks
├── fablers-rag.template.md           # Config template
└── SKILL.md                          # Root skill
```

---

## Key Design Decisions

### Hybrid Search (Vector + BM25)

Pure vector search misses exact terminology. Pure keyword search misses semantics. The hybrid approach (alpha=0.6 vector, 0.4 BM25) captures both.

### Complexity-Based Branching

Simple factual questions skip the query analyst and evaluator, reducing latency from 5 agent calls to 1. Complex multi-part questions get the full pipeline.

### CRAG Loop

Not all retrieval attempts succeed. The evaluator checks passage sufficiency and can trigger up to 2 query rewrites, making the pipeline self-correcting.

---

## Configuration

| Setting | Description |
|---------|-------------|
| `rag_data_path` | Absolute path to the directory containing `chunks.json`, `embeddings.npz`, `bm25_corpus.json` |
| `openai_api_key` | OpenAI API key for `text-embedding-3-small` query embedding |

---

## License

MIT
