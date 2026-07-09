---
title: "GP Classification — Laplace Approximation and EP"
slug: "gp-classification"
description: "Non-Gaussian likelihoods for binary and multi-class GP classification: Laplace approximation via Newton's method, Expectation Propagation, variational inference, and predictive comparison."
tags: ["gaussian-processes", "kernel-methods", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Why GP Classification Is Harder"},{"type":"text","content":"For classification the likelihood p(y|f) = σ(y·f) where σ is the sigmoid function is non-Gaussian. The posterior p(f|X,y) ∝ p(y|f)p(f|X) is no longer Gaussian — it has no closed form. We need approximations. Three families are standard: (1) Laplace approximation — Gaussian centred at the MAP estimate; (2) Expectation Propagation (EP) — moment-matching approximation; (3) variational inference — optimise a lower bound on the marginal likelihood. Each trades off accuracy, cost, and implementation complexity."},{"type":"list","ordered":false,"items":["GP regression: Gaussian likelihood → closed-form posterior GP","GP classification: sigmoid/softmax likelihood → intractable posterior","Laplace: fastest, mode-matching Gaussian approximation at MAP","EP: more accurate, moment-matching, iterative cavity updates","Variational (SVGP): scalable to large n via inducing points and ELBO","MCMC (HMC/NUTS): gold standard accuracy but very high computational cost"]},{"type":"heading","level":2,"content":"Laplace Approximation via Newton\u0027s Method"},{"type":"text","content":"The Laplace approximation (1) finds the MAP estimate f̂ = argmax log p(f|X,y) = argmax [log p(y|f) − ½ fᵀ K⁻¹ f], (2) approximates the posterior with a Gaussian centred at f̂ with covariance (K⁻¹ + W)⁻¹ where W = −∇∇ log p(y|f̂) is the negative Hessian of the log likelihood. For binary classification W = diag(πᵢ(1−πᵢ)) where πᵢ = σ(f̂ᵢ). The MAP optimisation uses Newton\u0027s method, equivalent to Iteratively Reweighted Least Squares (IRLS)."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.special import expit as sigmoid\nfrom scipy.linalg import cho_factor, cho_solve\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell=1.0, sf2=1.0):\n    X1=np.atleast_2d(X1).reshape(-1,1); X2=np.atleast_2d(X2).reshape(-1,1)\n    return sf2*np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef laplace_gp_classify(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, n_iter=20):\n    n = len(y_tr)\n    K = rbf_kernel(X_tr, X_tr, ell, sf2)\n    f = np.zeros(n)  # initialise latent values at zero\n    for _ in range(n_iter):\n        pi  = sigmoid(f)                        # class probabilities\n        W   = pi*(1 - pi)                       # Hessian diagonal\n        W_sq = np.sqrt(W)\n        B   = np.eye(n) + W_sq[:,None]*K*W_sq[None,:]  # I + W^{1/2} K W^{1/2}\n        L   = np.linalg.cholesky(B)\n        b   = W*f + (y_tr+1)/2 - pi            # gradient step target\n        a   = b - W_sq*cho_solve(cho_factor(L), W_sq*(K@b))\n        f   = K @ a\n    pi  = sigmoid(f)\n    K_s = rbf_kernel(X_tr, X_te, ell, sf2)\n    mu_s = K_s.T @ ((y_tr+1)/2 - sigmoid(f))   # posterior mean approximation\n    pi_star = sigmoid(mu_s)\n    return pi_star, mu_s\n\nnp.random.seed(42)\nX_tr = np.sort(np.random.uniform(-5,5,30))\ny_tr = np.sign(np.sin(X_tr) + 0.2*np.random.randn(30)).astype(int)\nX_te = np.linspace(-6,6,200)\nprob, _ = laplace_gp_classify(X_tr, y_tr, X_te)\n\nplt.figure(figsize=(10,4))\nplt.plot(X_te, prob, lw=2, label=\u0027P(y=+1|x*)\u0027)\nplt.scatter(X_tr, (y_tr+1)/2, c=\u0027r\u0027, zorder=5, s=50, label=\u0027Training labels\u0027)\nplt.axhline(0.5, ls=\u0027--\u0027, color=\u0027gray\u0027)\nplt.title(\u0027GP Classification — Laplace Approximation\u0027)\nplt.xlabel(\u0027x\u0027); plt.ylabel(\u0027Predicted probability\u0027); plt.legend(); plt.show()"},{"type":"table","headers":["Method","Approximation Strategy","Accuracy vs EP","Cost","Implementation"],"rows":[["Laplace","Gaussian at MAP (mode-matching)","Lower — misses skew","O(n³) Newton steps","Moderate — Newton IRLS loop"],["EP","Gaussian matching moments iteratively","Best among approximations","O(n³) per sweep","Complex — cavity distributions"],["Variational (SVGP)","ELBO lower bound, inducing points","Moderate, scalable","O(nm²) — scalable","GPyTorch VariationalGP"],["MCMC (HMC)","Gold standard — exact asymptotically","Highest (given enough samples)","Very high","Pyro / NumPyro"]]},{"type":"heading","level":2,"content":"GPyTorch GP Classifier with Variational Inference"},{"type":"text","content":"For GP classification in GPyTorch, the standard approach uses variational inference (VariationalGP) with a Bernoulli likelihood. This avoids the non-Gaussian posterior problem by optimising a variational lower bound ELBO = E_q[log p(y|f)] − KL[q(f)||p(f)]. Inducing points approximate the full GP, giving O(nm²) cost with m inducing points."},{"type":"code","language":"python","content":"import torch\nimport gpytorch\nfrom gpytorch.models import ApproximateGP\nfrom gpytorch.variational import CholeskyVariationalDistribution, VariationalStrategy\nimport numpy as np\n\nclass GPClassifier(ApproximateGP):\n    def __init__(self, inducing_points):\n        var_dist = CholeskyVariationalDistribution(inducing_points.size(0))\n        var_strat = VariationalStrategy(self, inducing_points, var_dist,\n                                        learn_inducing_locations=True)\n        super().__init__(var_strat)\n        self.mean_module  = gpytorch.means.ZeroMean()\n        self.covar_module = gpytorch.kernels.ScaleKernel(gpytorch.kernels.RBFKernel())\n\n    def forward(self, x):\n        return gpytorch.distributions.MultivariateNormal(\n            self.mean_module(x), self.covar_module(x))\n\nnp.random.seed(0)\nX_np = np.sort(np.random.uniform(-5,5,80))\ny_np = (np.sin(X_np)\u003e0).astype(float)\ntrain_x = torch.tensor(X_np, dtype=torch.float32)\ntrain_y = torch.tensor(y_np, dtype=torch.float32)\ninducing = torch.linspace(-5,5,20)\n\nlikelihood = gpytorch.likelihoods.BernoulliLikelihood()\nmodel = GPClassifier(inducing)\noptimizer = torch.optim.Adam([{\u0027params\u0027:model.parameters()},\n                               {\u0027params\u0027:likelihood.parameters()}], lr=0.05)\nmll = gpytorch.mlls.VariationalELBO(likelihood, model, num_data=len(train_y))\nmodel.train(); likelihood.train()\nfor _ in range(200):\n    optimizer.zero_grad(); loss=-mll(model(train_x),train_y); loss.backward(); optimizer.step()\n\nmodel.eval(); likelihood.eval()\nwith torch.no_grad():\n    test_x = torch.linspace(-6,6,200)\n    probs  = likelihood(model(test_x)).probs\nprint(\u0027Variational GP Classifier trained. Inducing point locations learned.\u0027)"},{"type":"heading","level":2,"content":"Expectation Propagation vs Laplace"},{"type":"text","content":"Expectation Propagation (EP) approximates each likelihood factor p(yᵢ|fᵢ) with a Gaussian tᵢ(fᵢ) = Zᵢ N(fᵢ; μᵢ, σᵢ²). The EP algorithm iterates: (1) compute the cavity distribution q₋ᵢ = q/tᵢ (remove one site), (2) project the product q₋ᵢ · p(yᵢ|fᵢ) onto a Gaussian by matching first two moments, (3) update tᵢ accordingly. EP converges to a Gaussian approximation whose moments match the true posterior\u0027s local moments — more accurate than Laplace, especially for unbalanced class distributions."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.special import expit as sigmoid, ndtr\nfrom scipy.stats import norm\nimport matplotlib.pyplot as plt\n\n# Simple comparison: Laplace vs Gaussian CDF likelihood (probit) predictive\ndef probit_laplace_pred(f_test_mean, f_test_var):\n    \"\"\"Predictive probability using Laplace approx with probit likelihood.\"\"\"\n    kappa = 1.0 / np.sqrt(1.0 + np.pi * f_test_var / 8.0)\n    return ndtr(kappa * f_test_mean)\n\ndef probit_ep_pred(f_test_mean, f_test_var):\n    \"\"\"EP predictive: integrate probit against N(f_test_mean, f_test_var).\"\"\"\n    # Exact for probit: p(y=1|x*) = Φ(μ/sqrt(1+σ²))\n    return ndtr(f_test_mean / np.sqrt(1.0 + f_test_var))\n\nlatent_means = np.linspace(-3, 3, 200)\nfor latent_var in [0.5, 1.0, 2.0]:\n    lap = probit_laplace_pred(latent_means, latent_var)\n    ep  = probit_ep_pred(latent_means,  latent_var)\n    diff = np.max(np.abs(lap - ep))\n    print(f\u0027Latent var={latent_var}: max|Laplace-EP| = {diff:.4f}\u0027)\n\nfig, ax = plt.subplots(figsize=(8,4))\nfor v, col in [(0.5,\u0027blue\u0027),(2.0,\u0027red\u0027)]:\n    x = latent_means\n    ax.plot(x, probit_laplace_pred(x,v), ls=\u0027--\u0027, color=col, label=f\u0027Laplace σ²={v}\u0027)\n    ax.plot(x, probit_ep_pred(x,v),      ls=\u0027-\u0027,  color=col, label=f\u0027EP σ²={v}\u0027)\nax.set_xlabel(\u0027Latent mean\u0027); ax.set_ylabel(\u0027P(y=+1)\u0027)\nax.legend(ncol=2); ax.set_title(\u0027Laplace vs EP Predictive Probabilities (probit likelihood)\u0027)\nplt.tight_layout(); plt.show()"},{"type":"callout","variant":"tip","title":"EP Is More Accurate Than Laplace for Classification","content":"Laplace approximation matches the posterior mode (MAP) and curvature — it can be over-confident when the true posterior is skewed. EP matches first and second moments of the local likelihood approximations and is typically more accurate, especially for small datasets or imbalanced classes. For most practical GP classification tasks, use EP or variational inference over Laplace."},{"type":"heading","level":2,"content":"Multi-Class GP Classification"},{"type":"text","content":"For K \u003e 2 classes, the likelihood p(y=k|f) = softmax(f)_k requires K latent GP functions — one per class. The posterior remains intractable. Common approaches: (1) One-vs-Rest with binary GP classifiers (simple but inconsistent probabilities), (2) Softmax likelihood with Laplace or EP (consistent but complex), (3) Dirichlet likelihood GP (naturally compositional). GPyTorch supports DirichletClassificationLikelihood for scalable multi-class GP classification."},{"type":"code","language":"python","content":"import torch\nimport gpytorch\nimport numpy as np\nfrom sklearn.datasets import load_iris\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.model_selection import train_test_split\n\ndata = load_iris()\nX_np, y_np = data.data[:,:2], data.target  # first 2 features for viz\nscaler = StandardScaler()\nX_np = scaler.fit_transform(X_np)\nX_tr, X_te, y_tr, y_te = train_test_split(X_np, y_np, test_size=0.2, random_state=42)\n\ntrain_x = torch.tensor(X_tr, dtype=torch.float32)\ntrain_y = torch.tensor(y_tr, dtype=torch.long)\ntest_x  = torch.tensor(X_te, dtype=torch.float32)\n\nlikelihood = gpytorch.likelihoods.DirichletClassificationLikelihood(\n    train_y, learn_additional_noise=True)\n\nclass MulticlassGP(gpytorch.models.ExactGP):\n    def __init__(self, train_x, train_y, likelihood):\n        super().__init__(train_x, train_y, likelihood)\n        self.mean_module  = gpytorch.means.ConstantMean(batch_shape=torch.Size([3]))\n        self.covar_module = gpytorch.kernels.ScaleKernel(\n            gpytorch.kernels.RBFKernel(batch_shape=torch.Size([3])),\n            batch_shape=torch.Size([3]))\n    def forward(self, x):\n        return gpytorch.distributions.MultivariateNormal(\n            self.mean_module(x), self.covar_module(x))\n\nmodel = MulticlassGP(train_x, likelihood.transformed_targets, likelihood)\noptimizer = torch.optim.Adam(model.parameters(), lr=0.1)\nmll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model)\nmodel.train(); likelihood.train()\nfor _ in range(100):\n    optimizer.zero_grad()\n    (-mll(model(train_x), likelihood.transformed_targets)).backward()\n    optimizer.step()\nprint(\u0027Dirichlet GP multi-class model trained on Iris (3 classes).\u0027)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"GP classification requires approximations because the sigmoid/softmax likelihood makes the posterior non-Gaussian. Laplace approximation is simple and fast: Gaussian centred at the MAP with curvature from the Hessian W = diag(πᵢ(1−πᵢ)). EP iteratively matches moments of local likelihood approximations and is more accurate than Laplace. Variational inference (SVGP) scales to large datasets via inducing points. Multi-class classification uses K latent GPs with Dirichlet or softmax likelihood."},{"type":"list","ordered":false,"items":["GP classification: p(y|f)=σ(yf) is non-Gaussian → approximate posterior required","Laplace: Gaussian at MAP; W=diag(π(1-π)) from sigmoid; IRLS Newton steps","EP: cavity distribution update, moment-matching; more accurate than Laplace","Variational (SVGP): ELBO optimisation with m inducing points; O(nm²) cost","Multi-class: K latent GPs + softmax/Dirichlet likelihood; one-vs-rest as baseline","GPyTorch: DirichletClassificationLikelihood for scalable multi-class GP"]},{"type":"callout","variant":"info","title":"Predictive Probability vs Latent Mean","content":"The GP classifier outputs a latent mean f*(x) ∈ ℝ. The predictive probability P(y=+1|x*) requires integrating σ(f*) over the posterior uncertainty in f*. This integral is approximated as σ(κ·μ*) where κ=(1+πσ²*/8)^{-1/2} in the Laplace case. Ignoring posterior uncertainty and using σ(μ*) alone produces over-confident probabilities."},{"type":"divider"}]"
---
# GP Classification — Laplace Approximation and EP

## Why GP Classification Is Harder

For classification the likelihood p(y|f) = σ(y·f) where σ is the sigmoid function is non-Gaussian. The posterior p(f|X,y) ∝ p(y|f)p(f|X) is no longer Gaussian — it has no closed form. We need approximations. Three families are standard: (1) Laplace approximation — Gaussian centred at the MAP estimate; (2) Expectation Propagation (EP) — moment-matching approximation; (3) variational inference — optimise a lower bound on the marginal likelihood. Each trades off accuracy, cost, and implementation complexity.

- GP regression: Gaussian likelihood → closed-form posterior GP
- GP classification: sigmoid/softmax likelihood → intractable posterior
- Laplace: fastest, mode-matching Gaussian approximation at MAP
- EP: more accurate, moment-matching, iterative cavity updates
- Variational (SVGP): scalable to large n via inducing points and ELBO
- MCMC (HMC/NUTS): gold standard accuracy but very high computational cost

## Laplace Approximation via Newton's Method

The Laplace approximation (1) finds the MAP estimate f̂ = argmax log p(f|X,y) = argmax [log p(y|f) − ½ fᵀ K⁻¹ f], (2) approximates the posterior with a Gaussian centred at f̂ with covariance (K⁻¹ + W)⁻¹ where W = −∇∇ log p(y|f̂) is the negative Hessian of the log likelihood. For binary classification W = diag(πᵢ(1−πᵢ)) where πᵢ = σ(f̂ᵢ). The MAP optimisation uses Newton's method, equivalent to Iteratively Reweighted Least Squares (IRLS).

```python
import numpy as np
from scipy.special import expit as sigmoid
from scipy.linalg import cho_factor, cho_solve
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell=1.0, sf2=1.0):
    X1=np.atleast_2d(X1).reshape(-1,1); X2=np.atleast_2d(X2).reshape(-1,1)
    return sf2*np.exp(-0.5*(X1-X2.T)**2/ell**2)

def laplace_gp_classify(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, n_iter=20):
    n = len(y_tr)
    K = rbf_kernel(X_tr, X_tr, ell, sf2)
    f = np.zeros(n)  # initialise latent values at zero
    for _ in range(n_iter):
        pi  = sigmoid(f)                        # class probabilities
        W   = pi*(1 - pi)                       # Hessian diagonal
        W_sq = np.sqrt(W)
        B   = np.eye(n) + W_sq[:,None]*K*W_sq[None,:]  # I + W^{1/2} K W^{1/2}
        L   = np.linalg.cholesky(B)
        b   = W*f + (y_tr+1)/2 - pi            # gradient step target
        a   = b - W_sq*cho_solve(cho_factor(L), W_sq*(K@b))
        f   = K @ a
    pi  = sigmoid(f)
    K_s = rbf_kernel(X_tr, X_te, ell, sf2)
    mu_s = K_s.T @ ((y_tr+1)/2 - sigmoid(f))   # posterior mean approximation
    pi_star = sigmoid(mu_s)
    return pi_star, mu_s

np.random.seed(42)
X_tr = np.sort(np.random.uniform(-5,5,30))
y_tr = np.sign(np.sin(X_tr) + 0.2*np.random.randn(30)).astype(int)
X_te = np.linspace(-6,6,200)
prob, _ = laplace_gp_classify(X_tr, y_tr, X_te)

plt.figure(figsize=(10,4))
plt.plot(X_te, prob, lw=2, label='P(y=+1|x*)')
plt.scatter(X_tr, (y_tr+1)/2, c='r', zorder=5, s=50, label='Training labels')
plt.axhline(0.5, ls='--', color='gray')
plt.title('GP Classification — Laplace Approximation')
plt.xlabel('x'); plt.ylabel('Predicted probability'); plt.legend(); plt.show()
```

| Method | Approximation Strategy | Accuracy vs EP | Cost | Implementation |
| --- | --- | --- | --- | --- |
| Laplace | Gaussian at MAP (mode-matching) | Lower — misses skew | O(n³) Newton steps | Moderate — Newton IRLS loop |
| EP | Gaussian matching moments iteratively | Best among approximations | O(n³) per sweep | Complex — cavity distributions |
| Variational (SVGP) | ELBO lower bound, inducing points | Moderate, scalable | O(nm²) — scalable | GPyTorch VariationalGP |
| MCMC (HMC) | Gold standard — exact asymptotically | Highest (given enough samples) | Very high | Pyro / NumPyro |

## GPyTorch GP Classifier with Variational Inference

For GP classification in GPyTorch, the standard approach uses variational inference (VariationalGP) with a Bernoulli likelihood. This avoids the non-Gaussian posterior problem by optimising a variational lower bound ELBO = E_q[log p(y|f)] − KL[q(f)||p(f)]. Inducing points approximate the full GP, giving O(nm²) cost with m inducing points.

```python
import torch
import gpytorch
from gpytorch.models import ApproximateGP
from gpytorch.variational import CholeskyVariationalDistribution, VariationalStrategy
import numpy as np

class GPClassifier(ApproximateGP):
    def __init__(self, inducing_points):
        var_dist = CholeskyVariationalDistribution(inducing_points.size(0))
        var_strat = VariationalStrategy(self, inducing_points, var_dist,
                                        learn_inducing_locations=True)
        super().__init__(var_strat)
        self.mean_module  = gpytorch.means.ZeroMean()
        self.covar_module = gpytorch.kernels.ScaleKernel(gpytorch.kernels.RBFKernel())

    def forward(self, x):
        return gpytorch.distributions.MultivariateNormal(
            self.mean_module(x), self.covar_module(x))

np.random.seed(0)
X_np = np.sort(np.random.uniform(-5,5,80))
y_np = (np.sin(X_np)>0).astype(float)
train_x = torch.tensor(X_np, dtype=torch.float32)
train_y = torch.tensor(y_np, dtype=torch.float32)
inducing = torch.linspace(-5,5,20)

likelihood = gpytorch.likelihoods.BernoulliLikelihood()
model = GPClassifier(inducing)
optimizer = torch.optim.Adam([{'params':model.parameters()},
                               {'params':likelihood.parameters()}], lr=0.05)
mll = gpytorch.mlls.VariationalELBO(likelihood, model, num_data=len(train_y))
model.train(); likelihood.train()
for _ in range(200):
    optimizer.zero_grad(); loss=-mll(model(train_x),train_y); loss.backward(); optimizer.step()

model.eval(); likelihood.eval()
with torch.no_grad():
    test_x = torch.linspace(-6,6,200)
    probs  = likelihood(model(test_x)).probs
print('Variational GP Classifier trained. Inducing point locations learned.')
```

## Expectation Propagation vs Laplace

Expectation Propagation (EP) approximates each likelihood factor p(yᵢ|fᵢ) with a Gaussian tᵢ(fᵢ) = Zᵢ N(fᵢ; μᵢ, σᵢ²). The EP algorithm iterates: (1) compute the cavity distribution q₋ᵢ = q/tᵢ (remove one site), (2) project the product q₋ᵢ · p(yᵢ|fᵢ) onto a Gaussian by matching first two moments, (3) update tᵢ accordingly. EP converges to a Gaussian approximation whose moments match the true posterior's local moments — more accurate than Laplace, especially for unbalanced class distributions.

```python
import numpy as np
from scipy.special import expit as sigmoid, ndtr
from scipy.stats import norm
import matplotlib.pyplot as plt

# Simple comparison: Laplace vs Gaussian CDF likelihood (probit) predictive
def probit_laplace_pred(f_test_mean, f_test_var):
    """Predictive probability using Laplace approx with probit likelihood."""
    kappa = 1.0 / np.sqrt(1.0 + np.pi * f_test_var / 8.0)
    return ndtr(kappa * f_test_mean)

def probit_ep_pred(f_test_mean, f_test_var):
    """EP predictive: integrate probit against N(f_test_mean, f_test_var)."""
    # Exact for probit: p(y=1|x*) = Φ(μ/sqrt(1+σ²))
    return ndtr(f_test_mean / np.sqrt(1.0 + f_test_var))

latent_means = np.linspace(-3, 3, 200)
for latent_var in [0.5, 1.0, 2.0]:
    lap = probit_laplace_pred(latent_means, latent_var)
    ep  = probit_ep_pred(latent_means,  latent_var)
    diff = np.max(np.abs(lap - ep))
    print(f'Latent var={latent_var}: max|Laplace-EP| = {diff:.4f}')

fig, ax = plt.subplots(figsize=(8,4))
for v, col in [(0.5,'blue'),(2.0,'red')]:
    x = latent_means
    ax.plot(x, probit_laplace_pred(x,v), ls='--', color=col, label=f'Laplace σ²={v}')
    ax.plot(x, probit_ep_pred(x,v),      ls='-',  color=col, label=f'EP σ²={v}')
ax.set_xlabel('Latent mean'); ax.set_ylabel('P(y=+1)')
ax.legend(ncol=2); ax.set_title('Laplace vs EP Predictive Probabilities (probit likelihood)')
plt.tight_layout(); plt.show()
```

> **EP Is More Accurate Than Laplace for Classification**: Laplace approximation matches the posterior mode (MAP) and curvature — it can be over-confident when the true posterior is skewed. EP matches first and second moments of the local likelihood approximations and is typically more accurate, especially for small datasets or imbalanced classes. For most practical GP classification tasks, use EP or variational inference over Laplace.

## Multi-Class GP Classification

For K > 2 classes, the likelihood p(y=k|f) = softmax(f)_k requires K latent GP functions — one per class. The posterior remains intractable. Common approaches: (1) One-vs-Rest with binary GP classifiers (simple but inconsistent probabilities), (2) Softmax likelihood with Laplace or EP (consistent but complex), (3) Dirichlet likelihood GP (naturally compositional). GPyTorch supports DirichletClassificationLikelihood for scalable multi-class GP classification.

```python
import torch
import gpytorch
import numpy as np
from sklearn.datasets import load_iris
from sklearn.preprocessing import StandardScaler
from sklearn.model_selection import train_test_split

data = load_iris()
X_np, y_np = data.data[:,:2], data.target  # first 2 features for viz
scaler = StandardScaler()
X_np = scaler.fit_transform(X_np)
X_tr, X_te, y_tr, y_te = train_test_split(X_np, y_np, test_size=0.2, random_state=42)

train_x = torch.tensor(X_tr, dtype=torch.float32)
train_y = torch.tensor(y_tr, dtype=torch.long)
test_x  = torch.tensor(X_te, dtype=torch.float32)

likelihood = gpytorch.likelihoods.DirichletClassificationLikelihood(
    train_y, learn_additional_noise=True)

class MulticlassGP(gpytorch.models.ExactGP):
    def __init__(self, train_x, train_y, likelihood):
        super().__init__(train_x, train_y, likelihood)
        self.mean_module  = gpytorch.means.ConstantMean(batch_shape=torch.Size([3]))
        self.covar_module = gpytorch.kernels.ScaleKernel(
            gpytorch.kernels.RBFKernel(batch_shape=torch.Size([3])),
            batch_shape=torch.Size([3]))
    def forward(self, x):
        return gpytorch.distributions.MultivariateNormal(
            self.mean_module(x), self.covar_module(x))

model = MulticlassGP(train_x, likelihood.transformed_targets, likelihood)
optimizer = torch.optim.Adam(model.parameters(), lr=0.1)
mll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model)
model.train(); likelihood.train()
for _ in range(100):
    optimizer.zero_grad()
    (-mll(model(train_x), likelihood.transformed_targets)).backward()
    optimizer.step()
print('Dirichlet GP multi-class model trained on Iris (3 classes).')
```

## Key Takeaways

GP classification requires approximations because the sigmoid/softmax likelihood makes the posterior non-Gaussian. Laplace approximation is simple and fast: Gaussian centred at the MAP with curvature from the Hessian W = diag(πᵢ(1−πᵢ)). EP iteratively matches moments of local likelihood approximations and is more accurate than Laplace. Variational inference (SVGP) scales to large datasets via inducing points. Multi-class classification uses K latent GPs with Dirichlet or softmax likelihood.

- GP classification: p(y|f)=σ(yf) is non-Gaussian → approximate posterior required
- Laplace: Gaussian at MAP; W=diag(π(1-π)) from sigmoid; IRLS Newton steps
- EP: cavity distribution update, moment-matching; more accurate than Laplace
- Variational (SVGP): ELBO optimisation with m inducing points; O(nm²) cost
- Multi-class: K latent GPs + softmax/Dirichlet likelihood; one-vs-rest as baseline
- GPyTorch: DirichletClassificationLikelihood for scalable multi-class GP

> **Predictive Probability vs Latent Mean**: The GP classifier outputs a latent mean f*(x) ∈ ℝ. The predictive probability P(y=+1|x*) requires integrating σ(f*) over the posterior uncertainty in f*. This integral is approximated as σ(κ·μ*) where κ=(1+πσ²*/8)^{-1/2} in the Laplace case. Ignoring posterior uncertainty and using σ(μ*) alone produces over-confident probabilities.

---

