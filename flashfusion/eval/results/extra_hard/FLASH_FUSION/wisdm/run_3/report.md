# Flash-Fusion Benchmark Report

Generated: 2026-09-15T22:56:15+00:00

## Summary Table

| Baseline     |   Avg LLM Accuracy |   Avg Latency (s) |   Avg Cost (USD) |
|:-------------|-------------------:|------------------:|-----------------:|
| FLASH_FUSION |             0.5000 |            6.3474 |           0.0021 |

## Typed-Operator Coverage

| Baseline     |   Queries |   Typed | Coverage   |   ReAct fallback |   Guardrail reject |   Typed avg latency (s) | Fallback avg latency (s)   |
|:-------------|----------:|--------:|:-----------|-----------------:|-------------------:|------------------------:|:---------------------------|
| FLASH_FUSION |         4 |       3 | 75%        |                0 |                  0 |                     6.8 | -                          |

Fallback causes: structural=1

## Per-Query Results

### Q17: For every subject_id, compute mean acceleration magnitude separately for dynamic activities (Walking, Jogging, Upstairs, Downstairs) and resting activities (Sitting, Standing). Return the subject_id with the largest dynamic-minus-resting mean magnitude.

#### FLASH_FUSION

**Answer:** The result is {'subject_id': 24, 'dynamic_mean_magnitude': 13.872703393647935, 'resting_mean_magnitude': 9.133463315662746, 'magnitude_difference': 4.739240077985189}

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: FILTER_NOT_EMPTY,DERIVE_VECTOR_MAGNITUDE,PARALLEL_AGGREGATE,DERIVE_BINARY,RANK_ROWS
- Latency: 6.29s | Cost: $0.00223

**Agent Trace**

```
Thought: typed operator step 1 (FILTER_NOT_EMPTY)
Action: typed_operator_exec
Action Input: df = df[df['activity_label'].notna() & df['activity_label'].astype(str).str.strip().ne('')]
Observation: rows=1098198
Thought: typed operator step 2 (DERIVE_VECTOR_MAGNITUDE)
Action: typed_operator_exec
Action Input: df['acceleration_magnitude'] = (df['x']**2 + df['y']**2 + df['z']**2)**0.5
Observation: derived 'acceleration_magnitude' (rows=1098198)
Thought: typed operator step 3 (PARALLEL_AGGREGATE)
Action: typed_operator_exec
Action Input: # PARALLEL_AGGREGATE branches:
branch_0 = df[df['activity_label'].isin(['Downstairs', 'Jogging', 'Upstairs', 'Walking'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
branch_1 = df[df['activity_label'].isin(['Sitting', 'Standing'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
merged = branch_0.merge(branch_1, on=['subject_id'], how='outer')
Observation: {'groups': 36, 'columns': ['subject_id', 'dynamic_mean_magnitude', 'resting_mean_magnitude']}
Thought: typed operator step 4 (DERIVE_BINARY)
Action: typed_operator_exec
Action Input: df['magnitude_difference'] = df['dynamic_mean_magnitude'] - df['resting_mean_magnitude']
Observation: derived 'magnitude_difference' (rows=36)
Thought: typed operator step 5 (RANK_ROWS)
Action: typed_operator_exec
Action Input: idx = df['magnitude_difference'].idxmax(); result = df.loc[idx, ['subject_id', 'dynamic_mean_magnitude', 'resting_mean_magnitude', 'magnitude_difference']].to_dict()
Observation: {'subject_id': 24, 'dynamic_mean_magnitude': 13.872703393647935, 'resting_mean_magnitude': 9.133463315662746, 'magnitude_difference': 4.739240077985189}
Final Answer: {'subject_id': 24, 'dynamic_mean_magnitude': 13.872703393647935, 'resting_mean_magnitude': 9.133463315662746, 'magnitude_difference': 4.739240077985189}
```

**Final Code Executed**

```python
df = df[df['activity_label'].notna() & df['activity_label'].astype(str).str.strip().ne('')]
df['acceleration_magnitude'] = (df['x']**2 + df['y']**2 + df['z']**2)**0.5
# PARALLEL_AGGREGATE branches:
branch_0 = df[df['activity_label'].isin(['Downstairs', 'Jogging', 'Upstairs', 'Walking'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
branch_1 = df[df['activity_label'].isin(['Sitting', 'Standing'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
merged = branch_0.merge(branch_1, on=['subject_id'], how='outer')
df['magnitude_difference'] = df['dynamic_mean_magnitude'] - df['resting_mean_magnitude']
idx = df['magnitude_difference'].idxmax(); result = df.loc[idx, ['subject_id', 'dynamic_mean_magnitude', 'resting_mean_magnitude', 'magnitude_difference']].to_dict()
```

---

### Q18: For every subject_id, compute x-acceleration variance separately while Jogging and while Walking. Return the subject_id for whom Jogging pulls furthest ahead of Walking.

#### FLASH_FUSION

**Answer:** 

- Executed: False | Rejected: False | Judge: N/A
- Stages: guardrail_plan,typed_plan_unavailable
- Path: typed_plan_unavailable
- Fallback (structural): structural: 1 validation error for GuardrailAndPlan
plan.steps.2.DERIVE_BINARY.operation
  Input should be 'add', 'subtract', 'multiply', 'divide' or 'abs_difference' [type=literal_error, input_value='difference', input_type=str]
    For further information visit https://errors.pydantic.dev/2.13/v/literal_error
- Latency: 4.98s | Cost: $0.00175

**Alignment Explanation**

Flash-Fusion could not produce a valid typed plan and ReAct fallback is disabled. Reason: structural: 1 validation error for GuardrailAndPlan
plan.steps.2.DERIVE_BINARY.operation
  Input should be 'add', 'subtract', 'multiply', 'divide' or 'abs_difference' [type=literal_error, input_value='difference', input_type=str]
    For further information visit https://errors.pydantic.dev/2.13/v/literal_error

---

### Q19: For every subject_id, compute mean acceleration magnitude while Jogging and while Walking. Report whether subjects who jog harder also walk harder, ranking subjects consistently across both activities.

#### FLASH_FUSION

**Answer:** The result is {'subject_id': 23, 'mean_jogging_mag': 17.04236300315029, 'mean_walking_mag': 12.89231971710706}

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: FILTER_NOT_EMPTY,DERIVE_VECTOR_MAGNITUDE,PARALLEL_AGGREGATE,RANK_ROWS
- Latency: 6.26s | Cost: $0.00199

**Agent Trace**

```
Thought: typed operator step 1 (FILTER_NOT_EMPTY)
Action: typed_operator_exec
Action Input: df = df[df['activity_label'].notna() & df['activity_label'].astype(str).str.strip().ne('')]
Observation: rows=1098198
Thought: typed operator step 2 (DERIVE_VECTOR_MAGNITUDE)
Action: typed_operator_exec
Action Input: df['acceleration_magnitude'] = (df['x']**2 + df['y']**2 + df['z']**2)**0.5
Observation: derived 'acceleration_magnitude' (rows=1098198)
Thought: typed operator step 3 (PARALLEL_AGGREGATE)
Action: typed_operator_exec
Action Input: # PARALLEL_AGGREGATE branches:
branch_0 = df[df['activity_label'].isin(['Jogging'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
branch_1 = df[df['activity_label'].isin(['Walking'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
merged = branch_0.merge(branch_1, on=['subject_id'], how='outer')
Observation: {'groups': 36, 'columns': ['subject_id', 'mean_jogging_mag', 'mean_walking_mag']}
Thought: typed operator step 4 (RANK_ROWS)
Action: typed_operator_exec
Action Input: idx = df['mean_jogging_mag'].idxmax(); result = df.loc[idx, ['subject_id', 'mean_jogging_mag', 'mean_walking_mag']].to_dict()
Observation: {'subject_id': 23, 'mean_jogging_mag': 17.04236300315029, 'mean_walking_mag': 12.89231971710706}
Final Answer: {'subject_id': 23, 'mean_jogging_mag': 17.04236300315029, 'mean_walking_mag': 12.89231971710706}
```

**Final Code Executed**

```python
df = df[df['activity_label'].notna() & df['activity_label'].astype(str).str.strip().ne('')]
df['acceleration_magnitude'] = (df['x']**2 + df['y']**2 + df['z']**2)**0.5
# PARALLEL_AGGREGATE branches:
branch_0 = df[df['activity_label'].isin(['Jogging'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
branch_1 = df[df['activity_label'].isin(['Walking'])].groupby(['subject_id'])['acceleration_magnitude'].mean()
merged = branch_0.merge(branch_1, on=['subject_id'], how='outer')
idx = df['mean_jogging_mag'].idxmax(); result = df.loc[idx, ['subject_id', 'mean_jogging_mag', 'mean_walking_mag']].to_dict()
```

---

### Q20: For every subject_id, derive elapsed seconds from timestamp, then compute total locomotion duration (Walking, Jogging, Upstairs, Downstairs) and total resting duration (Sitting, Standing). Among subjects with more locomotion than resting time, return the subject_id with the largest locomotion-minus-resting duration.

#### FLASH_FUSION

**Answer:** The result is {'subject_id': 19, 'locomotion_duration': 131357.35168599998, 'resting_duration': 266.179779, 'duration_delta': 131091.17190699998}

- Executed: True | Rejected: False | Judge: N/A
- Stages: guardrail_plan,plan_validated,typed_exec
- Path: typed_operator
- Operators: FILTER_NOT_EMPTY,DERIVE_DURATION_SECONDS,PARALLEL_AGGREGATE,DERIVE_BINARY,FILTER_COMPARE,RANK_ROWS
- Latency: 7.86s | Cost: $0.00256

**Agent Trace**

```
Thought: typed operator step 1 (FILTER_NOT_EMPTY)
Action: typed_operator_exec
Action Input: df = df[df['activity_label'].notna() & df['activity_label'].astype(str).str.strip().ne('')]
Observation: rows=1098198
Thought: typed operator step 2 (DERIVE_DURATION_SECONDS)
Action: typed_operator_exec
Action Input: df = df.sort_values(['subject_id', 'timestamp']); df['dt_s'] = df.groupby(['subject_id'])['timestamp'].diff().dt.total_seconds().clip(lower=0).fillna(0.0)
Observation: derived 'dt_s' (rows=1098198, total=841190.608454s)
Thought: typed operator step 3 (PARALLEL_AGGREGATE)
Action: typed_operator_exec
Action Input: # PARALLEL_AGGREGATE branches:
branch_0 = df[df['activity_label'].isin(['Downstairs', 'Jogging', 'Upstairs', 'Walking'])].groupby(['subject_id'])['dt_s'].sum()
branch_1 = df[df['activity_label'].isin(['Sitting', 'Standing'])].groupby(['subject_id'])['dt_s'].sum()
merged = branch_0.merge(branch_1, on=['subject_id'], how='outer')
merged[['locomotion_duration', 'resting_duration']] = merged[['locomotion_duration', 'resting_duration']].fillna(0)
Observation: {'groups': 36, 'columns': ['subject_id', 'locomotion_duration', 'resting_duration']}
Thought: typed operator step 4 (DERIVE_BINARY)
Action: typed_operator_exec
Action Input: df['duration_delta'] = df['locomotion_duration'] - df['resting_duration']
Observation: derived 'duration_delta' (rows=36)
Thought: typed operator step 5 (FILTER_COMPARE)
Action: typed_operator_exec
Action Input: df = df[df['duration_delta'] > 0]
Observation: rows=33
Thought: typed operator step 6 (RANK_ROWS)
Action: typed_operator_exec
Action Input: idx = df['duration_delta'].idxmax(); result = df.loc[idx, ['subject_id', 'locomotion_duration', 'resting_duration', 'duration_delta']].to_dict()
Observation: {'subject_id': 19, 'locomotion_duration': 131357.35168599998, 'resting_duration': 266.179779, 'duration_delta': 131091.17190699998}
Final Answer: {'subject_id': 19, 'locomotion_duration': 131357.35168599998, 'resting_duration': 266.179779, 'duration_delta': 131091.17190699998}
```

**Final Code Executed**

```python
df = df[df['activity_label'].notna() & df['activity_label'].astype(str).str.strip().ne('')]
df = df.sort_values(['subject_id', 'timestamp']); df['dt_s'] = df.groupby(['subject_id'])['timestamp'].diff().dt.total_seconds().clip(lower=0).fillna(0.0)
# PARALLEL_AGGREGATE branches:
branch_0 = df[df['activity_label'].isin(['Downstairs', 'Jogging', 'Upstairs', 'Walking'])].groupby(['subject_id'])['dt_s'].sum()
branch_1 = df[df['activity_label'].isin(['Sitting', 'Standing'])].groupby(['subject_id'])['dt_s'].sum()
merged = branch_0.merge(branch_1, on=['subject_id'], how='outer')
merged[['locomotion_duration', 'resting_duration']] = merged[['locomotion_duration', 'resting_duration']].fillna(0)
df['duration_delta'] = df['locomotion_duration'] - df['resting_duration']
df = df[df['duration_delta'] > 0]
idx = df['duration_delta'].idxmax(); result = df.loc[idx, ['subject_id', 'locomotion_duration', 'resting_duration', 'duration_delta']].to_dict()
```

---
