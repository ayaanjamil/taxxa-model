# Build Journey

## Phase 1 — Setup
- Reviewed plan, confirmed layered approach (baseline → graph → agents)
- Downloaded `finland_kb` (63k HTML files, 584MB) + `question_bank.json` (83 QA pairs)
- Created Python venv, installed dependencies

## Phase 2 — Eval Harness
- Wrote `eval_harness.py` — loads QA bank, calls answer function, LLM-judges
  key fact coverage, prints scores by tier
- Confirmed baseline: stub answer returns 0% across all tiers

## Phase 3 — Parser
- Wrote `parser.py` — keyword-filters tax-relevant HTML, extracts
  title/text/§-refs/date into `nodes.json`
- Multiple corpus quirks (challenges #1–#5): Finnish morphology breaking
  statute detection, § notation with case suffixes, vero files cut off
  by `--limit`, Finlex stored as amendment history (not consolidated law)
  with TVL §124 sitting past the 4k-char parse cap
- Final corpus: 376,200 chunks across 37,212 parent documents

## Phase 4 — Baseline Retriever + Answerer (broken, then repaired)
- First eval: 0% fact coverage, 93% citation rate — citations present,
  facts wrong
- Seven cascading bugs (challenges #6–#12): dead reference expansion,
  English/Finnish embedding gap, keyword-matched nodes buried by vector
  scores, naive multi-query merge, planner echoing user compounds,
  `format_nodes` truncation cutting answers, judge LLM silent JSON
  parse failure
- After fixes: basic tier 0% → 40%, then climbing to 60% overall on
  20-question sample

## Phase 5 — Voikko + Treaty Retrieval (handoff 001)
- **Q20 ("Finland-Austria treaty dividend rate") as forcing function** —
  the bilateral-treaty document existed in the corpus but never
  surfaced. Root causes: BM25 missed `Itävalta` vs `Itävallan`
  morphology; vero ×1.15 boost buried treaties; article body lacked the
  country name; parent cap kept the right chunk out
- Integrated `libvoikko` Finnish morphological analyzer into BM25
  tokenization (each token emits both surface form and BASEFORM)
- Treaty boost (×1.15), treaty neighbor expansion (±3 chunks),
  treaty parent cap raised to 4
- Planner system prompt rewritten: every treaty sub-query MUST combine
  country name + article-content keywords in the same string

## Phase 6 — Streaming API + Cytoscape Frontend (handoff 002)
- All model names moved behind env vars (`TAXXA_ANSWER_MODEL`,
  `TAXXA_PLANNER_MODEL`, `TAXXA_JUDGE_MODEL`, `TAXXA_WEB_MODEL`)
- `.env.cheap` overlay for cheap-model A/Bs without touching code
- `api.py` FastAPI SSE endpoint streams phased events
  (`plan` → `entry` → `sub_done` → `hop` → `sources` → `token` → `done`)
- Next.js + Cytoscape.js frontend visualizes graph traversal in real
  time alongside the streamed answer

## Phase 7 — Graph Layer + LLM-Typed Edges (handoff 003)
- `graph_builder.py` builds parent-level NetworkX DiGraph: 1,048
  deterministic `cites` edges (Vero → Finlex via §), 658 `amends`
  edges (Finlex amendment headers)
- `extract_edges.py` re-types `cites` edges into semantic relations
  (`interpreted_by`, `clarified_by`, `overrides`, `references`) using
  Haiku with a Finnish-aware prompt — ~$0.50 for all 596 pairs
- Confidence ≥ 0.7 floor; graph_v2 swapped in via `TAXXA_GRAPH_VERSION=v2`
- **Result:** LLM edges added +4pp over the deterministic graph, but
  graph mode still trailed plain baseline by ~4pp. Defaulted back to
  v1 (deterministic) for the demo path
- Retriever A/B switches (`TAXXA_DEDUP_MODE`, `TAXXA_RRF_K`,
  `TAXXA_ENTRY_FRONTIER_MULT`) added as env-var ablation knobs

## Phase 8 — Embedder Swap to BGE-M3 (this session)
- Baseline state: 60% fact coverage, mpnet (2021) was the weakest link.
  Difficulty_4/5 stuck at ~22–25%
- Swapped `paraphrase-multilingual-mpnet-base-v2` (768-dim) →
  `BAAI/bge-m3` (1024-dim, stronger Finnish)
- `modal_embed.py` runs 4 parallel Modal A10G workers via `.starmap()`.
  First single-shard attempt was preempted at 55%; sharded version
  finished cleanly in ~27 min (shorter per-shard runtime = lower
  preemption blast radius)
- `embedder.py` + `retriever.py` registry made model-switchable via
  `TAXXA_EMBED_MODEL`; mpnet path retained for fast revert. Query
  encoder runs on MPS on Apple Silicon (~35ms/encode)
- Synthesis context cap raised 14k → 18k chars (`TAXXA_CTX_CHARS`)
- **Result on same 15 stratified questions:**

  | Tier         | mpnet | BGE-M3 | Δ      |
  |--------------|------:|-------:|-------:|
  | medium       |  33%  |   53%  | +20    |
  | hard         |  80%  |   83%  |  +3    |
  | difficulty_2 |  33%  |   67%  | +34    |
  | difficulty_4 |  39%  |   44%  |  +5    |
  | difficulty_5 |  33%  |   22%  | -11    |
  | **OVERALL**  | **44%** | **54%** | **+10** |
  | citations    |  80%  |   93%  | +13    |

  Big lifts on previously-broken cases (Q23 0→60, Q49 40→100, N3 0→100,
  N48 0→100); regressions on a few that mpnet had been solving via
  BM25 (Q12, Q38, N7, N42). Net positive
- `ARCHITECTURE.md` written; `EVAL_RESULTS.md` records the before/after
