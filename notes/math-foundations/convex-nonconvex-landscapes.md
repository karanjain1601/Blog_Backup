---
title: "Convex vs Non-Convex Loss Landscapes"
slug: "convex-nonconvex-landscapes"
description: "Deep dive into convex and non-convex loss landscapes: definitions, Jensen's inequality, strong convexity, saddle points, loss landscape visualization, mode connectivity, and the NTK regime."
tags: ["calculus", "optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The geometry of the loss landscape determines whether optimization is tractable, whether gradient descent converges, and where it converges to. Convex landscapes have a single global bowl; non-convex landscapes have ridges, valleys, saddle points, and many local minima. Understanding the difference is essential for choosing optimizers, diagnosing training failures, and reasoning about generalization."},{"type":"heading","level":2,"content":"What is a Convex Function?"},{"type":"text","content":"A function f: ℝⁿ → ℝ is convex if for all x, y in its domain and all λ ∈ [0,1]: f(λx + (1−λ)y) ≤ λf(x) + (1−λ)f(y). Geometrically, the chord connecting any two points on the graph lies above or on the graph. Equivalently (for differentiable f): f(y) ≥ f(x) + ∇f(x)ᵀ(y−x) — the function lies above all its tangent hyperplanes. For twice-differentiable f: the Hessian ∇²f(x) ⪰ 0 (positive semidefinite) everywhere."},{"type":"list","ordered":false,"items":["Convex: f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y) — chord lies above graph","Strictly convex: strict inequality for x≠y — unique minimizer","μ-strongly convex: f(y) ≥ f(x) + ∇f(x)ᵀ(y-x) + (μ/2)‖y-x‖² — quadratic lower bound guarantees unique global minimum","L-smooth: ‖∇f(x)-∇f(y)‖ ≤ L‖x-y‖ — Lipschitz gradient, controls step size"]},{"type":"callout","variant":"info","title":"Jensen\u0027s Inequality","content":"For a convex function f and any probability distribution p(x): f(E[x]) ≤ E[f(x)]. This is the functional form of convexity and underlies EM, variational inference, and the log-sum-exp bound. Equality holds iff x is constant or f is linear."},{"type":"heading","level":2,"content":"Strongly Convex Functions"},{"type":"text","content":"A μ-strongly convex function curves at least as sharply as a quadratic with curvature μ. This guarantees: (1) a unique global minimum, (2) gradient descent converges at a linear rate O((1−μ/L)ᵏ), (3) the condition number κ = L/μ controls convergence speed — smaller κ means faster convergence. Ridge regression (L2-regularized) is strongly convex even when the data matrix is rank-deficient."},{"type":"heading","level":2,"content":"Why Convexity Matters for ML"},{"type":"text","content":"Convex objectives offer algorithmic guarantees: any local minimum is a global minimum, gradient descent with appropriate step size converges, and we can certify optimality via duality. Non-convex objectives lack these guarantees — gradient descent may converge to different solutions depending on initialization, learning rate, and noise."},{"type":"table","headers":["Property","Convex","Strongly Convex","Non-Convex"],"rows":[["Definition","f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y)","f(y) ≥ f(x)+∇f(x)ᵀ(y-x)+(μ/2)‖y-x‖²","No global curvature guarantee"],["Global Minimum","Any local min is global","Unique global minimum","Multiple local minima possible"],["Hessian","∇²f ⪰ 0 everywhere","∇²f ⪰ μI everywhere","Indefinite in general"],["Examples","Linear regression, logistic regression, SVMs","Ridge regression, elastic net","Neural networks, matrix factorization"],["Optimization","GD converges to global min","GD converges, linear rate 1-μ/L","SGD/Adam, no convergence guarantee"]]},{"type":"heading","level":2,"content":"Common Convex ML Objectives"},{"type":"text","content":"Several foundational ML models have convex loss functions, which is why they can be solved reliably. Linear regression with squared loss is strongly convex when X has full column rank. Logistic regression with log-loss is convex (but not strongly convex without regularization). SVMs with hinge loss are convex QPs. Adding L2 regularization makes any of these strongly convex."},{"type":"list","ordered":false,"items":["Linear regression: f(w) = ‖Xw - y‖² — quadratic, strongly convex if X full rank","Logistic regression: f(w) = Σ log(1+exp(-yᵢwᵀxᵢ)) — convex, smooth","SVM hinge loss: f(w) = (λ/2)‖w‖² + Σmax(0,1-yᵢwᵀxᵢ) — strongly convex","Lasso: f(w) = ‖Xw-y‖² + λ‖w‖₁ — convex but non-smooth"]},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\n# Define convex and non-convex functions\ndef convex_fn(x, y):\n    \"\"\"Convex: f(x,y) = x^2 + y^2\"\"\"\n    return x**2 + y**2\n\ndef nonconvex_fn(x, y):\n    \"\"\"Non-convex: f(x,y) = sin(x)*cos(y) + 0.1*(x^2+y^2)\"\"\"\n    return np.sin(x) * np.cos(y) + 0.1 * (x**2 + y**2)\n\ndef gradient_descent(fn_grad, x0, lr=0.1, steps=50):\n    path = [x0.copy()]\n    x = x0.copy()\n    for _ in range(steps):\n        x = x - lr * fn_grad(x)\n        path.append(x.copy())\n    return np.array(path)\n\ndef grad_convex(x):\n    return 2 * x\n\ndef grad_nonconvex(x):\n    return np.array([\n        np.cos(x[0]) * np.cos(x[1]) + 0.2 * x[0],\n        -np.sin(x[0]) * np.sin(x[1]) + 0.2 * x[1]\n    ])\n\n# Run GD from multiple starts on the non-convex surface\nstarts = [np.array([3.0, 2.0]), np.array([-3.0, 2.5]), np.array([1.5, -2.0])]\npaths_nc = [gradient_descent(grad_nonconvex, s, lr=0.05) for s in starts]\n\nprint(f\"Convex fn global minimum: {convex_fn(0, 0):.4f}\")\nprint(\"Non-convex: GD converges to different minima depending on start:\")\nfor i, path in enumerate(paths_nc):\n    final = path[-1]\n    print(f\"  Start {starts[i]}: converged to {final}, f={nonconvex_fn(*final):.4f}\")"},{"type":"heading","level":2,"content":"Neural Networks Are Non-Convex"},{"type":"text","content":"Neural networks are non-convex because they compose non-linear activation functions with learned weight matrices. Even a single hidden layer with ReLU activations creates a piecewise-linear, non-convex loss surface. The non-convexity arises from weight space symmetries (permutation of neurons), the product structure of weight matrices (bilinear interactions), and non-linear activations. Critical points where ∇L=0 are classified by the Hessian: positive definite → local min, negative definite → local max, indefinite → saddle point."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.linalg import eigh\n\ndef classify_critical_point(hess_matrix):\n    \"\"\"Classify a critical point via Hessian eigenvalues.\"\"\"\n    eigenvalues, _ = eigh(hess_matrix)\n    if np.all(eigenvalues \u003e 1e-10):\n        return \"local minimum\", eigenvalues\n    elif np.all(eigenvalues \u003c -1e-10):\n        return \"local maximum\", eigenvalues\n    else:\n        return \"saddle point\", eigenvalues\n\n# Canonical saddle: f(x,y) = x^2 - y^2, Hessian = diag(2, -2)\nH_saddle = np.array([[2.0, 0.0], [0.0, -2.0]])\nkind, eigs = classify_critical_point(H_saddle)\nprint(f\"f(x,y)=x²-y²  |  Hessian eigenvalues: {eigs}  |  {kind}\")\n\n# In high dimensions, almost all critical points are saddles\nnp.random.seed(42)\nfor n_dims in [10, 100, 500]:\n    n_trials = 300\n    saddle_count = 0\n    for _ in range(n_trials):\n        # Random symmetric matrix with mixed eigenvalues\n        R = np.random.randn(n_dims, n_dims)\n        H_sym = (R + R.T) / 2\n        eigs_nd = np.linalg.eigvalsh(H_sym)\n        if np.any(eigs_nd \u003e 0) and np.any(eigs_nd \u003c 0):\n            saddle_count += 1\n    pct = 100 * saddle_count / n_trials\n    print(f\"n={n_dims:4d}: {pct:.1f}% of critical points are saddles\")\n\nprint(\"\\nDauphin et al. (2014): in high-dim non-convex functions,\")\nprint(\"critical points are overwhelmingly saddle points, not local minima.\")"},{"type":"callout","variant":"warning","title":"Saddle Points Dominate High Dimensions","content":"Dauphin et al. (2014) showed that in high-dimensional non-convex functions, nearly all critical points are saddle points rather than local minima. The probability that a random critical point is a local minimum decreases exponentially with dimension. The loss at saddle points is close to the global minimum for neural networks — escaping them (not finding the global min) is the real challenge."},{"type":"heading","level":2,"content":"Loss Landscape Visualization"},{"type":"text","content":"Directly visualizing the loss landscape of a neural network is impossible (millions of parameters), but Garipov et al. introduced filter normalization: project onto two random directions d₁, d₂ with each filter scaled to match the corresponding filter norm in the trained weights. This removes the scale ambiguity across layers and produces interpretable 2D surface plots."},{"type":"code","language":"python","content":"import numpy as np\n\ndef filter_normalize_direction(weights_list):\n    \"\"\"Create a filter-normalized random perturbation direction (Garipov et al.).\"\"\"\n    direction = []\n    for w in weights_list:\n        d = np.random.randn(*w.shape)\n        if d.ndim \u003e= 2:\n            # Normalize each filter (row) to match the weight filter norm\n            for i in range(d.shape[0]):\n                w_norm = np.linalg.norm(w[i]) + 1e-10\n                d_norm = np.linalg.norm(d[i]) + 1e-10\n                d[i] = d[i] * (w_norm / d_norm)\n        else:\n            d = d * (np.linalg.norm(w) / (np.linalg.norm(d) + 1e-10))\n        direction.append(d)\n    return direction\n\ndef landscape_grid(base_weights, dir1, dir2, loss_fn, n=25, scale=1.0):\n    \"\"\"Evaluate loss on a 2D grid around base_weights.\"\"\"\n    alphas = np.linspace(-scale, scale, n)\n    grid = np.zeros((n, n))\n    for i, a in enumerate(alphas):\n        for j, b in enumerate(alphas):\n            pw = [w + a*d1 + b*d2 for w, d1, d2 in zip(base_weights, dir1, dir2)]\n            grid[i, j] = loss_fn(pw)\n    return alphas, grid\n\nnp.random.seed(7)\nbase = [np.random.randn(8, 4) * 0.3, np.random.randn(8) * 0.1]\n\ndef quad_loss(ws):\n    return sum(np.sum(w**2) for w in ws)\n\nd1 = filter_normalize_direction(base)\nd2 = filter_normalize_direction(base)\nalphas, L = landscape_grid(base, d1, d2, quad_loss, n=20, scale=0.8)\nprint(f\"Landscape grid shape: {L.shape}\")\nprint(f\"Min loss: {L.min():.4f}  Max loss: {L.max():.4f}\")\nprint(f\"Loss at center (0,0): {L[10,10]:.4f}\")\nprint(\"Filter normalization removes scale artifacts — interpretable topology.\")"},{"type":"heading","level":2,"content":"Mode Connectivity and the NTK Regime"},{"type":"text","content":"Garipov et al. and Draxler et al. found that two SGD solutions can be connected by a low-loss path (mode connectivity). The linear interpolation between two solutions often passes through a high-loss barrier, but a curved path (e.g., Bézier curve) can maintain low loss throughout. This suggests the loss landscape has connected valleys rather than isolated minima. In the NTK (Neural Tangent Kernel) regime — infinite-width networks trained with infinitesimal learning rate — the network behaves as a linear model and the loss landscape becomes effectively convex."},{"type":"code","language":"python","content":"import numpy as np\n\ndef linear_interpolate(wa, wb, alpha):\n    \"\"\"Linearly interpolate between two weight sets.\"\"\"\n    return [(1 - alpha) * a + alpha * b for a, b in zip(wa, wb)]\n\ndef path_loss_profile(wa, wb, loss_fn, n_points=25):\n    \"\"\"Evaluate loss along the linear interpolation path.\"\"\"\n    alphas = np.linspace(0, 1, n_points)\n    return alphas, np.array([loss_fn(linear_interpolate(wa, wb, a)) for a in alphas])\n\ndef simulate_sgd(init_weights, lr=0.01, noise_scale=0.15, steps=150):\n    \"\"\"Simulate SGD with gradient noise, landing at different minima.\"\"\"\n    w = [x.copy() for x in init_weights]\n    for _ in range(steps):\n        w = [x - lr * (2 * x + noise_scale * np.random.randn(*x.shape)) for x in w]\n    return w\n\nnp.random.seed(0)\ninit = [np.random.randn(6, 6) * 1.5, np.random.randn(6) * 1.5]\nmodel_a = simulate_sgd(init, lr=0.02, noise_scale=0.3)\nmodel_b = simulate_sgd(init, lr=0.02, noise_scale=0.3)\n\ndef loss_fn(ws):\n    return sum(np.sum(w**2) for w in ws)\n\nalphas, losses = path_loss_profile(model_a, model_b, loss_fn)\nmid = losses[len(losses) // 2]\nend_avg = (losses[0] + losses[-1]) / 2\nbarrier = mid - end_avg\nprint(f\"Model A loss: {losses[0]:.4f}\")\nprint(f\"Model B loss: {losses[-1]:.4f}\")\nprint(f\"Midpoint loss: {mid:.4f}\")\nprint(f\"Loss barrier (mid - avg endpoints): {barrier:.4f}\")\nprint(\"Low barrier =\u003e mode connectivity; models share the same loss basin.\")"},{"type":"list","ordered":false,"items":["NTK regime: infinite-width networks trained with gradient flow → loss is convex in function space","Finite-width networks leave the NTK regime quickly; practical landscapes are non-convex","Mode connectivity: two SGD solutions connected by a low-loss curved path (Garipov 2018)","Loss barrier on linear path does not imply isolation — curved paths often bypass it","Practical implication: model averaging (SWA) works because solutions lie in a connected valley"]},{"type":"divider"}]"
---
# Convex vs Non-Convex Loss Landscapes

The geometry of the loss landscape determines whether optimization is tractable, whether gradient descent converges, and where it converges to. Convex landscapes have a single global bowl; non-convex landscapes have ridges, valleys, saddle points, and many local minima. Understanding the difference is essential for choosing optimizers, diagnosing training failures, and reasoning about generalization.

## What is a Convex Function?

A function f: ℝⁿ → ℝ is convex if for all x, y in its domain and all λ ∈ [0,1]: f(λx + (1−λ)y) ≤ λf(x) + (1−λ)f(y). Geometrically, the chord connecting any two points on the graph lies above or on the graph. Equivalently (for differentiable f): f(y) ≥ f(x) + ∇f(x)ᵀ(y−x) — the function lies above all its tangent hyperplanes. For twice-differentiable f: the Hessian ∇²f(x) ⪰ 0 (positive semidefinite) everywhere.

- Convex: f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y) — chord lies above graph
- Strictly convex: strict inequality for x≠y — unique minimizer
- μ-strongly convex: f(y) ≥ f(x) + ∇f(x)ᵀ(y-x) + (μ/2)‖y-x‖² — quadratic lower bound guarantees unique global minimum
- L-smooth: ‖∇f(x)-∇f(y)‖ ≤ L‖x-y‖ — Lipschitz gradient, controls step size

> **Jensen's Inequality**: For a convex function f and any probability distribution p(x): f(E[x]) ≤ E[f(x)]. This is the functional form of convexity and underlies EM, variational inference, and the log-sum-exp bound. Equality holds iff x is constant or f is linear.

## Strongly Convex Functions

A μ-strongly convex function curves at least as sharply as a quadratic with curvature μ. This guarantees: (1) a unique global minimum, (2) gradient descent converges at a linear rate O((1−μ/L)ᵏ), (3) the condition number κ = L/μ controls convergence speed — smaller κ means faster convergence. Ridge regression (L2-regularized) is strongly convex even when the data matrix is rank-deficient.

## Why Convexity Matters for ML

Convex objectives offer algorithmic guarantees: any local minimum is a global minimum, gradient descent with appropriate step size converges, and we can certify optimality via duality. Non-convex objectives lack these guarantees — gradient descent may converge to different solutions depending on initialization, learning rate, and noise.

| Property | Convex | Strongly Convex | Non-Convex |
| --- | --- | --- | --- |
| Definition | f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y) | f(y) ≥ f(x)+∇f(x)ᵀ(y-x)+(μ/2)‖y-x‖² | No global curvature guarantee |
| Global Minimum | Any local min is global | Unique global minimum | Multiple local minima possible |
| Hessian | ∇²f ⪰ 0 everywhere | ∇²f ⪰ μI everywhere | Indefinite in general |
| Examples | Linear regression, logistic regression, SVMs | Ridge regression, elastic net | Neural networks, matrix factorization |
| Optimization | GD converges to global min | GD converges, linear rate 1-μ/L | SGD/Adam, no convergence guarantee |

## Common Convex ML Objectives

Several foundational ML models have convex loss functions, which is why they can be solved reliably. Linear regression with squared loss is strongly convex when X has full column rank. Logistic regression with log-loss is convex (but not strongly convex without regularization). SVMs with hinge loss are convex QPs. Adding L2 regularization makes any of these strongly convex.

- Linear regression: f(w) = ‖Xw - y‖² — quadratic, strongly convex if X full rank
- Logistic regression: f(w) = Σ log(1+exp(-yᵢwᵀxᵢ)) — convex, smooth
- SVM hinge loss: f(w) = (λ/2)‖w‖² + Σmax(0,1-yᵢwᵀxᵢ) — strongly convex
- Lasso: f(w) = ‖Xw-y‖² + λ‖w‖₁ — convex but non-smooth

```python
import numpy as np
import matplotlib.pyplot as plt

# Define convex and non-convex functions
def convex_fn(x, y):
    """Convex: f(x,y) = x^2 + y^2"""
    return x**2 + y**2

def nonconvex_fn(x, y):
    """Non-convex: f(x,y) = sin(x)*cos(y) + 0.1*(x^2+y^2)"""
    return np.sin(x) * np.cos(y) + 0.1 * (x**2 + y**2)

def gradient_descent(fn_grad, x0, lr=0.1, steps=50):
    path = [x0.copy()]
    x = x0.copy()
    for _ in range(steps):
        x = x - lr * fn_grad(x)
        path.append(x.copy())
    return np.array(path)

def grad_convex(x):
    return 2 * x

def grad_nonconvex(x):
    return np.array([
        np.cos(x[0]) * np.cos(x[1]) + 0.2 * x[0],
        -np.sin(x[0]) * np.sin(x[1]) + 0.2 * x[1]
    ])

# Run GD from multiple starts on the non-convex surface
starts = [np.array([3.0, 2.0]), np.array([-3.0, 2.5]), np.array([1.5, -2.0])]
paths_nc = [gradient_descent(grad_nonconvex, s, lr=0.05) for s in starts]

print(f"Convex fn global minimum: {convex_fn(0, 0):.4f}")
print("Non-convex: GD converges to different minima depending on start:")
for i, path in enumerate(paths_nc):
    final = path[-1]
    print(f"  Start {starts[i]}: converged to {final}, f={nonconvex_fn(*final):.4f}")
```

## Neural Networks Are Non-Convex

Neural networks are non-convex because they compose non-linear activation functions with learned weight matrices. Even a single hidden layer with ReLU activations creates a piecewise-linear, non-convex loss surface. The non-convexity arises from weight space symmetries (permutation of neurons), the product structure of weight matrices (bilinear interactions), and non-linear activations. Critical points where ∇L=0 are classified by the Hessian: positive definite → local min, negative definite → local max, indefinite → saddle point.

```python
import numpy as np
from scipy.linalg import eigh

def classify_critical_point(hess_matrix):
    """Classify a critical point via Hessian eigenvalues."""
    eigenvalues, _ = eigh(hess_matrix)
    if np.all(eigenvalues > 1e-10):
        return "local minimum", eigenvalues
    elif np.all(eigenvalues < -1e-10):
        return "local maximum", eigenvalues
    else:
        return "saddle point", eigenvalues

# Canonical saddle: f(x,y) = x^2 - y^2, Hessian = diag(2, -2)
H_saddle = np.array([[2.0, 0.0], [0.0, -2.0]])
kind, eigs = classify_critical_point(H_saddle)
print(f"f(x,y)=x²-y²  |  Hessian eigenvalues: {eigs}  |  {kind}")

# In high dimensions, almost all critical points are saddles
np.random.seed(42)
for n_dims in [10, 100, 500]:
    n_trials = 300
    saddle_count = 0
    for _ in range(n_trials):
        # Random symmetric matrix with mixed eigenvalues
        R = np.random.randn(n_dims, n_dims)
        H_sym = (R + R.T) / 2
        eigs_nd = np.linalg.eigvalsh(H_sym)
        if np.any(eigs_nd > 0) and np.any(eigs_nd < 0):
            saddle_count += 1
    pct = 100 * saddle_count / n_trials
    print(f"n={n_dims:4d}: {pct:.1f}% of critical points are saddles")

print("\nDauphin et al. (2014): in high-dim non-convex functions,")
print("critical points are overwhelmingly saddle points, not local minima.")
```

> **Saddle Points Dominate High Dimensions**: Dauphin et al. (2014) showed that in high-dimensional non-convex functions, nearly all critical points are saddle points rather than local minima. The probability that a random critical point is a local minimum decreases exponentially with dimension. The loss at saddle points is close to the global minimum for neural networks — escaping them (not finding the global min) is the real challenge.

## Loss Landscape Visualization

Directly visualizing the loss landscape of a neural network is impossible (millions of parameters), but Garipov et al. introduced filter normalization: project onto two random directions d₁, d₂ with each filter scaled to match the corresponding filter norm in the trained weights. This removes the scale ambiguity across layers and produces interpretable 2D surface plots.

```python
import numpy as np

def filter_normalize_direction(weights_list):
    """Create a filter-normalized random perturbation direction (Garipov et al.)."""
    direction = []
    for w in weights_list:
        d = np.random.randn(*w.shape)
        if d.ndim >= 2:
            # Normalize each filter (row) to match the weight filter norm
            for i in range(d.shape[0]):
                w_norm = np.linalg.norm(w[i]) + 1e-10
                d_norm = np.linalg.norm(d[i]) + 1e-10
                d[i] = d[i] * (w_norm / d_norm)
        else:
            d = d * (np.linalg.norm(w) / (np.linalg.norm(d) + 1e-10))
        direction.append(d)
    return direction

def landscape_grid(base_weights, dir1, dir2, loss_fn, n=25, scale=1.0):
    """Evaluate loss on a 2D grid around base_weights."""
    alphas = np.linspace(-scale, scale, n)
    grid = np.zeros((n, n))
    for i, a in enumerate(alphas):
        for j, b in enumerate(alphas):
            pw = [w + a*d1 + b*d2 for w, d1, d2 in zip(base_weights, dir1, dir2)]
            grid[i, j] = loss_fn(pw)
    return alphas, grid

np.random.seed(7)
base = [np.random.randn(8, 4) * 0.3, np.random.randn(8) * 0.1]

def quad_loss(ws):
    return sum(np.sum(w**2) for w in ws)

d1 = filter_normalize_direction(base)
d2 = filter_normalize_direction(base)
alphas, L = landscape_grid(base, d1, d2, quad_loss, n=20, scale=0.8)
print(f"Landscape grid shape: {L.shape}")
print(f"Min loss: {L.min():.4f}  Max loss: {L.max():.4f}")
print(f"Loss at center (0,0): {L[10,10]:.4f}")
print("Filter normalization removes scale artifacts — interpretable topology.")
```

## Mode Connectivity and the NTK Regime

Garipov et al. and Draxler et al. found that two SGD solutions can be connected by a low-loss path (mode connectivity). The linear interpolation between two solutions often passes through a high-loss barrier, but a curved path (e.g., Bézier curve) can maintain low loss throughout. This suggests the loss landscape has connected valleys rather than isolated minima. In the NTK (Neural Tangent Kernel) regime — infinite-width networks trained with infinitesimal learning rate — the network behaves as a linear model and the loss landscape becomes effectively convex.

```python
import numpy as np

def linear_interpolate(wa, wb, alpha):
    """Linearly interpolate between two weight sets."""
    return [(1 - alpha) * a + alpha * b for a, b in zip(wa, wb)]

def path_loss_profile(wa, wb, loss_fn, n_points=25):
    """Evaluate loss along the linear interpolation path."""
    alphas = np.linspace(0, 1, n_points)
    return alphas, np.array([loss_fn(linear_interpolate(wa, wb, a)) for a in alphas])

def simulate_sgd(init_weights, lr=0.01, noise_scale=0.15, steps=150):
    """Simulate SGD with gradient noise, landing at different minima."""
    w = [x.copy() for x in init_weights]
    for _ in range(steps):
        w = [x - lr * (2 * x + noise_scale * np.random.randn(*x.shape)) for x in w]
    return w

np.random.seed(0)
init = [np.random.randn(6, 6) * 1.5, np.random.randn(6) * 1.5]
model_a = simulate_sgd(init, lr=0.02, noise_scale=0.3)
model_b = simulate_sgd(init, lr=0.02, noise_scale=0.3)

def loss_fn(ws):
    return sum(np.sum(w**2) for w in ws)

alphas, losses = path_loss_profile(model_a, model_b, loss_fn)
mid = losses[len(losses) // 2]
end_avg = (losses[0] + losses[-1]) / 2
barrier = mid - end_avg
print(f"Model A loss: {losses[0]:.4f}")
print(f"Model B loss: {losses[-1]:.4f}")
print(f"Midpoint loss: {mid:.4f}")
print(f"Loss barrier (mid - avg endpoints): {barrier:.4f}")
print("Low barrier => mode connectivity; models share the same loss basin.")
```

- NTK regime: infinite-width networks trained with gradient flow → loss is convex in function space
- Finite-width networks leave the NTK regime quickly; practical landscapes are non-convex
- Mode connectivity: two SGD solutions connected by a low-loss curved path (Garipov 2018)
- Loss barrier on linear path does not imply isolation — curved paths often bypass it
- Practical implication: model averaging (SWA) works because solutions lie in a connected valley

---

