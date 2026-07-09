---
title: "Expectation, Variance, Covariance, and Correlation"
slug: "expectation-variance-covariance"
description: "Expectation via LOTUS, variance and standard deviation, covariance and correlation, covariance matrices and PSD properties, conditional expectation, and the law of total variance."
tags: ["probability", "statistics", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Expectation, variance, and covariance are the fundamental second-order statistics that characterise probability distributions in ML. They appear everywhere: loss functions are expected costs, weight initialisation strategies target specific variance levels, feature normalisation controls first and second moments, PCA extracts eigenvectors of the covariance matrix, and batch normalisation explicitly whitens activations. Understanding these quantities rigorously — including the covariance matrix's positive semi-definite property, conditional expectation, and the law of total variance — is essential for designing training procedures and diagnosing instabilities."}, {"type": "heading", "level": 2, "content": "Expectation"}, {"type": "text", "content": "The expectation (expected value) of a random variable X is:\n\nDiscrete: E[X] = Σₓ x × P(X = x)\nContinuous: E[X] = ∫₋∞^∞ x × f(x) dx   where f is the PDF\n\nKey properties:\n- Linearity: E[aX + bY] = a E[X] + b E[Y] (holds regardless of dependence between X and Y)\n- LOTUS (Law of the Unconscious Statistician): E[g(X)] = Σₓ g(x) P(X=x) or ∫ g(x) f(x) dx — no need to find the distribution of g(X) separately\n- E[constant] = constant\n- If X and Y are independent: E[XY] = E[X] E[Y]\n\nLOTUS is particularly useful in ML: E[‖X‖²] = ∫ ‖x‖² f(x) dx directly gives the expected squared norm without computing the distribution of ‖X‖²."}, {"type": "heading", "level": 2, "content": "Variance and Standard Deviation"}, {"type": "text", "content": "The variance measures spread around the mean:\n\nVar(X) = E[(X − μ)²] = E[X²] − (E[X])²   where μ = E[X]\n\nThe second form (computational formula) is useful for calculation but numerically unstable when the mean is large (catastrophic cancellation). Use Welford's algorithm for online computation.\n\nStandard deviation: σ = √Var(X) — same units as X.\n\nKey properties:\n- Var(aX + b) = a² Var(X) (shift doesn't change variance; scale squares)\n- Var(X + Y) = Var(X) + Var(Y) + 2 Cov(X, Y)\n- Var(X + Y) = Var(X) + Var(Y)  if X and Y are independent\n- Sample variance: s² = (1/(n−1)) Σ(xᵢ − x̄)² (Bessel's correction for unbiasedness)\n\nBessel's correction n−1 instead of n arises because the sample mean x̄ already uses the data, consuming one degree of freedom. The MLE estimate uses n (biased but minimum MSE for Gaussian)."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy import stats\n\nrng = np.random.default_rng(42)\n\n# Theoretical vs sample moments for Gaussian N(3, 4) [mean=3, var=4]\nmu_true, sigma_true = 3.0, 2.0\nn = 10_000\nX = rng.normal(mu_true, sigma_true, n)\n\nprint(\"=== Gaussian N(3, 4) moments ===\")\nprint(f\"Theoretical mean:     {mu_true:.4f}\")\nprint(f\"Sample mean:          {np.mean(X):.4f}\")\nprint(f\"Theoretical variance: {sigma_true**2:.4f}\")\nprint(f\"Sample variance:      {np.var(X, ddof=1):.4f}  (Bessel's correction)\")\nprint(f\"Biased variance:      {np.var(X, ddof=0):.4f}  (MLE, n denominator)\")\nprint(f\"Sample std dev:       {np.std(X, ddof=1):.4f}\")\n\n# LOTUS: E[X^2] and E[exp(X)]\nprint(\"\\n=== LOTUS examples ===\")\nprint(f\"E[X^2] theoretical:   {mu_true**2 + sigma_true**2:.4f}  (mu^2 + sigma^2)\")\nprint(f\"E[X^2] sample:        {np.mean(X**2):.4f}\")\n# E[exp(X)] for X~N(mu, sigma^2) = exp(mu + sigma^2/2)  [log-normal formula]\nprint(f\"E[exp(X)] theoretical:{np.exp(mu_true + sigma_true**2/2):.4f}  (log-normal MGF)\")\nprint(f\"E[exp(X)] sample:     {np.mean(np.exp(X)):.4f}\")\n\n# Variance of sum: Var(X+Y) vs Var(X) + Var(Y) + 2Cov(X,Y)\nY = 0.7 * X + rng.normal(0, 1.5, n)   # Y is correlated with X\nS = X + Y\nprint(\"\\n=== Variance of Sum ===\")\nprint(f\"Var(X): {np.var(X, ddof=1):.4f}\")\nprint(f\"Var(Y): {np.var(Y, ddof=1):.4f}\")\ncov_xy = np.cov(X, Y, ddof=1)[0, 1]\nprint(f\"2*Cov(X,Y): {2*cov_xy:.4f}\")\nprint(f\"Var(X)+Var(Y)+2Cov: {np.var(X, ddof=1)+np.var(Y, ddof=1)+2*cov_xy:.4f}\")\nprint(f\"Var(X+Y) direct:     {np.var(S, ddof=1):.4f}\")"}, {"type": "heading", "level": 2, "content": "Covariance, Correlation, and Covariance Matrices"}, {"type": "text", "content": "Covariance measures linear dependence between two random variables:\n\nCov(X, Y) = E[(X − μₓ)(Y − μᵧ)] = E[XY] − E[X] E[Y]\n\nCov(X, X) = Var(X). Cov(X, Y) = 0 for independent X, Y (but not conversely in general).\n\nCorrelation normalises covariance to [−1, 1]:\n\nρ(X, Y) = Cov(X, Y) / (σₓ σᵧ)\n\nρ = 1 means perfect positive linear dependence; ρ = −1 means perfect negative; ρ = 0 means uncorrelated (not necessarily independent).\n\nFor a d-dimensional random vector X = (X₁, …, Xd)^T, the covariance matrix Σ ∈ ℝ^{d×d} has entries:\n\nΣᵢⱼ = Cov(Xᵢ, Xⱼ)\n\nKey properties of Σ:\n- Symmetric: Σ = Σ^T (since Cov(X,Y) = Cov(Y,X))\n- Positive semi-definite (PSD): v^T Σ v ≥ 0 for all v (variance of any linear combination is non-negative)\n- Diagonal when components are uncorrelated\n- The precision matrix Λ = Σ⁻¹ (when it exists) appears in the Gaussian exponent: −½(x−μ)^T Λ (x−μ)"}, {"type": "code", "language": "python", "content": "import numpy as np\nimport scipy.linalg\n\n# Covariance matrix: construction and PSD verification\nrng = np.random.default_rng(42)\nd, n = 4, 1000\nA = rng.standard_normal((d, d))\nSigma_true = A @ A.T / d + 0.1 * np.eye(d)  # guaranteed PSD\n\n# Sample covariance matrix\nX = rng.multivariate_normal(mean=np.zeros(d), cov=Sigma_true, size=n)\nSigma_hat = np.cov(X.T, ddof=1)   # (d, d) sample covariance\n\nprint(\"=== Covariance Matrix ===\")\nprint(f\"True Sigma (diagonal):\\n{np.diag(Sigma_true).round(3)}\")\nprint(f\"Sample Sigma (diagonal):\\n{np.diag(Sigma_hat).round(3)}\")\n\n# Verify PSD: all eigenvalues >= 0\neigenvalues = np.linalg.eigvalsh(Sigma_hat)\nprint(f\"\\nEigenvalues of Sigma_hat: {eigenvalues.round(4)}\")\nprint(f\"All eigenvalues >= 0: {np.all(eigenvalues >= -1e-10)}\")  # PSD\n\n# Correlation matrix from covariance\nD = np.diag(1.0 / np.sqrt(np.diag(Sigma_hat)))\nCorr = D @ Sigma_hat @ D\nprint(f\"\\nCorrelation matrix diagonal (should be 1s): {np.diag(Corr).round(4)}\")\nprint(f\"Corr[0,1] = {Corr[0,1]:.4f}\")\n\n# Precision matrix (inverse covariance)\nLambda = np.linalg.inv(Sigma_hat)\nprint(f\"\\nPrecision matrix (top-left 2x2):\\n{Lambda[:2,:2].round(3)}\")\n\n# Verify Sigma @ Lambda = I\nprod = Sigma_hat @ Lambda\nprint(f\"Sigma @ Lambda = I? max_off_diag={np.max(np.abs(prod - np.eye(d))):.2e}\")"}, {"type": "heading", "level": 2, "content": "Conditional Expectation"}, {"type": "text", "content": "The conditional expectation E[Y|X] is a function of X that gives the expected value of Y given the observed value of X:\n\nE[Y|X = x] = ∫ y f(y|x) dy\n\nKey properties:\n- Tower property (law of iterated expectation): E[E[Y|X]] = E[Y]\n- E[g(X) Y | X] = g(X) E[Y|X]  (take-out-what-is-known)\n- E[Y|X] is the best predictor of Y given X in the mean squared error sense: argmin_{f(X)} E[(Y − f(X))²] = E[Y|X]\n\nThe tower property says: first compute the conditional expectation (given X), then average over X — the result equals the unconditional expectation. This is why Monte Carlo estimates are unbiased: E_x[f(x)] = E[f(X)] when x ~ p(X)."}, {"type": "heading", "level": 2, "content": "Law of Total Variance"}, {"type": "text", "content": "The law of total variance (Eve's law) decomposes variance into explained and unexplained components:\n\nVar(Y) = E[Var(Y|X)] + Var(E[Y|X])\n\nInterpretation:\n- Var(Y|X): variance of Y within each group defined by X (unexplained variance)\n- E[Var(Y|X)]: average within-group variance (what remains unpredictable even knowing X)\n- Var(E[Y|X]): variance of the conditional mean across groups (between-group variance)\n- Var(E[Y|X]): the reduction in variance achieved by knowing X — the explained variance\n\nIn ML: R² (coefficient of determination) = Var(E[Y|X]) / Var(Y) = fraction of variance explained by the model. The law of total variance also underlies the bias-variance decomposition of MSE: E[(Y − ŷ)²] = Bias² + Variance + Noise."}, {"type": "code", "language": "python", "content": "import numpy as np\n\nrng = np.random.default_rng(42)\nn = 100_000\n\n# Law of total variance demonstration\n# Y depends on X: Y | X=x ~ N(2x, x^2)  (mean and variance both depend on x)\nX = rng.exponential(scale=1.0, size=n)   # X ~ Exp(1)\nY = rng.normal(loc=2*X, scale=X)          # Y|X ~ N(2X, X^2)\n\n# Theoretical values\n# E[Y] = E[E[Y|X]] = E[2X] = 2*E[X] = 2*1 = 2\n# E[Var(Y|X)] = E[X^2] = Var(X) + E[X]^2 = 1 + 1 = 2\n# Var(E[Y|X]) = Var(2X) = 4*Var(X) = 4*1 = 4\n# Var(Y) = E[Var(Y|X)] + Var(E[Y|X]) = 2 + 4 = 6\n\nE_Y_given_X = 2 * X       # E[Y|X=x] = 2x\nVar_Y_given_X = X**2       # Var(Y|X=x) = x^2 (std dev = x)\n\nprint(\"=== Law of Total Variance ===\")\nprint(f\"E[Y] theoretical:        2.0000\")\nprint(f\"E[Y] sample:             {np.mean(Y):.4f}\")\nprint()\nprint(f\"E[Var(Y|X)] theoretical: 2.0000\")\nprint(f\"E[Var(Y|X)] sample:      {np.mean(Var_Y_given_X):.4f}\")\nprint()\nprint(f\"Var(E[Y|X]) theoretical: 4.0000\")\nprint(f\"Var(E[Y|X]) sample:      {np.var(E_Y_given_X):.4f}\")\nprint()\nprint(f\"Var(Y) theoretical:      6.0000\")\nprint(f\"Var(Y) sample:           {np.var(Y):.4f}\")\nprint(f\"Sum check:               {np.mean(Var_Y_given_X) + np.var(E_Y_given_X):.4f}\")\n\n# Fraction of variance explained (R-squared analog)\nR2 = np.var(E_Y_given_X) / np.var(Y)\nprint(f\"\\nFraction of Var(Y) explained by X: {R2:.4f}\")\nprint(f\"(= Var(E[Y|X]) / Var(Y) = 4/6 = {4/6:.4f})\")"}, {"type": "heading", "level": 2, "content": "ML and AI Connections"}, {"type": "text", "content": "Second-order statistics pervade ML theory and practice:\n\n- **Weight initialisation**: He initialisation for ReLU sets Var(W) = 2/fan_in to preserve variance across layers. Xavier/Glorot targets Var(W) = 2/(fan_in + fan_out). Both derive from the requirement Var(output) = Var(input).\n\n- **Batch normalisation**: explicitly sets E[activations] = 0 and Var(activations) = 1 at each layer (then rescales with learnable γ, β). This whitens activations, reducing covariate shift.\n\n- **PCA**: extracts eigenvectors of the sample covariance matrix, ranked by eigenvalue (variance). The top-k eigenvectors capture the k dimensions of maximum variance.\n\n- **Kalman filter**: maintains a Gaussian posterior with mean (conditional expectation) and covariance (conditional variance) that are updated with each new observation.\n\n- **Gaussian process regression**: posterior mean is the MMSE estimate E[f(x*)|data]; posterior variance quantifies uncertainty."}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "Common mistakes with second-order statistics:\n\n1. **Using n instead of n−1 for sample variance**: the MLE estimate (n denominator) underestimates the true variance, especially for small n. Use ddof=1 in numpy.\n\n2. **Computing variance as E[X²] − E[X]² for large means**: catastrophic cancellation when both terms are large and nearly equal. Use Welford's algorithm or centre the data first.\n\n3. **Treating zero correlation as independence**: zero covariance ≠ independence except for jointly Gaussian variables. Example: Y = X², where X ~ N(0,1): Cov(X, Y) = E[X³] = 0 but X and Y are highly dependent.\n\n4. **Assuming covariance matrix is invertible**: singular covariance (rank deficient) occurs when features are perfectly correlated or n < d. Use pseudoinverse or add regularisation λI."}, {"type": "callout", "variant": "tip", "title": "PSD and the Cholesky Decomposition", "content": "Any valid covariance matrix Σ is positive semi-definite (PSD). The Cholesky decomposition Σ = L L^T (where L is lower triangular) exists iff Σ is PSD. It is the efficient way to: (1) sample from N(μ,Σ) as μ + L z where z ~ N(0,I); (2) solve Σ x = b as two triangular solves; (3) compute log det(Σ) = 2 Σ log(Lᵢᵢ) in O(d²) instead of O(d³). Always use Cholesky over direct matrix inverse for covariance operations."}, {"type": "table", "headers": ["Quantity", "Definition", "Key Property", "ML Application"], "rows": [["E[X]", "Σ x p(x) or ∫ x f(x) dx", "Linearity; E[aX+bY]=aE[X]+bE[Y]", "Loss is expected cost"], ["Var(X)", "E[(X−μ)²]", "Var(aX)=a²Var(X)", "Weight init, batch norm"], ["Cov(X,Y)", "E[(X−μₓ)(Y−μᵧ)]", "0 for independent; Σᵢᵢ=Var(Xᵢ)", "Feature correlation"], ["Corr(X,Y)", "Cov(X,Y)/(σₓσᵧ)", "∈ [−1,1]; scale-invariant", "Feature selection"], ["Covariance matrix Σ", "Σᵢⱼ=Cov(Xᵢ,Xⱼ)", "Always PSD, symmetric", "PCA, GPs, Kalman"], ["E[Y|X]", "Best MSE predictor of Y given X", "Tower property: E[E[Y|X]]=E[Y]", "Regression target"], ["Var(Y)", "E[Var(Y|X)]+Var(E[Y|X])", "Total=within+between", "Bias-variance tradeoff"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["E[X] is the probability-weighted average; linearity E[aX+bY]=aE[X]+bE[Y] holds regardless of dependence between X and Y.", "LOTUS: E[g(X)] = ∫ g(x) f(x) dx — no need to find the distribution of g(X) to compute its expectation.", "Var(X) = E[X²] − E[X]²; sample variance uses ddof=1 (Bessel's correction) for unbiasedness.", "Cov(X,Y) = E[XY] − E[X]E[Y]; zero covariance does not imply independence except for jointly Gaussian variables.", "Any covariance matrix Σ is symmetric and positive semi-definite (PSD) — all eigenvalues ≥ 0; use Cholesky for efficient sampling and log-determinant computation.", "The conditional expectation E[Y|X] is the best MSE predictor of Y given X; the tower property E[E[Y|X]]=E[Y] is the foundation of Monte Carlo unbiasedness.", "Law of total variance: Var(Y)=E[Var(Y|X)]+Var(E[Y|X]) — total variance = within-group + between-group; R² = Var(E[Y|X])/Var(Y) is the fraction explained."]}]"
---
# Expectation, Variance, Covariance, and Correlation

Expectation, variance, and covariance are the fundamental second-order statistics that characterise probability distributions in ML. They appear everywhere: loss functions are expected costs, weight initialisation strategies target specific variance levels, feature normalisation controls first and second moments, PCA extracts eigenvectors of the covariance matrix, and batch normalisation explicitly whitens activations. Understanding these quantities rigorously — including the covariance matrix's positive semi-definite property, conditional expectation, and the law of total variance — is essential for designing training procedures and diagnosing instabilities.

## Expectation

The expectation (expected value) of a random variable X is:

Discrete: E[X] = Σₓ x × P(X = x)
Continuous: E[X] = ∫₋∞^∞ x × f(x) dx   where f is the PDF

Key properties:
- Linearity: E[aX + bY] = a E[X] + b E[Y] (holds regardless of dependence between X and Y)
- LOTUS (Law of the Unconscious Statistician): E[g(X)] = Σₓ g(x) P(X=x) or ∫ g(x) f(x) dx — no need to find the distribution of g(X) separately
- E[constant] = constant
- If X and Y are independent: E[XY] = E[X] E[Y]

LOTUS is particularly useful in ML: E[‖X‖²] = ∫ ‖x‖² f(x) dx directly gives the expected squared norm without computing the distribution of ‖X‖².

## Variance and Standard Deviation

The variance measures spread around the mean:

Var(X) = E[(X − μ)²] = E[X²] − (E[X])²   where μ = E[X]

The second form (computational formula) is useful for calculation but numerically unstable when the mean is large (catastrophic cancellation). Use Welford's algorithm for online computation.

Standard deviation: σ = √Var(X) — same units as X.

Key properties:
- Var(aX + b) = a² Var(X) (shift doesn't change variance; scale squares)
- Var(X + Y) = Var(X) + Var(Y) + 2 Cov(X, Y)
- Var(X + Y) = Var(X) + Var(Y)  if X and Y are independent
- Sample variance: s² = (1/(n−1)) Σ(xᵢ − x̄)² (Bessel's correction for unbiasedness)

Bessel's correction n−1 instead of n arises because the sample mean x̄ already uses the data, consuming one degree of freedom. The MLE estimate uses n (biased but minimum MSE for Gaussian).

```python
import numpy as np
from scipy import stats

rng = np.random.default_rng(42)

# Theoretical vs sample moments for Gaussian N(3, 4) [mean=3, var=4]
mu_true, sigma_true = 3.0, 2.0
n = 10_000
X = rng.normal(mu_true, sigma_true, n)

print("=== Gaussian N(3, 4) moments ===")
print(f"Theoretical mean:     {mu_true:.4f}")
print(f"Sample mean:          {np.mean(X):.4f}")
print(f"Theoretical variance: {sigma_true**2:.4f}")
print(f"Sample variance:      {np.var(X, ddof=1):.4f}  (Bessel's correction)")
print(f"Biased variance:      {np.var(X, ddof=0):.4f}  (MLE, n denominator)")
print(f"Sample std dev:       {np.std(X, ddof=1):.4f}")

# LOTUS: E[X^2] and E[exp(X)]
print("\n=== LOTUS examples ===")
print(f"E[X^2] theoretical:   {mu_true**2 + sigma_true**2:.4f}  (mu^2 + sigma^2)")
print(f"E[X^2] sample:        {np.mean(X**2):.4f}")
# E[exp(X)] for X~N(mu, sigma^2) = exp(mu + sigma^2/2)  [log-normal formula]
print(f"E[exp(X)] theoretical:{np.exp(mu_true + sigma_true**2/2):.4f}  (log-normal MGF)")
print(f"E[exp(X)] sample:     {np.mean(np.exp(X)):.4f}")

# Variance of sum: Var(X+Y) vs Var(X) + Var(Y) + 2Cov(X,Y)
Y = 0.7 * X + rng.normal(0, 1.5, n)   # Y is correlated with X
S = X + Y
print("\n=== Variance of Sum ===")
print(f"Var(X): {np.var(X, ddof=1):.4f}")
print(f"Var(Y): {np.var(Y, ddof=1):.4f}")
cov_xy = np.cov(X, Y, ddof=1)[0, 1]
print(f"2*Cov(X,Y): {2*cov_xy:.4f}")
print(f"Var(X)+Var(Y)+2Cov: {np.var(X, ddof=1)+np.var(Y, ddof=1)+2*cov_xy:.4f}")
print(f"Var(X+Y) direct:     {np.var(S, ddof=1):.4f}")
```

## Covariance, Correlation, and Covariance Matrices

Covariance measures linear dependence between two random variables:

Cov(X, Y) = E[(X − μₓ)(Y − μᵧ)] = E[XY] − E[X] E[Y]

Cov(X, X) = Var(X). Cov(X, Y) = 0 for independent X, Y (but not conversely in general).

Correlation normalises covariance to [−1, 1]:

ρ(X, Y) = Cov(X, Y) / (σₓ σᵧ)

ρ = 1 means perfect positive linear dependence; ρ = −1 means perfect negative; ρ = 0 means uncorrelated (not necessarily independent).

For a d-dimensional random vector X = (X₁, …, Xd)^T, the covariance matrix Σ ∈ ℝ^{d×d} has entries:

Σᵢⱼ = Cov(Xᵢ, Xⱼ)

Key properties of Σ:
- Symmetric: Σ = Σ^T (since Cov(X,Y) = Cov(Y,X))
- Positive semi-definite (PSD): v^T Σ v ≥ 0 for all v (variance of any linear combination is non-negative)
- Diagonal when components are uncorrelated
- The precision matrix Λ = Σ⁻¹ (when it exists) appears in the Gaussian exponent: −½(x−μ)^T Λ (x−μ)

```python
import numpy as np
import scipy.linalg

# Covariance matrix: construction and PSD verification
rng = np.random.default_rng(42)
d, n = 4, 1000
A = rng.standard_normal((d, d))
Sigma_true = A @ A.T / d + 0.1 * np.eye(d)  # guaranteed PSD

# Sample covariance matrix
X = rng.multivariate_normal(mean=np.zeros(d), cov=Sigma_true, size=n)
Sigma_hat = np.cov(X.T, ddof=1)   # (d, d) sample covariance

print("=== Covariance Matrix ===")
print(f"True Sigma (diagonal):\n{np.diag(Sigma_true).round(3)}")
print(f"Sample Sigma (diagonal):\n{np.diag(Sigma_hat).round(3)}")

# Verify PSD: all eigenvalues >= 0
eigenvalues = np.linalg.eigvalsh(Sigma_hat)
print(f"\nEigenvalues of Sigma_hat: {eigenvalues.round(4)}")
print(f"All eigenvalues >= 0: {np.all(eigenvalues >= -1e-10)}")  # PSD

# Correlation matrix from covariance
D = np.diag(1.0 / np.sqrt(np.diag(Sigma_hat)))
Corr = D @ Sigma_hat @ D
print(f"\nCorrelation matrix diagonal (should be 1s): {np.diag(Corr).round(4)}")
print(f"Corr[0,1] = {Corr[0,1]:.4f}")

# Precision matrix (inverse covariance)
Lambda = np.linalg.inv(Sigma_hat)
print(f"\nPrecision matrix (top-left 2x2):\n{Lambda[:2,:2].round(3)}")

# Verify Sigma @ Lambda = I
prod = Sigma_hat @ Lambda
print(f"Sigma @ Lambda = I? max_off_diag={np.max(np.abs(prod - np.eye(d))):.2e}")
```

## Conditional Expectation

The conditional expectation E[Y|X] is a function of X that gives the expected value of Y given the observed value of X:

E[Y|X = x] = ∫ y f(y|x) dy

Key properties:
- Tower property (law of iterated expectation): E[E[Y|X]] = E[Y]
- E[g(X) Y | X] = g(X) E[Y|X]  (take-out-what-is-known)
- E[Y|X] is the best predictor of Y given X in the mean squared error sense: argmin_{f(X)} E[(Y − f(X))²] = E[Y|X]

The tower property says: first compute the conditional expectation (given X), then average over X — the result equals the unconditional expectation. This is why Monte Carlo estimates are unbiased: E_x[f(x)] = E[f(X)] when x ~ p(X).

## Law of Total Variance

The law of total variance (Eve's law) decomposes variance into explained and unexplained components:

Var(Y) = E[Var(Y|X)] + Var(E[Y|X])

Interpretation:
- Var(Y|X): variance of Y within each group defined by X (unexplained variance)
- E[Var(Y|X)]: average within-group variance (what remains unpredictable even knowing X)
- Var(E[Y|X]): variance of the conditional mean across groups (between-group variance)
- Var(E[Y|X]): the reduction in variance achieved by knowing X — the explained variance

In ML: R² (coefficient of determination) = Var(E[Y|X]) / Var(Y) = fraction of variance explained by the model. The law of total variance also underlies the bias-variance decomposition of MSE: E[(Y − ŷ)²] = Bias² + Variance + Noise.

```python
import numpy as np

rng = np.random.default_rng(42)
n = 100_000

# Law of total variance demonstration
# Y depends on X: Y | X=x ~ N(2x, x^2)  (mean and variance both depend on x)
X = rng.exponential(scale=1.0, size=n)   # X ~ Exp(1)
Y = rng.normal(loc=2*X, scale=X)          # Y|X ~ N(2X, X^2)

# Theoretical values
# E[Y] = E[E[Y|X]] = E[2X] = 2*E[X] = 2*1 = 2
# E[Var(Y|X)] = E[X^2] = Var(X) + E[X]^2 = 1 + 1 = 2
# Var(E[Y|X]) = Var(2X) = 4*Var(X) = 4*1 = 4
# Var(Y) = E[Var(Y|X)] + Var(E[Y|X]) = 2 + 4 = 6

E_Y_given_X = 2 * X       # E[Y|X=x] = 2x
Var_Y_given_X = X**2       # Var(Y|X=x) = x^2 (std dev = x)

print("=== Law of Total Variance ===")
print(f"E[Y] theoretical:        2.0000")
print(f"E[Y] sample:             {np.mean(Y):.4f}")
print()
print(f"E[Var(Y|X)] theoretical: 2.0000")
print(f"E[Var(Y|X)] sample:      {np.mean(Var_Y_given_X):.4f}")
print()
print(f"Var(E[Y|X]) theoretical: 4.0000")
print(f"Var(E[Y|X]) sample:      {np.var(E_Y_given_X):.4f}")
print()
print(f"Var(Y) theoretical:      6.0000")
print(f"Var(Y) sample:           {np.var(Y):.4f}")
print(f"Sum check:               {np.mean(Var_Y_given_X) + np.var(E_Y_given_X):.4f}")

# Fraction of variance explained (R-squared analog)
R2 = np.var(E_Y_given_X) / np.var(Y)
print(f"\nFraction of Var(Y) explained by X: {R2:.4f}")
print(f"(= Var(E[Y|X]) / Var(Y) = 4/6 = {4/6:.4f})")
```

## ML and AI Connections

Second-order statistics pervade ML theory and practice:

- **Weight initialisation**: He initialisation for ReLU sets Var(W) = 2/fan_in to preserve variance across layers. Xavier/Glorot targets Var(W) = 2/(fan_in + fan_out). Both derive from the requirement Var(output) = Var(input).

- **Batch normalisation**: explicitly sets E[activations] = 0 and Var(activations) = 1 at each layer (then rescales with learnable γ, β). This whitens activations, reducing covariate shift.

- **PCA**: extracts eigenvectors of the sample covariance matrix, ranked by eigenvalue (variance). The top-k eigenvectors capture the k dimensions of maximum variance.

- **Kalman filter**: maintains a Gaussian posterior with mean (conditional expectation) and covariance (conditional variance) that are updated with each new observation.

- **Gaussian process regression**: posterior mean is the MMSE estimate E[f(x*)|data]; posterior variance quantifies uncertainty.

## Pitfalls

Common mistakes with second-order statistics:

1. **Using n instead of n−1 for sample variance**: the MLE estimate (n denominator) underestimates the true variance, especially for small n. Use ddof=1 in numpy.

2. **Computing variance as E[X²] − E[X]² for large means**: catastrophic cancellation when both terms are large and nearly equal. Use Welford's algorithm or centre the data first.

3. **Treating zero correlation as independence**: zero covariance ≠ independence except for jointly Gaussian variables. Example: Y = X², where X ~ N(0,1): Cov(X, Y) = E[X³] = 0 but X and Y are highly dependent.

4. **Assuming covariance matrix is invertible**: singular covariance (rank deficient) occurs when features are perfectly correlated or n < d. Use pseudoinverse or add regularisation λI.

> **TIP: PSD and the Cholesky Decomposition**
>
> Any valid covariance matrix Σ is positive semi-definite (PSD). The Cholesky decomposition Σ = L L^T (where L is lower triangular) exists iff Σ is PSD. It is the efficient way to: (1) sample from N(μ,Σ) as μ + L z where z ~ N(0,I); (2) solve Σ x = b as two triangular solves; (3) compute log det(Σ) = 2 Σ log(Lᵢᵢ) in O(d²) instead of O(d³). Always use Cholesky over direct matrix inverse for covariance operations.

| Quantity | Definition | Key Property | ML Application |
| --- | --- | --- | --- |
| E[X] | Σ x p(x) or ∫ x f(x) dx | Linearity; E[aX+bY]=aE[X]+bE[Y] | Loss is expected cost |
| Var(X) | E[(X−μ)²] | Var(aX)=a²Var(X) | Weight init, batch norm |
| Cov(X,Y) | E[(X−μₓ)(Y−μᵧ)] | 0 for independent; Σᵢᵢ=Var(Xᵢ) | Feature correlation |
| Corr(X,Y) | Cov(X,Y)/(σₓσᵧ) | ∈ [−1,1]; scale-invariant | Feature selection |
| Covariance matrix Σ | Σᵢⱼ=Cov(Xᵢ,Xⱼ) | Always PSD, symmetric | PCA, GPs, Kalman |
| E[Y|X] | Best MSE predictor of Y given X | Tower property: E[E[Y|X]]=E[Y] | Regression target |
| Var(Y) | E[Var(Y|X)]+Var(E[Y|X]) | Total=within+between | Bias-variance tradeoff |

---

## Key Takeaways

- E[X] is the probability-weighted average; linearity E[aX+bY]=aE[X]+bE[Y] holds regardless of dependence between X and Y.
- LOTUS: E[g(X)] = ∫ g(x) f(x) dx — no need to find the distribution of g(X) to compute its expectation.
- Var(X) = E[X²] − E[X]²; sample variance uses ddof=1 (Bessel's correction) for unbiasedness.
- Cov(X,Y) = E[XY] − E[X]E[Y]; zero covariance does not imply independence except for jointly Gaussian variables.
- Any covariance matrix Σ is symmetric and positive semi-definite (PSD) — all eigenvalues ≥ 0; use Cholesky for efficient sampling and log-determinant computation.
- The conditional expectation E[Y|X] is the best MSE predictor of Y given X; the tower property E[E[Y|X]]=E[Y] is the foundation of Monte Carlo unbiasedness.
- Law of total variance: Var(Y)=E[Var(Y|X)]+Var(E[Y|X]) — total variance = within-group + between-group; R² = Var(E[Y|X])/Var(Y) is the fraction explained.
