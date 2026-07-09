---
title: "Temporal Train/Val/Test Split — No Random Shuffling"
slug: "temporal-train-val-test-split"
description: "Learn why random shuffling destroys time-series structure, implement correct chronological splits, handle gaps to prevent feature leakage, and apply Lopez de Prado purging and embargo for financial panel data."
tags: ["time-series", "forecasting", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The cardinal rule for time-series modelling is never shuffle the data before splitting. Random shuffling breaks temporal ordering, allowing future observations into the training set (leakage) and breaking autocorrelation structure that the model should learn. The correct approach is a chronological split: train on the earliest segment, validate on the next segment, and test on the held-out final segment — with no overlap and, where needed, a gap between segments to prevent feature contamination."},{"type":"list","ordered":false,"items":["Train → Validation → Test: always in chronological order, never shuffled.","Test set: last 15–20% of observations (or last 2× seasonal period m, whichever is larger).","Validation set: immediately before test set; used only for hyperparameter tuning.","Gap: insert g ≥ max rolling window length observations between each pair of segments.","Panel data: apply the same temporal cutoff to all series — never split different series at different time points."]},{"type":"heading","level":2,"content":"Why Random Shuffle Fails"},{"type":"text","content":"If a time series is autocorrelated at lag 1 with ρ₁ = 0.9 and you randomly shuffle rows, observations in the test fold include values from throughout the series. The training set then contains observations from t+1, t+2, ... for any test point t. Two problems arise: (1) future leakage — the model trains on data it would not have available at prediction time; (2) autocorrelation inflation — training points adjacent in time to a test point are nearly identical to it, producing unrealistically good cross-validation scores. The reported CV RMSE can be 30–50% lower than true out-of-sample RMSE."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.linear_model import Ridge\nfrom sklearn.model_selection import KFold, TimeSeriesSplit\nfrom sklearn.metrics import mean_squared_error\n\nnp.random.seed(42)\nT = 300\ny = np.zeros(T)\nfor t in range(1, T):            # AR(1) with rho=0.9\n    y[t] = 0.9 * y[t-1] + np.random.randn()\n\nlags = 5\nX = np.column_stack([np.roll(y, k) for k in range(1, lags + 1)])[lags:]\ny_a = y[lags:]\n\n# Wrong: random k-fold\nkf_scores = []\nfor tr, te in KFold(n_splits=5, shuffle=True, random_state=0).split(X):\n    m = Ridge().fit(X[tr], y_a[tr])\n    kf_scores.append(np.sqrt(mean_squared_error(y_a[te], m.predict(X[te]))))\n\n# Correct: TimeSeriesSplit\nts_scores = []\nfor tr, te in TimeSeriesSplit(n_splits=5).split(X):\n    m = Ridge().fit(X[tr], y_a[tr])\n    ts_scores.append(np.sqrt(mean_squared_error(y_a[te], m.predict(X[te]))))\n\nprint(f\u0027Random k-fold RMSE : {np.mean(kf_scores):.4f}  (optimistically biased)\u0027)\nprint(f\u0027TimeSeriesSplit RMSE: {np.mean(ts_scores):.4f}  (unbiased)\u0027)"},{"type":"heading","level":2,"content":"Correct Chronological Split"},{"type":"text","content":"The chronological split divides the series in temporal order: train [0, t₁), validation [t₁, t₂), test [t₂, T). Standard proportions: last 15–20% of the series for test, last 10–15% before test for validation, remainder for training. The validation set is used to tune hyperparameters and early-stop; the test set is touched exactly once for final reporting. For seasonal series, ensure each split contains at least one full seasonal cycle — a test set shorter than the seasonal period m cannot assess seasonal accuracy."},{"type":"code","language":"python","content":"import numpy as np\nimport pandas as pd\nfrom sklearn.linear_model import Ridge\nfrom sklearn.metrics import mean_absolute_error\n\nnp.random.seed(0)\nT = 500\nt = np.arange(T)\ny = 50 + 0.1 * t + 10 * np.sin(2 * np.pi * t / 52) + np.random.randn(T) * 3\ndates = pd.date_range(\u00272015-01-01\u0027, periods=T, freq=\u0027W\u0027)\ndf = pd.DataFrame({\u0027date\u0027: dates, \u0027y\u0027: y}).set_index(\u0027date\u0027)\n\n# Chronological split: 70 / 15 / 15\nn_test = int(0.15 * T)\nn_val  = int(0.15 * T)\nn_train = T - n_val - n_test\n\ntrain_df = df.iloc[:n_train]\nval_df   = df.iloc[n_train:n_train + n_val]\ntest_df  = df.iloc[n_train + n_val:]\n\nprint(f\u0027Train: {train_df.index[0].date()} to {train_df.index[-1].date()}  ({len(train_df)} obs)\u0027)\nprint(f\u0027Val:   {val_df.index[0].date()} to {val_df.index[-1].date()}  ({len(val_df)} obs)\u0027)\nprint(f\u0027Test:  {test_df.index[0].date()} to {test_df.index[-1].date()}  ({len(test_df)} obs)\u0027)"},{"type":"heading","level":2,"content":"Gap Between Splits to Prevent Leakage"},{"type":"text","content":"Rolling features computed on observation t include observations t-w+1 through t. If the last training point is t₁ and the first validation point is t₁+1, the validation features for t₁+1 use observations up to t₁ — no leakage. However, if rolling features have a large window w and the model uses these features at prediction time, inserting a gap of g ≥ w-1 observations between train end and val start ensures the validation features are computed entirely from pre-training-cutoff data. This matters most for models trained with global rolling means over long windows."},{"type":"heading","level":2,"content":"Purging and Embargo for Financial Data"},{"type":"text","content":"In financial ML (Lopez de Prado, Advances in Financial Machine Learning), labels often span multiple time steps — e.g., a triple-barrier label for trade t covers [tₑₙₜᵣᵧ, tₑₓᵢₜ]. If tₑₓᵢₜ of a training sample falls after the test observation entry time, information from the test period contaminates training. Purging removes training samples whose label spans overlap with any test period. Embargo adds a buffer of E bars after each test block to eliminate residual autocorrelation leakage, preventing the model from learning patterns that bridge the train/test boundary through overlapping windows."},{"type":"code","language":"python","content":"import numpy as np\nimport pandas as pd\n\ndef purge_and_embargo(train_idx, test_idx, label_end_times, embargo_periods=5):\n    \"\"\"\n    Remove training samples whose label end time overlaps with the test period,\n    then add an embargo buffer after the test block.\n    train_idx, test_idx: array-like integer indices\n    label_end_times: array of label end times (same index space as series)\n    \"\"\"\n    test_start = test_idx.min()\n    test_end   = test_idx.max()\n    embargo_end = test_end + embargo_periods\n\n    # Purge: remove train samples whose label ends during or after test start\n    purged_mask = np.array([\n        label_end_times[i] \u003c test_start for i in train_idx\n    ])\n    purged_train = train_idx[purged_mask]\n\n    # Embargo: remove train samples that fall in the embargo window after test\n    embargo_mask = purged_train \u003c= embargo_end\n    final_train  = purged_train[~embargo_mask | (purged_train \u003c test_start)]\n    return final_train\n\nnp.random.seed(42)\nT = 200\nlabel_end = np.arange(T) + np.random.randint(1, 10, T)  # labels end 1-9 bars later\ntrain_idx = np.arange(0, 150)\ntest_idx  = np.arange(150, 180)\nfinal_train = purge_and_embargo(train_idx, test_idx, label_end, embargo_periods=5)\nprint(f\u0027Original train size : {len(train_idx)}\u0027)\nprint(f\u0027After purge+embargo : {len(final_train)}\u0027)\nprint(f\u0027Removed: {len(train_idx) - len(final_train)} samples\u0027)"},{"type":"callout","variant":"tip","title":"Seasonal Test Set Length","content":"Ensure the test set contains at least one full seasonal cycle (m periods). For weekly data with annual seasonality (m=52), a test set shorter than 52 weeks cannot measure seasonal accuracy. A common rule: test = max(20% of total, 2·m) and validate = max(15% of total, m), with the remainder for training."},{"type":"heading","level":2,"content":"Multi-Series Dataset Splitting"},{"type":"code","language":"python","content":"import numpy as np\nimport pandas as pd\nfrom sklearn.linear_model import Ridge\nfrom sklearn.metrics import mean_absolute_error\n\nnp.random.seed(1)\nn_series = 20\nT = 200\nall_series = []\nfor i in range(n_series):\n    t = np.arange(T)\n    y = np.random.uniform(20, 80) + 0.1 * t + 8 * np.sin(2 * np.pi * t / 12 + np.random.rand())\n    y += np.random.randn(T) * 3\n    df = pd.DataFrame({\u0027series_id\u0027: i, \u0027time\u0027: t, \u0027y\u0027: y})\n    all_series.append(df)\n\npanel = pd.concat(all_series, ignore_index=True)\n\n# Global temporal split: last 20% of time steps → test\nsplit_t = int(0.8 * T)\ntrain_panel = panel[panel[\u0027time\u0027] \u003c  split_t]\ntest_panel  = panel[panel[\u0027time\u0027] \u003e= split_t]\n\n# Lag features per series\ndef make_lags(df, lags=3):\n    df = df.sort_values(\u0027time\u0027).copy()\n    for k in range(1, lags + 1):\n        df[f\u0027lag_{k}\u0027] = df[\u0027y\u0027].shift(k)\n    return df.dropna()\n\ntrain_feat = train_panel.groupby(\u0027series_id\u0027, group_keys=False).apply(make_lags)\ntest_feat  = test_panel.groupby(\u0027series_id\u0027, group_keys=False).apply(make_lags)\n\nfeat_cols = [c for c in train_feat.columns if c.startswith(\u0027lag\u0027)]\nmodel = Ridge().fit(train_feat[feat_cols], train_feat[\u0027y\u0027])\npred  = model.predict(test_feat[feat_cols])\nprint(f\u0027Panel test MAE: {mean_absolute_error(test_feat[\"y\"], pred):.3f}\u0027)"},{"type":"heading","level":2,"content":"Split Strategy Reference"},{"type":"table","headers":["Strategy","Train Size","Test Window","Leakage","Compute","Notes"],"rows":[["Single holdout (chronological)","Fixed early portion","Fixed final portion","None","Very low","High variance estimate; use for very large n"],["Expanding walk-forward","Grows each fold","Fixed horizon H","None","Medium","Preferred for stationary series"],["Rolling walk-forward","Fixed window W","Fixed horizon H","None","Medium","Preferred for non-stationary / regime change"],["Anchored walk-forward","Fixed start, grows","Fixed horizon H","None","Medium","Same as expanding window"],["Purge + embargo (financial)","Varies by label span","Fixed horizon H","None","Medium-high","Required for overlapping financial labels"]]},{"type":"list","ordered":false,"items":["Never use random shuffling or stratification by target for time-series splits.","For panel data (multiple series), apply the same temporal cutoff to all series to avoid cold-start bias.","The validation set serves only for hyperparameter tuning — report final accuracy on the test set only.","Use purging and embargo whenever label construction spans multiple time steps (financial events, cumulative returns).","When the series is very short (T \u003c 100), single holdout may be more reliable than walk-forward due to high fold-to-fold variance."]},{"type":"text","content":"A common mistake in time-series projects is to normalise or standardise the entire dataset before splitting. Computing the mean and standard deviation over all T observations (including the test set) leaks summary statistics from the future into the training pipeline. The correct approach: fit the scaler only on the training set, then apply the same transform to the validation and test sets — exactly as you would with a tabular dataset."},{"type":"text","content":"For very long series (T ≥ 10,000) where a fixed holdout test set is used, the test set representativeness risk increases: if the series has structural breaks (policy change, COVID-19 demand shift), the test period may be fundamentally different from the training period. Stratified temporal holdout — ensuring each season and regime appears proportionally in train/test — is one mitigation, but the safest approach for non-stationary series is walk-forward evaluation with a rolling window that tracks recent behaviour."},{"type":"divider"}]"
---
# Temporal Train/Val/Test Split — No Random Shuffling

The cardinal rule for time-series modelling is never shuffle the data before splitting. Random shuffling breaks temporal ordering, allowing future observations into the training set (leakage) and breaking autocorrelation structure that the model should learn. The correct approach is a chronological split: train on the earliest segment, validate on the next segment, and test on the held-out final segment — with no overlap and, where needed, a gap between segments to prevent feature contamination.

- Train → Validation → Test: always in chronological order, never shuffled.
- Test set: last 15–20% of observations (or last 2× seasonal period m, whichever is larger).
- Validation set: immediately before test set; used only for hyperparameter tuning.
- Gap: insert g ≥ max rolling window length observations between each pair of segments.
- Panel data: apply the same temporal cutoff to all series — never split different series at different time points.

## Why Random Shuffle Fails

If a time series is autocorrelated at lag 1 with ρ₁ = 0.9 and you randomly shuffle rows, observations in the test fold include values from throughout the series. The training set then contains observations from t+1, t+2, ... for any test point t. Two problems arise: (1) future leakage — the model trains on data it would not have available at prediction time; (2) autocorrelation inflation — training points adjacent in time to a test point are nearly identical to it, producing unrealistically good cross-validation scores. The reported CV RMSE can be 30–50% lower than true out-of-sample RMSE.

```python
import numpy as np
from sklearn.linear_model import Ridge
from sklearn.model_selection import KFold, TimeSeriesSplit
from sklearn.metrics import mean_squared_error

np.random.seed(42)
T = 300
y = np.zeros(T)
for t in range(1, T):            # AR(1) with rho=0.9
    y[t] = 0.9 * y[t-1] + np.random.randn()

lags = 5
X = np.column_stack([np.roll(y, k) for k in range(1, lags + 1)])[lags:]
y_a = y[lags:]

# Wrong: random k-fold
kf_scores = []
for tr, te in KFold(n_splits=5, shuffle=True, random_state=0).split(X):
    m = Ridge().fit(X[tr], y_a[tr])
    kf_scores.append(np.sqrt(mean_squared_error(y_a[te], m.predict(X[te]))))

# Correct: TimeSeriesSplit
ts_scores = []
for tr, te in TimeSeriesSplit(n_splits=5).split(X):
    m = Ridge().fit(X[tr], y_a[tr])
    ts_scores.append(np.sqrt(mean_squared_error(y_a[te], m.predict(X[te]))))

print(f'Random k-fold RMSE : {np.mean(kf_scores):.4f}  (optimistically biased)')
print(f'TimeSeriesSplit RMSE: {np.mean(ts_scores):.4f}  (unbiased)')
```

## Correct Chronological Split

The chronological split divides the series in temporal order: train [0, t₁), validation [t₁, t₂), test [t₂, T). Standard proportions: last 15–20% of the series for test, last 10–15% before test for validation, remainder for training. The validation set is used to tune hyperparameters and early-stop; the test set is touched exactly once for final reporting. For seasonal series, ensure each split contains at least one full seasonal cycle — a test set shorter than the seasonal period m cannot assess seasonal accuracy.

```python
import numpy as np
import pandas as pd
from sklearn.linear_model import Ridge
from sklearn.metrics import mean_absolute_error

np.random.seed(0)
T = 500
t = np.arange(T)
y = 50 + 0.1 * t + 10 * np.sin(2 * np.pi * t / 52) + np.random.randn(T) * 3
dates = pd.date_range('2015-01-01', periods=T, freq='W')
df = pd.DataFrame({'date': dates, 'y': y}).set_index('date')

# Chronological split: 70 / 15 / 15
n_test = int(0.15 * T)
n_val  = int(0.15 * T)
n_train = T - n_val - n_test

train_df = df.iloc[:n_train]
val_df   = df.iloc[n_train:n_train + n_val]
test_df  = df.iloc[n_train + n_val:]

print(f'Train: {train_df.index[0].date()} to {train_df.index[-1].date()}  ({len(train_df)} obs)')
print(f'Val:   {val_df.index[0].date()} to {val_df.index[-1].date()}  ({len(val_df)} obs)')
print(f'Test:  {test_df.index[0].date()} to {test_df.index[-1].date()}  ({len(test_df)} obs)')
```

## Gap Between Splits to Prevent Leakage

Rolling features computed on observation t include observations t-w+1 through t. If the last training point is t₁ and the first validation point is t₁+1, the validation features for t₁+1 use observations up to t₁ — no leakage. However, if rolling features have a large window w and the model uses these features at prediction time, inserting a gap of g ≥ w-1 observations between train end and val start ensures the validation features are computed entirely from pre-training-cutoff data. This matters most for models trained with global rolling means over long windows.

## Purging and Embargo for Financial Data

In financial ML (Lopez de Prado, Advances in Financial Machine Learning), labels often span multiple time steps — e.g., a triple-barrier label for trade t covers [tₑₙₜᵣᵧ, tₑₓᵢₜ]. If tₑₓᵢₜ of a training sample falls after the test observation entry time, information from the test period contaminates training. Purging removes training samples whose label spans overlap with any test period. Embargo adds a buffer of E bars after each test block to eliminate residual autocorrelation leakage, preventing the model from learning patterns that bridge the train/test boundary through overlapping windows.

```python
import numpy as np
import pandas as pd

def purge_and_embargo(train_idx, test_idx, label_end_times, embargo_periods=5):
    """
    Remove training samples whose label end time overlaps with the test period,
    then add an embargo buffer after the test block.
    train_idx, test_idx: array-like integer indices
    label_end_times: array of label end times (same index space as series)
    """
    test_start = test_idx.min()
    test_end   = test_idx.max()
    embargo_end = test_end + embargo_periods

    # Purge: remove train samples whose label ends during or after test start
    purged_mask = np.array([
        label_end_times[i] < test_start for i in train_idx
    ])
    purged_train = train_idx[purged_mask]

    # Embargo: remove train samples that fall in the embargo window after test
    embargo_mask = purged_train <= embargo_end
    final_train  = purged_train[~embargo_mask | (purged_train < test_start)]
    return final_train

np.random.seed(42)
T = 200
label_end = np.arange(T) + np.random.randint(1, 10, T)  # labels end 1-9 bars later
train_idx = np.arange(0, 150)
test_idx  = np.arange(150, 180)
final_train = purge_and_embargo(train_idx, test_idx, label_end, embargo_periods=5)
print(f'Original train size : {len(train_idx)}')
print(f'After purge+embargo : {len(final_train)}')
print(f'Removed: {len(train_idx) - len(final_train)} samples')
```

> **Seasonal Test Set Length**: Ensure the test set contains at least one full seasonal cycle (m periods). For weekly data with annual seasonality (m=52), a test set shorter than 52 weeks cannot measure seasonal accuracy. A common rule: test = max(20% of total, 2·m) and validate = max(15% of total, m), with the remainder for training.

## Multi-Series Dataset Splitting

```python
import numpy as np
import pandas as pd
from sklearn.linear_model import Ridge
from sklearn.metrics import mean_absolute_error

np.random.seed(1)
n_series = 20
T = 200
all_series = []
for i in range(n_series):
    t = np.arange(T)
    y = np.random.uniform(20, 80) + 0.1 * t + 8 * np.sin(2 * np.pi * t / 12 + np.random.rand())
    y += np.random.randn(T) * 3
    df = pd.DataFrame({'series_id': i, 'time': t, 'y': y})
    all_series.append(df)

panel = pd.concat(all_series, ignore_index=True)

# Global temporal split: last 20% of time steps → test
split_t = int(0.8 * T)
train_panel = panel[panel['time'] <  split_t]
test_panel  = panel[panel['time'] >= split_t]

# Lag features per series
def make_lags(df, lags=3):
    df = df.sort_values('time').copy()
    for k in range(1, lags + 1):
        df[f'lag_{k}'] = df['y'].shift(k)
    return df.dropna()

train_feat = train_panel.groupby('series_id', group_keys=False).apply(make_lags)
test_feat  = test_panel.groupby('series_id', group_keys=False).apply(make_lags)

feat_cols = [c for c in train_feat.columns if c.startswith('lag')]
model = Ridge().fit(train_feat[feat_cols], train_feat['y'])
pred  = model.predict(test_feat[feat_cols])
print(f'Panel test MAE: {mean_absolute_error(test_feat["y"], pred):.3f}')
```

## Split Strategy Reference

| Strategy | Train Size | Test Window | Leakage | Compute | Notes |
| --- | --- | --- | --- | --- | --- |
| Single holdout (chronological) | Fixed early portion | Fixed final portion | None | Very low | High variance estimate; use for very large n |
| Expanding walk-forward | Grows each fold | Fixed horizon H | None | Medium | Preferred for stationary series |
| Rolling walk-forward | Fixed window W | Fixed horizon H | None | Medium | Preferred for non-stationary / regime change |
| Anchored walk-forward | Fixed start, grows | Fixed horizon H | None | Medium | Same as expanding window |
| Purge + embargo (financial) | Varies by label span | Fixed horizon H | None | Medium-high | Required for overlapping financial labels |

- Never use random shuffling or stratification by target for time-series splits.
- For panel data (multiple series), apply the same temporal cutoff to all series to avoid cold-start bias.
- The validation set serves only for hyperparameter tuning — report final accuracy on the test set only.
- Use purging and embargo whenever label construction spans multiple time steps (financial events, cumulative returns).
- When the series is very short (T < 100), single holdout may be more reliable than walk-forward due to high fold-to-fold variance.

A common mistake in time-series projects is to normalise or standardise the entire dataset before splitting. Computing the mean and standard deviation over all T observations (including the test set) leaks summary statistics from the future into the training pipeline. The correct approach: fit the scaler only on the training set, then apply the same transform to the validation and test sets — exactly as you would with a tabular dataset.

For very long series (T ≥ 10,000) where a fixed holdout test set is used, the test set representativeness risk increases: if the series has structural breaks (policy change, COVID-19 demand shift), the test period may be fundamentally different from the training period. Stratified temporal holdout — ensuring each season and regime appears proportionally in train/test — is one mitigation, but the safest approach for non-stationary series is walk-forward evaluation with a rolling window that tracks recent behaviour.

---

