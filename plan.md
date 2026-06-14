# CodeXLR8 — Architecture & Design Specification

## Problem Statement

LLM coding agents burn tokens on navigation. Given a task like "fix the login bug," an agent with no prior knowledge of the codebase resorts to `ls`, broad `grep`, and speculative file reads. This is noisy (grep matches comments, tests, vendored code), expensive (reading irrelevant files burns API tokens), and error-prone (hidden dependencies and invariants go undiscovered).

Existing tools (Sourcegraph, Zoekt, ctags, Livegrep, GitHub Code Search) are designed for **human browsing** — web UIs, regex-based queries, no ranking tuned for agent needs, no metadata enrichment.

## Design Goals

1. **Agent-first**: The primary consumer is an LLM agent, not a human browsing a web UI.
2. **Zero setup works**: The engine produces useful results on any codebase without metadata.
3. **Incrementally adoptable**: Optional `.meta.yaml` sidecars add precision over time.
4. **Language agnostic**: No AST parsing. Pure tokenization of file content.
5. **No external dependencies**: SQLite FTS5 + PyYAML + Click. No servers, no API keys, no Docker.
6. **Fast**: <100ms results for codebases up to 10,000 files.

## Architecture

```
                    ┌──────────────────────┐
                    │   Agent (MCP Client)  │
                    │  codebase_search()    │
                    └──────────┬───────────┘
                               │ stdio / HTTP
                    ┌──────────▼───────────┐
                    │     MCP Server        │
                    │  codebase_search      │
                    │  codebase_index       │
                    └──────────┬───────────┘
                               │
                    ┌──────────▼───────────┐
                    │  SearchEngine (core)  │
                    │  build_index()        │
                    │  search()             │
                    └──────┬───────┬───────┘
                           │       │
              ┌────────────▼─┐  ┌──▼────────────┐
              │   Scanner     │  │  Config        │
              │  walk + read  │  │  .codexlr8.yaml│
              │  (no parsing) │  │  defaults      │
              └───────┬───────┘  └────────────────┘
                      │
              ┌───────▼────────┐
              │  .meta.yaml     │  ← optional curated layer
              │  summary, tags, │
              │  public_api     │
              └────────────────┘
```

### Module Map

```
src/codexlr8/
  scanner.py     — Walk project, read raw file content
  search.py      — SQLite FTS5 index, OR-semantics query with token-coverage scoring
  meta.py        — .meta.yaml read/write/generate/validate
  config.py      — .codexlr8.yaml loading with defaults
  cli.py         — Click CLI (scan, init, index, search, status, setup)
  mcp_server.py  — MCP stdio server wrapping SearchEngine
  eval.py        — Search quality evaluation and metrics
  embeddings.py  — Embedding provider, cosine similarity, hybrid rerank
  train.py       — TSDAE fine-tuning on codebase
```

## The Three-Layer Value Stack

| Layer | Source | What | Weight |
|---|---|---|---|
| 1 | File content | Function names, variable names, comments, docstrings | 0.3× per token |
| 2a | File path | Filename, directory components | 0.5–0.8× per token |
| 2b | `.meta.yaml` curated fields | summary + tags | 0.6–0.8× boost |
| 3 | `.meta.yaml` public_api | Explicit symbol list | 1.0× boost |

**Layer 1** and **2a** work immediately, zero setup, on any codebase — path weighting provides differentiation even without metadata. **Layers 2b–3** add precision through optional human/agent curation.

## Search Engine Design

### Index

SQLite FTS5 with `porter unicode61` tokenizer. Virtual table columns:

| Column | Content |
|---|---|
| `path` | Relative file path |
| `summary` | From `.meta.yaml` |
| `tags` | Space-joined from `.meta.yaml` |
| `public_api` | Space-joined from `.meta.yaml` |
| `content` | Raw file content |

A companion `file_meta` table stores `content_size`, `has_meta`, `is_init`, `file_mtime`, and `index_built_at` for incremental updates and status reporting.

### Query Semantics

**OR with token-coverage scoring.** All tokens are searched with OR. A custom scoring layer (path weighting, metadata boosts, match ratio) surfaces files that match more tokens. A post-filter requires ≥50% token match for multi-token queries. This replaces the previous AND-then-OR fallback, which caused precise multi-token queries to return zero results (AND too strict) or too many flatly-scored results (OR fallback with no differentiation).

### Tokenization

Matches identifiers (`[a-zA-Z_][a-zA-Z0-9_]*`) and standalone numbers (`\d+`). Single-letter tokens are discarded. `"Phase 28"` → `["phase", "28"]`. Number support was added in v0.1 after discovering that OR semantics + no-number matching made queries like "Phase 28" only match on "phase".

### Scoring

```
score = (∑ token_boost) × match_ratio

token_boost:
  token ∈ public_api     → 1.0
  token == filename      → 0.8   (e.g. "axes3d" in axes3d.py)
  token ∈ tags           → 0.8
  token ∈ filename_part  → 0.7   (e.g. "axes3d" in rotate_axes3d_sgskip.py)
  token ∈ summary        → 0.6
  token ∈ dir_path       → 0.5   (e.g. "mplot3d" in lib/mpl_toolkits/mplot3d/)
  token ∈ content (FTS5) → 0.3

match_ratio: matched_tokens / total_query_tokens

Penalties:
  __init__.py            → score × 0.6
```

Path weighting means a file whose name IS the query token ranks above one that merely mentions it in content. Directory-component matching provides a middle tier. This gives the engine differentiation even when metadata is absent.

### Incremental Indexing

Tracks `file_mtime` per indexed file. `--incremental` mode compares timestamps and only re-indexes changed, new, or deleted files. Removed files are dropped from the index.

### Exclusion

Files are excluded at **index time** (never enter the index) and **query time** (filtered from results). Patterns are globs matched against both full path and basename. Default excludes: `tests/*`, `test/*`, `spec/*`, `__tests__/*`, `test_*`, `*_test.*`, `examples/*`, `docs/*`, `tutorials/*`, `benchmarks/*`.

## Metadata Sidecar Format (`.meta.yaml`)

```yaml
public_api: [login, logout, reset_password]   # auto: regenerated by tools
dependencies: [models.user, utils.hashing]     # auto: from imports
used_by: [main, api.auth_routes]               # auto: reverse dependency graph
last_modified: "2026-06-14T10:30:00Z"          # auto: timestamp

summary: "User auth: login, session, password reset"  # curated
tags: [auth, security, session]                        # curated
invariants:                                            # curated
  - "db.connect() must be called first"
  - "Passwords are bcrypt hashes, never plaintext"
examples: null                                         # curated
```

### Curation Model

Metadata is **agent-maintained**, not developer-maintained. The agent skill instructs agents to:
- Bootstrap missing `.meta.yaml` files at session start
- Update `summary`, `tags`, `public_api` when modifying a file
- Backfill only files they touch — no mass curation campaigns

## Configuration (`.codexlr8.yaml`)

```yaml
root: "."
include: []                     # scope: only scan these directories
exclude:                        # filter: skip these
  - tests/*
  - test_*
  - *_test.*
extensions:                     # file types to index
  - .py
  - .js
  - .ts
ignore_dirs:                    # skip directories entirely
  - .git
  - __pycache__
  - node_modules
```

All fields have defaults. A missing config file uses `DEFAULT_EXTENSIONS` and `DEFAULT_IGNORE_DIRS` with no include restrictions. CLI `--exclude` flags override config for that command.

## MCP Integration

Two tools: `codebase_search(query, path?, limit?, exclude?, scope?)` and `codebase_index(path?, incremental?, exclude?)`.

**`codebase_search`**: `path` defaults to config `root` or current directory. `scope` restricts results to a path prefix (like `grep -rn "pattern" directory/`), applied as a pre-score SQL filter. `exclude` patterns filter results post-score.

**`codebase_index`**: builds or incrementally updates the search index.

The MCP server runs as a subprocess and communicates over stdio per the Model Context Protocol. Results include paths, line ranges, scores, summaries, tags, matched tokens, and preview snippets. No file read tool — agents use their existing read tool.

## Search Result Clustering

...

## Query Diagnostics (`--explain`)

The `--explain` / `-e` flag surfaces the engine's internal query processing to the agent. Instead of guessing why search failed, the agent sees:

```
$ codexlr8 search . "3d axes not hiding" --explain

Query analysis:
  Original:  "3d axes not hiding"
  Tokens:    3d, axes, not, hiding

  "3d"      6 matches    — very specific
  "axes"    212 matches  — broad term (212/212 results)
  "not"     77 matches
  "hiding"  0 matches    — consider dropping or replacing

  Top score: 1.20 (strong)
  Tip: "hiding" doesn't exist — try a synonym or drop it.
```

### What it shows

| Diagnostic | Source | Agent action |
|---|---|---|
| Per-token hit count | Token presence in results (path + summary + tags) | Drop noisy terms, keep specific ones |
| Zero-match tokens | Token not found in any result | Replace with synonyms or drop entirely |
| Filtered words | Single-letter words removed by tokenizer | Use full terms |
| Top score | Max result score | Confidence signal: am I getting quality hits? |

### What it doesn't do

- No auto-suggestions — the LLM agent knows the task context and is better at choosing replacements
- No confidence thresholds — what's "strong" varies by codebase metadata coverage
- No per-file token breakdown — use `matched_tokens` on individual results for that

## Search Quality Evaluation (`eval`)

The `eval` command measures search accuracy against a known query set, giving deterministic before/after metrics for any layer change.

```
$ codexlr8 eval . --queries queries.json

  Query                   Expected          Rank  Score   Status
  ────────────────────────────────────────────────────────────────
  "login auth"            auth/session.py    1    1.60    ✓
  "checkout cart"         cart/cart.py        2    0.90    ✓ (top-3)
  "payment stripe"        payments/stripe.py  —    —       ✗ not found

  ────────────────────────────────────────
  Precision@1:  50%  (2/4)
  MRR:          0.71
  Recall@5:     75%  (3/4)
```

### Queries file schema

```json
[
  {"query": "login auth", "expected": "auth/session.py", "min_rank": 1},
  {"query": "checkout",  "expected": "cart/cart.py",     "min_rank": 3}
]
```

| Field | Required | Default | Meaning |
|-------|----------|---------|---------|
| `query` | yes | — | Search query to test |
| `expected` | yes | — | File path that should appear in results |
| `min_rank` | no | 1 | Required position (1=must be #1, 3=top-3) |

### Metrics

| Metric | Formula | Meaning |
|--------|---------|---------|
| Precision@1 | (rank-1 matches) / total | How often the correct file is first |
| MRR | Σ(1/rank) / total | Reciprocal rank averaged — accounts for position |
| Recall@5 | (found in top-5) / total | How often the file appears at all |

### Workflow

```bash
codexlr8 eval . --queries baseline.json   # measure current setup
vim .codexlr8.yaml                         # toggle a layer (fuzzy, embeddings)
codexlr8 eval . --queries baseline.json   # measure again → see delta
```

The eval framework is the prerequisite for every search quality improvement — it proves a layer helps before shipping it.

## Search Result Clustering

The CLI supports an optional `--grouped` / `-g` flag that clusters flat search results by directory prefix before displaying them. This gives agents the same narrowing signal that `grep | awk | sort | uniq -c` gives human grep users.

### Format

```
$ codexlr8 search . "get_visible" --grouped

12 results in 3 directories (8 files) across project:

lib/foo/  (5 files)
  lib/foo/bar.py:486  [score: 0.90]
    bar module summary
  lib/foo/baz.py:120  [score: 0.70]
    baz helper
  lib/foo/qux.py:55  [score: 0.50]
  ... and 2 more files

src/core/  (2 files)
  src/core/engine.py:10  [score: 0.60]

...

Use --scope <dir> to narrow results (e.g. --scope lib/foo/)
```

### Rules

1. Groups are sorted by **max score** in the group, not total match count
2. Up to 3 files shown per group; remaining shown as `... and N more files`
3. Group depth defaults to 3 directory levels; configurable via `--group-depth <n>`
4. Root-level files (no directory) group under `"."`
5. A `--scope <dir>` hint at the bottom gives the agent a direct follow-up path
6. Grouping is **CLI-only** — the MCP server and JSON output return flat results (or a `"grouped": true` wrapper in JSON when requested)
7. When `--scope` is already active, the hint changes to "Already scoped."

## Design Decisions

### Why no AST parsing?

AST parsing requires per-language dependencies (tree-sitter grammars, Python AST, etc.) and still can't handle comments/docstrings well. Pure tokenization of file content across 20+ languages with FTS5 indexing is simpler, faster, and language-agnostic. The metadata layer provides precision where parsing would help.

### Why SQLite FTS5?

Zero dependencies (stdlib `sqlite3`). Free features: stemming, prefix queries, phrase matching, BM25 ranking. No server process. Portable across platforms. Scales fine for codebases up to millions of tokens.

### Why OR semantics with scoring?

Pure AND was too strict — a 4-token query frequently returned zero results because code rarely contains all exact words together. Pure OR was too noisy — a 10-word query matched thousands of files. The AND-then-OR fallback was fragile: precise queries hit the OR wall and got flatly-scored noise.

OR with token-coverage scoring uses the scoring layer (path weighting, metadata boosts, match ratio) to naturally surface files matching more tokens. A ≥50% post-filter for multi-token queries eliminates single-token noise. The result: more tokens = higher score, not zero results.

### Why sidecars and not inline metadata?

- Indexer reads YAML directly — no source parsing needed
- Auto fields can be regenerated without touching source code
- Works for any file type (code, SQL, Markdown, configs)
- Reading a 15-line `.meta.yaml` costs ~50 tokens

## Search Quality Infrastructure (Phase 8)

### Layer Cascade

Search runs through a configurable layer cascade:

```
Query → FTS5 BM25 (always) → Fuzzy fallback (on zero) → Embedding hybrid rerank (opt-in)
```

Each layer toggles independently in `.codexlr8.yaml`:

```yaml
fuzzy: true
embeddings:
  enabled: false
  model: all-MiniLM-L6-v2
  bm25_weight: 0.6
```

### Fuzzy Fallback

Triggered only when FTS5 returns zero results. Uses `difflib.get_close_matches` against the FTS5 vocabulary table (created lazily via `fts5vocab`) to correct typo'd tokens. Edit distance cutoff: 0.78. First-letter prefix filter for performance. Zero deps (stdlib only).

### Embedding Layer (Opt-in)

Requires `pip install codexlr8[embeddings]` (adds `sentence-transformers`).

- **Storage**: JSON vectors in a `embeddings` table in the same `.codexlr8_index.db`
- **Model**: Any sentence-transformers model (default: `all-MiniLM-L6-v2`, 23M params)
- **Hybrid rerank**: normalized BM25 score blended with cosine similarity, default 60/40 weight
- **Lazy loading**: model loaded on first search, never at import time
- **Incremental**: `--incremental` only re-embeds changed files; removed files also cleaned from embeddings table

### TSDAE Fine-Tuning

`codexlr8 train .` adapts a pretrained model to the codebase vocabulary:

1. Scan files, combine path + metadata + first 2000 chars of content
2. Randomly mask 30% of tokens in each text (corruption)
3. Train SentenceTransformer to denoise (reconstruct original)
4. Save to `.codexlr8_model/`, update `.codexlr8.yaml` to use it

Training time: ~50ms per file per epoch on CPU. 1,000 files → ~2.5 minutes. 50,000 files → ~2 hours.

`codexlr8 recommend-model .` analyzes codebase size and suggests:
- <500K tokens → `all-MiniLM-L6-v2` (23M, +5-8% MRR)
- 500K-2M tokens → `all-MiniLM-L6-v2` (23M, +7-12% MRR)
- >2M tokens → `all-mpnet-base-v2` (110M, +10-18% MRR)

### Eval Framework

`codexlr8 eval . --queries q.json` measures Precision@1, MRR, Recall@5. Three assert modes: `file` (path+rank), `scope` (line overlap), `exact` (≥80% line overlap). The feedback loop — eval, toggle layers, eval again — proves each layer's value before shipping.

## Design Decisions (continued)

### Future Work

- **Symbol-level indexing** (see above)
- **Semantic search enhancements**: Embeddings layer is in place. Future: sqlite-vec ANN acceleration, graph-based reranking, cross-file embedding similarity
- **Cross-file dependency tracking**: Follow `dependencies` / `used_by` chains
- **Language-specific extractors**: Optional tree-sitter plug-ins
- **Watch mode**: `codexlr8 watch`
- **Multi-repo monorepo support**: Per-subproject configs

## Project Constraints

- No AST or tree-sitter parsing in core — tokenization only
- No external services (DB servers, APIs, cloud dependencies)
- Python 3.10+ only (no async/await except in MCP server)
- FTS5 index stored as `.codexlr8_index.db` in project root
- 100% local operation — no telemetry, no network access
