# GovMate AI: Australian Government RAG Assistant

[![Python](https://img.shields.io/badge/python-3.14-blue)](https://python.org)
[![FastAPI](https://img.shields.io/badge/FastAPI-0.110-green)](https://fastapi.tiangolo.com)
[![Qdrant](https://img.shields.io/badge/Qdrant-latest-red)](https://qdrant.tech)
[![DeepSeek](https://img.shields.io/badge/DeepSeek-API-orange)](https://deepseek.com)

A locally-deployable, citation-grounded Retrieval-Augmented Generation (RAG) system that answers questions about Australian Government services — specifically the **Australian Taxation Office (ATO)** and **Services Australia (Centrelink, Medicare)**.

> New to RAG or LLMs? See [WALKTHROUGH.md](./WALKTHROUGH.md) for a beginner-friendly explanation of every component.
> Just want to run it? See [QUICKSTART.md](./QUICKSTART.md) for copy-paste commands.
> Want to deploy to the cloud? See [CLOUDDEPLOYMENT.md](./CLOUDDEPLOYMENT.md).

---

## Problem Statement

Australian residents frequently struggle to navigate complex government services. Information is scattered across thousands of web pages, using dense jargon. Generic search engines return lengthy PDFs rather than direct answers.

**GovMate AI** solves this by providing a single conversational interface that retrieves precise, citation-backed answers exclusively from official government documentation, eliminating hallucinated tax or welfare rules.

---

## Architecture Overview

```
User → FastAPI + HTMX → Retriever (Qdrant Hybrid Search) → Reranker (Cross-Encoder) → Prompt Builder → DeepSeek API → Citation Formatter → UI
```

### Key Pipeline Stages

| Stage | Technology | Purpose |
|-------|-----------|---------|
| **Crawling** | Python + Requests + Trafilatura | Downloads ATO/Services Australia HTML, extracts main content |
| **Chunking** | LangChain `RecursiveCharacterTextSplitter` | Splits Markdown into 1000-char chunks with 200-char overlap |
| **Embedding** | FastEmbed (`BAAI/bge-small-en-v1.5`) | Generates Dense (384d) + Sparse (BM25) vectors locally at zero cost |
| **Storage** | Qdrant (local Docker) | Vector database for hybrid search |
| **Retrieval** | Qdrant Native Hybrid Search (RRF) | Merges Dense semantic + Sparse keyword results |
| **Re-ranking** | Cross-Encoder (`ms-marco-MiniLM-L-6-v2`) | Re-ranks top 15 → top 5 most relevant chunks |
| **Generation** | DeepSeek API (`deepseek-chat`) | Generates grounded answer with inline citations `【1】` |
| **Monitoring** | PostgreSQL + Streamlit | Tracks latency, cost, user feedback, relevance scores |

---

## Technology Stack

| Component | Technology | Cost |
|-----------|-----------|------|
| LLM | DeepSeek API (OpenAI-compatible) | ~$0.05 total |
| Embeddings | FastEmbed + bge-small-en-v1.5 (local CPU) | $0 |
| Vector DB | Qdrant (Docker) | $0 |
| Backend | FastAPI / Uvicorn | $0 |
| Frontend | Jinja2 + HTMX + Tailwind CSS | $0 |
| Monitoring | PostgreSQL + Streamlit | $0 |
| Containerization | Docker / Docker Compose | $0 |

---

## Evaluation & Design Decisions

### Retrieval Evaluation

Three approaches were evaluated during development:

| Approach | Result | Decision |
|----------|--------|----------|
| **Dense Only** (semantic) | Failed on specific codes (e.g., "JobSeeker" vs "unemployment") | ❌ |
| **Sparse Only** (BM25) | Failed on natural phrasing ("Can I claim my laptop?") | ❌ |
| **Hybrid RRF** (Dense + Sparse) | **~20% higher Context Precision** — captured both semantics and keywords | ✅ **Selected** |

### LLM Evaluation

| Approach | Result | Decision |
|----------|--------|----------|
| Standard prompt | LLM summarized without directly answering | ❌ |
| Strict grounding with XML tags | **Zero hallucinations** + high Answer Relevancy | ✅ **Selected** |

**Running the evaluation:**
```bash
uv run python scripts/run_eval.py
```

Expected output:
```
=========================================
     GovMate AI Evaluation Report
=========================================
Total test cases:       3
Citation coverage:      3/3 (100%)
Retrieval accuracy:     3/3 (100%)
```

---

## Quick Start

### Prerequisites

- [Docker Desktop](https://www.docker.com/products/docker-desktop/)
- [uv](https://docs.astral.sh/uv/) (Python package manager)

### Step 1: Clone & Configure

```bash
git clone <your-repo-url>
cd govmateai
cp .env.example .env
```

Edit `.env` and add your **DeepSeek API key**:
```
DEEPSEEK_API_KEY=sk-your-deepseek-key-here
```

### Step 2: Start Infrastructure

```bash
docker compose -f docker/docker-compose.yml up -d qdrant postgres
```

### Step 3: Install Dependencies & Ingest Data

```bash
uv sync
uv run python scripts/run_ingestion.py
```

This crawls ATO and Services Australia websites, chunks the content, generates local embeddings, and upserts to Qdrant (~10-15 minutes).

### Step 4: Run the App

```bash
uv run python -m uvicorn backend.main:app --reload --reload-exclude monitoring/
```

Visit **http://localhost:8000** to chat with GovMate AI.

### Step 5: Launch Monitoring Dashboard (Separate Terminal)

```bash
uv run python -m streamlit run monitoring/dashboard.py
```

Visit **http://localhost:8501** for real-time metrics.

---

## Project Structure

```
govmate-ai/
├── backend/
│   ├── api/              # FastAPI endpoints & HTMX streaming
│   │   └── endpoints/
│   │       ├── chat.py         # Chat + Feedback + Streaming
│   │       ├── health.py       # Health check
│   │       └── suggestions.py  # Clickable suggestion chips
│   ├── core/
│   │   ├── config.py           # Pydantic Settings (env vars)
│   │   └── database.py         # PostgreSQL init
│   ├── ingestion/
│   │   ├── crawlers/base.py    # BFS crawler with retry logic
│   │   ├── processors/html_parser.py  # Trafilatura + Markdownify
│   │   ├── chunkers/markdown_chunker.py  # LangChain chunking
│   │   ├── embedders/local_embedder.py   # FastEmbed (zero cost)
│   │   └── pipeline.py         # Orchestrates ingestion
│   ├── models/
│   │   ├── schemas.py          # Pydantic request/response models
│   │   └── qdrant_payload.py   # Qdrant payload schema
│   └── rag/
│       ├── retriever.py        # Qdrant hybrid search (RRF)
│       ├── reranker.py         # Cross-encoder re-ranking
│       ├── prompt_builder.py   # System + user prompt construction
│       ├── query_rewriter.py   # Slang → formal query reformulation
│       ├── citation_formatter.py  # 【X】→ URL mapping
│       ├── orchestrator.py     # Ties retrieval + generation
│       ├── metrics.py          # PostgreSQL metric logging
│       └── judge.py            # LLM-as-a-judge (background)
├── datasets/
│   ├── seeds.yaml              # ATO & Services AU URL config
│   ├── raw/                    # Downloaded HTML (gitignored)
│   └── processed/              # Cleaned Markdown (gitignored)
├── docker/
│   ├── Dockerfile              # Multi-stage build
│   └── docker-compose.yml      # App + Qdrant + Postgres + Dashboard
├── frontend/
│   ├── static/css/
│   └── templates/
│       ├── base.html           # Tailwind + HTMX + Alpine.js
│       ├── index.html          # Chat interface
│       └── components/         # HTMX partials
├── monitoring/
│   └── dashboard.py            # Streamlit monitoring dashboard
├── scripts/
│   ├── run_ingestion.py        # Pipeline entry point
│   └── run_eval.py             # Evaluation script
├── .env.example
├── pyproject.toml              # uv project config
└── README.md
```

---

## Monitoring Dashboard

A real-time Streamlit dashboard tracks:

1. **Total Queries** — request count
2. **Query Latency** — line chart over time
3. **Cumulative Cost** — area chart (DeepSeek API cost tracking)
4. **User Feedback** — Thumbs Up / Down distribution (bar chart)
5. **LLM-as-a-Judge Relevance Score** — automatic relevance rating (line chart)
6. **Token Usage** — Prompt & Completion token bar charts
7. **Recent Conversations** — data table of latest 10 interactions

User feedback is collected via 👍/👎 buttons rendered by HTMX after each answer.

See [EVALUATION.md](./EVALUATION.md) for how the project meets the course evaluation criteria.

## Best Practices Implemented

- ✅ **Query Rewriting**: DeepSeek reformulates slang terms into formal program names ("dole" → "JobSeeker Payment")
- ✅ **Hybrid Search**: Native Dense + Sparse vectors via Qdrant RRF
- ✅ **Document Re-ranking**: Cross-encoder (`MiniLM-L-6-v2`) for precision
- ✅ **Metadata Filtering**: Agency-level payload indexing in Qdrant
- ✅ **Idempotent Ingestion**: SHA-256 content hashing prevents duplicates
- ✅ **Streaming**: HTMX + `StreamingResponse` for real-time token output
- ✅ **Citation Parsing**: Regex `【X】` → structured source objects
- ✅ **LLM-as-a-Judge**: Background relevance scoring using DeepSeek
- ✅ **User Feedback**: Thumbs up/down persisted to PostgreSQL

---

## Data Source

Data is crawled live from official `.gov.au` domains based on `datasets/seeds.yaml`. No static datasets are included. This ensures the most up-to-date government policies are always used.

- **ATO**: ~350-450 pages (deductions, rental properties, crypto, GST, super)
- **Services Australia**: ~300-400 pages (JobSeeker, Age Pension, Medicare, Centrelink)

---

## License

MIT
