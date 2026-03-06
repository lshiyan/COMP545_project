# COMP545-TempRAG

Temporal Retrieval-Augmented Generation (TempRAG) for answering complex temporal questions over a Temporal Knowledge Graph (TKG).

This project builds a semantic search index over temporal knowledge graph edges, retrieves temporally relevant facts with constraint-aware filtering, reranks candidates, and uses a ReAct-style agent to answer temporal questions. The current codebase includes:

- **TKG indexing with FAISS**
- **Sentence-transformer embeddings**
- **Temporal filtering** (`before`, `after`, `on`)
- **Pointwise reranking**
- **LangChain-based query agent**
- **MultiTQ evaluation pipeline** :contentReference[oaicite:1]{index=1}

---

## Overview

The pipeline works in four stages:

1. **Convert TKG edges into natural-language sentences**
2. **Embed those sentences and build a FAISS index**
3. **Retrieve and rerank temporally relevant facts**
4. **Use an agent to answer temporal questions using retrieved context only** :contentReference[oaicite:2]{index=2}

This repository was developed around experiments on **MultiTQ**, with scripts for building the graph/index and running sampled evaluations by question type, label, answer type, or time level. :contentReference[oaicite:3]{index=3}

---

## Repository Structure

```text
COMP545-TempRAG/
├── all-MiniLM-L6-v2/         # local embedding model assets
├── data/                     # datasets, indexed artifacts, questions
├── experiments/              # evaluation scripts (e.g. MultiTQ)
├── logs/                     # experiment logs
├── model/                    # agent, search, reranker, tools
├── prompts/                  # prompt templates
├── reranker/                 # reranker-related assets/code
├── build_graph.py            # build FAISS index + metadata
├── build_graph.sh            # cluster job script for indexing
├── MultiTQ_experiment.sh     # cluster job script for evaluation
├── const.py                  # model loaders / shared configuration
└── README.md
