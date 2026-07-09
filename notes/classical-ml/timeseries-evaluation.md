---
title: "Time-Series Evaluation — MAE, MAPE, SMAPE, CRPS, and Calibration"
slug: "timeseries-evaluation"
description: "Master forecasting evaluation: MAE, RMSE, MAPE, sMAPE, MASE for point forecasts; CRPS and WQL for probabilistic forecasts; calibration checks for prediction intervals; and a backtesting framework for comparing models across multiple metrics."
tags: ["time-series", "forecasting", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Choosing the right evaluation metric is as important as choosing the right model. A metric that is scale-dependent cannot compare models across different series. A metric undefined at zero values (MAPE) misleads on intermittent demand data. A point metric ignores forecast uncertainty entirely. This note covers the full hierarchy of time-series evaluation metrics, explains when each is appropriate, and builds a principled backtesting framework that computes all metrics simultaneously."},{"type":"heading","level":2,"content":"Scale-Dependent Metrics — MAE and RMSE"},{"type":"text","content":"MAE = (1/H)Σ|y_t - ŷ_t| is robust, interpretable, and in the same units as the series. It is the minimum expected loss under an asymmetric L1 loss and the appropriate metric when large errors are not disproportionately more costly. MSE = (1/H)Σ(y_t - ŷ_t)² penalises large errors quadratically and is differentiable. RMSE = √MSE restores units. These are scale-dependent: a RMSE of 100 units is meaningless without knowing the series scale, making cross-series comparison impossible."},{"type":"code","language":"python","content":"import numpy as np\n\ndef mae(y_true, y_pred):\n    return np.mean(np.abs(y_true - y_pred))\n\ndef rmse(y_true, y_pred):\n    return np.sqrt(np.mean((y_true - y_pred)**2))\n\ndef mape(y_true, y_pred, eps=1e-8):\n    \"\"\"MAPE: undefined/unstable when y_true ~ 0; use eps guard.\"\"\"\n    return 100 * np.mean(np.abs((y_true - y_pred) / (np.abs(y_true) + eps)))\n\ndef smape(y_true, y_pred, eps=1e-8):\n    \"\"\"Symmetric MAPE: bounded in [0, 200] but still problematic near zero.\"\"\"\n    num = np.abs(y_true - y_pred)\n    den = (np.abs(y_true) + np.abs(y_pred)) / 2 + eps\n    return 100 * np.mean(num / den)\n\ndef mase(y_true, y_pred, y_train, seasonality=1):\n    \"\"\"MASE: MAE scaled by in-sample seasonal naive MAE.\"\"\"\n    naive_errors = np.abs(y_train[seasonality:] - y_train[:-seasonality])\n    scale = naive_errors.mean()\n    return mae(y_true, y_pred) / (scale + 1e-8)\n\nnp.random.seed(42)\ny_true  = np.array([100, 110, 95, 120, 130, 115, 105, 125, 118, 108], dtype=float)\ny_pred  = np.array([102, 108, 97, 118, 132, 113, 107, 123, 120, 110], dtype=float)\ny_train = np.random.randn(100) * 10 + 100\n\nprint(f\u0027MAE:   {mae(y_true, y_pred):.4f}\u0027)\nprint(f\u0027RMSE:  {rmse(y_true, y_pred):.4f}\u0027)\nprint(f\u0027MAPE:  {mape(y_true, y_pred):.4f}%\u0027)\nprint(f\u0027sMAPE: {smape(y_true, y_pred):.4f}%\u0027)\nprint(f\u0027MASE:  {mase(y_true, y_pred, y_train, seasonality=1):.4f}\u0027)"},{"type":"heading","level":2,"content":"Scale-Free Metrics — MAPE, sMAPE, and MASE"},{"type":"text","content":"MAPE is undefined when y_t = 0 and asymmetric: a prediction of 120 for actual 100 gives MAPE=20%, but a prediction of 80 for actual 100 gives MAPE=20% too (but they are not equivalent errors). sMAPE uses (|y| + |ŷ|)/2 in the denominator, making it symmetric, but it still has pathological behaviour when both y and ŷ approach 0. MASE (Hyndman \u0026 Koehler, 2006) scales by the in-sample seasonal naive MAE: MASE = MAE / MAE_naive. MASE = 1.0 means the model performs at naive-seasonal level; MASE \u003c 1 is better than naive. MASE is well-defined, scale-free, and suitable for cross-series comparison."},{"type":"heading","level":2,"content":"CRPS for Probabilistic Forecasts"},{"type":"text","content":"CRPS (Continuous Ranked Probability Score) is a proper scoring rule for distributional forecasts. For ensemble samples {x_1,...,x_M}: CRPS = (1/M)Σ|x_m - y| - (1/2M²)Σ|x_m - x_{m\u0027}|. Lower is better. CRPS reduces to MAE for a point forecast (delta distribution). WQL (Weighted Quantile Loss) is the M5 competition probabilistic metric: WQL = (2/HΣ|y_t|) Σ_τ Σ_t L_τ(y_t, q_{t,τ}) where L_τ is the pinball loss. Both CRPS and WQL are proper: the true distribution minimises expected score."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.stats import norm\n\ndef crps_gaussian(mu, sigma, y):\n    \"\"\"Analytical CRPS for Gaussian predictive distribution.\"\"\"\n    z   = (y - mu) / sigma\n    phi = norm.pdf(z)\n    Phi = norm.cdf(z)\n    return sigma * (z * (2*Phi - 1) + 2*phi - 1/np.sqrt(np.pi))\n\ndef crps_ensemble(samples, y):\n    \"\"\"CRPS from M ensemble samples.\"\"\"\n    M = samples.shape[0]\n    term1 = np.mean(np.abs(samples - y))\n    term2 = np.mean(np.abs(samples[:, None] - samples[None, :]))\n    return term1 - 0.5 * term2\n\ndef wql(y_true, quantile_forecasts, quantile_levels):\n    \"\"\"Weighted Quantile Loss (M5 metric).\"\"\"\n    total, scale = 0.0, np.abs(y_true).mean() * 2 + 1e-8\n    for q, qf in zip(quantile_levels, quantile_forecasts.T):\n        err = y_true - qf\n        loss = np.where(err \u003e= 0, q * err, (q - 1) * err)\n        total += loss.mean()\n    return total / (scale * len(quantile_levels))\n\nnp.random.seed(0)\ny = np.random.randn(200) * 2 + 5\nmu, sigma = 5.0, 2.0\ncrps_vals = crps_gaussian(mu * np.ones(200), sigma * np.ones(200), y)\nprint(f\u0027Mean CRPS (Gaussian, correct sigma=2): {crps_vals.mean():.4f}\u0027)\ncrps_wide = crps_gaussian(mu * np.ones(200), 4.0 * np.ones(200), y)\nprint(f\u0027Mean CRPS (too wide sigma=4):          {crps_wide.mean():.4f}\u0027)"},{"type":"heading","level":2,"content":"Calibration — Coverage of Prediction Intervals"},{"type":"text","content":"A calibrated probabilistic forecast satisfies: empirical coverage at nominal level α ≈ α. That is, 80% prediction intervals should contain the true value 80% of the time. Calibration is assessed by computing coverage at multiple levels (50%, 80%, 90%) and plotting nominal vs empirical coverage — a calibration curve. A perfectly calibrated model lies on the diagonal. Under-coverage (empirical \u003c nominal) means intervals are too narrow; over-coverage (empirical \u003e nominal) means intervals are too wide."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.stats import norm\n\ndef check_calibration(y_true, mu_pred, sigma_pred, levels=None):\n    \"\"\"\n    Check calibration of Gaussian prediction intervals.\n    Returns dict of {nominal_level: empirical_coverage}.\n    \"\"\"\n    if levels is None:\n        levels = [0.50, 0.80, 0.90, 0.95]\n    results = {}\n    for level in levels:\n        alpha = 1 - level\n        z = norm.ppf(1 - alpha / 2)\n        lower = mu_pred - z * sigma_pred\n        upper = mu_pred + z * sigma_pred\n        coverage = np.mean((y_true \u003e= lower) \u0026 (y_true \u003c= upper))\n        results[level] = coverage\n    return results\n\nnp.random.seed(42)\nn = 500\ny_true     = np.random.randn(n) * 2 + 3\nmu_pred    = 3.0 * np.ones(n)\nsigma_good = 2.0 * np.ones(n)   # correctly calibrated\nsigma_bad  = 0.8 * np.ones(n)   # under-dispersed (too narrow)\n\ncal_good = check_calibration(y_true, mu_pred, sigma_good)\ncal_bad  = check_calibration(y_true, mu_pred, sigma_bad)\n\nprint(\u0027Nominal  |  Good model  |  Narrow model\u0027)\nprint(\u0027-\u0027 * 45)\nfor lvl in [0.50, 0.80, 0.90, 0.95]:\n    print(f\u0027{lvl:.0%}      |  {cal_good[lvl]:.3f}       |  {cal_bad[lvl]:.3f}\u0027)\nprint(\u0027Good model empirical coverage ≈ nominal; narrow model under-covers.\u0027)"},{"type":"heading","level":2,"content":"Backtesting Framework"},{"type":"text","content":"A robust backtesting framework uses rolling or expanding window cross-validation to evaluate forecasting models on multiple held-out test windows. This avoids lucky or unlucky single test splits and provides confidence intervals on metric estimates. The framework should: (1) generate multiple (train, test) splits, (2) fit each model on each train split, (3) compute all relevant metrics on each test window, (4) aggregate with mean and std across splits."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.linear_model import Ridge\n\ndef lag_features(y, n_lags=12):\n    X = np.stack([y[i:len(y)-n_lags+i] for i in range(n_lags)], axis=1)\n    return X[:-1], y[n_lags:]\n\ndef rolling_cv(y, horizon=12, n_splits=5, min_train=100):\n    \"\"\"Rolling window cross-validation for time series.\"\"\"\n    n = len(y)\n    results = []\n    step = (n - min_train - horizon) // n_splits\n    for i in range(n_splits):\n        split = min_train + i * step\n        y_train = y[:split]\n        y_test  = y[split:split + horizon]\n        X_all, y_feat = lag_features(y[:split + horizon])\n        X_tr, y_tr = X_all[:split - 12], y_feat[:split - 12]\n        X_te, y_te = X_all[split - 12:split - 12 + horizon], y_feat[split - 12:split - 12 + horizon]\n        model = Ridge(alpha=1.0).fit(X_tr, y_tr)\n        y_hat = model.predict(X_te)\n        mae_val  = np.abs(y_te - y_hat).mean()\n        rmse_val = np.sqrt(((y_te - y_hat)**2).mean())\n        mape_val = (np.abs((y_te - y_hat) / (np.abs(y_te) + 1e-8)) * 100).mean()\n        results.append({\u0027split\u0027: i, \u0027mae\u0027: mae_val, \u0027rmse\u0027: rmse_val, \u0027mape\u0027: mape_val})\n    return results\n\nnp.random.seed(42)\ny = np.cumsum(np.random.randn(300)) + 50\nresults = rolling_cv(y, horizon=12, n_splits=5)\nfor r in results:\n    print(f\u0027Split {r[\"split\"]}: MAE={r[\"mae\"]:.3f}, RMSE={r[\"rmse\"]:.3f}, MAPE={r[\"mape\"]:.2f}%\u0027)\nmaes = [r[\u0027mae\u0027] for r in results]\nprint(f\u0027Mean MAE: {np.mean(maes):.3f} +/- {np.std(maes):.3f}\u0027)"},{"type":"callout","variant":"warning","title":"Never Evaluate on a Single Test Window","content":"A single train-test split can be misleading: the test period may be unusually easy (low volatility) or hard (an outlier event). Rolling cross-validation with 5–10 test windows provides a more reliable estimate of out-of-sample performance and enables confidence intervals on metric differences between models."},{"type":"heading","level":2,"content":"Evaluation Metric Comparison"},{"type":"table","headers":["Metric","Type","Scale-Free","Zero-Safe","Cross-Series","Proper Scoring Rule"],"rows":[["MAE","Point","No","Yes","No","N/A"],["RMSE","Point","No","Yes","No","N/A"],["MAPE","Point","Yes","No (undefined at 0)","Yes","N/A"],["sMAPE","Point","Yes","No (unstable near 0)","Yes","N/A"],["MASE","Point","Yes","Yes","Yes (best for M comps)","N/A"],["CRPS","Probabilistic","No (same units as series)","Yes","No","Yes"],["WQL","Probabilistic (quantile)","Yes (normalised)","Yes","Yes","Yes (pinball)"]]},{"type":"heading","level":2,"content":"Cross-Series Comparison with MASE"},{"type":"text","content":"MASE is the recommended metric for comparing models across multiple series of different scales, as used in the M1–M5 competitions. The naive seasonal baseline divides each series’ scale by MAE of the in-sample seasonal random walk: ŷ_t = y_{t-m} where m is the seasonal period. A model with MASE \u003c 1 beats the seasonal naive. WRMSSE (M5) extends MASE to weighted root mean squared form with hierarchical aggregation weights."},{"type":"list","ordered":false,"items":["Use MAE for operational dashboards where interpretability in original units matters.","Use MASE for M-competition-style cross-series comparison and academic benchmarks.","Avoid MAPE on intermittent demand series (retail SKU level) — use MASE or sMAPE instead.","Always report CRPS alongside MAE for probabilistic forecasts; CRPS is the gold standard.","Calibration check: compute PI coverage at 50%, 80%, and 90% levels and compare to nominal.","Rolling CV: use at least 5 test windows; report mean and standard deviation of each metric."]},{"type":"divider"}]"
---
# Time-Series Evaluation — MAE, MAPE, SMAPE, CRPS, and Calibration

Choosing the right evaluation metric is as important as choosing the right model. A metric that is scale-dependent cannot compare models across different series. A metric undefined at zero values (MAPE) misleads on intermittent demand data. A point metric ignores forecast uncertainty entirely. This note covers the full hierarchy of time-series evaluation metrics, explains when each is appropriate, and builds a principled backtesting framework that computes all metrics simultaneously.

## Scale-Dependent Metrics — MAE and RMSE

MAE = (1/H)Σ|y_t - ŷ_t| is robust, interpretable, and in the same units as the series. It is the minimum expected loss under an asymmetric L1 loss and the appropriate metric when large errors are not disproportionately more costly. MSE = (1/H)Σ(y_t - ŷ_t)² penalises large errors quadratically and is differentiable. RMSE = √MSE restores units. These are scale-dependent: a RMSE of 100 units is meaningless without knowing the series scale, making cross-series comparison impossible.

```python
import numpy as np

def mae(y_true, y_pred):
    return np.mean(np.abs(y_true - y_pred))

def rmse(y_true, y_pred):
    return np.sqrt(np.mean((y_true - y_pred)**2))

def mape(y_true, y_pred, eps=1e-8):
    """MAPE: undefined/unstable when y_true ~ 0; use eps guard."""
    return 100 * np.mean(np.abs((y_true - y_pred) / (np.abs(y_true) + eps)))

def smape(y_true, y_pred, eps=1e-8):
    """Symmetric MAPE: bounded in [0, 200] but still problematic near zero."""
    num = np.abs(y_true - y_pred)
    den = (np.abs(y_true) + np.abs(y_pred)) / 2 + eps
    return 100 * np.mean(num / den)

def mase(y_true, y_pred, y_train, seasonality=1):
    """MASE: MAE scaled by in-sample seasonal naive MAE."""
    naive_errors = np.abs(y_train[seasonality:] - y_train[:-seasonality])
    scale = naive_errors.mean()
    return mae(y_true, y_pred) / (scale + 1e-8)

np.random.seed(42)
y_true  = np.array([100, 110, 95, 120, 130, 115, 105, 125, 118, 108], dtype=float)
y_pred  = np.array([102, 108, 97, 118, 132, 113, 107, 123, 120, 110], dtype=float)
y_train = np.random.randn(100) * 10 + 100

print(f'MAE:   {mae(y_true, y_pred):.4f}')
print(f'RMSE:  {rmse(y_true, y_pred):.4f}')
print(f'MAPE:  {mape(y_true, y_pred):.4f}%')
print(f'sMAPE: {smape(y_true, y_pred):.4f}%')
print(f'MASE:  {mase(y_true, y_pred, y_train, seasonality=1):.4f}')
```

## Scale-Free Metrics — MAPE, sMAPE, and MASE

MAPE is undefined when y_t = 0 and asymmetric: a prediction of 120 for actual 100 gives MAPE=20%, but a prediction of 80 for actual 100 gives MAPE=20% too (but they are not equivalent errors). sMAPE uses (|y| + |ŷ|)/2 in the denominator, making it symmetric, but it still has pathological behaviour when both y and ŷ approach 0. MASE (Hyndman & Koehler, 2006) scales by the in-sample seasonal naive MAE: MASE = MAE / MAE_naive. MASE = 1.0 means the model performs at naive-seasonal level; MASE < 1 is better than naive. MASE is well-defined, scale-free, and suitable for cross-series comparison.

## CRPS for Probabilistic Forecasts

CRPS (Continuous Ranked Probability Score) is a proper scoring rule for distributional forecasts. For ensemble samples {x_1,...,x_M}: CRPS = (1/M)Σ|x_m - y| - (1/2M²)Σ|x_m - x_{m'}|. Lower is better. CRPS reduces to MAE for a point forecast (delta distribution). WQL (Weighted Quantile Loss) is the M5 competition probabilistic metric: WQL = (2/HΣ|y_t|) Σ_τ Σ_t L_τ(y_t, q_{t,τ}) where L_τ is the pinball loss. Both CRPS and WQL are proper: the true distribution minimises expected score.

```python
import numpy as np
from scipy.stats import norm

def crps_gaussian(mu, sigma, y):
    """Analytical CRPS for Gaussian predictive distribution."""
    z   = (y - mu) / sigma
    phi = norm.pdf(z)
    Phi = norm.cdf(z)
    return sigma * (z * (2*Phi - 1) + 2*phi - 1/np.sqrt(np.pi))

def crps_ensemble(samples, y):
    """CRPS from M ensemble samples."""
    M = samples.shape[0]
    term1 = np.mean(np.abs(samples - y))
    term2 = np.mean(np.abs(samples[:, None] - samples[None, :]))
    return term1 - 0.5 * term2

def wql(y_true, quantile_forecasts, quantile_levels):
    """Weighted Quantile Loss (M5 metric)."""
    total, scale = 0.0, np.abs(y_true).mean() * 2 + 1e-8
    for q, qf in zip(quantile_levels, quantile_forecasts.T):
        err = y_true - qf
        loss = np.where(err >= 0, q * err, (q - 1) * err)
        total += loss.mean()
    return total / (scale * len(quantile_levels))

np.random.seed(0)
y = np.random.randn(200) * 2 + 5
mu, sigma = 5.0, 2.0
crps_vals = crps_gaussian(mu * np.ones(200), sigma * np.ones(200), y)
print(f'Mean CRPS (Gaussian, correct sigma=2): {crps_vals.mean():.4f}')
crps_wide = crps_gaussian(mu * np.ones(200), 4.0 * np.ones(200), y)
print(f'Mean CRPS (too wide sigma=4):          {crps_wide.mean():.4f}')
```

## Calibration — Coverage of Prediction Intervals

A calibrated probabilistic forecast satisfies: empirical coverage at nominal level α ≈ α. That is, 80% prediction intervals should contain the true value 80% of the time. Calibration is assessed by computing coverage at multiple levels (50%, 80%, 90%) and plotting nominal vs empirical coverage — a calibration curve. A perfectly calibrated model lies on the diagonal. Under-coverage (empirical < nominal) means intervals are too narrow; over-coverage (empirical > nominal) means intervals are too wide.

```python
import numpy as np
from scipy.stats import norm

def check_calibration(y_true, mu_pred, sigma_pred, levels=None):
    """
    Check calibration of Gaussian prediction intervals.
    Returns dict of {nominal_level: empirical_coverage}.
    """
    if levels is None:
        levels = [0.50, 0.80, 0.90, 0.95]
    results = {}
    for level in levels:
        alpha = 1 - level
        z = norm.ppf(1 - alpha / 2)
        lower = mu_pred - z * sigma_pred
        upper = mu_pred + z * sigma_pred
        coverage = np.mean((y_true >= lower) & (y_true <= upper))
        results[level] = coverage
    return results

np.random.seed(42)
n = 500
y_true     = np.random.randn(n) * 2 + 3
mu_pred    = 3.0 * np.ones(n)
sigma_good = 2.0 * np.ones(n)   # correctly calibrated
sigma_bad  = 0.8 * np.ones(n)   # under-dispersed (too narrow)

cal_good = check_calibration(y_true, mu_pred, sigma_good)
cal_bad  = check_calibration(y_true, mu_pred, sigma_bad)

print('Nominal  |  Good model  |  Narrow model')
print('-' * 45)
for lvl in [0.50, 0.80, 0.90, 0.95]:
    print(f'{lvl:.0%}      |  {cal_good[lvl]:.3f}       |  {cal_bad[lvl]:.3f}')
print('Good model empirical coverage ≈ nominal; narrow model under-covers.')
```

## Backtesting Framework

A robust backtesting framework uses rolling or expanding window cross-validation to evaluate forecasting models on multiple held-out test windows. This avoids lucky or unlucky single test splits and provides confidence intervals on metric estimates. The framework should: (1) generate multiple (train, test) splits, (2) fit each model on each train split, (3) compute all relevant metrics on each test window, (4) aggregate with mean and std across splits.

```python
import numpy as np
from sklearn.linear_model import Ridge

def lag_features(y, n_lags=12):
    X = np.stack([y[i:len(y)-n_lags+i] for i in range(n_lags)], axis=1)
    return X[:-1], y[n_lags:]

def rolling_cv(y, horizon=12, n_splits=5, min_train=100):
    """Rolling window cross-validation for time series."""
    n = len(y)
    results = []
    step = (n - min_train - horizon) // n_splits
    for i in range(n_splits):
        split = min_train + i * step
        y_train = y[:split]
        y_test  = y[split:split + horizon]
        X_all, y_feat = lag_features(y[:split + horizon])
        X_tr, y_tr = X_all[:split - 12], y_feat[:split - 12]
        X_te, y_te = X_all[split - 12:split - 12 + horizon], y_feat[split - 12:split - 12 + horizon]
        model = Ridge(alpha=1.0).fit(X_tr, y_tr)
        y_hat = model.predict(X_te)
        mae_val  = np.abs(y_te - y_hat).mean()
        rmse_val = np.sqrt(((y_te - y_hat)**2).mean())
        mape_val = (np.abs((y_te - y_hat) / (np.abs(y_te) + 1e-8)) * 100).mean()
        results.append({'split': i, 'mae': mae_val, 'rmse': rmse_val, 'mape': mape_val})
    return results

np.random.seed(42)
y = np.cumsum(np.random.randn(300)) + 50
results = rolling_cv(y, horizon=12, n_splits=5)
for r in results:
    print(f'Split {r["split"]}: MAE={r["mae"]:.3f}, RMSE={r["rmse"]:.3f}, MAPE={r["mape"]:.2f}%')
maes = [r['mae'] for r in results]
print(f'Mean MAE: {np.mean(maes):.3f} +/- {np.std(maes):.3f}')
```

> **Never Evaluate on a Single Test Window**: A single train-test split can be misleading: the test period may be unusually easy (low volatility) or hard (an outlier event). Rolling cross-validation with 5–10 test windows provides a more reliable estimate of out-of-sample performance and enables confidence intervals on metric differences between models.

## Evaluation Metric Comparison

| Metric | Type | Scale-Free | Zero-Safe | Cross-Series | Proper Scoring Rule |
| --- | --- | --- | --- | --- | --- |
| MAE | Point | No | Yes | No | N/A |
| RMSE | Point | No | Yes | No | N/A |
| MAPE | Point | Yes | No (undefined at 0) | Yes | N/A |
| sMAPE | Point | Yes | No (unstable near 0) | Yes | N/A |
| MASE | Point | Yes | Yes | Yes (best for M comps) | N/A |
| CRPS | Probabilistic | No (same units as series) | Yes | No | Yes |
| WQL | Probabilistic (quantile) | Yes (normalised) | Yes | Yes | Yes (pinball) |

## Cross-Series Comparison with MASE

MASE is the recommended metric for comparing models across multiple series of different scales, as used in the M1–M5 competitions. The naive seasonal baseline divides each series’ scale by MAE of the in-sample seasonal random walk: ŷ_t = y_{t-m} where m is the seasonal period. A model with MASE < 1 beats the seasonal naive. WRMSSE (M5) extends MASE to weighted root mean squared form with hierarchical aggregation weights.

- Use MAE for operational dashboards where interpretability in original units matters.
- Use MASE for M-competition-style cross-series comparison and academic benchmarks.
- Avoid MAPE on intermittent demand series (retail SKU level) — use MASE or sMAPE instead.
- Always report CRPS alongside MAE for probabilistic forecasts; CRPS is the gold standard.
- Calibration check: compute PI coverage at 50%, 80%, and 90% levels and compare to nominal.
- Rolling CV: use at least 5 test windows; report mean and standard deviation of each metric.

---

