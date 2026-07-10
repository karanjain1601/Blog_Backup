---
title: "Vanishing Gradient in RNNs — Mathematical Derivation"
slug: "vanishing-gradient-rnn"
description: "Derive the vanishing gradient analytically, plot gradient norm vs time lag, compare vanilla RNN to LSTM on long-range tasks, and analyse orthogonal initialisation as a mitigation strategy."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The vanishing gradient problem in RNNs is not a numerical issue — it is a consequence of the mathematical structure of gradient backpropagation through time. The gradient of the loss at step T with respect to the hidden state at step k is: dLₜ/dhₖ = (dLₜ/dhₜ) · Πⱼ₌ₖ₊₁ᵀ (dhⱼ/dhⱼ₋₁). Each Jacobian factor ∂hⱼ/∂hⱼ₋₁ = Wₕₕᵀ · diag(tanh\u0027(hⱼ)) where tanh\u0027(x) = 1 − tanh(x)² ∈ [0,1]. If the largest singular value of Wₕₕ is less than 1 (or tanh saturates), the product decays exponentially with T−k. This means the RNN gradient for a dependency at lag 50 is typically 10⁻¹⁵ times smaller than the gradient for a dependency at lag 1 — numerically zero in float32."},{"type":"heading","level":2,"content":"Mathematical Derivation of Vanishing Gradient"},{"type":"text","content":"Define the Jacobian of hⱼ with respect to hⱼ₋₁: Jⱼ = ∂hⱼ/∂hⱼ₋₁ = Wₕₕᵀ · diag(1 − hⱼ²). The gradient of the loss at time t with respect to hₖ is: dLₜ/dhₖ = (dLₜ/dhₜ) · Jₜ · Jₜ₋₁ · ... · Jₖ₊₁ (a product of t−k matrices). By the sub-multiplicativity of matrix norms: ‖Πⱼ Jⱼ‖ ≤ Πⱼ ‖Jⱼ‖. Since ‖Jⱼ‖ ≤ σ_max(Wₕₕ) · ‖diag(tanh\u0027)‖ ≤ σ_max(Wₕₕ), if σ_max(Wₕₕ) \u003c 1 then ‖dLₜ/dhₖ‖ ≤ ‖dLₜ/dhₜ‖ · σ_max(Wₕₕ)^(t−k) → 0 exponentially. This is not an implementation bug — it is the fundamental reason plain RNNs cannot learn long-range dependencies."},{"type":"code","language":"python","content":"import numpy as np\n\nnp.random.seed(42)\nT, H, I = 50, 16, 4\n\ndef gradient_norm_vs_lag(Whh_scale, T=50, H=16, I=4, seed=0):\n    rng = np.random.RandomState(seed)\n    Wxh = rng.randn(H, I) * 0.1\n    Whh = rng.randn(H, H) * Whh_scale / np.sqrt(H)\n    bh  = np.zeros((H, 1))\n    xs  = [rng.randn(I, 1) for _ in range(T)]\n    hs  = {-1: np.zeros((H, 1))}\n    for t in range(T):\n        hs[t] = np.tanh(Wxh @ xs[t] + Whh @ hs[t-1] + bh)\n    dh = np.ones((H, 1)) / H  # unit gradient at t = T-1\n    norms = {}\n    for t in reversed(range(T)):\n        norms[t] = float(np.linalg.norm(dh))\n        dtanh    = (1 - hs[t]**2) * dh\n        dh       = Whh.T @ dtanh\n    return [norms[t] for t in range(T)]\n\nprint(f\u0027{\"Scale\":\u003e8} {\"t=T-1\":\u003e12} {\"t=T/2\":\u003e12} {\"t=0\":\u003e12} {\"Regime\":\u003e12}\u0027)\nfor scale, label in [(0.5, \u0027vanishing\u0027), (1.0, \u0027marginal\u0027), (2.0, \u0027exploding\u0027)]:\n    norms = gradient_norm_vs_lag(scale)\n    mid   = T // 2\n    print(f\u0027{scale:\u003e8.1f} {norms[T-1]:\u003e12.4e} {norms[mid]:\u003e12.4e} \u0027\n          f\u0027{norms[0]:\u003e12.4e} {label:\u003e12}\u0027)\nprint(f\u0027For scale=0.5: ratio norms[t=0]/norms[t=T-1] ~ (0.5/sqrt(H))^{T} ~ 0\u0027)"},{"type":"heading","level":2,"content":"1D RNN Analytical Gradient"},{"type":"text","content":"For a 1D RNN (H=1), the gradient has a closed form that makes the decay explicit. With h_t = tanh(w_hh · h_{t-1} + w_xh · x_t + b), the gradient dL/dh_k = dL/dh_T · Πⱼ₌ₖ₊₁ᵀ (w_hh · (1 − h_j²)). If w_hh = 0.9 and tanh\u0027(hⱼ) ≈ 0.9 (near zero), each factor is ~0.81, and after 50 steps the gradient is ~0.81⁵⁰ ≈ 1.8×10⁻⁵. This 1D analysis makes the exponential decay transparent and generalises to higher dimensions where σ_max(Wₕₕ) plays the role of w_hh."},{"type":"code","language":"python","content":"import numpy as np\n\n\"\"\"\n1D RNN: h_t = tanh(w_hh * h_{t-1} + w_xh * x_t + b)\nGradient: dL/dh_k = dL/dh_T * prod_{j=k+1}^{T} [w_hh * (1 - h_j^2)]\n\"\"\"\n\nnp.random.seed(0)\n\ndef analytical_grad_1d(w_hh, T=30, w_xh=0.1, b=0.0, seed=0):\n    rng = np.random.RandomState(seed)\n    xs  = rng.randn(T) * 0.5\n    hs  = [0.0]\n    for t in range(T):\n        hs.append(np.tanh(w_hh * hs[-1] + w_xh * xs[t] + b))\n    # Compute dL/dh_k for each k given unit gradient at T-1\n    dL_dhk = [0.0] * T\n    dL_dhk[-1] = 1.0\n    for k in range(T - 2, -1, -1):\n        product = 1.0\n        for j in range(k + 1, T):\n            tanh_prime = 1.0 - hs[j + 1] ** 2\n            product   *= w_hh * tanh_prime\n        dL_dhk[k] = product\n    return hs[1:], dL_dhk\n\nprint(f\u0027{\"w_hh\":\u003e8} {\"lag\":\u003e5} {\"dL/dh_k\":\u003e14} {\"Analysis\"}\u0027)\nfor w_hh in [0.5, 0.9, 1.0, 1.5]:\n    _, grads = analytical_grad_1d(w_hh)\n    T = len(grads)\n    for lag in [1, 5, 15, 29]:\n        k = T - 1 - lag\n        g = abs(grads[k])\n        regime = \u0027vanishing\u0027 if g \u003c 1e-3 else (\u0027exploding\u0027 if g \u003e 1e3 else \u0027stable\u0027)\n        print(f\u0027{w_hh:\u003e8.1f} {lag:\u003e5} {g:\u003e14.4e} {regime}\u0027)"},{"type":"heading","level":2,"content":"Gradient Norm vs Time Lag"},{"type":"text","content":"Plotting gradient norm against time lag (distance from loss to hidden state) reveals the regime clearly: exponential decay for small Wₕₕ, near-constant for orthogonal Wₕₕ, exponential growth for large Wₕₕ. In practice, even well-initialised RNNs transition to vanishing within 20–50 steps as tanh saturation accumulates. The LSTM solves this with an additive cell state update (Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ) — the forget gate allows gradient to flow through the cell state with only elementwise multiplication by fₜ, avoiding the repeated matrix multiplication by Wₕₕᵀ."},{"type":"heading","level":2,"content":"LSTM and GRU as Solutions"},{"type":"text","content":"The LSTM introduces a cell state Cₜ that is updated additively: Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ. The gradient of the loss with respect to the cell state at time k flows back through the forget gate only: ∂Cₜ/∂Cₜ₋₁ = diag(fₜ). Since fₜ ∈ (0,1)ᴴ (element-wise sigmoid), this is a diagonal matrix — no repeated matrix multiplication by Wₕₕ. With forget gates initialised near 1 (bias = 1), the gradient can flow through hundreds of steps without exponential decay. The GRU uses a simpler two-gate design that achieves similar long-range gradient flow."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(42)\n\ndef make_copy_batch(B=64, T=50, n_classes=8):\n    \"\"\"Copy task: remember item from t=0 after T filler steps.\"\"\"\n    target = torch.randint(n_classes, (B,))\n    x = torch.zeros(B, T + 1, n_classes + 1)\n    x[:, 0, :n_classes] = nn.functional.one_hot(target, n_classes).float()\n    x[:, 1:, n_classes] = 1.0  # filler signal\n    return x, target\n\nclass SeqClassifier(nn.Module):\n    def __init__(self, cell_type, inp, hid, n_classes):\n        super().__init__()\n        RNNClass = nn.RNN if cell_type == \u0027rnn\u0027 else nn.LSTM\n        self.rnn  = RNNClass(inp, hid, batch_first=True)\n        self.fc   = nn.Linear(hid, n_classes)\n        self.is_lstm = (cell_type == \u0027lstm\u0027)\n    def forward(self, x):\n        out = self.rnn(x)[0]  # (B, T, H)\n        return self.fc(out[:, -1, :])\n\nn_classes, H, B, epochs, T_lag = 8, 64, 64, 300, 50\nfor cell in [\u0027rnn\u0027, \u0027lstm\u0027]:\n    model = SeqClassifier(cell, n_classes + 1, H, n_classes)\n    opt   = torch.optim.Adam(model.parameters(), lr=1e-3)\n    for ep in range(epochs):\n        x, y = make_copy_batch(B, T_lag, n_classes)\n        loss = nn.functional.cross_entropy(model(x), y)\n        opt.zero_grad(); loss.backward(); opt.step()\n    with torch.no_grad():\n        x, y  = make_copy_batch(512, T_lag, n_classes)\n        acc   = (model(x).argmax(1) == y).float().mean().item()\n    print(f\u0027{cell.upper():4s} T_lag={T_lag}: acc={acc:.4f} (chance={1/n_classes:.4f})\u0027)"},{"type":"heading","level":2,"content":"Orthogonal Initialization"},{"type":"text","content":"Orthogonal initialisation sets Wₕₕ to an orthogonal matrix (WₕₕᵀWₕₕ = I), giving spectral radius exactly 1 at initialisation. This means all eigenvalues lie on the unit circle: no vanishing or exploding at initialisation. As training proceeds, Wₕₕ moves away from orthogonality, but the careful start delays the onset of vanishing. Orthogonal init helps but does not solve the long-term problem — after many training steps, the spectral radius can drift. It is most useful combined with other techniques (LSTM, gradient clipping, careful learning rates)."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\nnp.random.seed(42); torch.manual_seed(42)\nH = 32\n\ndef spectral_analysis(W, label):\n    eigvals = np.linalg.eigvals(W)\n    mags    = np.abs(eigvals)\n    print(f\u0027{label}:\u0027)\n    print(f\u0027  spectral radius = {mags.max():.4f}\u0027)\n    print(f\u0027  min |lambda| = {mags.min():.4f}, fraction \u003c 1 = {(mags \u003c 1).mean():.2f}\u0027)\n    return mags.max()\n\n# Random normal initialization\nW_rand = np.random.randn(H, H) * 0.1\nrho_rand = spectral_analysis(W_rand, \u0027Random normal (scale=0.1)\u0027)\n\n# Orthogonal initialization\nW_t = torch.empty(H, H)\nnn.init.orthogonal_(W_t)\nW_orth = W_t.numpy()\nrho_orth = spectral_analysis(W_orth, \u0027Orthogonal init\u0027)\n\n# Identity initialization\nW_id = np.eye(H)\nrho_id = spectral_analysis(W_id, \u0027Identity init\u0027)\n\n# Estimated gradient decay after T steps\nT = 40\nprint(f\u0027Estimated gradient magnitude after T={T} steps (rho^T):\u0027)\nfor rho, label in [(rho_rand, \u0027Random\u0027), (rho_orth, \u0027Orthogonal\u0027), (rho_id, \u0027Identity\u0027)]:\n    print(f\u0027  {label}: rho={rho:.4f}, rho^{T} = {rho**T:.4e}\u0027)"},{"type":"heading","level":2,"content":"Consequence for Training"},{"type":"text","content":"The vanishing gradient is specifically a training problem, not an inference problem. At inference, an RNN can carry information forward through its hidden state for any number of steps — the information is there, but the model was not able to learn to use it because the training signal could not propagate back to the parameters responsible. Equivalently: if you could somehow train the model to use long-range patterns, it would work at inference. The challenge is that gradient descent cannot find those parameters because the loss surface provides no gradient signal for long-range weights."},{"type":"callout","variant":"warning","title":"Vanishing Gradient Is a Training Problem","content":"A trained LSTM with forget gates set to 1 can preserve information for thousands of steps at inference. The vanishing gradient problem prevents gradient descent from learning to set those forget gates appropriately. Gradient clipping helps with exploding but not vanishing. The architectural fix (LSTM/GRU additive cell state) is the only reliable solution; orthogonal init and batch norm are partial mitigations."},{"type":"heading","level":2,"content":"Solutions Comparison"},{"type":"table","headers":["Method","Gradient Path","Long-Range Ability","Extra Params vs RNN","Training Complexity"],"rows":[["Vanilla RNN","Through Wₕₕᵀ at each step (product of matrices)","Poor — exponential decay in T−k","None — baseline","Simple; gradient clipping required"],["LSTM","Through cell state Cₜ (additive update, diagonal gate)","Good — linear gradient highway","4x (4 gates instead of 1)","Moderate; forget gate bias init = 1"],["GRU","Through update gate (convex combination of h_prev and candidate)","Good — similar to LSTM","3x (3 gates)","Simpler than LSTM; often comparable performance"],["Orthogonal init","Still through Wₕₕᵀ — but spectral radius = 1 at init","Moderate — delays onset of vanishing","None — init change only","Same as RNN; effect diminishes after early training"],["Chrono init (forget bias=1)","LSTM with forget gate initialised near open (1)","Good — LSTM benefit + better init","Same as LSTM","Easy to apply; recommended default for LSTM training"]]},{"type":"list","ordered":false,"items":["Vanishing gradient: ‖dLt/dhk‖ ~ sigma_max(Whh)^(t-k) -- exponential in lag.","Exploding gradient: same formula with sigma_max \u003e 1; fix with gradient clipping.","LSTM solution: additive cell update Ct = ft*Ct-1 + it*C_tilde avoids repeated Whh multiplication.","GRU solution: update gate zt = sigma(Wz[ht-1, xt]); ht = (1-zt)*ht-1 + zt*h_tilde.","Orthogonal init: WhhT Whh = I at init; spectral radius = 1; use nn.init.orthogonal_.","Practical: use LSTM/GRU for any task with dependencies \u003e 20 steps; plain RNN only for short sequences."]},{"type":"divider"}]"
---
# Vanishing Gradient in RNNs — Mathematical Derivation

The vanishing gradient problem in RNNs is not a numerical issue — it is a consequence of the mathematical structure of gradient backpropagation through time. The gradient of the loss at step T with respect to the hidden state at step k is: dLₜ/dhₖ = (dLₜ/dhₜ) · Πⱼ₌ₖ₊₁ᵀ (dhⱼ/dhⱼ₋₁). Each Jacobian factor ∂hⱼ/∂hⱼ₋₁ = Wₕₕᵀ · diag(tanh'(hⱼ)) where tanh'(x) = 1 − tanh(x)² ∈ [0,1]. If the largest singular value of Wₕₕ is less than 1 (or tanh saturates), the product decays exponentially with T−k. This means the RNN gradient for a dependency at lag 50 is typically 10⁻¹⁵ times smaller than the gradient for a dependency at lag 1 — numerically zero in float32.

## Mathematical Derivation of Vanishing Gradient

Define the Jacobian of hⱼ with respect to hⱼ₋₁: Jⱼ = ∂hⱼ/∂hⱼ₋₁ = Wₕₕᵀ · diag(1 − hⱼ²). The gradient of the loss at time t with respect to hₖ is: dLₜ/dhₖ = (dLₜ/dhₜ) · Jₜ · Jₜ₋₁ · ... · Jₖ₊₁ (a product of t−k matrices). By the sub-multiplicativity of matrix norms: ‖Πⱼ Jⱼ‖ ≤ Πⱼ ‖Jⱼ‖. Since ‖Jⱼ‖ ≤ σ_max(Wₕₕ) · ‖diag(tanh')‖ ≤ σ_max(Wₕₕ), if σ_max(Wₕₕ) < 1 then ‖dLₜ/dhₖ‖ ≤ ‖dLₜ/dhₜ‖ · σ_max(Wₕₕ)^(t−k) → 0 exponentially. This is not an implementation bug — it is the fundamental reason plain RNNs cannot learn long-range dependencies.

```python
import numpy as np

np.random.seed(42)
T, H, I = 50, 16, 4

def gradient_norm_vs_lag(Whh_scale, T=50, H=16, I=4, seed=0):
    rng = np.random.RandomState(seed)
    Wxh = rng.randn(H, I) * 0.1
    Whh = rng.randn(H, H) * Whh_scale / np.sqrt(H)
    bh  = np.zeros((H, 1))
    xs  = [rng.randn(I, 1) for _ in range(T)]
    hs  = {-1: np.zeros((H, 1))}
    for t in range(T):
        hs[t] = np.tanh(Wxh @ xs[t] + Whh @ hs[t-1] + bh)
    dh = np.ones((H, 1)) / H  # unit gradient at t = T-1
    norms = {}
    for t in reversed(range(T)):
        norms[t] = float(np.linalg.norm(dh))
        dtanh    = (1 - hs[t]**2) * dh
        dh       = Whh.T @ dtanh
    return [norms[t] for t in range(T)]

print(f'{"Scale":>8} {"t=T-1":>12} {"t=T/2":>12} {"t=0":>12} {"Regime":>12}')
for scale, label in [(0.5, 'vanishing'), (1.0, 'marginal'), (2.0, 'exploding')]:
    norms = gradient_norm_vs_lag(scale)
    mid   = T // 2
    print(f'{scale:>8.1f} {norms[T-1]:>12.4e} {norms[mid]:>12.4e} '
          f'{norms[0]:>12.4e} {label:>12}')
print(f'For scale=0.5: ratio norms[t=0]/norms[t=T-1] ~ (0.5/sqrt(H))^{T} ~ 0')
```

## 1D RNN Analytical Gradient

For a 1D RNN (H=1), the gradient has a closed form that makes the decay explicit. With h_t = tanh(w_hh · h_{t-1} + w_xh · x_t + b), the gradient dL/dh_k = dL/dh_T · Πⱼ₌ₖ₊₁ᵀ (w_hh · (1 − h_j²)). If w_hh = 0.9 and tanh'(hⱼ) ≈ 0.9 (near zero), each factor is ~0.81, and after 50 steps the gradient is ~0.81⁵⁰ ≈ 1.8×10⁻⁵. This 1D analysis makes the exponential decay transparent and generalises to higher dimensions where σ_max(Wₕₕ) plays the role of w_hh.

```python
import numpy as np

"""
1D RNN: h_t = tanh(w_hh * h_{t-1} + w_xh * x_t + b)
Gradient: dL/dh_k = dL/dh_T * prod_{j=k+1}^{T} [w_hh * (1 - h_j^2)]
"""

np.random.seed(0)

def analytical_grad_1d(w_hh, T=30, w_xh=0.1, b=0.0, seed=0):
    rng = np.random.RandomState(seed)
    xs  = rng.randn(T) * 0.5
    hs  = [0.0]
    for t in range(T):
        hs.append(np.tanh(w_hh * hs[-1] + w_xh * xs[t] + b))
    # Compute dL/dh_k for each k given unit gradient at T-1
    dL_dhk = [0.0] * T
    dL_dhk[-1] = 1.0
    for k in range(T - 2, -1, -1):
        product = 1.0
        for j in range(k + 1, T):
            tanh_prime = 1.0 - hs[j + 1] ** 2
            product   *= w_hh * tanh_prime
        dL_dhk[k] = product
    return hs[1:], dL_dhk

print(f'{"w_hh":>8} {"lag":>5} {"dL/dh_k":>14} {"Analysis"}')
for w_hh in [0.5, 0.9, 1.0, 1.5]:
    _, grads = analytical_grad_1d(w_hh)
    T = len(grads)
    for lag in [1, 5, 15, 29]:
        k = T - 1 - lag
        g = abs(grads[k])
        regime = 'vanishing' if g < 1e-3 else ('exploding' if g > 1e3 else 'stable')
        print(f'{w_hh:>8.1f} {lag:>5} {g:>14.4e} {regime}')
```

## Gradient Norm vs Time Lag

Plotting gradient norm against time lag (distance from loss to hidden state) reveals the regime clearly: exponential decay for small Wₕₕ, near-constant for orthogonal Wₕₕ, exponential growth for large Wₕₕ. In practice, even well-initialised RNNs transition to vanishing within 20–50 steps as tanh saturation accumulates. The LSTM solves this with an additive cell state update (Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ) — the forget gate allows gradient to flow through the cell state with only elementwise multiplication by fₜ, avoiding the repeated matrix multiplication by Wₕₕᵀ.

## LSTM and GRU as Solutions

The LSTM introduces a cell state Cₜ that is updated additively: Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ. The gradient of the loss with respect to the cell state at time k flows back through the forget gate only: ∂Cₜ/∂Cₜ₋₁ = diag(fₜ). Since fₜ ∈ (0,1)ᴴ (element-wise sigmoid), this is a diagonal matrix — no repeated matrix multiplication by Wₕₕ. With forget gates initialised near 1 (bias = 1), the gradient can flow through hundreds of steps without exponential decay. The GRU uses a simpler two-gate design that achieves similar long-range gradient flow.

```python
import torch
import torch.nn as nn

torch.manual_seed(42)

def make_copy_batch(B=64, T=50, n_classes=8):
    """Copy task: remember item from t=0 after T filler steps."""
    target = torch.randint(n_classes, (B,))
    x = torch.zeros(B, T + 1, n_classes + 1)
    x[:, 0, :n_classes] = nn.functional.one_hot(target, n_classes).float()
    x[:, 1:, n_classes] = 1.0  # filler signal
    return x, target

class SeqClassifier(nn.Module):
    def __init__(self, cell_type, inp, hid, n_classes):
        super().__init__()
        RNNClass = nn.RNN if cell_type == 'rnn' else nn.LSTM
        self.rnn  = RNNClass(inp, hid, batch_first=True)
        self.fc   = nn.Linear(hid, n_classes)
        self.is_lstm = (cell_type == 'lstm')
    def forward(self, x):
        out = self.rnn(x)[0]  # (B, T, H)
        return self.fc(out[:, -1, :])

n_classes, H, B, epochs, T_lag = 8, 64, 64, 300, 50
for cell in ['rnn', 'lstm']:
    model = SeqClassifier(cell, n_classes + 1, H, n_classes)
    opt   = torch.optim.Adam(model.parameters(), lr=1e-3)
    for ep in range(epochs):
        x, y = make_copy_batch(B, T_lag, n_classes)
        loss = nn.functional.cross_entropy(model(x), y)
        opt.zero_grad(); loss.backward(); opt.step()
    with torch.no_grad():
        x, y  = make_copy_batch(512, T_lag, n_classes)
        acc   = (model(x).argmax(1) == y).float().mean().item()
    print(f'{cell.upper():4s} T_lag={T_lag}: acc={acc:.4f} (chance={1/n_classes:.4f})')
```

## Orthogonal Initialization

Orthogonal initialisation sets Wₕₕ to an orthogonal matrix (WₕₕᵀWₕₕ = I), giving spectral radius exactly 1 at initialisation. This means all eigenvalues lie on the unit circle: no vanishing or exploding at initialisation. As training proceeds, Wₕₕ moves away from orthogonality, but the careful start delays the onset of vanishing. Orthogonal init helps but does not solve the long-term problem — after many training steps, the spectral radius can drift. It is most useful combined with other techniques (LSTM, gradient clipping, careful learning rates).

```python
import numpy as np
import torch
import torch.nn as nn

np.random.seed(42); torch.manual_seed(42)
H = 32

def spectral_analysis(W, label):
    eigvals = np.linalg.eigvals(W)
    mags    = np.abs(eigvals)
    print(f'{label}:')
    print(f'  spectral radius = {mags.max():.4f}')
    print(f'  min |lambda| = {mags.min():.4f}, fraction < 1 = {(mags < 1).mean():.2f}')
    return mags.max()

# Random normal initialization
W_rand = np.random.randn(H, H) * 0.1
rho_rand = spectral_analysis(W_rand, 'Random normal (scale=0.1)')

# Orthogonal initialization
W_t = torch.empty(H, H)
nn.init.orthogonal_(W_t)
W_orth = W_t.numpy()
rho_orth = spectral_analysis(W_orth, 'Orthogonal init')

# Identity initialization
W_id = np.eye(H)
rho_id = spectral_analysis(W_id, 'Identity init')

# Estimated gradient decay after T steps
T = 40
print(f'Estimated gradient magnitude after T={T} steps (rho^T):')
for rho, label in [(rho_rand, 'Random'), (rho_orth, 'Orthogonal'), (rho_id, 'Identity')]:
    print(f'  {label}: rho={rho:.4f}, rho^{T} = {rho**T:.4e}')
```

## Consequence for Training

The vanishing gradient is specifically a training problem, not an inference problem. At inference, an RNN can carry information forward through its hidden state for any number of steps — the information is there, but the model was not able to learn to use it because the training signal could not propagate back to the parameters responsible. Equivalently: if you could somehow train the model to use long-range patterns, it would work at inference. The challenge is that gradient descent cannot find those parameters because the loss surface provides no gradient signal for long-range weights.

> **Vanishing Gradient Is a Training Problem**: A trained LSTM with forget gates set to 1 can preserve information for thousands of steps at inference. The vanishing gradient problem prevents gradient descent from learning to set those forget gates appropriately. Gradient clipping helps with exploding but not vanishing. The architectural fix (LSTM/GRU additive cell state) is the only reliable solution; orthogonal init and batch norm are partial mitigations.

## Solutions Comparison

| Method | Gradient Path | Long-Range Ability | Extra Params vs RNN | Training Complexity |
| --- | --- | --- | --- | --- |
| Vanilla RNN | Through Wₕₕᵀ at each step (product of matrices) | Poor — exponential decay in T−k | None — baseline | Simple; gradient clipping required |
| LSTM | Through cell state Cₜ (additive update, diagonal gate) | Good — linear gradient highway | 4x (4 gates instead of 1) | Moderate; forget gate bias init = 1 |
| GRU | Through update gate (convex combination of h_prev and candidate) | Good — similar to LSTM | 3x (3 gates) | Simpler than LSTM; often comparable performance |
| Orthogonal init | Still through Wₕₕᵀ — but spectral radius = 1 at init | Moderate — delays onset of vanishing | None — init change only | Same as RNN; effect diminishes after early training |
| Chrono init (forget bias=1) | LSTM with forget gate initialised near open (1) | Good — LSTM benefit + better init | Same as LSTM | Easy to apply; recommended default for LSTM training |

- Vanishing gradient: ‖dLt/dhk‖ ~ sigma_max(Whh)^(t-k) -- exponential in lag.
- Exploding gradient: same formula with sigma_max > 1; fix with gradient clipping.
- LSTM solution: additive cell update Ct = ft*Ct-1 + it*C_tilde avoids repeated Whh multiplication.
- GRU solution: update gate zt = sigma(Wz[ht-1, xt]); ht = (1-zt)*ht-1 + zt*h_tilde.
- Orthogonal init: WhhT Whh = I at init; spectral radius = 1; use nn.init.orthogonal_.
- Practical: use LSTM/GRU for any task with dependencies > 20 steps; plain RNN only for short sequences.

---

