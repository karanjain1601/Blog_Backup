---
title: "S4 — Structured State Space Sequence Models"
slug: "s4-structured-state-space"
description: "S4 structured state space models — continuous-time SSMs, HiPPO polynomial approximation, and efficient O(L log L) training via global convolution and the Cauchy kernel."
tags: ["deep-learning", "rnns", "sequence-models", "state-space-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"State space models (SSMs) have a long history in control theory and signal processing, but applying them to deep sequence modeling required solving three hard problems simultaneously: how to initialize the state matrix A to capture long-range dependencies, how to train efficiently without sequential recurrence, and how to handle very long sequences (L = 16,000+) where transformers are prohibitively expensive. S4 (Gu et al., 2021) solved all three by combining the HiPPO framework for A initialization with a structured normal plus low-rank (NPLR) representation that admits an O(L log L) convolutional computation."},{"type":"heading","level":2,"content":"State Space Models — The Continuous-Time Foundation"},{"type":"text","content":"A linear time-invariant SSM maps input u(t) to output y(t) through a latent state x(t) ∈ ℝᴺ. The continuous-time equations are x\u0027(t) = Ax(t) + Bu(t) and y(t) = Cx(t) + Du(t), where A ∈ ℝ^{N×N}, B ∈ ℝ^{N×1}, C ∈ ℝ^{1×N}, D ∈ ℝ. For discrete sequences, the system is discretized using zero-order hold (ZOH): Ā = exp(ΔA), B̄ = (Ā - I)A⁻¹B, giving the recurrence xₙ = Āxₙ₋₁ + B̄uₙ and yₙ = Cxₙ + Duₙ. The step size Δ controls the time resolution and is a learnable parameter."},{"type":"list","ordered":false,"items":["N = state dimension (typically 64–256): controls memory capacity of the SSM","Ā ∈ ℝ^{N×N}: discretized state transition — determines what the state remembers","B̄ ∈ ℝ^{N×1}: input projection — how new input modifies the state","C ∈ ℝ^{1×N}: output projection — how state maps to scalar output","Recurrent mode: O(N) per step for inference; Convolutional mode: O(L log L) for training"]},{"type":"heading","level":2,"content":"The HiPPO Framework for Long-Range Memory"},{"type":"text","content":"The key insight behind S4 is that naive random initialization of A leads to poor long-range memory — the state rapidly forgets distant inputs. HiPPO (High-order Polynomial Projection Operators, Gu et al. 2020) provides a principled initialization: A is chosen so that the hidden state x(t) at any time t is the optimal polynomial approximation of the input history u(0:t) in a Legendre polynomial basis. HiPPO-LegT sets A[n,k] = -(2n+1)^{0.5}(2k+1)^{0.5} for k ≤ n. This matrix has a structured skew-Hermitian plus diagonal form that can be diagonalized efficiently, enabling O(L log L) convolution via Cauchy kernel computation."},{"type":"callout","variant":"info","title":"Why the A Matrix Matters","content":"For an SSM to learn long-range dependencies, the state transition Ā must preserve information from far-distant inputs. Random A matrices have eigenvalues with large negative real parts — the state decays exponentially fast. HiPPO initializes A so its eigenvalues cluster near the imaginary axis, enabling the state to maintain polynomial approximations of the entire input history without exponential forgetting."},{"type":"heading","level":2,"content":"Code 1 — Discrete SSM in Recurrent Mode"},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.linalg import expm\n\ndef discretize_zoh(A, B, delta):\n    \"\"\"Zero-order hold discretization: Abar=exp(delta*A), Bbar=(Abar-I)A^{-1}B.\"\"\"\n    N = A.shape[0]\n    A_bar = expm(delta * A)\n    B_bar = np.linalg.solve(A, (A_bar - np.eye(N)) @ B)\n    return A_bar, B_bar\n\ndef ssm_recurrent(A_bar, B_bar, C, u_seq):\n    \"\"\"\n    Run discrete SSM in recurrent mode: O(N) per step.\n    A_bar: (N,N), B_bar: (N,1), C: (1,N), u_seq: (L,)\n    Returns y: (L,)\n    \"\"\"\n    N = A_bar.shape[0]\n    x = np.zeros(N)\n    y = []\n    for u in u_seq:\n        x = A_bar @ x + B_bar.ravel() * u   # state update\n        y.append((C @ x).item())             # output\n    return np.array(y)\n\n# 4-state stable diagonal system\nnp.random.seed(42)\nN = 4\nA = -np.diag(np.arange(1, N+1, dtype=float))   # stable: all eigenvalues negative real\nB = np.ones((N, 1))\nC = np.random.randn(1, N) * 0.1\ndelta = 0.01\nA_bar, B_bar = discretize_zoh(A, B, delta)\nL = 200\nu = np.sin(np.linspace(0, 4 * np.pi, L))\ny = ssm_recurrent(A_bar, B_bar, C, u)\nprint(f\"Input: {u.shape}, Output: {y.shape}\")\nprint(f\"Output range: [{y.min():.4f}, {y.max():.4f}]\")"},{"type":"heading","level":2,"content":"Code 2 — SSM in Convolutional Mode"},{"type":"text","content":"The SSM can also be viewed as a global convolutional filter: the impulse response K[l] = C·Āˡ·B̄ gives the convolution kernel, and the output y = K * u. This is because the recurrence unrolls as yₙ = Σₗ C·Āˡ·B̄·uₙ₋ₗ — exactly a (causal) convolution. The kernel has length L (same as the sequence), making it a global convolution. Computing it naively costs O(L·N²) due to the matrix powers, but S4 uses the fact that the diagonalized A enables fast Cauchy kernel computation. In practice, FFT-based convolution runs in O(L log L)."},{"type":"code","language":"python","content":"import numpy as np\n\ndef ssm_kernel(A_bar, B_bar, C, L):\n    \"\"\"Compute global SSM convolution kernel K[l] = C @ A_bar^l @ B_bar.\"\"\"\n    N = A_bar.shape[0]\n    K = np.zeros(L)\n    A_pow = np.eye(N)\n    for l in range(L):\n        K[l] = (C @ A_pow @ B_bar).item()\n        A_pow = A_pow @ A_bar\n    return K\n\ndef ssm_conv_forward(K, u):\n    \"\"\"Apply SSM as causal convolution: y = K * u (output length = L).\"\"\"\n    return np.convolve(K, u)[:len(u)]\n\ndef ssm_conv_fft(K, u):\n    \"\"\"FFT-based convolution: O(L log L) — matches causal conv result.\"\"\"\n    L = len(u)\n    K_fft = np.fft.rfft(K, n=2*L)\n    u_fft = np.fft.rfft(u, n=2*L)\n    return np.fft.irfft(K_fft * u_fft, n=2*L)[:L]\n\n# Euler discretization for simplicity (replace with ZOH in practice)\nN, L = 4, 128\nA = -np.diag(np.arange(1, N+1, dtype=float))\nB, C  = np.ones((N, 1)), np.random.randn(1, N) * 0.1\nA_bar = np.eye(N) + 0.01 * A\nB_bar = 0.01 * B\nK = ssm_kernel(A_bar, B_bar, C, L)\nu = np.sin(np.linspace(0, 4*np.pi, L))\ny_direct = ssm_conv_forward(K, u)\ny_fft    = ssm_conv_fft(K, u)\nprint(f\"Kernel: {K.shape}, first 3: {K[:3]}\")\nprint(f\"Direct vs FFT max diff: {np.abs(y_direct - y_fft).max():.2e}\")"},{"type":"heading","level":2,"content":"Code 3 — HiPPO Matrix Initialization"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef hippo_legt_matrix(N):\n    \"\"\"HiPPO-LegT A matrix: optimal polynomial approximation of input history.\"\"\"\n    A = np.zeros((N, N))\n    for n in range(N):\n        for k in range(N):\n            if k \u003c= n:\n                A[n, k] = -np.sqrt(2*n+1) * np.sqrt(2*k+1)\n    return A\n\ndef hippo_b_vector(N):\n    \"\"\"HiPPO B vector: b[n] = sqrt(2n+1).\"\"\"\n    return np.sqrt(np.arange(1, 2*N, 2, dtype=float)).reshape(N, 1)\n\nN = 32\nA_hippo = hippo_legt_matrix(N)\nB_hippo = hippo_b_vector(N)\neigenvalues = np.linalg.eigvals(A_hippo)\nprint(f\"HiPPO-LegT A shape: {A_hippo.shape}\")\nprint(f\"Eigenvalue real range: [{eigenvalues.real.min():.1f}, {eigenvalues.real.max():.1f}]\")\nprint(f\"All eigenvalues non-positive real: {(eigenvalues.real \u003c= 1e-8).all()}\")\n\nfig, axes = plt.subplots(1, 2, figsize=(12, 4))\naxes[0].imshow(A_hippo, cmap=\u0027RdBu\u0027, aspect=\u0027auto\u0027)\naxes[0].set_title(f\u0027HiPPO-LegT A (N={N})\u0027)\naxes[0].set_xlabel(\u0027k\u0027); axes[0].set_ylabel(\u0027n\u0027)\naxes[1].scatter(eigenvalues.real, eigenvalues.imag, c=\u0027steelblue\u0027, s=50)\naxes[1].axvline(0, color=\u0027red\u0027, linestyle=\u0027--\u0027, label=\u0027stability boundary\u0027)\naxes[1].set_title(\u0027Eigenvalue spectrum (stable if real \u003c 0)\u0027)\naxes[1].set_xlabel(\u0027Real\u0027); axes[1].set_ylabel(\u0027Imaginary\u0027)\naxes[1].legend()\nplt.tight_layout()\nplt.savefig(\u0027hippo_matrix.png\u0027, dpi=120)\nplt.show()"},{"type":"heading","level":2,"content":"Code 4 — S4 on Long-Sequence Classification"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass S4Layer(nn.Module):\n    \"\"\"Simplified S4 layer using learned global convolution kernel via FFT.\"\"\"\n    def __init__(self, d_model, seq_len):\n        super().__init__()\n        self.d_model = d_model\n        self.seq_len = seq_len\n        # Learnable convolution kernel (replaces structured SSM kernel in full S4)\n        self.kernel = nn.Parameter(torch.randn(d_model, seq_len) * 0.01)\n        self.D      = nn.Parameter(torch.ones(d_model))   # skip connection\n        self.norm   = nn.LayerNorm(d_model)\n\n    def forward(self, u):\n        # u: (B, L, d_model) -\u003e y: (B, L, d_model)\n        B, L, d = u.shape\n        y = torch.zeros_like(u)\n        for i in range(d):\n            k      = self.kernel[i, :L]\n            k_fft  = torch.fft.rfft(k, n=2*L)\n            u_fft  = torch.fft.rfft(u[..., i], n=2*L)\n            y[..., i] = torch.fft.irfft(k_fft * u_fft, n=2*L)[:, :L]\n        y = y + self.D * u          # skip (D term in SSM)\n        return self.norm(y)\n\n# Toy long-range classification task\ntorch.manual_seed(42)\nL, d, B = 1024, 32, 8\nmodel = nn.Sequential(\n    S4Layer(d, L),\n    nn.Linear(d, 64),\n    nn.GELU(),\n    nn.Linear(64, 2)\n)\ndummy_x = torch.randn(B, L, d)\nlogits  = model(dummy_x).mean(dim=1)      # global average pooling\nloss    = nn.CrossEntropyLoss()(logits, torch.randint(0, 2, (B,)))\nprint(f\"S4 output: {logits.shape}, Loss: {loss.item():.4f}\")\nprint(f\"Params: {sum(p.numel() for p in model.parameters()):,}\")"},{"type":"heading","level":2,"content":"S4 Variants and Related Work"},{"type":"text","content":"The S4 paper spawned a family of simplified variants. S4D (diagonal S4) restricts A to be diagonal, eliminating the need for the NPLR decomposition and making the model easier to implement while retaining most performance. DSS (Diagonal State Spaces) independently proposed diagonal A. S5 (Simplified S4) uses a multi-input multi-output (MIMO) SSM with diagonal A and a parallel scan for training. Liquid S4 combines SSMs with liquid time-constant networks for adaptive dynamics. All variants inherit S4\u0027s key advantage: they can switch between recurrent mode (O(1) per step, ideal for inference) and convolutional mode (O(L log L), ideal for training)."},{"type":"list","ordered":false,"items":["S4D: diagonal A — simpler, nearly identical LRA performance to full S4","DSS: independently derived diagonal SSM with similar formulation","S5: MIMO SSM with parallel scan — vectorized across d_model channels","Liquid S4: time-varying state transitions from liquid networks","Mamba: extends S4 with input-dependent (selective) transitions — see mamba-selective-ssm"]},{"type":"heading","level":2,"content":"RNN vs Transformer vs S4 Comparison"},{"type":"text","content":"S4 occupies a unique position in the sequence modeling landscape. Unlike RNNs it trains in parallel (via global convolution), and unlike Transformers its inference is O(1) per step with a fixed-size state — no KV cache that grows with sequence length. The Long Range Arena (LRA) benchmark, which tests on sequences up to length 16,384, showed that S4 was the first model to match or exceed attention on all six tasks including the notoriously difficult Path-X task (sequences of 16,384 pixels forming paths to classify), where transformers scored at chance level."},{"type":"table","headers":["Property","RNN (LSTM/GRU)","Transformer","S4","Mamba"],"rows":[["Training parallelism","Sequential (slow)","Fully parallel","O(L log L) conv","Parallel scan"],["Inference per step","O(N)","O(L·d)","O(N)","O(N)"],["Long-range modeling","Poor (vanishing grad)","Strong (full attention)","Strong (HiPPO)","Strong (selective)"],["KV cache at inference","No (fixed state)","O(L) grows","No (fixed state)","No (fixed state)"],["Typical max length","1K–10K","512–8K","16K+","16K+"],["LRA Path-X accuracy","~50% (chance)","~50% (chance)","~96%","~98%"]]},{"type":"text","content":"S4 demonstrated that the long-standing dichotomy between parallelizable training (Transformer) and efficient recurrent inference (RNN) could be resolved. The structured SSM framework provides the best of both: train like a CNN (fully parallel convolutional pass), infer like an RNN (constant-memory recurrence). This insight sparked a wave of SSM-based architectures, culminating in Mamba and RetNet, which further address content-selectivity and language modeling respectively."}]"
---
# S4 — Structured State Space Sequence Models

State space models (SSMs) have a long history in control theory and signal processing, but applying them to deep sequence modeling required solving three hard problems simultaneously: how to initialize the state matrix A to capture long-range dependencies, how to train efficiently without sequential recurrence, and how to handle very long sequences (L = 16,000+) where transformers are prohibitively expensive. S4 (Gu et al., 2021) solved all three by combining the HiPPO framework for A initialization with a structured normal plus low-rank (NPLR) representation that admits an O(L log L) convolutional computation.

## State Space Models — The Continuous-Time Foundation

A linear time-invariant SSM maps input u(t) to output y(t) through a latent state x(t) ∈ ℝᴺ. The continuous-time equations are x'(t) = Ax(t) + Bu(t) and y(t) = Cx(t) + Du(t), where A ∈ ℝ^{N×N}, B ∈ ℝ^{N×1}, C ∈ ℝ^{1×N}, D ∈ ℝ. For discrete sequences, the system is discretized using zero-order hold (ZOH): Ā = exp(ΔA), B̄ = (Ā - I)A⁻¹B, giving the recurrence xₙ = Āxₙ₋₁ + B̄uₙ and yₙ = Cxₙ + Duₙ. The step size Δ controls the time resolution and is a learnable parameter.

- N = state dimension (typically 64–256): controls memory capacity of the SSM
- Ā ∈ ℝ^{N×N}: discretized state transition — determines what the state remembers
- B̄ ∈ ℝ^{N×1}: input projection — how new input modifies the state
- C ∈ ℝ^{1×N}: output projection — how state maps to scalar output
- Recurrent mode: O(N) per step for inference; Convolutional mode: O(L log L) for training

## The HiPPO Framework for Long-Range Memory

The key insight behind S4 is that naive random initialization of A leads to poor long-range memory — the state rapidly forgets distant inputs. HiPPO (High-order Polynomial Projection Operators, Gu et al. 2020) provides a principled initialization: A is chosen so that the hidden state x(t) at any time t is the optimal polynomial approximation of the input history u(0:t) in a Legendre polynomial basis. HiPPO-LegT sets A[n,k] = -(2n+1)^{0.5}(2k+1)^{0.5} for k ≤ n. This matrix has a structured skew-Hermitian plus diagonal form that can be diagonalized efficiently, enabling O(L log L) convolution via Cauchy kernel computation.

> **Why the A Matrix Matters**: For an SSM to learn long-range dependencies, the state transition Ā must preserve information from far-distant inputs. Random A matrices have eigenvalues with large negative real parts — the state decays exponentially fast. HiPPO initializes A so its eigenvalues cluster near the imaginary axis, enabling the state to maintain polynomial approximations of the entire input history without exponential forgetting.

## Code 1 — Discrete SSM in Recurrent Mode

```python
import numpy as np
from scipy.linalg import expm

def discretize_zoh(A, B, delta):
    """Zero-order hold discretization: Abar=exp(delta*A), Bbar=(Abar-I)A^{-1}B."""
    N = A.shape[0]
    A_bar = expm(delta * A)
    B_bar = np.linalg.solve(A, (A_bar - np.eye(N)) @ B)
    return A_bar, B_bar

def ssm_recurrent(A_bar, B_bar, C, u_seq):
    """
    Run discrete SSM in recurrent mode: O(N) per step.
    A_bar: (N,N), B_bar: (N,1), C: (1,N), u_seq: (L,)
    Returns y: (L,)
    """
    N = A_bar.shape[0]
    x = np.zeros(N)
    y = []
    for u in u_seq:
        x = A_bar @ x + B_bar.ravel() * u   # state update
        y.append((C @ x).item())             # output
    return np.array(y)

# 4-state stable diagonal system
np.random.seed(42)
N = 4
A = -np.diag(np.arange(1, N+1, dtype=float))   # stable: all eigenvalues negative real
B = np.ones((N, 1))
C = np.random.randn(1, N) * 0.1
delta = 0.01
A_bar, B_bar = discretize_zoh(A, B, delta)
L = 200
u = np.sin(np.linspace(0, 4 * np.pi, L))
y = ssm_recurrent(A_bar, B_bar, C, u)
print(f"Input: {u.shape}, Output: {y.shape}")
print(f"Output range: [{y.min():.4f}, {y.max():.4f}]")
```

## Code 2 — SSM in Convolutional Mode

The SSM can also be viewed as a global convolutional filter: the impulse response K[l] = C·Āˡ·B̄ gives the convolution kernel, and the output y = K * u. This is because the recurrence unrolls as yₙ = Σₗ C·Āˡ·B̄·uₙ₋ₗ — exactly a (causal) convolution. The kernel has length L (same as the sequence), making it a global convolution. Computing it naively costs O(L·N²) due to the matrix powers, but S4 uses the fact that the diagonalized A enables fast Cauchy kernel computation. In practice, FFT-based convolution runs in O(L log L).

```python
import numpy as np

def ssm_kernel(A_bar, B_bar, C, L):
    """Compute global SSM convolution kernel K[l] = C @ A_bar^l @ B_bar."""
    N = A_bar.shape[0]
    K = np.zeros(L)
    A_pow = np.eye(N)
    for l in range(L):
        K[l] = (C @ A_pow @ B_bar).item()
        A_pow = A_pow @ A_bar
    return K

def ssm_conv_forward(K, u):
    """Apply SSM as causal convolution: y = K * u (output length = L)."""
    return np.convolve(K, u)[:len(u)]

def ssm_conv_fft(K, u):
    """FFT-based convolution: O(L log L) — matches causal conv result."""
    L = len(u)
    K_fft = np.fft.rfft(K, n=2*L)
    u_fft = np.fft.rfft(u, n=2*L)
    return np.fft.irfft(K_fft * u_fft, n=2*L)[:L]

# Euler discretization for simplicity (replace with ZOH in practice)
N, L = 4, 128
A = -np.diag(np.arange(1, N+1, dtype=float))
B, C  = np.ones((N, 1)), np.random.randn(1, N) * 0.1
A_bar = np.eye(N) + 0.01 * A
B_bar = 0.01 * B
K = ssm_kernel(A_bar, B_bar, C, L)
u = np.sin(np.linspace(0, 4*np.pi, L))
y_direct = ssm_conv_forward(K, u)
y_fft    = ssm_conv_fft(K, u)
print(f"Kernel: {K.shape}, first 3: {K[:3]}")
print(f"Direct vs FFT max diff: {np.abs(y_direct - y_fft).max():.2e}")
```

## Code 3 — HiPPO Matrix Initialization

```python
import numpy as np
import matplotlib.pyplot as plt

def hippo_legt_matrix(N):
    """HiPPO-LegT A matrix: optimal polynomial approximation of input history."""
    A = np.zeros((N, N))
    for n in range(N):
        for k in range(N):
            if k <= n:
                A[n, k] = -np.sqrt(2*n+1) * np.sqrt(2*k+1)
    return A

def hippo_b_vector(N):
    """HiPPO B vector: b[n] = sqrt(2n+1)."""
    return np.sqrt(np.arange(1, 2*N, 2, dtype=float)).reshape(N, 1)

N = 32
A_hippo = hippo_legt_matrix(N)
B_hippo = hippo_b_vector(N)
eigenvalues = np.linalg.eigvals(A_hippo)
print(f"HiPPO-LegT A shape: {A_hippo.shape}")
print(f"Eigenvalue real range: [{eigenvalues.real.min():.1f}, {eigenvalues.real.max():.1f}]")
print(f"All eigenvalues non-positive real: {(eigenvalues.real <= 1e-8).all()}")

fig, axes = plt.subplots(1, 2, figsize=(12, 4))
axes[0].imshow(A_hippo, cmap='RdBu', aspect='auto')
axes[0].set_title(f'HiPPO-LegT A (N={N})')
axes[0].set_xlabel('k'); axes[0].set_ylabel('n')
axes[1].scatter(eigenvalues.real, eigenvalues.imag, c='steelblue', s=50)
axes[1].axvline(0, color='red', linestyle='--', label='stability boundary')
axes[1].set_title('Eigenvalue spectrum (stable if real < 0)')
axes[1].set_xlabel('Real'); axes[1].set_ylabel('Imaginary')
axes[1].legend()
plt.tight_layout()
plt.savefig('hippo_matrix.png', dpi=120)
plt.show()
```

## Code 4 — S4 on Long-Sequence Classification

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class S4Layer(nn.Module):
    """Simplified S4 layer using learned global convolution kernel via FFT."""
    def __init__(self, d_model, seq_len):
        super().__init__()
        self.d_model = d_model
        self.seq_len = seq_len
        # Learnable convolution kernel (replaces structured SSM kernel in full S4)
        self.kernel = nn.Parameter(torch.randn(d_model, seq_len) * 0.01)
        self.D      = nn.Parameter(torch.ones(d_model))   # skip connection
        self.norm   = nn.LayerNorm(d_model)

    def forward(self, u):
        # u: (B, L, d_model) -> y: (B, L, d_model)
        B, L, d = u.shape
        y = torch.zeros_like(u)
        for i in range(d):
            k      = self.kernel[i, :L]
            k_fft  = torch.fft.rfft(k, n=2*L)
            u_fft  = torch.fft.rfft(u[..., i], n=2*L)
            y[..., i] = torch.fft.irfft(k_fft * u_fft, n=2*L)[:, :L]
        y = y + self.D * u          # skip (D term in SSM)
        return self.norm(y)

# Toy long-range classification task
torch.manual_seed(42)
L, d, B = 1024, 32, 8
model = nn.Sequential(
    S4Layer(d, L),
    nn.Linear(d, 64),
    nn.GELU(),
    nn.Linear(64, 2)
)
dummy_x = torch.randn(B, L, d)
logits  = model(dummy_x).mean(dim=1)      # global average pooling
loss    = nn.CrossEntropyLoss()(logits, torch.randint(0, 2, (B,)))
print(f"S4 output: {logits.shape}, Loss: {loss.item():.4f}")
print(f"Params: {sum(p.numel() for p in model.parameters()):,}")
```

## S4 Variants and Related Work

The S4 paper spawned a family of simplified variants. S4D (diagonal S4) restricts A to be diagonal, eliminating the need for the NPLR decomposition and making the model easier to implement while retaining most performance. DSS (Diagonal State Spaces) independently proposed diagonal A. S5 (Simplified S4) uses a multi-input multi-output (MIMO) SSM with diagonal A and a parallel scan for training. Liquid S4 combines SSMs with liquid time-constant networks for adaptive dynamics. All variants inherit S4's key advantage: they can switch between recurrent mode (O(1) per step, ideal for inference) and convolutional mode (O(L log L), ideal for training).

- S4D: diagonal A — simpler, nearly identical LRA performance to full S4
- DSS: independently derived diagonal SSM with similar formulation
- S5: MIMO SSM with parallel scan — vectorized across d_model channels
- Liquid S4: time-varying state transitions from liquid networks
- Mamba: extends S4 with input-dependent (selective) transitions — see mamba-selective-ssm

## RNN vs Transformer vs S4 Comparison

S4 occupies a unique position in the sequence modeling landscape. Unlike RNNs it trains in parallel (via global convolution), and unlike Transformers its inference is O(1) per step with a fixed-size state — no KV cache that grows with sequence length. The Long Range Arena (LRA) benchmark, which tests on sequences up to length 16,384, showed that S4 was the first model to match or exceed attention on all six tasks including the notoriously difficult Path-X task (sequences of 16,384 pixels forming paths to classify), where transformers scored at chance level.

| Property | RNN (LSTM/GRU) | Transformer | S4 | Mamba |
| --- | --- | --- | --- | --- |
| Training parallelism | Sequential (slow) | Fully parallel | O(L log L) conv | Parallel scan |
| Inference per step | O(N) | O(L·d) | O(N) | O(N) |
| Long-range modeling | Poor (vanishing grad) | Strong (full attention) | Strong (HiPPO) | Strong (selective) |
| KV cache at inference | No (fixed state) | O(L) grows | No (fixed state) | No (fixed state) |
| Typical max length | 1K–10K | 512–8K | 16K+ | 16K+ |
| LRA Path-X accuracy | ~50% (chance) | ~50% (chance) | ~96% | ~98% |

S4 demonstrated that the long-standing dichotomy between parallelizable training (Transformer) and efficient recurrent inference (RNN) could be resolved. The structured SSM framework provides the best of both: train like a CNN (fully parallel convolutional pass), infer like an RNN (constant-memory recurrence). This insight sparked a wave of SSM-based architectures, culminating in Mamba and RetNet, which further address content-selectivity and language modeling respectively.

