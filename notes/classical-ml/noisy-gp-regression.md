---
title: "Noisy GP Regression — Signal vs Noise Separation"
slug: "noisy-gp-regression"
description: "Observation model y=f(x)+ε, learning noise variance from data, heteroskedastic GPs, and the signal-to-noise ratio diagnostic for diagnosing overfitting vs underfitting."
tags: ["gaussian-processes", "kernel-methods", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"The Observation Model"},{"type":"text","content":"In GP regression the observation model is y(x) = f(x) + ε, where f ~ GP(m, k) is the latent function and ε ~ N(0, σ²_n) is independent observation noise. The combined covariance of observations at two inputs x, x\u0027 is k_y(x,x\u0027) = k_f(x,x\u0027) + σ²_n δ(x,x\u0027). Adding σ²_n to the diagonal of the kernel matrix K has two effects: it smooths the posterior mean (does not interpolate exactly) and it stabilises the matrix inversion numerically (improves condition number)."},{"type":"list","ordered":false,"items":["Latent function f ~ GP(m, k): the true underlying signal being estimated","Observation noise ε ~ N(0, σ²_n): independent per-observation measurement error","Combined observation covariance: K_y = K_f + σ²_n I (noise on diagonal only)","σ²_n \u003e 0: smoothed posterior, improved numerical conditioning","σ²_n = 0: exact interpolation, numerically fragile — always add at least a jitter","Signal-to-Noise Ratio (SNR) = σ²_f / σ²_n — key model health diagnostic"]},{"type":"callout","variant":"info","title":"Noise vs Jitter — Two Distinct Roles","content":"Observation noise σ²_n is a modelling choice that reflects real measurement uncertainty. Jitter (typically 1e-6) is a pure numerical device added to guarantee positive definiteness regardless of σ²_n. When σ²_n is already large, jitter is irrelevant; for noiseless models σ²_n=0 the jitter becomes critical."},{"type":"heading","level":2,"content":"Noisy vs Noiseless Posterior Behaviour"},{"type":"text","content":"With noise σ²_n \u003e 0: posterior mean is a smoothed estimate of f that does not pass through observations; posterior variance at training inputs is positive (≈ σ²_n for well-fitted models). With noise σ²_n = 0 (or very small jitter): posterior is an exact interpolant through training points; posterior variance is 0 at training inputs. Noiseless models are appropriate only for deterministic simulators or computer experiments where observations carry no measurement error."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell=1.0, sf2=1.0):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef gp_predict(X_tr, y_tr, X_te, ell, sf2, sn2):\n    n = len(X_tr)\n    K    = rbf_kernel(X_tr, X_tr, ell, sf2) + sn2*np.eye(n)\n    K_s  = rbf_kernel(X_tr, X_te, ell, sf2)\n    K_ss = rbf_kernel(X_te, X_te, ell, sf2)\n    L    = np.linalg.cholesky(K)\n    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y_tr))\n    mu   = K_s.T @ alpha\n    v    = np.linalg.solve(L, K_s)\n    var  = np.maximum(np.diag(K_ss - v.T@v), 0)\n    return mu, np.sqrt(var)\n\nnp.random.seed(1)\nX_tr = np.sort(np.random.uniform(-4,4,12))\ny_tr = np.sin(X_tr) + 0.4*np.random.randn(12)\nX_te = np.linspace(-5, 5, 300)\n\nfig, axes = plt.subplots(1, 2, figsize=(13,4), sharey=True)\nfor ax, sn2, lbl in zip(axes, [1e-6, 0.3],\n    [\u0027Noiseless (σ²_n=0) — interpolation\u0027, \u0027Noisy (σ²_n=0.3) — smoothing\u0027]):\n    mu, std = gp_predict(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, sn2=sn2)\n    ax.fill_between(X_te, mu-2*std, mu+2*std, alpha=0.25)\n    ax.plot(X_te, mu, lw=2)\n    ax.scatter(X_tr, y_tr, c=\u0027r\u0027, zorder=5, s=60)\n    ax.set_title(lbl); ax.set_xlabel(\u0027x\u0027)\naxes[0].set_ylabel(\u0027y\u0027); plt.tight_layout(); plt.show()"},{"type":"table","headers":["Property","Noiseless GP (σ_n≈0)","Noisy GP (σ_n\u003e0)"],"rows":[["Passes through training data","Yes — exact interpolation","No — smooth fit"],["Posterior variance at X_train","0","Approx σ²_n"],["Numerical stability","Poor (nearly singular K)","Good (diagonal regularisation)"],["Use case","Deterministic simulators, exact data","Real-world sensor/measurement data"],["Marginal likelihood","Tends to overfit (sharp peak)","Balanced fit-complexity trade-off"]]},{"type":"heading","level":2,"content":"Learning Noise Level from Data"},{"type":"text","content":"The noise variance σ²_n should be learned from data via marginal likelihood optimisation rather than set by hand. The marginal likelihood automatically assigns a noise level consistent with the observed scatter. If σ²_n is too small, the model interpolates and overfits; if too large, the mean function is over-smoothed. The learned SNR = σ²_f / σ²_n provides a useful diagnostic: SNR \u003c 1 means the model sees more noise than signal."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import minimize\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell, sf2):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef neg_lml(params, X, y):\n    ell, sf2, sn2 = np.exp(params)\n    n = len(y)\n    K = rbf_kernel(X, X, ell, sf2) + sn2*np.eye(n)\n    try:\n        L = np.linalg.cholesky(K)\n        alpha = np.linalg.solve(L.T, np.linalg.solve(L, y))\n        return 0.5*(y@alpha) + np.sum(np.log(np.diag(L))) + 0.5*n*np.log(2*np.pi)\n    except Exception:\n        return 1e10\n\nnp.random.seed(7)\nX = np.sort(np.random.uniform(-5,5,60))\ntrue_snr_scenario = {\u0027low_noise\u0027: 0.1, \u0027high_noise\u0027: 1.0}\nfor scenario, sn in true_snr_scenario.items():\n    y = np.sin(X) + sn*np.random.randn(60)\n    res = minimize(neg_lml, [0,0,-2], args=(X,y), method=\u0027L-BFGS-B\u0027)\n    ell, sf2, sn2 = np.exp(res.x)\n    print(f\u0027{scenario}: ℓ={ell:.3f}, σ²_f={sf2:.3f}, σ²_n={sn2:.4f}, SNR={sf2/sn2:.2f}\u0027)"},{"type":"callout","variant":"warning","title":"SNR as a Model Health Diagnostic","content":"After optimisation, compute SNR = σ²_f / σ²_n. SNR \u003e\u003e 1 (e.g., 10+): model is dominated by signal — check for overfitting if the posterior fits training data too tightly. SNR ≈ 1: signal and noise are comparable — typical for real-world data. SNR \u003c\u003c 1: noise dominates — data may be too noisy for the model to extract signal, or length-scale is misconfigured."},{"type":"heading","level":2,"content":"Heteroskedastic GP — Input-Dependent Noise"},{"type":"text","content":"Homoskedastic GPs assume constant σ²_n everywhere. Real signals often have input-dependent noise (heteroskedasticity) — e.g., measurement uncertainty varies with sensor load, or financial volatility clusters in time. Heteroskedastic GPs model the noise as a function of x, often by placing a second GP over log σ²_n(x) or by using a warped likelihood. A simple approximation: binned noise estimation followed by a fixed diagonal noise matrix."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell=1.0, sf2=1.0):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\nnp.random.seed(4)\nX_tr = np.sort(np.random.uniform(-5,5,60))\n# Noise grows with |x|\nnoise_std = 0.1 + 0.3*np.abs(X_tr)\ny_tr = np.sin(X_tr) + noise_std*np.random.randn(60)\n\nX_te = np.linspace(-6,6,300)\n\ndef gp_hetero(X_tr, y_tr, X_te, noise_vec, ell=1.5, sf2=1.0):\n    K    = rbf_kernel(X_tr,X_tr,ell,sf2) + np.diag(noise_vec**2)\n    K_s  = rbf_kernel(X_tr,X_te,ell,sf2)\n    K_ss = rbf_kernel(X_te,X_te,ell,sf2)\n    L    = np.linalg.cholesky(K)\n    alpha = np.linalg.solve(L.T,np.linalg.solve(L,y_tr))\n    mu   = K_s.T@alpha\n    v    = np.linalg.solve(L,K_s)\n    return mu, np.sqrt(np.maximum(np.diag(K_ss-v.T@v),0))\n\nmu, std = gp_hetero(X_tr, y_tr, X_te, noise_std)\nplt.figure(figsize=(10,4))\nplt.fill_between(X_te,mu-2*std,mu+2*std,alpha=0.25,label=\u0027±2σ (homoskedastic post.)\u0027)\nplt.plot(X_te, mu, lw=2, label=\u0027Posterior mean\u0027)\nplt.errorbar(X_tr, y_tr, yerr=2*noise_std, fmt=\u0027r.\u0027, alpha=0.4, ms=4, label=\u0027Obs ±2σ_n(x)\u0027)\nplt.title(\u0027Heteroskedastic GP (known input-dependent noise)\u0027)\nplt.xlabel(\u0027x\u0027); plt.ylabel(\u0027y\u0027); plt.legend(); plt.tight_layout(); plt.show()"},{"type":"heading","level":2,"content":"Model Selection via Marginal Likelihood"},{"type":"text","content":"The log marginal likelihood can compare different noise assumptions without a held-out set. Models with unrealistically small σ²_n will have high data-fit but a large complexity penalty from the almost-singular kernel matrix; the marginal likelihood penalises this. Comparing LML values across model variants (different kernels, different noise models) implements formal Bayesian model selection."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import minimize\n\ndef rbf_kernel(X1, X2, ell, sf2):\n    X1=np.atleast_2d(X1).reshape(-1,1); X2=np.atleast_2d(X2).reshape(-1,1)\n    return sf2*np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef fit_and_score(X, y, fixed_sn2=None):\n    def neg_lml(params):\n        if fixed_sn2 is None:\n            ell,sf2,sn2 = np.exp(params)\n        else:\n            ell,sf2 = np.exp(params); sn2 = fixed_sn2\n        n = len(y); K = rbf_kernel(X,X,ell,sf2)+sn2*np.eye(n)\n        try:\n            L=np.linalg.cholesky(K); a=np.linalg.solve(L.T,np.linalg.solve(L,y))\n            return 0.5*(y@a)+np.sum(np.log(np.diag(L)))+0.5*n*np.log(2*np.pi)\n        except: return 1e10\n    n_params = 2 if fixed_sn2 else 3\n    x0 = np.zeros(n_params)\n    res = minimize(neg_lml, x0, method=\u0027L-BFGS-B\u0027)\n    return -res.fun\n\nnp.random.seed(99)\nX = np.sort(np.random.uniform(-5,5,50))\ny = np.sin(X)+0.2*np.random.randn(50)\nfor label, sn in [(\u0027Interpolating (σ_n=1e-4)\u0027,1e-4),\n                  (\u0027Learned noise\u0027, None),\n                  (\u0027Over-smoothed (σ_n=2.0)\u0027,2.0)]:\n    lml = fit_and_score(X, y, fixed_sn2=sn if sn else None)\n    print(f\u0027{label:\u003c35s}: LML = {lml:.2f}\u0027)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"The observation model y = f(x) + ε separates the latent signal f from measurement noise ε ~ N(0, σ²_n). Adding σ²_n to the diagonal of K regularises the matrix (numerical stability) and produces a smoothed posterior mean rather than exact interpolation. The noise level is best learned via marginal likelihood optimisation. SNR = σ²_f/σ²_n is a useful health diagnostic. Heteroskedastic extensions model input-dependent noise via a second GP over log noise."},{"type":"list","ordered":false,"items":["σ²_n on K diagonal: numerical stability + smoothed posterior","Noiseless GP (σ²_n=0): interpolation, appropriate only for deterministic simulators","Learn σ²_n from marginal likelihood — not cross-validation","SNR = σ²_f/σ²_n: high → signal-dominated; low → noise-dominated","Heteroskedastic GP: model σ²_n(x) as a function of input for non-constant noise","Marginal likelihood formally compares noise models without held-out data"]},{"type":"divider"}]"
---
# Noisy GP Regression — Signal vs Noise Separation

## The Observation Model

In GP regression the observation model is y(x) = f(x) + ε, where f ~ GP(m, k) is the latent function and ε ~ N(0, σ²_n) is independent observation noise. The combined covariance of observations at two inputs x, x' is k_y(x,x') = k_f(x,x') + σ²_n δ(x,x'). Adding σ²_n to the diagonal of the kernel matrix K has two effects: it smooths the posterior mean (does not interpolate exactly) and it stabilises the matrix inversion numerically (improves condition number).

- Latent function f ~ GP(m, k): the true underlying signal being estimated
- Observation noise ε ~ N(0, σ²_n): independent per-observation measurement error
- Combined observation covariance: K_y = K_f + σ²_n I (noise on diagonal only)
- σ²_n > 0: smoothed posterior, improved numerical conditioning
- σ²_n = 0: exact interpolation, numerically fragile — always add at least a jitter
- Signal-to-Noise Ratio (SNR) = σ²_f / σ²_n — key model health diagnostic

> **Noise vs Jitter — Two Distinct Roles**: Observation noise σ²_n is a modelling choice that reflects real measurement uncertainty. Jitter (typically 1e-6) is a pure numerical device added to guarantee positive definiteness regardless of σ²_n. When σ²_n is already large, jitter is irrelevant; for noiseless models σ²_n=0 the jitter becomes critical.

## Noisy vs Noiseless Posterior Behaviour

With noise σ²_n > 0: posterior mean is a smoothed estimate of f that does not pass through observations; posterior variance at training inputs is positive (≈ σ²_n for well-fitted models). With noise σ²_n = 0 (or very small jitter): posterior is an exact interpolant through training points; posterior variance is 0 at training inputs. Noiseless models are appropriate only for deterministic simulators or computer experiments where observations carry no measurement error.

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell=1.0, sf2=1.0):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)

def gp_predict(X_tr, y_tr, X_te, ell, sf2, sn2):
    n = len(X_tr)
    K    = rbf_kernel(X_tr, X_tr, ell, sf2) + sn2*np.eye(n)
    K_s  = rbf_kernel(X_tr, X_te, ell, sf2)
    K_ss = rbf_kernel(X_te, X_te, ell, sf2)
    L    = np.linalg.cholesky(K)
    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y_tr))
    mu   = K_s.T @ alpha
    v    = np.linalg.solve(L, K_s)
    var  = np.maximum(np.diag(K_ss - v.T@v), 0)
    return mu, np.sqrt(var)

np.random.seed(1)
X_tr = np.sort(np.random.uniform(-4,4,12))
y_tr = np.sin(X_tr) + 0.4*np.random.randn(12)
X_te = np.linspace(-5, 5, 300)

fig, axes = plt.subplots(1, 2, figsize=(13,4), sharey=True)
for ax, sn2, lbl in zip(axes, [1e-6, 0.3],
    ['Noiseless (σ²_n=0) — interpolation', 'Noisy (σ²_n=0.3) — smoothing']):
    mu, std = gp_predict(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, sn2=sn2)
    ax.fill_between(X_te, mu-2*std, mu+2*std, alpha=0.25)
    ax.plot(X_te, mu, lw=2)
    ax.scatter(X_tr, y_tr, c='r', zorder=5, s=60)
    ax.set_title(lbl); ax.set_xlabel('x')
axes[0].set_ylabel('y'); plt.tight_layout(); plt.show()
```

| Property | Noiseless GP (σ_n≈0) | Noisy GP (σ_n>0) |
| --- | --- | --- |
| Passes through training data | Yes — exact interpolation | No — smooth fit |
| Posterior variance at X_train | 0 | Approx σ²_n |
| Numerical stability | Poor (nearly singular K) | Good (diagonal regularisation) |
| Use case | Deterministic simulators, exact data | Real-world sensor/measurement data |
| Marginal likelihood | Tends to overfit (sharp peak) | Balanced fit-complexity trade-off |

## Learning Noise Level from Data

The noise variance σ²_n should be learned from data via marginal likelihood optimisation rather than set by hand. The marginal likelihood automatically assigns a noise level consistent with the observed scatter. If σ²_n is too small, the model interpolates and overfits; if too large, the mean function is over-smoothed. The learned SNR = σ²_f / σ²_n provides a useful diagnostic: SNR < 1 means the model sees more noise than signal.

```python
import numpy as np
from scipy.optimize import minimize
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell, sf2):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)

def neg_lml(params, X, y):
    ell, sf2, sn2 = np.exp(params)
    n = len(y)
    K = rbf_kernel(X, X, ell, sf2) + sn2*np.eye(n)
    try:
        L = np.linalg.cholesky(K)
        alpha = np.linalg.solve(L.T, np.linalg.solve(L, y))
        return 0.5*(y@alpha) + np.sum(np.log(np.diag(L))) + 0.5*n*np.log(2*np.pi)
    except Exception:
        return 1e10

np.random.seed(7)
X = np.sort(np.random.uniform(-5,5,60))
true_snr_scenario = {'low_noise': 0.1, 'high_noise': 1.0}
for scenario, sn in true_snr_scenario.items():
    y = np.sin(X) + sn*np.random.randn(60)
    res = minimize(neg_lml, [0,0,-2], args=(X,y), method='L-BFGS-B')
    ell, sf2, sn2 = np.exp(res.x)
    print(f'{scenario}: ℓ={ell:.3f}, σ²_f={sf2:.3f}, σ²_n={sn2:.4f}, SNR={sf2/sn2:.2f}')
```

> **SNR as a Model Health Diagnostic**: After optimisation, compute SNR = σ²_f / σ²_n. SNR >> 1 (e.g., 10+): model is dominated by signal — check for overfitting if the posterior fits training data too tightly. SNR ≈ 1: signal and noise are comparable — typical for real-world data. SNR << 1: noise dominates — data may be too noisy for the model to extract signal, or length-scale is misconfigured.

## Heteroskedastic GP — Input-Dependent Noise

Homoskedastic GPs assume constant σ²_n everywhere. Real signals often have input-dependent noise (heteroskedasticity) — e.g., measurement uncertainty varies with sensor load, or financial volatility clusters in time. Heteroskedastic GPs model the noise as a function of x, often by placing a second GP over log σ²_n(x) or by using a warped likelihood. A simple approximation: binned noise estimation followed by a fixed diagonal noise matrix.

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell=1.0, sf2=1.0):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)

np.random.seed(4)
X_tr = np.sort(np.random.uniform(-5,5,60))
# Noise grows with |x|
noise_std = 0.1 + 0.3*np.abs(X_tr)
y_tr = np.sin(X_tr) + noise_std*np.random.randn(60)

X_te = np.linspace(-6,6,300)

def gp_hetero(X_tr, y_tr, X_te, noise_vec, ell=1.5, sf2=1.0):
    K    = rbf_kernel(X_tr,X_tr,ell,sf2) + np.diag(noise_vec**2)
    K_s  = rbf_kernel(X_tr,X_te,ell,sf2)
    K_ss = rbf_kernel(X_te,X_te,ell,sf2)
    L    = np.linalg.cholesky(K)
    alpha = np.linalg.solve(L.T,np.linalg.solve(L,y_tr))
    mu   = K_s.T@alpha
    v    = np.linalg.solve(L,K_s)
    return mu, np.sqrt(np.maximum(np.diag(K_ss-v.T@v),0))

mu, std = gp_hetero(X_tr, y_tr, X_te, noise_std)
plt.figure(figsize=(10,4))
plt.fill_between(X_te,mu-2*std,mu+2*std,alpha=0.25,label='±2σ (homoskedastic post.)')
plt.plot(X_te, mu, lw=2, label='Posterior mean')
plt.errorbar(X_tr, y_tr, yerr=2*noise_std, fmt='r.', alpha=0.4, ms=4, label='Obs ±2σ_n(x)')
plt.title('Heteroskedastic GP (known input-dependent noise)')
plt.xlabel('x'); plt.ylabel('y'); plt.legend(); plt.tight_layout(); plt.show()
```

## Model Selection via Marginal Likelihood

The log marginal likelihood can compare different noise assumptions without a held-out set. Models with unrealistically small σ²_n will have high data-fit but a large complexity penalty from the almost-singular kernel matrix; the marginal likelihood penalises this. Comparing LML values across model variants (different kernels, different noise models) implements formal Bayesian model selection.

```python
import numpy as np
from scipy.optimize import minimize

def rbf_kernel(X1, X2, ell, sf2):
    X1=np.atleast_2d(X1).reshape(-1,1); X2=np.atleast_2d(X2).reshape(-1,1)
    return sf2*np.exp(-0.5*(X1-X2.T)**2/ell**2)

def fit_and_score(X, y, fixed_sn2=None):
    def neg_lml(params):
        if fixed_sn2 is None:
            ell,sf2,sn2 = np.exp(params)
        else:
            ell,sf2 = np.exp(params); sn2 = fixed_sn2
        n = len(y); K = rbf_kernel(X,X,ell,sf2)+sn2*np.eye(n)
        try:
            L=np.linalg.cholesky(K); a=np.linalg.solve(L.T,np.linalg.solve(L,y))
            return 0.5*(y@a)+np.sum(np.log(np.diag(L)))+0.5*n*np.log(2*np.pi)
        except: return 1e10
    n_params = 2 if fixed_sn2 else 3
    x0 = np.zeros(n_params)
    res = minimize(neg_lml, x0, method='L-BFGS-B')
    return -res.fun

np.random.seed(99)
X = np.sort(np.random.uniform(-5,5,50))
y = np.sin(X)+0.2*np.random.randn(50)
for label, sn in [('Interpolating (σ_n=1e-4)',1e-4),
                  ('Learned noise', None),
                  ('Over-smoothed (σ_n=2.0)',2.0)]:
    lml = fit_and_score(X, y, fixed_sn2=sn if sn else None)
    print(f'{label:<35s}: LML = {lml:.2f}')
```

## Key Takeaways

The observation model y = f(x) + ε separates the latent signal f from measurement noise ε ~ N(0, σ²_n). Adding σ²_n to the diagonal of K regularises the matrix (numerical stability) and produces a smoothed posterior mean rather than exact interpolation. The noise level is best learned via marginal likelihood optimisation. SNR = σ²_f/σ²_n is a useful health diagnostic. Heteroskedastic extensions model input-dependent noise via a second GP over log noise.

- σ²_n on K diagonal: numerical stability + smoothed posterior
- Noiseless GP (σ²_n=0): interpolation, appropriate only for deterministic simulators
- Learn σ²_n from marginal likelihood — not cross-validation
- SNR = σ²_f/σ²_n: high → signal-dominated; low → noise-dominated
- Heteroskedastic GP: model σ²_n(x) as a function of input for non-constant noise
- Marginal likelihood formally compares noise models without held-out data

---

