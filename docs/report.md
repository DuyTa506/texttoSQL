# Retrieval Analysis Report: BIRD Dev — Full Benchmark (1 534 Examples)

**Date**: 2026-03-17 (updated)
**Benchmark**: BIRD Dev — all 11 databases, 1 534 examples
**Graph versions tested**:
- `bird_dev_enriched_v2.json` — GraphRetriever v2 (8-fix batch)
- `bird_dev_v3.json` — GraphRetriever v3 (TABLE_FK + INFERRED_FK + reduced CO_JOIN + FK bridge + adaptive gap)
- `bird_dev_v3b.json` — GraphRetriever v3b (v3 + Layer 2b: EMBEDDING_SIMILAR + SYNONYM_MATCH edges)
- `bird_dev_v3_rebuild.json` — GraphRetriever v3+fix (v3 rebuild + adaptive gap ratio bug fix: small DB now uses looser ratio)

**Script**: `scripts/analyze_retrieval.py`
**Result files**:

| Retriever | JSON path |
|---|---|
| HybridRetriever | `results/bird_retrieval_analysis_full.json` |
| GraphRetriever v2 | `results/bird_retrieval_analysis_graph_v2_full.json` |
| GraphRetriever v3 | `results/bird_retrieval_analysis_graph_v3_full.json` |
| GraphRetriever v3b | `results/bird_retrieval_analysis_graph_full.json` |
| **GraphRetriever v3+fix** | `results/bird_retrieval_analysis_graph_1534.json` |
| Graph+Hybrid merge *(v2)* | `results/bird_retrieval_analysis_hybrid_merge_full.json` |
| **Graph+Hybrid merge *(v3+fix)*** | `results/bird_retrieval_analysis_hybrid_merge_1534.json` |

---

## 1. Executive Summary

Four retrievers evaluated side-by-side on the full BIRD Dev set, plus graph variants.
All metrics are schema-linking only (no SQL generation).

| Retriever | Tbl Recall | Tbl Prec | **Tbl F1** | Exact Match | Missed Ex | Noisy Ex | Avg Tokens |
|---|---|---|---|---|---|---|---|
| HybridRetriever *(baseline)* | **0.988** | 0.392 | 0.561 | 2.9% | 46 | 767 | 193 |
| GraphRetriever v1 *(pre-8-fix)* | — | — | 0.672 | — | — | — | — |
| GraphRetriever v2 *(8-fix)* | 0.925 | **0.622** | **0.744** | **21.9%** | 251 | **260** | **77** |
| GraphRetriever v3 | 0.931 | 0.599 | 0.729 | 20.0% | 236 | 298 | 80 |
| GraphRetriever v3b *(+Layer 2b)* | 0.932 | 0.590 | 0.723 | 20.1% | 230 | 323 | 77 |
| **GraphRetriever v3+fix** *(adaptive gap fix)* | **0.936** | 0.600 | 0.731 | 20.8% | **223** | 279 | **78** |
| Graph+Hybrid merge *(v2)* | 0.974 | 0.486 | 0.648 | 5.5% | 96 | 363 | 109 |
| **Graph+Hybrid merge *(v3+fix)*** | 0.972 | 0.489 | 0.651 | 5.7% | 102 | 344 | 106 |

**Key headline numbers:**

- GraphRetriever v2 **F1 +18.3 pp** vs Hybrid (0.744 vs 0.561), driven by +23 pp precision.
- **v3+fix is the best graph variant**: recall 0.936 (+1.0 pp over v2), 223 missed examples (−28 vs v2), F1 0.731.
- The adaptive gap ratio fix (small DB: `min()→max()`) alone recovered **+0.5 pp recall** vs v3 on the same graph.
- v3 targets (F1 ≥ 0.78, Recall ≥ 0.95) **not yet met** — precision needs improvement on dense-FK DBs.
- Context size: Graph v3+fix averages **78 tokens** vs Hybrid's 193 (2.5× smaller prompt).
- Exact match (recall=1 AND precision=1): **Graph v2 21.9%** / v3+fix **20.8%** vs Hybrid 2.9%.
- Zero-recall examples (complete miss): **0 for all retrievers**.

---

## 2. Detailed Metrics

### 2.1 Core Set-Membership Metrics

| Metric | Hybrid | Graph v2 | **Graph v3+fix** | Merge v3+fix |
|---|---|---|---|---|
| Table Recall | **0.9879** | 0.9246 | 0.9356 | 0.9720 |
| Table Precision | 0.3920 | **0.6221** | 0.6000 | 0.4889 |
| **Table F1** | 0.5613 | **0.7438** | 0.7311 | 0.6506 |
| Column Recall | **0.9912** | 0.9345 | 0.9450 | 0.9750 |
| Column Precision | 0.1054 | **0.1407** | 0.1370 | 0.1180 |
| Column F1 | 0.1905 | **0.2446** | 0.2393 | 0.2106 |
| Perfect recall % | **97.0%** | 83.6% | 85.5% | 93.4% |
| Exact match % | 2.9% | **21.9%** | 20.8% | 5.7% |
| Zero recall % | 0% | 0% | 0% | 0% |
| Missed examples | **46** | 251 | **223** | 102 |
| Noisy (>3 extra tables) | 767 | **260** | 279 | 344 |

### 2.2 Rank-Quality Metrics

| Metric | Hybrid | Graph v2 | **Graph v3+fix** | Merge v3+fix |
|---|---|---|---|---|
| NDCG@15 | **0.9332** | 0.8942 | 0.8956 | 0.9201 |
| MRR | **0.9453** | 0.9444 | 0.9343 | 0.9361 |
| Hit@3 | 0.9974 | 0.9967 | 0.9948 | 0.9954 |
| FK pair recall | **0.9833** | 0.8800 | 0.8992 | 0.9517 |

> All retrievers find the **first** gold table at almost the same rank (MRR ~0.934–0.945).
> Graph v3+fix improves FK pair recall by +1.9 pp over v2 (0.899 vs 0.880) — TABLE_FK edges
> and FK bridge injection helping multi-table queries.

### 2.3 Context Budget

| Metric | Hybrid | Graph v2 | **Graph v3+fix** | Merge v3+fix |
|---|---|---|---|---|
| Avg schema tokens | 193 | **77** | 78 | 106 |
| FK pair recall | **0.983** | 0.880 | 0.899 | 0.952 |
| Redundant table ratio | 0.608 | **0.378** | — | — |
| Contexts >2 000 tokens | 0 | 0 | 0 | 0 |

> Graph v3+fix generates **2.5× smaller** schema prompts vs Hybrid (78 vs 193 tokens).
> Merge v3+fix trades +28 tokens (+36%) for +3.6 pp recall over pure Graph.

---

## 3. Join-Complexity Stratification

Table F1 by number of gold tables required per query.

| Complexity | #Ex | Hybrid F1 | Graph v2 F1 | **Graph v3+fix F1** | Merge F1 | v3+fix Recall | v3+fix Prec |
|---|---|---|---|---|---|---|---|
| **1-table** | 364 | 0.362 | **0.636** | 0.610 | 0.471 | 1.000 | 0.438 |
| **2-table** | 928 | 0.591 | **0.773** | 0.760 | 0.679 | 0.937 | 0.639 |
| **3-table** | 202 | 0.689 | 0.759 | **0.762** | 0.755 | 0.843 | 0.695 |
| **4+-table** | 40 | 0.691 | 0.700 | **0.727** | 0.739 | 0.784 | 0.677 |

Key findings:

- **Graph v3+fix leads at 3-table and 4+-table queries** over v2 (+0.3 pp / +2.7 pp F1) — TABLE_FK edges improve multi-hop reach.
- **Graph v2 still leads at 1-table and 2-table** — FK bridge injection adds noise on simpler queries.
- **Merge wins 4+-table** (F1 0.739) — Hybrid recall matters when many tables must all be found.
- 1-table recall = **1.000** for both Graph variants — no gold table ever missed on single-table queries.

---

## 4. Difficulty Stratification (BIRD Labels)

| Difficulty | #Ex | Hybrid F1 | Graph v2 F1 | **Graph v3+fix F1** | Merge F1 | v3+fix NDCG |
|---|---|---|---|---|---|---|
| Simple | 925 | 0.507 | **0.717** | 0.693 | 0.611 | 0.906 |
| Moderate | 464 | 0.631 | 0.779 | **0.783** | 0.701 | 0.886 |
| Challenging | 145 | 0.655 | **0.778** | 0.773 | 0.718 | 0.858 |

- Graph v3+fix **beats v2 on moderate queries** (+0.4 pp) — FK bridge helps medium-complexity joins.
- Simple queries: v3+fix loses −2.4 pp to v2 — FK bridge adds noise on 1-table simple queries.
- Challenging queries: v3+fix −0.5 pp vs v2 — broadly equivalent.

---

## 5. Per-Database Breakdown

### 5.1 Graph v3+fix vs v2 Per-Database

| Database | n | v2 F1 | **v3+fix F1** | Δ F1 | v3+fix Recall | v3+fix Prec | NDCG | FK Pair | Tokens |
|---|---|---|---|---|---|---|---|---|---|
| thrombosis_prediction | 163 | 0.875 | **0.887** | **+0.012** | 0.945 | 0.835 | 0.946 | 0.877 | 47 |
| debit_card_specializing | 64 | 0.788 | **0.801** | **+0.013** | 0.904 | 0.719 | 0.890 | 0.969 | 29 |
| student_club | 158 | 0.769 | **0.780** | **+0.011** | 0.959 | 0.657 | 0.935 | 0.918 | 59 |
| financial | 106 | 0.719 | **0.722** | **+0.002** | 0.846 | 0.630 | 0.815 | 0.729 | 67 |
| codebase_community | 186 | 0.585 | **0.586** | +0.001 | 0.976 | 0.419 | 0.932 | 0.972 | 110 |
| california_schools | 89 | **0.855** | 0.851 | −0.005 | 0.916 | 0.794 | 0.908 | 0.854 | 49 |
| card_games | 191 | **0.851** | 0.839 | −0.012 | 0.947 | 0.753 | 0.921 | 0.942 | 50 |
| toxicology | 145 | **0.695** | 0.685 | −0.011 | **0.998** | 0.521 | 0.900 | **1.000** | 51 |
| european_football_2 | 129 | **0.748** | 0.738 | −0.009 | 0.867 | 0.643 | 0.855 | 0.775 | 139 |
| formula_1 | 174 | **0.506** | 0.467 | **−0.039** | 0.887 | 0.317 | 0.761 | 0.825 | 132 |
| superhero | 129 | **0.757** | 0.644 | **−0.114** | 0.989 | 0.477 | 0.970 | 0.984 | 87 |

Notable changes:
- **Winners** (v3+fix > v2): thrombosis_prediction, debit_card_specializing, student_club, financial — all medium FK-depth schemas where TABLE_FK edges help.
- **Regressions**: superhero (−11.4 pp F1) — FK bridge injects `hero_attribute`/`hero_power` tables excessively (+22/+26× over-retrieval). formula_1 (−3.9 pp) — FK flooding worse with new TABLE_FK shortcuts.

### 5.2 All-Retriever Comparison

| Database | n | H Recall | **H F1** | G v2 Recall | **G v2 F1** | G v3+fix Recall | **G v3+fix F1** | M Recall | **M F1** |
|---|---|---|---|---|---|---|---|---|---|
| thrombosis_prediction | 163 | 0.998 | 0.792 | 0.917 | **0.875** | 0.945 | **0.887** | 0.982 | 0.793 |
| california_schools | 89 | 1.000 | 0.804 | 0.876 | **0.855** | 0.916 | 0.851 | 0.966 | 0.816 |
| card_games | 191 | 0.988 | 0.524 | 0.942 | **0.851** | 0.947 | 0.839 | 0.987 | 0.726 |
| debit_card_specializing | 64 | 1.000 | 0.555 | 0.904 | 0.788 | 0.904 | **0.801** | 0.984 | 0.596 |
| european_football_2 | 129 | 0.992 | 0.443 | 0.879 | **0.748** | 0.867 | 0.738 | 0.973 | 0.556 |
| student_club | 158 | 0.993 | 0.492 | 0.930 | 0.769 | 0.959 | **0.780** | 0.979 | 0.595 |
| superhero | 129 | 0.992 | 0.623 | **0.989** | **0.757** | 0.989 | 0.644 | 0.996 | 0.749 |
| financial | 106 | 0.986 | 0.571 | 0.843 | 0.719 | 0.846 | **0.722** | 0.960 | 0.636 |
| toxicology | 145 | 0.998 | 0.627 | 0.987 | **0.695** | **0.998** | 0.685 | 0.995 | 0.636 |
| codebase_community | 186 | 0.984 | 0.421 | 0.969 | **0.585** | 0.976 | **0.586** | 0.983 | 0.559 |
| formula_1 | 174 | 0.954 | 0.341 | 0.877 | **0.506** | 0.887 | 0.467 | 0.914 | 0.440 |

---

## 6. Most Missed and Over-Retrieved Tables (Graph v3+fix)

### 6.1 Most Missed Tables

| Table | v3+fix misses | v2 misses | Δ | Root cause |
|---|---|---|---|---|
| `financial.account` | 22× | 23× | −1 | Implicit reference — queries mention transactions/loans |
| `thrombosis_prediction.patient` | 19× | 24× | **−5** ✅ | FK hub; TABLE_FK now helps propagate |
| `formula_1.races` | 17× | 28× | **−11** ✅ | TABLE_FK shortcut improved PPR reach |
| `european_football_2.player` | 15× | 12× | +3 ❌ | Now over-seeded from player_attributes FK |
| `formula_1.drivers` | 13× | 10× | +3 ❌ | TABLE_FK flooding → score diluted |
| `european_football_2.team` | 11× | 11× | 0 | Multi-hop chain still too deep |
| `student_club.member` | 11× | 12× | −1 | Marginal improvement |
| `california_schools.schools` | 9× | 14× | **−5** ✅ | Adaptive gap fix (small DB) recovered these |
| `financial.loan` | 9× | 9× | 0 | Queried via account/disp FK columns |
| `card_games.cards` | 9× | 9× | 0 | — |

**Improvements**: formula_1.races (−11), thrombosis_prediction.patient (−5), california_schools.schools (−5)
**Regressions**: european_football_2.player (+3), formula_1.drivers (+3) — TABLE_FK edges created new confusion paths

### 6.2 Most Over-Retrieved Tables

| Table | v3+fix | v2 | Δ | Root cause |
|---|---|---|---|---|
| `codebase_community.posthistory` | 132× | 120× | +12 | Dense CO_JOIN cluster — still over-propagating |
| `codebase_community.comments` | 111× | 121× | −10 | — |
| `formula_1.constructorresults` | 100× | 70× | **+30** ❌ | New TABLE_FK shortcuts from results/races |
| `formula_1.constructorstandings` | 91× | 73× | **+18** ❌ | Same FK flood |
| `superhero.hero_attribute` | 85× | 63× | **+22** ❌ | TABLE_FK from superhero → attributes |
| `superhero.hero_power` | 81× | 55× | **+26** ❌ | Same — superhero star topology |
| `codebase_community.votes` | 87× | 95× | −8 | — |
| `formula_1.laptimes` | 88× | 99× | −11 | — |
| `toxicology.bond` | 76× | 68× | +8 | Ring-topology still problematic |

**Main regression source**: `formula_1` and `superhero` — star FK topologies where new TABLE_FK
shortcuts amplify PPR flooding to all leaf tables.

---

## 7. The 8-Fix Batch — What Was Changed and Why

All fixes applied in a single commit to `graph_builder.py`, `graph_retriever.py`,
and `schema_filter.py`.

| Fix | Code change | Measured effect |
|---|---|---|
| **Fix 1** — Real PPR scores | `graph_builder.retrieve()` returns `list[tuple[KGNode, float]]`; `_nodes_to_dicts()` uses real score instead of `1/(i+1)` | Correct confidence weights for downstream RRF fusion |
| **Fix 2** — Adaptive `max_nodes` | `adaptive_max = min(max_nodes, max(6, db_table_count))` per query | Primary precision driver: +10.0 pp (0.522 → 0.622) |
| **Fix 3** — Score-gap pruning | Drop tail nodes where `prev_score/curr_score > gap_ratio=3.0` | Noisy examples: 400+ (v1) → 260 (v2) |
| **Fix 4** — NL stopword filter | `_NL_STOPWORDS` frozenset (what/are/the/…) excluded from synonym tokens | Removes spurious seed boosts from generic question words |
| **Fix 5** — Per-DB PPR subgraph | `G.subgraph(db_node_ids)` passed to `nx.pagerank` instead of full graph | ~4× PPR speedup; prevents cross-DB probability leakage |
| **Fix 6** — FK bridge tables | After PPR, add FK-target tables missing from result with bridge score | Orphaned FK rate: 0.086 (v1) → 0.000 (v2) on all 11 DBs |
| **Fix 7** — Column score filtering | `SchemaFilter` shows only scored columns + PK/FK for Graph path | Column precision: ~4.7% (v1) → 14.1% (v2) = **3× improvement** |
| **Fix 8** — `hybrid_weight` in RRF | `_rrf_merge(graph_results, *others)` applies `self.hybrid_weight` to graph list | Enables tunable fusion; was dead code before |

**Combined Graph v2 vs v1:**

| Metric | v1 (pre-fix) | v2 (post-fix) | Δ |
|---|---|---|---|
| Table F1 | 0.672 | **0.744** | **+7.2 pp** |
| Table Precision | ~0.522 | 0.622 | **+10.0 pp** |
| Column Precision | ~0.047 | 0.141 | **+9.4 pp (3×)** |
| Noisy examples | ~400+ | **260** | **−35%** |
| Avg prompt tokens | ~120 | **77** | **−36%** |

---

## 8. Retriever Characteristic Profiles

| Dimension | HybridRetriever | GraphRetriever v2 | **Graph v3+fix** | Graph+Hybrid Merge v3 |
|---|---|---|---|---|
| **Table F1** | 0.561 | **0.744** | 0.731 | 0.651 |
| **Table Recall** | **0.988** | 0.925 | 0.936 | 0.972 |
| **Table Precision** | 0.392 | **0.622** | 0.600 | 0.489 |
| **Exact match** | 2.9% | **21.9%** | 20.8% | 5.7% |
| **Avg prompt tokens** | 193 | **77** | 78 | 106 |
| **FK pair recall** | **0.983** | 0.880 | 0.899 | 0.952 |
| **Missed examples** | **46** | 251 | **223** | 102 |
| **Noisy examples** | 767 | **260** | 279 | 344 |
| **NDCG@15** | **0.933** | 0.894 | 0.896 | 0.920 |
| Zero-recall examples | 0 | 0 | 0 | 0 |

**When to use each:**

- **GraphRetriever v3+fix** — best recall among graph variants (0.936), smallest prompts (78 tokens), 223 missed examples (−28 vs v2). Best default choice. Preferred for schemas with medium FK depth (thrombosis, financial, student_club).
- **GraphRetriever v2** — still best F1 (0.744) and exact match (21.9%) due to tighter precision. Use when over-retrieval is more costly than recall. Best on schemas with clear semantic clusters (card_games, superhero).
- **HybridRetriever** — best recall (0.988) and FK pair recall (0.983). Use when missing any gold table is catastrophic and prompt size is not a constraint. Degrades on large/dense schemas (formula_1, codebase_community).
- **Graph+Hybrid merge v3** — best tradeoff for production when schemas vary widely. Recall 97.2%, 43% fewer noisy examples than Hybrid, 45% fewer tokens. Use when high recall is required but Hybrid's context explosion is unacceptable.

---

## 9. Remaining Failure Modes and Next Steps

### 9.1 Graph v2 Recall Failures (251 missed-table examples)

**Pattern A — FK hub tables (~40% of misses)**: `races`, `patient`, `account`, `member`, `player`.
PPR seeds on leaf columns and propagates through edges, but hub tables sit "above" the seed
neighborhood and receive insufficient personalization mass.
*Fix*: Add explicit table-level PPR seeds whenever a FK column is seeded.

**Pattern B — Implicit entity references (~25%)**: `financial.account` missed 23× because queries
mention "transactions" or "loans" and seed those columns; `account` is only referenced via FK.
*Fix*: Strengthen `COLUMN_BELONGS_TO` edge weight to ensure PPR mass flows back to parent table nodes.

**Pattern C — Vague questions (~20%)**: "school info", "player stats" don't activate the right
synonyms.
*Fix*: Expand synonym vocabulary with more NL paraphrases (gpt-4o, 10 synonyms per node).

**Pattern D — Multi-hop FK chains (~15%)**: `european_football_2` chain:
`match → player_attributes → player → team`. PPR with alpha=0.7 barely reaches `team` from
`match` seeds.
*Fix*: Lower `alpha` to 0.65 or increase `max_hops` to 3 for schemas with FK chain depth > 2.

### 9.2 Graph v2 Precision Failures (260 noisy examples)

**formula_1** (99× `laptimes`, 85× `driverstandings`, 83× `pitstops`): Star FK topology from
`races`. Every race-related column seeds `races` which propagates to all 6 FK children.
*Fix*: Per-DB adaptive `score_gap_ratio` — increase to 4–5 for DBs with n_tables ≥ 10.

**codebase_community** (121× `comments`, 120× `posthistory`, 95× `votes`): Dense Layer-3
`CO_JOIN` edges make all community tables look co-relevant.
*Fix*: Reduce `CO_JOIN` edge weight from 0.80 to 0.50, or disable Layer-3 for FK-ring schemas.

### 9.3 v2 Recommended Next Iteration *(implemented in v3)*

| Priority | Fix | Expected impact | v3 Status |
|---|---|---|---|
| **High** | Table-level PPR seeds for FK columns | +3–5 pp recall on formula_1, financial, european_football_2 | ✅ `TABLE_FK` / `TABLE_FK_REV` edges (w=0.85) |
| **High** | Per-DB adaptive `score_gap_ratio` (ratio=5 for n_tables ≥ 10) | −50+ noisy examples on formula_1/codebase | ✅ Adaptive: 4.5 (≥10 tbl), 3.0 (5-9), 2.0 (≤4) |
| **Medium** | `alpha=0.65` + `max_hops=3` for chain-depth DBs | +2 pp recall on multi-hop schemas | — Not implemented |
| **Medium** | Layer-3 edge weight tuning (`CO_JOIN` 0.80→0.50) | Better precision on stat-dense DBs | ✅ `CO_JOIN` capped at 0.50 |
| **Low** | Expanded synonym vocabulary (gpt-4o, 10 synonyms/node) | +1–2 pp recall on simple queries | — Not implemented |

---

## 10. GraphRetriever v3 Evaluation

### 10.1 v3 Changes

Graph structure changes (offline — `build_schema_graph.py`):
- **`TABLE_FK` / `TABLE_FK_REV`** (w=0.85): Table-level FK shortcut edges. PPR can now hop between FK-related tables in 1 step (was 4-hop: Table→Col→Col→Table).
- **`INFERRED_FK` / `INFERRED_FK_REV`** (w=0.95): Column-level FK edges inferred from VALUE_OVERLAP where Jaccard ≥ 0.5. Captures undeclared foreign keys.
- **`CO_JOIN` weight cap**: Reduced from 0.80 → 0.50 to prevent statistical co-occurrence from overwhelming structural signals.

Runtime retrieval changes (`graph_retriever.py`):
- **Adaptive score-gap ratio**: `gap_ratio` adjusted per-DB: 4.5 for ≥10 tables (looser), 2.0 for ≤4 tables (tighter), 3.0 default.
- **FK bridge injection**: After PPR, missing FK-target tables are injected when FK columns appear in results.
- **Value seed boosting**: When `ValueScanner` is enabled, columns matching question values get boosted seed scores.

### 10.2 v3 Results (without Layer 2b)

Graph file: `bird_dev_v3.json` (6,981 edges)

| Metric | v2 | **v3** | Δ |
|---|---|---|---|
| Table Recall | 0.925 | **0.931** | **+0.6 pp** |
| Table Precision | **0.622** | 0.599 | −2.3 pp |
| Table F1 | **0.744** | 0.729 | −1.5 pp |
| Perfect recall % | 83.6% | **84.6%** | +1.0 pp |
| Missed examples | 251 | **236** | **−15** |
| Noisy examples | **260** | 298 | +38 |
| FK pair recall | 0.880 | **0.891** | +1.1 pp |
| Avg tokens | **77** | 80 | +3 |

**Join-complexity breakdown (v2 → v3):**

| Complexity | v2 Recall | v3 Recall | Δ | v2 F1 | v3 F1 | Δ |
|---|---|---|---|---|---|---|
| 1-table | 1.000 | 1.000 | +0.0 | **0.636** | 0.611 | −2.5 |
| 2-table | 0.924 | **0.930** | +0.6 | **0.773** | 0.758 | −1.5 |
| 3-table | 0.823 | **0.837** | **+1.3** | **0.759** | 0.754 | −0.5 |
| 4+-table | 0.763 | **0.784** | **+2.2** | 0.700 | **0.727** | **+2.7** |

**Key per-table miss changes (v2 → v3):**

| Table | v2 misses | v3 misses | Δ |
|---|---|---|---|
| `formula_1.races` | 28 | **15** | **−13** ✅ |
| `codebase_community.posthistory` | 7 | **2** | **−5** ✅ |
| `thrombosis_prediction.patient` | 24 | 30 | +6 ❌ |

**Verdict**: v3 successfully improved recall on multi-table queries (especially 3+ tables) and dramatically reduced `formula_1.races` misses (−13). However, FK bridge injection is too aggressive — adds whole tables, inflating noise and dropping precision. Net F1 is negative.

### 10.3 v3b Results (v3 + Layer 2b edges)

Graph file: `bird_dev_v3b.json` (53,685 edges: +4,348 EMBEDDING_SIMILAR + 42,356 SYNONYM_MATCH)

| Metric | v2 | v3 | **v3b** | v3b vs v2 |
|---|---|---|---|---|
| Table Recall | 0.925 | 0.931 | **0.932** | **+0.8 pp** |
| Table Precision | **0.622** | 0.599 | 0.590 | −3.2 pp |
| Table F1 | **0.744** | 0.729 | 0.723 | −2.1 pp |
| Perfect recall % | 83.6% | 84.6% | **85.0%** | **+1.4 pp** |
| Missed examples | 251 | 236 | **230** | **−21** |
| Noisy examples | **260** | 298 | 323 | +63 |
| MRR | **0.944** | 0.935 | 0.915 | −2.9 pp |
| FK pair recall | 0.880 | 0.891 | **0.891** | +1.1 pp |
| Avg tokens | 77 | 80 | **77** | +0.7 |

**Key per-table miss changes (v2 → v3b):**

| Table | v2 | v3 | v3b | Δ(v3b-v2) |
|---|---|---|---|---|
| `formula_1.races` | 28 | 15 | **20** | **−8** ✅ |
| `thrombosis_prediction.patient` | 24 | 30 | **18** | **−6** ✅ |
| `financial.account` | 23 | 23 | **17** | **−6** ✅ |
| `thrombosis_prediction.examination` | 6 | 9 | **4** | **−2** ✅ |
| `student_club.member` | 12 | 11 | **9** | **−3** ✅ |
| `codebase_community.users` | 5 | 5 | 11 | +6 ❌ |
| `formula_1.drivers` | 10 | 13 | 14 | +4 ❌ |

**Per-DB recall changes (v2 → v3b):**

| Database | v2 Recall | v3b Recall | Δ |
|---|---|---|---|
| thrombosis_prediction | 0.917 | **0.939** | **+2.2 pp** ✅ |
| student_club | 0.930 | **0.960** | **+3.0 pp** ✅ |
| california_schools | 0.876 | **0.899** | **+2.3 pp** ✅ |
| financial | 0.843 | **0.852** | **+0.9 pp** ✅ |
| toxicology | 0.987 | **0.998** | **+1.0 pp** ✅ |
| codebase_community | **0.969** | 0.957 | −1.2 pp ❌ |
| european_football_2 | **0.879** | 0.863 | −1.6 pp ❌ |

**Verdict**: Layer 2b edges help recall on domain-specific schemas (clinical, financial) where synonym/embedding similarity bridges lexical gaps. But the 42K SYNONYM_MATCH edges are too dense — they spread PPR mass everywhere, causing MRR to drop (−2.9 pp) and introducing 63 more noisy examples. The EMBEDDING_SIMILAR edges (4,348) are more surgical but get drowned out.

### 10.4 v3 Diagnosis: Recall-Precision Tradeoff

The fundamental tension in v3: **every new edge or bridge table improves recall but dilutes PPR mass and hurts precision**. The v3 targets (F1 ≥ 0.78, Recall ≥ 0.95, Precision ≥ 0.58) require a more surgical approach:

| Issue | Observation | Potential fix |
|---|---|---|
| FK bridge too aggressive | Injects whole tables (all columns), adding noise | Only inject when ≥2 FK columns point to bridge table |
| SYNONYM_MATCH too dense | 42K edges vs 4K EMBEDDING_SIMILAR | Raise `synonym_min_overlap` from 1→3, or reduce `W_SYNONYM_MAX` 0.85→0.50 |
| CO_JOIN still noisy | `codebase_community` tables indistinguishable | Further reduce CO_JOIN to 0.30 or disable for star-topology DBs |
| EMBEDDING_SIMILAR threshold | 0.75 may be too loose for cross-table pairs | Raise to 0.80 for cross-table, keep 0.75 for same-table |
| PPR damping | `alpha=0.7` limits reach to 2-3 hops | Try `alpha=0.65` for deep FK chains (european_football_2) |

**Next-iteration strategy**: Rather than adding more edges, focus on **edge weight tuning** and **selective pruning** to shift the precision-recall curve right.

---

## 11. Historical Progression

| Milestone | Date | Retriever | F1 | Precision | Recall | Avg Tokens | Notes |
|---|---|---|---|---|---|---|---|
| Baseline | 2025-07 | HybridRetriever | 0.561 | 0.392 | 0.988 | 193 | BM25+semantic+FK BFS, 1 534 ex |
| Graph structural only | 2025-07 | GraphRetriever v0 | 0.763 | 0.694 | 0.848 | — | Layer 1+2a, raw names, 100 ex |
| Graph LLM-enriched | 2025-07 | GraphRetriever v1 | 0.672 | 0.522 | 0.945 | ~120 | All 3 layers, 1 534 ex, pre-fix |
| **Graph v2 — 8-fix batch** | **2026-03** | **GraphRetriever v2** | **0.744** | **0.622** | **0.925** | **77** | **All 8 fixes, 1 534 ex** |
| Graph v3 — structural+runtime | 2026-03 | GraphRetriever v3 | 0.729 | 0.599 | 0.931 | 80 | TABLE_FK, INFERRED_FK, CO_JOIN↓, FK bridge, adaptive gap |
| Graph v3b — +Layer 2b edges | 2026-03 | GraphRetriever v3b | 0.723 | 0.590 | 0.932 | 77 | +4.3K EMBEDDING_SIMILAR, +42K SYNONYM_MATCH |
| **Graph v3+fix — adaptive gap fix** | **2026-03-17** | **GraphRetriever v3+fix** | **0.731** | **0.600** | **0.936** | **78** | **Reversed small-DB gap ratio (min→max). Best recall of all graph variants. 223 missed (−28 vs v2).** |

---

*Full per-example results in the JSON files listed at the top of this document.*
*Graph built with `scripts/build_schema_graph.py`, analysis with `scripts/analyze_retrieval.py`.*
