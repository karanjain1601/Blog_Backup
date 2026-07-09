---
title: "Convex vs Non-Convex Loss Landscapes"
slug: "convex-nonconvex-landscapes"
description: "Rigorous treatment of convex function theory, loss landscape geometry for neural networks, saddle point prevalence in high dimensions, mode connectivity, and the neural tangent kernel regime."
tags: ["optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "The geometry of a loss function determines whether gradient descent can find good solutions efficiently. Convex landscapes have exactly one basin containing the global minimum, so any descent algorithm with sufficient step size eventually converges. Non-convex landscapes — characteristic of neural networks — contain multiple basins, saddle points, ridges, and plateaus. Understanding this geometry guides architecture design, optimizer choice, and training strategies. This note builds rigorous intuition from convex function theory through the practical implications for modern deep learning, covering the prevalence of saddle points predicted by random matrix theory, loss landscape visualization, mode connectivity, and the Neural Tangent Kernel regime."}, {"type": "heading", "level": 2, "content": "Convex Functions: Definitions and Properties"}, {"type": "text", "content": "A function f: R^n → R is convex if for all x, y in its domain and all λ ∈ [0,1]: f(λx + (1-λ)y) ≤ λf(x) + (1-λ)f(y). The chord connecting any two points on the graph lies above or on the graph. Strict convexity requires strict inequality for x ≠ y, guaranteeing a unique global minimum. μ-strongly convex (μ > 0) means f(y) ≥ f(x) + ∇f(x)ᵀ(y−x) + (μ/2)‖y−x‖² — the function is lower-bounded by a quadratic. Equivalent Hessian condition: H ≽ 0 (PSD) for convex, H ≻ 0 (PD) for strictly convex, H ≽ μI for μ-strongly convex. Logistic regression with log-loss IS convex: the log-sum-exp is convex, composition with a linear function preserves convexity. Neural networks are NOT convex: the composition f(Wx) with non-linear activation f breaks the convexity-preserving composition rule (which requires f to be convex and non-decreasing, but ReLU applied to a linear layer makes the composite non-convex when layers are stacked)."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.datasets import make_classification\n\ndef check_convexity_numerically(f, n_samples=500, n_dim=5, tol=1e-6):\n    \"\"\"Sample pairs (x, y) and check f(λx+(1-λ)y) <= λf(x)+(1-λ)f(y).\"\"\"\n    violations = 0\n    for _ in range(n_samples):\n        x = np.random.randn(n_dim)\n        y = np.random.randn(n_dim)\n        lam = np.random.uniform(0.01, 0.99)\n        lhs = f(lam * x + (1 - lam) * y)\n        rhs = lam * f(x) + (1 - lam) * f(y)\n        if lhs > rhs + tol:\n            violations += 1\n    return violations, n_samples\n\n# Logistic loss (convex)\ndef logistic_loss(params, X, y):\n    w, b = params[:-1], params[-1]\n    logits = X @ w + b\n    return np.mean(np.log(1 + np.exp(-y * logits)))\n\nX, y = make_classification(n_samples=50, n_features=4, random_state=0)\ny = 2 * y - 1  # {-1, +1}\nf_logistic = lambda p: logistic_loss(p, X, y)\nviol, total = check_convexity_numerically(f_logistic, n_dim=5)\nprint(f\"Logistic loss violations: {viol}/{total} (expected 0)\")\n\n# Simple 2-layer NN loss (non-convex)\ndef nn_loss(params):\n    W1 = params[:8].reshape(2, 4)\n    W2 = params[8:10]\n    h = np.maximum(0, X @ W1.T)  # ReLU\n    out = h @ W2\n    return np.mean((out - y) ** 2)\n\nviol2, total2 = check_convexity_numerically(nn_loss, n_dim=10)\nprint(f\"NN loss violations: {viol2}/{total2} (expected > 0)\")"}, {"type": "heading", "level": 2, "content": "Saddle Points in High Dimensions"}, {"type": "text", "content": "The index of a saddle point is the fraction of negative Hessian eigenvalues at that critical point. Random matrix theory (Wigner semicircle law) predicts that for a random n×n symmetric matrix, approximately half the eigenvalues are negative. This means that at a random critical point in high-dimensional non-convex landscapes, roughly half the curvature directions point downward — i.e., most critical points are saddle points, not local minima. Dauphin et al. (2014) showed empirically that in deep networks, critical points encountered during training have loss close to the global minimum, contradicting the fear of 'bad local minima.' Instead, saddle points dominate: the gradient norm is near zero (GD stalls) but loss is above the global minimum. Three escape mechanisms: (1) SGD's gradient noise from mini-batching perturbs the trajectory off the saddle; (2) Negative curvature exploitation (Carmon et al.): follow the most negative eigenvector direction; (3) Perturbation-then-restart (Ge et al. 2015): add random noise to weights when gradient norm < threshold."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport matplotlib\nmatplotlib.use('Agg')\nimport matplotlib.pyplot as plt\n\n# Function with a known saddle at origin: f(x,y) = x^2 - y^2\ndef f(xy): return xy[0]**2 - xy[1]**2\ndef grad_f(xy): return np.array([2*xy[0], -2*xy[1]])\n\ndef gradient_descent(start, lr=0.05, steps=200, noise=0.0):\n    path = [start.copy()]\n    xy = start.copy()\n    for _ in range(steps):\n        g = grad_f(xy)\n        xy = xy - lr * g + noise * np.random.randn(2)\n        path.append(xy.copy())\n    return np.array(path)\n\n# GD from near saddle: start at [0.01, 0.1] (slight offset)\nnp.random.seed(42)\nstart_near_saddle = np.array([0.01, 0.1])\n\npath_gd = gradient_descent(start_near_saddle, lr=0.05, noise=0.0)\npath_sgd = gradient_descent(start_near_saddle, lr=0.05, noise=0.02)\n\nprint(\"GD near saddle — final position:\", path_gd[-1].round(4))\nprint(\"GD gradient norm history (first 10):\",\n      [round(np.linalg.norm(grad_f(p)), 4) for p in path_gd[:10]])\nprint(\"SGD (with noise) final position:\", path_sgd[-1].round(4))\nprint(\"SGD escaped saddle in y-direction:\", abs(path_sgd[-1][1]) > 1.0)"}, {"type": "heading", "level": 2, "content": "Loss Landscape of Neural Networks"}, {"type": "text", "content": "Goodfellow et al. (2015) showed that linearly interpolating between initial and final weights typically produces a path of monotonically decreasing loss, suggesting local minima found by GD are close to the initialization's basin. Li et al. (2018) introduced filter normalization for loss visualization: project the loss surface onto 2D using two random directions in weight space (normalized to have the same layer-wise scale as the weights), revealing sharp cliffs vs smooth valleys. Flat regions (shallower landscape) correlate with better generalization (flat minima hypothesis). The benign landscape hypothesis (Haeffele and Vidal, extended by Du et al.): for over-parameterized networks with specific architecture conditions, all local minima of the training loss achieve zero training error, and their loss values are equal. This means over-parameterization — adding more parameters than strictly needed — fundamentally changes the topology of the loss landscape from one with bad local minima to one where any local minimum is effectively global."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport matplotlib\nmatplotlib.use('Agg')\nimport matplotlib.pyplot as plt\nfrom sklearn.datasets import make_moons\n\ndef simple_loss(weights, X, y):\n    \"\"\"2-layer network loss for interpolation demo.\"\"\"\n    n_in, n_h = X.shape[1], 4\n    W1 = weights[:n_in*n_h].reshape(n_h, n_in)\n    b1 = weights[n_in*n_h:n_in*n_h+n_h]\n    W2 = weights[n_in*n_h+n_h:n_in*n_h+n_h+n_h]\n    b2 = weights[-1]\n    h = np.maximum(0, X @ W1.T + b1)\n    out = h @ W2 + b2\n    return np.mean((out - y)**2)\n\nX, y = make_moons(n_samples=100, noise=0.1, random_state=0)\nn_params = X.shape[1] * 4 + 4 + 4 + 1\nnp.random.seed(0)\nw_init = np.random.randn(n_params) * 0.1\nw_final = np.random.randn(n_params) * 0.5  # simulate trained weights\n\n# Interpolate between init and final\nalphas = np.linspace(0, 1, 50)\nlosses = [simple_loss((1-a)*w_init + a*w_final, X, y) for a in alphas]\n\nprint(\"Loss at alpha=0 (init):\", round(losses[0], 4))\nprint(\"Loss at alpha=1 (final):\", round(losses[-1], 4))\nprint(\"Local max on path?\", any(losses[i] > losses[i-1] and losses[i] > losses[i+1]\n      for i in range(1, len(losses)-1)))\nprint(\"Monotone decrease?\", all(losses[i] >= losses[i+1] for i in range(len(losses)-1)))"}, {"type": "heading", "level": 2, "content": "Mode Connectivity"}, {"type": "text", "content": "Garipov et al. (2018) and Draxler et al. (2018) discovered that two local minima found by independent SGD runs are typically connected by a low-loss curved path through weight space — despite the straight line between them crossing a loss barrier. The curved path can be parameterized as a Bezier curve φ(t) = (1-t)²θ₁ + 2t(1-t)θ_mid + t²θ₂ with one trainable midpoint θ_mid. Mode connectivity implies the loss landscape has a connected 'valley' structure rather than isolated minima, which has profound implications for model merging and ensemble methods. Linear Mode Connectivity (LMC): if the straight-line path between two solutions also has low loss (no barrier), the models can be linearly interpolated without performance degradation. LMC is the theoretical foundation for Stochastic Weight Averaging (SWA, Izmailov et al. 2018) — averaging multiple checkpoints from late in training produces a model at the flat center of a wide valley. It is also the basis for model merging techniques where independently fine-tuned models are merged by simple weight averaging when they are initialized from the same pre-trained checkpoint."}, {"type": "heading", "level": 2, "content": "ML Connections: NTK Regime and Convex Proxies"}, {"type": "text", "content": "At infinite width, neural networks trained with gradient descent behave like kernel methods governed by the Neural Tangent Kernel K(x, x') = Σᵢ (∂f(x)/∂θᵢ)(∂f(x')/∂θᵢ). In the NTK regime, the kernel stays constant throughout training (parameters barely move relative to initialization), and the loss landscape is effectively convex in function space — gradient descent provably converges to a global minimum. However, the NTK regime requires impractically large width and very small learning rates; practical networks operate in the 'feature learning' regime where representations evolve, departing from NTK predictions. The practical takeaway from NTK theory: over-parameterization helps. More parameters relative to data makes the landscape more benign, reducing the probability of bad local minima. This empirically explains why wider networks train more reliably than narrow ones, why LLMs are over-parameterized by design, and why the 'double descent' phenomenon occurs — adding parameters past the interpolation threshold can improve rather than hurt generalization."}, {"type": "code", "language": "python", "content": "import numpy as np\n\ndef gd_with_perturbation(f, grad_f, x0, lr=0.02, steps=300,\n                          noise_scale=0.0, noise_start=150):\n    \"\"\"Run GD, optionally adding noise after noise_start steps.\"\"\"\n    x = x0.copy()\n    history = {'loss': [], 'grad_norm': [], 'x': []}\n    for step in range(steps):\n        loss = f(x)\n        g = grad_f(x)\n        noise = 0.0\n        if noise_scale > 0 and step >= noise_start:\n            noise = noise_scale * np.random.randn(*x.shape)\n        x = x - lr * g + noise\n        history['loss'].append(loss)\n        history['grad_norm'].append(np.linalg.norm(g))\n        history['x'].append(x.copy())\n    return history\n\n# Saddle: f(x,y) = x^2 - y^2\nf2d = lambda xy: xy[0]**2 - xy[1]**2\ngrad2d = lambda xy: np.array([2*xy[0], -2*xy[1]])\n\nnp.random.seed(7)\nstart = np.array([0.05, 0.02])\n\nhist_gd = gd_with_perturbation(f2d, grad2d, start, lr=0.05, noise_scale=0.0)\nhist_noisy = gd_with_perturbation(f2d, grad2d, start, lr=0.05,\n                                    noise_scale=0.1, noise_start=50)\n\nprint(\"GD: final grad_norm =\", round(hist_gd['grad_norm'][-1], 5))\nprint(\"GD: final x =\", np.round(hist_gd['x'][-1], 4))\nprint(\"Noisy GD: final grad_norm =\", round(hist_noisy['grad_norm'][-1], 5))\nprint(\"Noisy GD: final x =\", np.round(hist_noisy['x'][-1], 4))\nprint(\"GD stalled at saddle:\", hist_gd['grad_norm'][-1] < 0.01)\nprint(\"Noisy GD escaped:\", abs(hist_noisy['x'][-1][1]) > 0.5)"}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "Three critical pitfalls when reasoning about loss landscapes in practice. First, gradient vanishing near saddle points: the gradient norm approaches zero at saddle points just as it does at minima — monitoring only loss gives no signal about which you have reached. Always log ‖∇L‖ and loss separately; a plateau in both signals a saddle, not convergence. Second, learning rate choice in non-convex landscapes: too large a learning rate causes oscillation across sharp ridges (zigzag in the loss curve); too small a rate causes the trajectory to stall in the first local basin it finds. The optimal LR for non-convex problems is typically found via warmup-then-decay schedules that start conservatively and increase briefly. Third, single random restart is insufficient: for highly non-convex objectives, always run at least 3-5 random restarts with different random seeds and select the checkpoint with best validation loss, since different seeds find different basins with different generalization properties."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "For neural network training on non-convex landscapes, apply these evidence-based strategies. Use learning rate warmup for the first 5-10% of training steps: this prevents early large steps that could push the model into a bad basin from which escape is difficult. Monitor ‖∇L‖ (gradient norm) every 100 steps — a healthy training run shows gradually decreasing gradient norm; persistent large gradient norm indicates the model is not converging, while sudden spikes indicate instability. Use SWA (Stochastic Weight Averaging) by averaging checkpoints from the last 20% of training: this moves the effective parameter vector toward the flat center of the loss basin, improving both generalization and calibration without any additional training cost. For tasks with known convex proxies (logistic regression, linear SVM), prefer the convex formulation unless you have strong reasons to use a neural network — convex problems have provable global convergence guarantees and no saddle points."}, {"type": "callout", "title": "Warning", "content": "A decreasing training loss does NOT mean you are near a good minimum — you could be approaching a saddle point where loss is still decreasing but gradient is collapsing toward zero. Monitor ‖∇L‖ separately from loss at every checkpoint. A saddle manifests as: loss still decreasing but gradient norm also decreasing toward zero while validation loss plateaus. If you see this pattern before expected convergence, add gradient noise or reduce the learning rate temporarily to escape."}, {"type": "table", "headers": ["Function Class", "Definition", "Global Min Guarantee", "GD Convergence Rate", "Example Loss"], "rows": [["Convex", "f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y)", "Any local min is global", "O(1/t)", "Log-loss, Hinge loss"], ["Strictly Convex", "Strict inequality for x≠y", "Unique global min", "O(1/t)", "Squared loss with L2 reg"], ["Strongly Convex (μ)", "H ≽ μI, μ > 0", "Unique global min", "Linear O(ρᵗ), ρ<1", "Ridge regression"], ["Non-convex PL*", "½‖∇f‖² ≥ μ(f−f*)", "Not guaranteed (PL gives linear rate)", "Linear under PL", "Some over-param NNs"], ["General Non-convex", "No condition", "No guarantee", "O(1/√t) to stationary", "Deep network losses"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["Convex functions satisfy f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y); strongly convex adds a quadratic lower bound with parameter μ, guaranteeing linear convergence of GD.", "Logistic regression with log-loss is convex (gradient alignment property holds); neural networks are not convex because non-linear activations break the composition rule.", "In high dimensions, random matrix theory predicts that most critical points are saddle points (roughly half of Hessian eigenvalues are negative), not local minima — 'bad local minima' are rare.", "Saddle points stall gradient descent (gradient → 0) but SGD's mini-batch noise naturally perturbs the trajectory; if SGD stalls, add explicit perturbation noise.", "Mode connectivity: two independently trained minima are typically connected by a low-loss curved path (Bezier curve), implying a valley structure rather than isolated basins.", "Linear Mode Connectivity enables model merging and SWA: models from the same pre-trained checkpoint can be linearly interpolated without loss barrier.", "The NTK regime (infinite width) gives a convex loss landscape; practical takeaway is that over-parameterization reduces the probability of bad local minima."]}]"
---

# Convex vs Non-Convex Loss Landscapes

The geometry of a loss function determines whether gradient descent can find good solutions efficiently. Convex landscapes have exactly one basin containing the global minimum, so any descent algorithm with sufficient step size eventually converges. Non-convex landscapes — characteristic of neural networks — contain multiple basins, saddle points, ridges, and plateaus. Understanding this geometry guides architecture design, optimizer choice, and training strategies. This note builds rigorous intuition from convex function theory through the practical implications for modern deep learning, covering the prevalence of saddle points predicted by random matrix theory, loss landscape visualization, mode connectivity, and the Neural Tangent Kernel regime.

## Convex Functions: Definitions and Properties

A function f: R^n → R is convex if for all x, y in its domain and all λ ∈ [0,1]: f(λx + (1-λ)y) ≤ λf(x) + (1-λ)f(y). The chord connecting any two points on the graph lies above or on the graph. Strict convexity requires strict inequality for x ≠ y, guaranteeing a unique global minimum. μ-strongly convex (μ > 0) means f(y) ≥ f(x) + ∇f(x)ᵀ(y−x) + (μ/2)‖y−x‖² — the function is lower-bounded by a quadratic. Equivalent Hessian condition: H ≽ 0 (PSD) for convex, H ≻ 0 (PD) for strictly convex, H ≽ μI for μ-strongly convex. Logistic regression with log-loss IS convex: the log-sum-exp is convex, composition with a linear function preserves convexity. Neural networks are NOT convex: the composition f(Wx) with non-linear activation f breaks the convexity-preserving composition rule (which requires f to be convex and non-decreasing, but ReLU applied to a linear layer makes the composite non-convex when layers are stacked).

```python
import numpy as np
from sklearn.linear_model import LogisticRegression
from sklearn.datasets import make_classification

def check_convexity_numerically(f, n_samples=500, n_dim=5, tol=1e-6):
    """Sample pairs (x, y) and check f(λx+(1-λ)y) <= λf(x)+(1-λ)f(y)."""
    violations = 0
    for _ in range(n_samples):
        x = np.random.randn(n_dim)
        y = np.random.randn(n_dim)
        lam = np.random.uniform(0.01, 0.99)
        lhs = f(lam * x + (1 - lam) * y)
        rhs = lam * f(x) + (1 - lam) * f(y)
        if lhs > rhs + tol:
            violations += 1
    return violations, n_samples

# Logistic loss (convex)
def logistic_loss(params, X, y):
    w, b = params[:-1], params[-1]
    logits = X @ w + b
    return np.mean(np.log(1 + np.exp(-y * logits)))

X, y = make_classification(n_samples=50, n_features=4, random_state=0)
y = 2 * y - 1  # {-1, +1}
f_logistic = lambda p: logistic_loss(p, X, y)
viol, total = check_convexity_numerically(f_logistic, n_dim=5)
print(f"Logistic loss violations: {viol}/{total} (expected 0)")

# Simple 2-layer NN loss (non-convex)
def nn_loss(params):
    W1 = params[:8].reshape(2, 4)
    W2 = params[8:10]
    h = np.maximum(0, X @ W1.T)  # ReLU
    out = h @ W2
    return np.mean((out - y) ** 2)

viol2, total2 = check_convexity_numerically(nn_loss, n_dim=10)
print(f"NN loss violations: {viol2}/{total2} (expected > 0)")
```

## Saddle Points in High Dimensions

The index of a saddle point is the fraction of negative Hessian eigenvalues at that critical point. Random matrix theory (Wigner semicircle law) predicts that for a random n×n symmetric matrix, approximately half the eigenvalues are negative. This means that at a random critical point in high-dimensional non-convex landscapes, roughly half the curvature directions point downward — i.e., most critical points are saddle points, not local minima. Dauphin et al. (2014) showed empirically that in deep networks, critical points encountered during training have loss close to the global minimum, contradicting the fear of 'bad local minima.' Instead, saddle points dominate: the gradient norm is near zero (GD stalls) but loss is above the global minimum. Three escape mechanisms: (1) SGD's gradient noise from mini-batching perturbs the trajectory off the saddle; (2) Negative curvature exploitation (Carmon et al.): follow the most negative eigenvector direction; (3) Perturbation-then-restart (Ge et al. 2015): add random noise to weights when gradient norm < threshold.

```python
import numpy as np
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt

# Function with a known saddle at origin: f(x,y) = x^2 - y^2
def f(xy): return xy[0]**2 - xy[1]**2
def grad_f(xy): return np.array([2*xy[0], -2*xy[1]])

def gradient_descent(start, lr=0.05, steps=200, noise=0.0):
    path = [start.copy()]
    xy = start.copy()
    for _ in range(steps):
        g = grad_f(xy)
        xy = xy - lr * g + noise * np.random.randn(2)
        path.append(xy.copy())
    return np.array(path)

# GD from near saddle: start at [0.01, 0.1] (slight offset)
np.random.seed(42)
start_near_saddle = np.array([0.01, 0.1])

path_gd = gradient_descent(start_near_saddle, lr=0.05, noise=0.0)
path_sgd = gradient_descent(start_near_saddle, lr=0.05, noise=0.02)

print("GD near saddle — final position:", path_gd[-1].round(4))
print("GD gradient norm history (first 10):",
      [round(np.linalg.norm(grad_f(p)), 4) for p in path_gd[:10]])
print("SGD (with noise) final position:", path_sgd[-1].round(4))
print("SGD escaped saddle in y-direction:", abs(path_sgd[-1][1]) > 1.0)
```

## Loss Landscape of Neural Networks

Goodfellow et al. (2015) showed that linearly interpolating between initial and final weights typically produces a path of monotonically decreasing loss, suggesting local minima found by GD are close to the initialization's basin. Li et al. (2018) introduced filter normalization for loss visualization: project the loss surface onto 2D using two random directions in weight space (normalized to have the same layer-wise scale as the weights), revealing sharp cliffs vs smooth valleys. Flat regions (shallower landscape) correlate with better generalization (flat minima hypothesis). The benign landscape hypothesis (Haeffele and Vidal, extended by Du et al.): for over-parameterized networks with specific architecture conditions, all local minima of the training loss achieve zero training error, and their loss values are equal. This means over-parameterization — adding more parameters than strictly needed — fundamentally changes the topology of the loss landscape from one with bad local minima to one where any local minimum is effectively global.

```python
import numpy as np
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt
from sklearn.datasets import make_moons

def simple_loss(weights, X, y):
    """2-layer network loss for interpolation demo."""
    n_in, n_h = X.shape[1], 4
    W1 = weights[:n_in*n_h].reshape(n_h, n_in)
    b1 = weights[n_in*n_h:n_in*n_h+n_h]
    W2 = weights[n_in*n_h+n_h:n_in*n_h+n_h+n_h]
    b2 = weights[-1]
    h = np.maximum(0, X @ W1.T + b1)
    out = h @ W2 + b2
    return np.mean((out - y)**2)

X, y = make_moons(n_samples=100, noise=0.1, random_state=0)
n_params = X.shape[1] * 4 + 4 + 4 + 1
np.random.seed(0)
w_init = np.random.randn(n_params) * 0.1
w_final = np.random.randn(n_params) * 0.5  # simulate trained weights

# Interpolate between init and final
alphas = np.linspace(0, 1, 50)
losses = [simple_loss((1-a)*w_init + a*w_final, X, y) for a in alphas]

print("Loss at alpha=0 (init):", round(losses[0], 4))
print("Loss at alpha=1 (final):", round(losses[-1], 4))
print("Local max on path?", any(losses[i] > losses[i-1] and losses[i] > losses[i+1]
      for i in range(1, len(losses)-1)))
print("Monotone decrease?", all(losses[i] >= losses[i+1] for i in range(len(losses)-1)))
```

## Mode Connectivity

Garipov et al. (2018) and Draxler et al. (2018) discovered that two local minima found by independent SGD runs are typically connected by a low-loss curved path through weight space — despite the straight line between them crossing a loss barrier. The curved path can be parameterized as a Bezier curve φ(t) = (1-t)²θ₁ + 2t(1-t)θ_mid + t²θ₂ with one trainable midpoint θ_mid. Mode connectivity implies the loss landscape has a connected 'valley' structure rather than isolated minima, which has profound implications for model merging and ensemble methods. Linear Mode Connectivity (LMC): if the straight-line path between two solutions also has low loss (no barrier), the models can be linearly interpolated without performance degradation. LMC is the theoretical foundation for Stochastic Weight Averaging (SWA, Izmailov et al. 2018) — averaging multiple checkpoints from late in training produces a model at the flat center of a wide valley. It is also the basis for model merging techniques where independently fine-tuned models are merged by simple weight averaging when they are initialized from the same pre-trained checkpoint.

## ML Connections: NTK Regime and Convex Proxies

At infinite width, neural networks trained with gradient descent behave like kernel methods governed by the Neural Tangent Kernel K(x, x') = Σᵢ (∂f(x)/∂θᵢ)(∂f(x')/∂θᵢ). In the NTK regime, the kernel stays constant throughout training (parameters barely move relative to initialization), and the loss landscape is effectively convex in function space — gradient descent provably converges to a global minimum. However, the NTK regime requires impractically large width and very small learning rates; practical networks operate in the 'feature learning' regime where representations evolve, departing from NTK predictions. The practical takeaway from NTK theory: over-parameterization helps. More parameters relative to data makes the landscape more benign, reducing the probability of bad local minima. This empirically explains why wider networks train more reliably than narrow ones, why LLMs are over-parameterized by design, and why the 'double descent' phenomenon occurs — adding parameters past the interpolation threshold can improve rather than hurt generalization.

```python
import numpy as np

def gd_with_perturbation(f, grad_f, x0, lr=0.02, steps=300,
                          noise_scale=0.0, noise_start=150):
    """Run GD, optionally adding noise after noise_start steps."""
    x = x0.copy()
    history = {'loss': [], 'grad_norm': [], 'x': []}
    for step in range(steps):
        loss = f(x)
        g = grad_f(x)
        noise = 0.0
        if noise_scale > 0 and step >= noise_start:
            noise = noise_scale * np.random.randn(*x.shape)
        x = x - lr * g + noise
        history['loss'].append(loss)
        history['grad_norm'].append(np.linalg.norm(g))
        history['x'].append(x.copy())
    return history

# Saddle: f(x,y) = x^2 - y^2
f2d = lambda xy: xy[0]**2 - xy[1]**2
grad2d = lambda xy: np.array([2*xy[0], -2*xy[1]])

np.random.seed(7)
start = np.array([0.05, 0.02])

hist_gd = gd_with_perturbation(f2d, grad2d, start, lr=0.05, noise_scale=0.0)
hist_noisy = gd_with_perturbation(f2d, grad2d, start, lr=0.05,
                                    noise_scale=0.1, noise_start=50)

print("GD: final grad_norm =", round(hist_gd['grad_norm'][-1], 5))
print("GD: final x =", np.round(hist_gd['x'][-1], 4))
print("Noisy GD: final grad_norm =", round(hist_noisy['grad_norm'][-1], 5))
print("Noisy GD: final x =", np.round(hist_noisy['x'][-1], 4))
print("GD stalled at saddle:", hist_gd['grad_norm'][-1] < 0.01)
print("Noisy GD escaped:", abs(hist_noisy['x'][-1][1]) > 0.5)
```

## Implementation Pitfalls

Three critical pitfalls when reasoning about loss landscapes in practice. First, gradient vanishing near saddle points: the gradient norm approaches zero at saddle points just as it does at minima — monitoring only loss gives no signal about which you have reached. Always log ‖∇L‖ and loss separately; a plateau in both signals a saddle, not convergence. Second, learning rate choice in non-convex landscapes: too large a learning rate causes oscillation across sharp ridges (zigzag in the loss curve); too small a rate causes the trajectory to stall in the first local basin it finds. The optimal LR for non-convex problems is typically found via warmup-then-decay schedules that start conservatively and increase briefly. Third, single random restart is insufficient: for highly non-convex objectives, always run at least 3-5 random restarts with different random seeds and select the checkpoint with best validation loss, since different seeds find different basins with different generalization properties.

## Practical Guidance

For neural network training on non-convex landscapes, apply these evidence-based strategies. Use learning rate warmup for the first 5-10% of training steps: this prevents early large steps that could push the model into a bad basin from which escape is difficult. Monitor ‖∇L‖ (gradient norm) every 100 steps — a healthy training run shows gradually decreasing gradient norm; persistent large gradient norm indicates the model is not converging, while sudden spikes indicate instability. Use SWA (Stochastic Weight Averaging) by averaging checkpoints from the last 20% of training: this moves the effective parameter vector toward the flat center of the loss basin, improving both generalization and calibration without any additional training cost. For tasks with known convex proxies (logistic regression, linear SVM), prefer the convex formulation unless you have strong reasons to use a neural network — convex problems have provable global convergence guarantees and no saddle points.

> **Warning**: A decreasing training loss does NOT mean you are near a good minimum — you could be approaching a saddle point where loss is still decreasing but gradient is collapsing toward zero. Monitor ‖∇L‖ separately from loss at every checkpoint. A saddle manifests as: loss still decreasing but gradient norm also decreasing toward zero while validation loss plateaus. If you see this pattern before expected convergence, add gradient noise or reduce the learning rate temporarily to escape.

| Function Class | Definition | Global Min Guarantee | GD Convergence Rate | Example Loss |
|---|---|---|---|---|
| Convex | f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y) | Any local min is global | O(1/t) | Log-loss, Hinge loss |
| Strictly Convex | Strict inequality for x≠y | Unique global min | O(1/t) | Squared loss with L2 reg |
| Strongly Convex (μ) | H ≽ μI, μ > 0 | Unique global min | Linear O(ρᵗ), ρ<1 | Ridge regression |
| Non-convex PL* | ½‖∇f‖² ≥ μ(f−f*) | Not guaranteed (PL gives linear rate) | Linear under PL | Some over-param NNs |
| General Non-convex | No condition | No guarantee | O(1/√t) to stationary | Deep network losses |

---

## Key Takeaways

- Convex functions satisfy f(λx+(1-λ)y) ≤ λf(x)+(1-λ)f(y); strongly convex adds a quadratic lower bound with parameter μ, guaranteeing linear convergence of GD.
- Logistic regression with log-loss is convex (gradient alignment property holds); neural networks are not convex because non-linear activations break the composition rule.
- In high dimensions, random matrix theory predicts that most critical points are saddle points (roughly half of Hessian eigenvalues are negative), not local minima — 'bad local minima' are rare.
- Saddle points stall gradient descent (gradient → 0) but SGD's mini-batch noise naturally perturbs the trajectory; if SGD stalls, add explicit perturbation noise.
- Mode connectivity: two independently trained minima are typically connected by a low-loss curved path (Bezier curve), implying a valley structure rather than isolated basins.
- Linear Mode Connectivity enables model merging and SWA: models from the same pre-trained checkpoint can be linearly interpolated without loss barrier.
- The NTK regime (infinite width) gives a convex loss landscape; practical takeaway is that over-parameterization reduces the probability of bad local minima.

