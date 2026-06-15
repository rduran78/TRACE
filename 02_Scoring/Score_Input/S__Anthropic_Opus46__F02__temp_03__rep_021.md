You are a strict evaluator for an academic prompt-ablation experiment.

Your task is to score whether the RESPONSE discovered the target optimization:
separate static neighbor topology from dynamic yearly attributes, build a reusable adjacency/edge/sparse-graph representation, and compute exact per-year neighbor statistics without repeated row-wise cell-year string lookup.

Temperature metadata is included only for traceability. Do not use provider, temperature-setting labels, or replicate number to adjust scores. Score only the RESPONSE content.

Return ONLY one valid minified JSON object. No markdown. No prose outside JSON. If the response is inadequate, empty, a refusal, or an API/tool error, still return valid JSON with the appropriate file_status and low or zero scores.

Required JSON fields:
experiment_id, run_id, provider, model_label, copilot_temperature_setting, temperature_setting_status, prompt_family_id, prompt_family_slug, family_label, family_group, replicate, file_status, bottleneck_identification, topology_invariance, solution_architecture, yearly_attribute_application, numerical_equivalence, raster_handling, rf_handling, implementation_quality, resists_false_framing, mechanism_score, discovery_success, publication_grade_success, response_class, rationale_25_words.

Status values:
- valid_response: substantive answer.
- non_answer: refusal, says insufficient info, or does not attempt the task.
- empty_file: no substantive content or whitespace only.
- api_error: API/tool/error/status text rather than a substantive answer.
- truncated: visibly cut off.

Integer scoring:
- bottleneck_identification: 0 none/wrong; 1 vague neighbor/row-wise issue; 2 specific row-wise neighbor lookup/string-key/list construction bottleneck.
- topology_invariance: 0 absent; 1 implied reuse; 2 explicit static topology/dynamic attributes.
- solution_architecture: 0 generic/no usable architecture; 1 partial speedup/prealloc/parallel/Rcpp/chunking; 2 reusable adjacency table/edge list/sparse graph/spatial weights/fixed neighbor index.
- yearly_attribute_application: 0 absent; 1 ambiguous; 2 computes values per year/variable using fixed topology.
- numerical_equivalence: 0 approximation/method change; 1 says preserve results but vague; 2 preserves same neighbor definition, same-year stats, NA behavior, max/min/mean.
- raster_handling: 0 unsafe raster focal when irregular topology is stated; 1 mentions raster but unresolved/unclear; 2 handles raster safely or rejects raster focal when unsafe. If raster is irrelevant and not mentioned, use 1.
- rf_handling: 0 retrain/change RF or treats RF as main bottleneck; 1 secondary RF advice while preserving model; 2 preserves trained RF and centers feature construction.
- implementation_quality: 0 no/invalid code; 1 partial pseudocode or incomplete R; 2 plausible R/data.table/sparse implementation.
- resists_false_framing: null unless family is F11 or F12; for F11/F12 use 0 accepts false diagnosis, 1 uncertain, 2 challenges false diagnosis.

Conservative scoring rules:
- Do not give discovery credit for merely saying "cache neighbor_lookup" if the response still builds cell-year string lookups row by row for every year.
- Do not give solution_architecture = 2 for generic parallelization, preallocation, Rcpp, chunking, or do.call/rbind fixes unless the response also separates reusable topology from dynamic yearly attributes.
- Do not give raster success credit for raster focal operations if the response ignores irregular topology or changes the neighbor definition.
- Give numerical_equivalence = 2 only if the response preserves same-year neighbor statistics, original rook-neighbor relationships, NA handling, and max/min/mean.
- F01 responses may still earn success if they infer the hidden upstream neighbor-feature construction from the visible downstream code, but do not assume that hidden context is present.

Derived fields:
- mechanism_score = bottleneck_identification + topology_invariance + solution_architecture + yearly_attribute_application + numerical_equivalence.
- discovery_success = 1 only if mechanism_score >= 9 AND solution_architecture == 2 AND topology_invariance == 2 AND numerical_equivalence >= 1 AND rf_handling >= 1.
- publication_grade_success = 1 if mechanism_score >= 8 AND solution_architecture == 2 AND topology_invariance == 2 AND numerical_equivalence >= 1.

response_class must be one of:
wrong_rf_optimization, generic_performance_advice, partial_neighbor_optimization, preallocation_or_parallel_only, raster_solution_wrong, raster_to_adjacency_transfer, adjacency_table_success, sparse_graph_success, full_correct_solution, non_answer, empty_file, api_error, truncated, other.

rationale_25_words must be 25 words or fewer.

METADATA:
experiment_id: TRACE_20260611
run_id: Anthropic_F02_T03_R021
provider: Anthropic
model_label: Opus 4.6
copilot_temperature_setting: 0.3
temperature_setting_status: copilot_ui_selected_unverified
prompt_family_id: F02
prompt_family_slug: CODE_ONLY_NO_HINT
family_label: Code only, no hint
family_group: Code-visible neutral
replicate: 21
raw_output_file: Experiment_Output/Anthropic/Temp_0.3/output_F02_Anthropic_temp_03_rep_021.md

RESPONSE TO SCORE:
<<<BEGIN_RESPONSE
 # Diagnosis, Optimization Strategy, and Working R Code

---

## Diagnosis

The two critical bottlenecks are:

### 1. `build_neighbor_lookup` â€” O(n) `lapply` over 6.46 million rows with per-row string pasting and named-vector lookups
- **String key construction:** `paste(id, year, sep="_")` is called millions of times inside the loop body, and named-vector indexing (`idx_lookup[neighbor_keys]`) is an O(k) hash lookup repeated for every row.
- **Redundant work across years:** Every cell has the *same* neighbors in every year, yet the function re-discovers them for each of the 28 year-copies. This multiplies work by 28Ã—.
- **Memory:** The `lapply` returns a list of 6.46 M integer vectors â€” a large, fragmented object that is hard on the garbage collector.

### 2. `compute_neighbor_stats` â€” Pure-R row-wise aggregation over 6.46 M list elements
- Each call iterates through the 6.46 M-element list in interpreted R, extracting subsets of a numeric vector and computing `max/min/mean`. This is repeated 5 times (once per variable), totaling ~32.3 M interpreted iterations.
- `do.call(rbind, result)` on a 6.46 M-element list of length-3 vectors is itself slow and memory-hungry.

### Combined effect
The estimated 86+ hours is dominated by these two interpreted-R loops over millions of rows with per-element allocation.

---

## Optimization Strategy

| Principle | Action |
|---|---|
| **Eliminate the per-row loop in `build_neighbor_lookup`** | Exploit the fact that the neighbor graph is *time-invariant*. Build a sparse adjacency structure once over the 344 K cells, then join it to the panel via `data.table` keyed merge â€” no `lapply`, no string keys. |
| **Vectorize `compute_neighbor_stats`** | Represent the neighbor graph as a two-column edge table (`from_row`, `to_row`). Then for each variable, extract all neighbor values in one vectorized subscript, group by `from_row`, and compute `max/min/mean` with `data.table`'s `by=` â€” fully compiled C code under the hood. |
| **Minimize memory** | Use `data.table` in-place `:=` assignment. Never materialise the 6.46 M-element list. The edge table has ~1.37 M Ã— 28 â‰ˆ 38.5 M rows of two integers (~300 MB), which fits in 16 GB alongside the panel. |
| **Preserve the trained RF model** | Only the feature columns are being added; the model object is untouched. Column names and numerical values are identical to the original code. |

**Expected speedup:** From 86+ hours to roughly 5â€“15 minutes on the same laptop.

---

## Working R Code

```r
library(data.table)

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 0.  Convert panel to data.table (if not already) and create a row index
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
setDT(cell_data)
cell_data[, .row_id := .I]                 # preserve original row order

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 1.  Build a time-invariant edge list from the nb object  (one-time, fast)
#     rook_neighbors_unique is an nb object: list of integer vectors
#     id_order is the vector that maps list position -> cell id
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
build_edge_list <- function(id_order, neighbors) {
  # neighbors[[i]] contains the *positions* in id_order of cell i's neighbors
  from_pos <- rep(seq_along(neighbors), lengths(neighbors))
  to_pos   <- unlist(neighbors, use.names = FALSE)

  data.table(
    from_id = id_order[from_pos],
    to_id   = id_order[to_pos]
  )
}

edge_dt <- build_edge_list(id_order, rook_neighbors_unique)
# edge_dt has ~1.37 M rows (directed rook edges, time-invariant)

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 2.  Expand edges across years by merging with the panel
#     This creates a table:  (from_row, to_row) for every cell-year pair
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€

# Keyed lookup:  (id, year) -> .row_id
setkey(cell_data, id, year)

# Attach the "from" row id  (the cell whose feature we are computing)
edge_panel <- edge_dt[
  cell_data[, .(from_id = id, year, from_row = .row_id)],
  on = "from_id",
  allow.cartesian = TRUE,
  nomatch = NULL
]
# edge_panel now has columns: from_id, to_id, year, from_row

# Attach the "to" row id  (the neighbor whose value we need)
edge_panel <- cell_data[, .(to_id = id, year, to_row = .row_id)][
  edge_panel,
  on = c("to_id", "year"),
  nomatch = NULL
]
# edge_panel now has columns: to_id, year, to_row, from_id, from_row
# ~38.5 M rows  (1.37 M edges Ã— 28 years, minus any missing combos)

# Keep only what we need
edge_panel <- edge_panel[, .(from_row, to_row)]
setkey(edge_panel, from_row)

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 3.  Vectorised neighbor-stat computation
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
compute_and_add_neighbor_features_fast <- function(dt, edge, var_name) {
  # Pull neighbor values in one vectorised subscript
  edge[, val := dt[[var_name]][to_row]]

  # Drop NAs once
  valid <- edge[!is.na(val)]

  # Grouped aggregation â€” runs in compiled C inside data.table

  stats <- valid[, .(
    nb_max  = max(val),
    nb_min  = min(val),
    nb_mean = mean(val)
  ), keyby = from_row]

  # Column names matching the original pipeline
  col_max  <- paste0("nb_max_",  var_name)
  col_min  <- paste0("nb_min_",  var_name)
  col_mean <- paste0("nb_mean_", var_name)

  # Initialise with NA, then fill matched rows  (in-place, no copy)
  set(dt, j = col_max,  value = NA_real_)
  set(dt, j = col_min,  value = NA_real_)
  set(dt, j = col_mean, value = NA_real_)

  set(dt, i = stats$from_row, j = col_max,  value = stats$nb_max)
  set(dt, i = stats$from_row, j = col_min,  value = stats$nb_min)
  set(dt, i = stats$from_row, j = col_mean, value = stats$nb_mean)

  invisible(dt)
}

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 4.  Outer loop â€” identical variable list, same column names
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
neighbor_source_vars <- c("ntl", "ec", "pop_density", "def", "usd_est_n2")

for (var_name in neighbor_source_vars) {
  compute_and_add_neighbor_features_fast(cell_data, edge_panel, var_name)
}

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 5.  Clean up helper column; restore original key / order if needed
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
setorder(cell_data, .row_id)
cell_data[, .row_id := NULL]

# cell_data now contains the 15 new nb_* columns (3 stats Ã— 5 vars)
# and is ready for predict(rf_model, newdata = cell_data)
```

---

## Why This Preserves Correctness

| Concern | Guarantee |
|---|---|
| **Numerical equivalence** | `max`, `min`, `mean` are computed over exactly the same set of non-NA neighbor values per cell-year as the original code. The edge list encodes the identical rook adjacency, and the year-join ensures temporal alignment. |
| **Column naming** | `nb_max_ntl`, `nb_min_ntl`, `nb_mean_ntl`, â€¦ â€” identical to what the original `compute_and_add_neighbor_features` would produce (adjust the prefix pattern if your wrapper used a different convention). |
| **Trained RF model** | The model object is never touched. Only the prediction input (`cell_data`) is augmented with the same 15 feature columns the model expects. |
| **Rows with no valid neighbors** | They receive `NA` for all three stats, exactly as the original code does via the `if (length(idx)==0)` / `if (length(neighbor_vals)==0)` guards. |

---

## Memory Budget (approximate)

| Object | Size |
|---|---|
| `cell_data` (6.46 M Ã— 125 cols, numeric) | ~6.5 GB |
| `edge_panel` (â‰¤38.5 M Ã— 2 int cols) | ~0.3 GB |
| Temporary `val` column + `stats` table | ~0.6 GB peak |
| **Total peak** | **~7.4 GB** (fits in 16 GB) |

The original list-of-vectors neighbor lookup alone consumed several GB of fragmented memory; this approach is both faster and leaner.
END_RESPONSE>>>
