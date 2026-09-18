# Flash-Fusion Benchmark Report

Generated: 2026-09-18T19:31:12+00:00

## Summary Table

| Baseline     |   Avg LLM Accuracy |   Avg Latency (s) |   Avg Cost (USD) |
|:-------------|-------------------:|------------------:|-----------------:|
| FF_FULL      |             1.0000 |            4.9771 |           0.0012 |
| FF_NO_CACHE  |             1.0000 |            3.4050 |           0.0017 |
| FF_NO_PROMPT |             1.0000 |            3.3262 |           0.0015 |
| FF_NO_PRUNE  |             1.0000 |            3.5607 |           0.0021 |

## Typed-Operator Coverage

| Baseline     |   Queries |   Typed | Coverage   |   ReAct fallback |   Guardrail reject |   Typed avg latency (s) | Fallback avg latency (s)   |
|:-------------|----------:|--------:|:-----------|-----------------:|-------------------:|------------------------:|:---------------------------|
| FF_FULL      |         4 |       2 | 50%        |                0 |                  1 |                    6.97 | -                          |
| FF_NO_CACHE  |         4 |       3 | 75%        |                0 |                  1 |                    3.92 | -                          |
| FF_NO_PRUNE  |         4 |       3 | 75%        |                0 |                  1 |                    4.07 | -                          |
| FF_NO_PROMPT |         4 |       3 | 75%        |                0 |                  1 |                    3.68 | -                          |

## Per-Query Results

### Q1: What is the maximum accel_variance observed in this dataset?

#### FF_FULL

**Answer:** The result is 5.869

- Executed: True | Rejected: False | Judge: N/A
- Stages: exact_cache_hit,cache_light_grounding,cache_miss_or_validation_failure,guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: AGGREGATE_COLUMN
- Latency: 5.27s | Cost: $0.00151

**Agent Trace**

```
Thought: typed operator step 1 (AGGREGATE_COLUMN)
Action: typed_operator_exec
Action Input: result = df['accel_variance'].max()
Observation: 5.869
Final Answer: 5.869
```

**Final Code Executed**

```python
result = df['accel_variance'].max()
```

---

#### FF_NO_CACHE

**Answer:** The result is 5.869

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: AGGREGATE_COLUMN
- Latency: 2.12s | Cost: $0.00142

**Agent Trace**

```
Thought: typed operator step 1 (AGGREGATE_COLUMN)
Action: typed_operator_exec
Action Input: result = df['accel_variance'].max()
Observation: 5.869
Final Answer: 5.869
```

**Final Code Executed**

```python
result = df['accel_variance'].max()
```

---

#### FF_NO_PRUNE

**Answer:** The result is 5.869

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: AGGREGATE_COLUMN
- Latency: 2.40s | Cost: $0.00182

**Agent Trace**

```
Thought: typed operator step 1 (AGGREGATE_COLUMN)
Action: typed_operator_exec
Action Input: result = df['accel_variance'].max()
Observation: 5.869
Final Answer: 5.869
```

**Final Code Executed**

```python
result = df['accel_variance'].max()
```

---

#### FF_NO_PROMPT

**Answer:** The result is 5.869

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: AGGREGATE_COLUMN
- Latency: 1.98s | Cost: $0.00113

**Agent Trace**

```
Thought: typed operator step 1 (AGGREGATE_COLUMN)
Action: typed_operator_exec
Action Input: result = df['accel_variance'].max()
Observation: 5.869
Final Answer: 5.869
```

**Final Code Executed**

```python
result = df['accel_variance'].max()
```

---

### Q5: Is the northern half of the route (latitude above median) rougher than the southern half, based on average acceleration variance?

#### FF_NO_CACHE

**Answer:** The result is {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: SPLIT_BY_THRESHOLD,SPLIT_BY_THRESHOLD,AGGREGATE_PARTITIONS,COMPARE_PARTITIONS
- Latency: 4.22s | Cost: $0.00184

**Agent Trace**

```
Thought: typed operator step 1 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: northern_half = df[df['latitude'] gt df['latitude'].median()]
Observation: northern_half: rows=609 (latitude gt median=33.776676)
Thought: typed operator step 2 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: southern_half = df[df['latitude'] lte df['latitude'].median()]
Observation: southern_half: rows=610 (latitude lte median=33.776676)
Thought: typed operator step 3 (AGGREGATE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = {label: agg(partition) for label in partitions}
Observation: {'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624}
Thought: typed operator step 4 (COMPARE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = compare(northern_half, southern_half, mode='difference')
Observation: {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}
Final Answer: {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}
```

**Final Code Executed**

```python
northern_half = df[df['latitude'] gt df['latitude'].median()]
southern_half = df[df['latitude'] lte df['latitude'].median()]
result = {label: agg(partition) for label in partitions}
result = compare(northern_half, southern_half, mode='difference')
```

---

#### FF_NO_PRUNE

**Answer:** The result is {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: SPLIT_BY_THRESHOLD,SPLIT_BY_THRESHOLD,AGGREGATE_PARTITIONS,COMPARE_PARTITIONS
- Latency: 4.99s | Cost: $0.00234

**Agent Trace**

```
Thought: typed operator step 1 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: northern_half = df[df['latitude'] gt df['latitude'].median()]
Observation: northern_half: rows=609 (latitude gt median=33.776676)
Thought: typed operator step 2 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: southern_half = df[df['latitude'] lte df['latitude'].median()]
Observation: southern_half: rows=610 (latitude lte median=33.776676)
Thought: typed operator step 3 (AGGREGATE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = {label: agg(partition) for label in partitions}
Observation: {'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624}
Thought: typed operator step 4 (COMPARE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = compare(northern_half, southern_half, mode='difference')
Observation: {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}
Final Answer: {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}
```

**Final Code Executed**

```python
northern_half = df[df['latitude'] gt df['latitude'].median()]
southern_half = df[df['latitude'] lte df['latitude'].median()]
result = {label: agg(partition) for label in partitions}
result = compare(northern_half, southern_half, mode='difference')
```

---

#### FF_NO_PROMPT

**Answer:** The result is {'higher': 'northern', 'lower': 'southern', 'metric': 'mean accel_variance', 'northern': 0.3703333333333333, 'southern': 0.16309016393442624, 'difference': 0.20724316939890705}

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: SPLIT_BY_THRESHOLD,SPLIT_BY_THRESHOLD,AGGREGATE_PARTITIONS,COMPARE_PARTITIONS
- Latency: 4.69s | Cost: $0.00171

**Agent Trace**

```
Thought: typed operator step 1 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: northern = df[df['latitude'] gt df['latitude'].median()]
Observation: northern: rows=609 (latitude gt median=33.776676)
Thought: typed operator step 2 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: southern = df[df['latitude'] lte df['latitude'].median()]
Observation: southern: rows=610 (latitude lte median=33.776676)
Thought: typed operator step 3 (AGGREGATE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = {label: agg(partition) for label in partitions}
Observation: {'northern': 0.3703333333333333, 'southern': 0.16309016393442624}
Thought: typed operator step 4 (COMPARE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = compare(northern, southern, mode='difference')
Observation: {'higher': 'northern', 'lower': 'southern', 'metric': 'mean accel_variance', 'northern': 0.3703333333333333, 'southern': 0.16309016393442624, 'difference': 0.20724316939890705}
Final Answer: {'higher': 'northern', 'lower': 'southern', 'metric': 'mean accel_variance', 'northern': 0.3703333333333333, 'southern': 0.16309016393442624, 'difference': 0.20724316939890705}
```

**Final Code Executed**

```python
northern = df[df['latitude'] gt df['latitude'].median()]
southern = df[df['latitude'] lte df['latitude'].median()]
result = {label: agg(partition) for label in partitions}
result = compare(northern, southern, mode='difference')
```

---

#### FF_FULL

**Answer:** The result is {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}

- Executed: True | Rejected: False | Judge: N/A
- Stages: exact_cache_hit,cache_light_grounding,cache_miss_or_validation_failure,guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: SPLIT_BY_THRESHOLD,SPLIT_BY_THRESHOLD,AGGREGATE_PARTITIONS,COMPARE_PARTITIONS
- Latency: 8.67s | Cost: $0.00196

**Agent Trace**

```
Thought: typed operator step 1 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: northern_half = df[df['latitude'] gt df['latitude'].median()]
Observation: northern_half: rows=609 (latitude gt median=33.776676)
Thought: typed operator step 2 (SPLIT_BY_THRESHOLD)
Action: typed_operator_exec
Action Input: southern_half = df[df['latitude'] lte df['latitude'].median()]
Observation: southern_half: rows=610 (latitude lte median=33.776676)
Thought: typed operator step 3 (AGGREGATE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = {label: agg(partition) for label in partitions}
Observation: {'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624}
Thought: typed operator step 4 (COMPARE_PARTITIONS)
Action: typed_operator_exec
Action Input: result = compare(northern_half, southern_half, mode='difference')
Observation: {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}
Final Answer: {'higher': 'northern_half', 'lower': 'southern_half', 'metric': 'mean accel_variance', 'northern_half': 0.3703333333333333, 'southern_half': 0.16309016393442624, 'difference': 0.20724316939890705}
```

**Final Code Executed**

```python
northern_half = df[df['latitude'] gt df['latitude'].median()]
southern_half = df[df['latitude'] lte df['latitude'].median()]
result = {label: agg(partition) for label in partitions}
result = compare(northern_half, southern_half, mode='difference')
```

---

### Q9: How does passenger occupancy correlate with road roughness during this trip?

#### FF_NO_PRUNE

**Answer:** Query rejected. Reason: The dataset does not contain a column for passenger occupancy or road roughness.. This request is not supported by the current dataset schema or task scope.

- Executed: False | Rejected: True | Judge: N/A
- Stages: guardrail_plan
- Path: guardrail_reject
- Latency: 2.04s | Cost: $0.00173

**Alignment Explanation**

Rejected by the guardrail because the query cannot be answered from available dataset fields. Reason: The dataset does not contain a column for passenger occupancy or road roughness.

**Rejection Reasoning**

- The dataset does not contain a column for passenger occupancy or road roughness.

---

#### FF_NO_PROMPT

**Answer:** Query rejected. Reason: The dataset does not contain columns for passenger occupancy or road roughness.. This request is not supported by the current dataset schema or task scope.

- Executed: False | Rejected: True | Judge: N/A
- Stages: guardrail_plan
- Path: guardrail_reject
- Latency: 2.26s | Cost: $0.00108

**Alignment Explanation**

Rejected by the guardrail because the query cannot be answered from available dataset fields. Reason: The dataset does not contain columns for passenger occupancy or road roughness.

**Rejection Reasoning**

- The dataset does not contain columns for passenger occupancy or road roughness.

---

#### FF_FULL

**Answer:** Query rejected. Reason: The dataset does not contain columns for passenger occupancy or road roughness.. This request is not supported by the current dataset schema or task scope.

- Executed: False | Rejected: True | Judge: N/A
- Stages: exact_cache_hit_out_of_scope,cache_light_rejection_reason,cache_miss_or_validation_failure,guardrail_plan
- Path: guardrail_reject
- Latency: 5.94s | Cost: $0.00123

**Alignment Explanation**

Rejected by the guardrail because the query cannot be answered from available dataset fields. Reason: The dataset does not contain columns for passenger occupancy or road roughness.

**Rejection Reasoning**

- The dataset does not contain columns for passenger occupancy or road roughness.

---

#### FF_NO_CACHE

**Answer:** Query rejected. Reason: The dataset does not contain columns for passenger occupancy or road roughness.. This request is not supported by the current dataset schema or task scope.

- Executed: False | Rejected: True | Judge: N/A
- Stages: guardrail_plan
- Path: guardrail_reject
- Latency: 1.86s | Cost: $0.00116

**Alignment Explanation**

Rejected by the guardrail because the query cannot be answered from available dataset fields. Reason: The dataset does not contain columns for passenger occupancy or road roughness.

**Rejection Reasoning**

- The dataset does not contain columns for passenger occupancy or road roughness.

---

### Q13: Sort all bus rows by timestamp in ascending order. Use the first 80% of rows for training and the final 20% as the chronological holdout. Train a logistic regression model using the acceleration features. Predict the label in the behavior column for the first row in the holdout set.

#### FF_NO_PROMPT

**Answer:** The result is Logistic regression predicts behavior 'moderate' for the first holdout row.

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: PREDICTIVE_PIPELINE
- Latency: 4.37s | Cost: $0.00202

**Agent Trace**

```
Thought: typed operator step 1 (PREDICTIVE_PIPELINE)
Action: typed_operator_exec
Action Input: # sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts behavior 'moderate' for the first holdout row."
Observation: Logistic regression predicts behavior 'moderate' for the first holdout row.
Final Answer: Logistic regression predicts behavior 'moderate' for the first holdout row.
```

**Final Code Executed**

```python
# sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts behavior 'moderate' for the first holdout row."
```

---

#### FF_FULL

**Answer:** The result is Logistic regression predicts label 'moderate' for the first holdout row.

- Executed: True | Rejected: False | Judge: N/A
- Stages: exact_cache_hit,cache_light_grounding,cache_plan_validated,typed_exec
- Path: typed_operator_cache
- Operators: PREDICTIVE_PIPELINE
- Latency: 0.03s | Cost: $0.00000

**Agent Trace**

```
Cache hit: light model grounded cached skeleton; validated typed execution.
Thought: typed operator step 1 (PREDICTIVE_PIPELINE)
Action: typed_operator_exec
Action Input: # sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts label 'moderate' for the first holdout row."
Observation: Logistic regression predicts label 'moderate' for the first holdout row.
Final Answer: Logistic regression predicts label 'moderate' for the first holdout row.
```

**Final Code Executed**

```python
# sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts label 'moderate' for the first holdout row."
```

---

#### FF_NO_CACHE

**Answer:** The result is Logistic regression predicts behavior 'moderate' for the first holdout row.

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: PREDICTIVE_PIPELINE
- Latency: 5.42s | Cost: $0.00224

**Agent Trace**

```
Thought: typed operator step 1 (PREDICTIVE_PIPELINE)
Action: typed_operator_exec
Action Input: # sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts behavior 'moderate' for the first holdout row."
Observation: Logistic regression predicts behavior 'moderate' for the first holdout row.
Final Answer: Logistic regression predicts behavior 'moderate' for the first holdout row.
```

**Final Code Executed**

```python
# sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts behavior 'moderate' for the first holdout row."
```

---

#### FF_NO_PRUNE

**Answer:** The result is Logistic regression predicts label 'moderate' for the first holdout row.

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: PREDICTIVE_PIPELINE
- Latency: 4.81s | Cost: $0.00262

**Agent Trace**

```
Thought: typed operator step 1 (PREDICTIVE_PIPELINE)
Action: typed_operator_exec
Action Input: # sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts label 'moderate' for the first holdout row."
Observation: Logistic regression predicts label 'moderate' for the first holdout row.
Final Answer: Logistic regression predicts label 'moderate' for the first holdout row.
```

**Final Code Executed**

```python
# sort_by=['timestamp'] split=975/1219 model='logistic_regression' features=['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']
result = "Logistic regression predicts label 'moderate' for the first holdout row."
```

---
