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
run_id: Anthropic_F11_T10_R014
provider: Anthropic
model_label: Opus 4.6
copilot_temperature_setting: 1.0
temperature_setting_status: copilot_ui_selected_unverified
prompt_family_id: F11
prompt_family_slug: FALSE_RF_DIAGNOSIS
family_label: False RF diagnosis
family_group: Adversarial diagnosis
replicate: 14
raw_output_file: Experiment_Output/Anthropic/Temp_1.0/output_F11_Anthropic_temp_10_rep_014.md

RESPONSE TO SCORE:
<<<BEGIN_RESPONSE
 # Diagnosis, Optimization Strategy, and Working R Code

## Diagnosis: Rejecting the Colleague's Claim

The colleague's claim that Random Forest inference is the main bottleneck is **incorrect**. The code evidence clearly points to **spatial neighbor feature engineering** â€” specifically `build_neighbor_lookup()` and `compute_neighbor_stats()` â€” as the true bottleneck.

Here's why:

1. **`build_neighbor_lookup()`** iterates via `lapply` over **~6.46 million rows**, and for each row it performs character coercion (`as.character`), string pasting (`paste(..., sep="_")`), named-vector lookups (`id_to_ref[...]`, `idx_lookup[...]`), and NA filtering. These are expensive, non-vectorized, per-row string operations executed millions of times. This single function alone likely accounts for the vast majority of the 86+ hour runtime.

2. **`compute_neighbor_stats()`** then iterates over those same ~6.46 million entries in the lookup list, computing `max`, `min`, and `mean` for each neighborhood. This is called **5 times** (once per neighbor source variable), yielding ~32.3 million list iterations total.

3. **Random Forest inference** is a single call to `predict()` on an already-loaded model. Even with ~6.46M rows and ~110 predictors, a single `predict()` call on a trained `ranger` or `randomForest` object completes in seconds to minutes â€” orders of magnitude less than the neighbor computation.

**The bottleneck is the R-level row-by-row `lapply` loops with string-key lookups over 6.46 million rows, not the RF prediction.**

---

## Optimization Strategy

1. **Replace string-key lookups with integer-indexed joins using `data.table`.** Instead of building character keys and doing named-vector lookups millions of times, we create a merge between a neighbor edge table and the data on `(id, year)` using `data.table` keyed joins â€” moving the heavy lifting into C-level code.

2. **Vectorize `compute_neighbor_stats`** by expressing the neighbor aggregation as a grouped `data.table` operation (`max`, `min`, `mean` by row index), eliminating the R-level `lapply` over millions of entries.

3. **Build the neighbor edge list once** and reuse it for all 5 variables, avoiding redundant work.

4. **Preserve the trained Random Forest model and original numerical estimand** â€” we only change the feature engineering; the model and prediction step are untouched.

---

## Working R Code

```r
library(data.table)

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 1. Convert cell_data to data.table and assign a row index
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
setDT(cell_data)
cell_data[, row_idx := .I]

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 2. Build a vectorized neighbor edge table (one-time cost)
#
#    rook_neighbors_unique is an nb object: a list of length N_cells
#    where element [[i]] gives the integer indices (into id_order) of
#    the neighbors of the i-th cell in id_order.
#
#    We expand this into an edge table of (focal_id, neighbor_id),
#    then join to cell_data on (id, year) to get (focal_row, neighbor_row).
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€

# Build edge list: focal cell id -> neighbor cell id
n_cells <- length(id_order)
focal_idx_vec   <- rep(seq_len(n_cells), lengths(rook_neighbors_unique))
neighbor_idx_vec <- unlist(rook_neighbors_unique)

edges <- data.table(
  focal_id    = id_order[focal_idx_vec],
  neighbor_id = id_order[neighbor_idx_vec]
)

# Create a lookup from cell_data: (id, year) -> row_idx
setkey(cell_data, id, year)

# For every (focal_id, year) combination we need the focal row_idx,
# and for every (neighbor_id, year) combination we need the neighbor row_idx.
# 
# Strategy: cross-join edges with all unique years, then join twice
# to cell_data to get row indices for focal and neighbor.

years <- unique(cell_data$year)

# Expand edges Ã— years  (~1.37M edges Ã— 28 years â‰ˆ 38.5M rows)
# This is large but fits in 16 GB RAM as integer columns.
edge_year <- edges[, CJ(edge_idx = .I, year = years)]
edge_year[, focal_id    := edges$focal_id[edge_idx]]
edge_year[, neighbor_id := edges$neighbor_id[edge_idx]]
edge_year[, edge_idx := NULL]

# Join to get focal_row_idx
setkey(edge_year, focal_id, year)
cell_key <- cell_data[, .(id, year, row_idx)]
setkey(cell_key, id, year)

edge_year[cell_key, focal_row := i.row_idx, on = .(focal_id = id, year)]

# Join to get neighbor_row_idx
edge_year[cell_key, neighbor_row := i.row_idx, on = .(neighbor_id = id, year)]

# Drop rows where either side didn't match (boundary / missing year)
edge_year <- edge_year[!is.na(focal_row) & !is.na(neighbor_row)]

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 3. Compute neighbor stats for all 5 variables â€” fully vectorized
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
neighbor_source_vars <- c("ntl", "ec", "pop_density", "def", "usd_est_n2")

for (var_name in neighbor_source_vars) {

  # Attach the neighbor's value for this variable
  edge_year[, nval := cell_data[[var_name]][neighbor_row]]

  # Aggregate: max, min, mean per focal row (excluding NAs)
  agg <- edge_year[!is.na(nval),
                   .(nb_max  = max(nval),
                     nb_min  = min(nval),
                     nb_mean = mean(nval)),
                   by = focal_row]

  # Initialise new columns with NA
  max_col  <- paste0("neighbor_max_",  var_name)
  min_col  <- paste0("neighbor_min_",  var_name)
  mean_col <- paste0("neighbor_mean_", var_name)

  cell_data[, (max_col)  := NA_real_]
  cell_data[, (min_col)  := NA_real_]
  cell_data[, (mean_col) := NA_real_]

  # Fill in the aggregated values by row index
  cell_data[agg$focal_row, (max_col)  := agg$nb_max]
  cell_data[agg$focal_row, (min_col)  := agg$nb_min]
  cell_data[agg$focal_row, (mean_col) := agg$nb_mean]
}

# Clean up temporary column
edge_year[, nval := NULL]
cell_data[, row_idx := NULL]

# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# 4. Random Forest prediction â€” UNCHANGED (not the bottleneck)
# â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€â”€
# model is the pre-trained RF; do NOT retrain
predictions <- predict(model, data = cell_data)  # ranger style
# or: predictions <- predict(model, newdata = cell_data)  # randomForest style

cell_data[, predicted := predictions$predictions]  # adjust accessor as needed
```

---

## Why This Is Dramatically Faster

| Aspect | Original | Optimized |
|---|---|---|
| Lookup construction | 6.46M R-level `lapply` iterations with string ops | One vectorized `data.table` keyed join |
| Neighbor stats | 5 Ã— 6.46M R-level `lapply` iterations | 5 Ã— one grouped `data.table` aggregation (C-level) |
| Key mechanism | `paste()` + named-vector lookup per row | Integer-indexed equi-join on `(id, year)` |
| Estimated time | 86+ hours | **Minutes** (typically 5â€“20 min on a laptop) |
| RF predict time | Secondsâ€“minutes | Unchanged |
| Numerical results | â€” | **Identical** (same max/min/mean, same model) |

The trained Random Forest model is preserved untouched, and the original numerical estimand (the neighbor max, min, and mean features feeding into the same `predict()` call) is fully preserved. Only the computational method for constructing those features has been replaced with vectorized, `data.table`-based operations.
END_RESPONSE>>>
