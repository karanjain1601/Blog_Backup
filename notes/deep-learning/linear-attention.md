---
title: "Linear Attention — Kernel Approximation of Softmax Attention"
slug: "linear-attention"
description: "Derive the kernel trick that reduces attention from O(L²) to O(Ld²), implement Performer FAVOR+ random feature approximation, verify quality versus softmax on short and long sequences, and benchmark throughput at L=1K, 4K, and 16K."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Softmax attention computes O = softmax(QKᵀ/√d) · V where the intermediate QKᵀ matrix has shape (B, h, L, L) — quadratic in sequence length. Linear attention replaces the softmax with a kernel function φ that factorises over query and key: attn(Q, K, V) ≈ φ(Q)(φ(K)ᵀV). Because matrix multiplication is associative, computing φ(K)ᵀV first (shape d × d) costs O(Ld²); then multiplying φ(Q) by this (shape L × d) costs O(Ld²) — total O(Ld²) independent of L. This eliminates the L² bottleneck at the cost of approximation error in the attention distribution."},{"type":"heading","level":2,"content":"Softmax Attention is O(L²d)"},{"type":"text","content":"The canonical derivation: softmax(QKᵀ/√d) is (L × L); multiplying by V is (L × L) × (L × d) = O(L²d) FLOPs and O(L²) memory. This cannot be factored without approximation because softmax is not a linear function: softmax(QKᵀ) ≠ Q · (Kᵀ · something). The key observation is that softmax(qᵢᵀkⱼ) can be viewed as a kernel function K(qᵢ, kⱼ) = exp(qᵢᵀkⱼ/√d) / Z — if K(q, k) = φ(q)ᵀφ(k) for some feature map φ, then the normalisation Z = Σⱼ φ(q)ᵀφ(kⱼ) = φ(q)ᵀ(Σⱼ φ(kⱼ)) can be computed in O(Ld) and the entire attention in O(Ld²)."},{"type":"heading","level":2,"content":"Linear Attention via the Kernel Trick"},{"type":"text","content":"Katharopoulos et al. (2020) propose using the feature map φ(x) = elu(x) + 1, which is always positive and approximates the exponential kernel. The linear attention formula is: O_i = φ(Q_i)ᵀ (Σⱼ φ(Kⱼ)Vⱼᵀ) / (φ(Q_i)ᵀ Σⱼ φ(Kⱼ)). The denominator (the normalisation) is φ(Q)ᵀ · (Σ φ(K)) — a dot product after summing the feature maps. Both the numerator (the output) and denominator are computed in O(Ld²) total by first accumulating Σⱼ φ(Kⱼ)Vⱼᵀ (shape d × d) and Σⱼ φ(Kⱼ) (shape d), then multiplying each query\u0027s φ(Q_i) against these accumulators."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef elu_feature_map(x):\n    \"\"\"ELU+1 feature map: always positive, approximates exp kernel.\"\"\"\n    return F.elu(x) + 1\n\ndef linear_attention(Q, K, V):\n    \"\"\"Linear attention O(Ld^2) via kernel trick with ELU+1 feature map.\n    Q, K, V: (B, h, L, d). Returns: (B, h, L, d).\n    \"\"\"\n    phi_Q = elu_feature_map(Q)  # (B, h, L, d)\n    phi_K = elu_feature_map(K)  # (B, h, L, d)\n    # Accumulate: KV = sum_j phi(K_j) V_j^T  -- shape (B, h, d, d)\n    KV = phi_K.transpose(-2, -1) @ V          # O(L * d^2)\n    # Accumulate: Ksum = sum_j phi(K_j)       -- shape (B, h, d)\n    Ksum = phi_K.sum(dim=-2)                  # O(L * d)\n    # Numerator: phi(Q) @ KV                  -- shape (B, h, L, d)\n    num = phi_Q @ KV                          # O(L * d^2)\n    # Denominator: phi(Q) . Ksum              -- shape (B, h, L, 1)\n    denom = (phi_Q * Ksum.unsqueeze(-2)).sum(dim=-1, keepdim=True)  # O(L*d)\n    return num / (denom + 1e-6)\n\ntorch.manual_seed(42)\nB, h, L, d = 1, 2, 32, 16\nQ, K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d), torch.randn(B,h,L,d)\nout_linear = linear_attention(Q, K, V)\nout_softmax = F.scaled_dot_product_attention(Q, K, V)\nprint(f\u0027Linear attention output: {out_linear.shape}\u0027)\nprint(f\u0027Max absolute diff from softmax: {(out_linear - out_softmax).abs().max().item():.4f}\u0027)\nprint(f\u0027Linear attention FLOPs: O(L*d^2) = {L * d**2} | Softmax: O(L^2*d) = {L**2 * d}\u0027)"},{"type":"heading","level":2,"content":"Performer: FAVOR+ Random Feature Approximation"},{"type":"text","content":"Performer (Choromanski et al. 2021) approximates the softmax kernel exp(qᵢᵀkⱼ/√d) using the FAVOR+ (Fast Attention Via positive Orthogonal Random features) method. The idea: by the Johnson-Lindenstrauss lemma, exp(qᵢᵀkⱼ/√d) ≈ (1/√m) Σ_r cos(ωᵣᵀqᵢ) cos(ωᵣᵀkⱼ) + sin(ωᵣᵀqᵢ) sin(ωᵣᵀkⱼ) where ωᵣ are Gaussian random vectors. Using m random features, the feature map φ_FAVOR(x) ∈ ℝ^{2m} provides an unbiased estimate of the kernel with variance decreasing as 1/m. The FAVOR+ variant uses orthogonal random features (samples from the Stiefel manifold) to reduce variance further."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef favor_plus_features(x, omega):\n    \"\"\"FAVOR+ random feature map for softmax kernel approximation.\n    x: (B, h, L, d)   omega: (d, m) random projections\n    Returns: (B, h, L, 2m) -- exp-normalised trig features\n    \"\"\"\n    d, m = omega.shape\n    proj = x @ omega  # (B, h, L, m)\n    # Normalise by exp(||x||^2 / 2) for unbiased softmax approximation\n    x_norm_sq = (x ** 2).sum(dim=-1, keepdim=True) / 2  # (B, h, L, 1)\n    scale = math.sqrt(1.0 / m)\n    phi = scale * torch.exp(-x_norm_sq) * torch.cat([torch.cos(proj), torch.sin(proj)], dim=-1)\n    return phi  # (B, h, L, 2m)\n\ndef performer_attention(Q, K, V, num_features=64):\n    \"\"\"Performer attention using FAVOR+ features. O(L * m * d).\"\"\"\n    d = Q.shape[-1]\n    omega = torch.randn(d, num_features) / math.sqrt(d)\n    phi_Q = favor_plus_features(Q, omega)  # (B,h,L,2m)\n    phi_K = favor_plus_features(K, omega)\n    # KV accumulator: (B, h, 2m, d)\n    KV   = phi_K.transpose(-2,-1) @ V\n    Ksum = phi_K.sum(dim=-2)              # (B, h, 2m)\n    num  = phi_Q @ KV\n    denom = (phi_Q * Ksum.unsqueeze(-2)).sum(dim=-1, keepdim=True)\n    return num / (denom + 1e-6)\n\ntorch.manual_seed(0)\nB, h, d = 1, 1, 32\nfor L, m in [(64, 32), (256, 64), (1024, 128)]:\n    Q, K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d), torch.randn(B,h,L,d)\n    out_p = performer_attention(Q, K, V, m)\n    out_s = F.scaled_dot_product_attention(Q, K, V)\n    diff = (out_p - out_s).abs().mean().item()\n    print(f\u0027L={L:4d}, m={m:3d}: mean abs diff = {diff:.4f}\u0027)"},{"type":"heading","level":2,"content":"Quality: Linear vs Softmax"},{"type":"text","content":"The quality gap between linear and softmax attention depends on sequence length and task. For short sequences (L \u003c 256), the ELU+1 kernel and FAVOR+ both approximate softmax closely — differences in perplexity are negligible. For long sequences (L \u003e 2048), approximation errors accumulate: the linear model may lose track of rare but important tokens that softmax would assign high attention weight. Perplexity gaps of 1–3 points are typical on language modelling benchmarks. Tasks requiring hard retrieval (find the one relevant sentence in a 16K document) show larger degradation; tasks with diffuse attention (summarisation) show less."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef elu_feature_map(x):\n    return F.elu(x) + 1\n\ndef linear_attention(Q, K, V):\n    phi_Q, phi_K = elu_feature_map(Q), elu_feature_map(K)\n    KV = phi_K.transpose(-2,-1) @ V\n    Ksum = phi_K.sum(-2)\n    return (phi_Q @ KV) / ((phi_Q * Ksum.unsqueeze(-2)).sum(-1, keepdim=True) + 1e-6)\n\ntorch.manual_seed(7)\nB, h, d = 1, 1, 32\nprint(f\"{\u0027L\u0027:\u003e6} {\u0027L-attn MSE\u0027:\u003e14} {\u0027L-attn MaxErr\u0027:\u003e16} {\u0027Quality verdict\u0027:\u003e18}\")\nfor L in [32, 128, 512, 2048, 8192]:\n    Q = torch.randn(B, h, L, d)\n    K = torch.randn(B, h, L, d)\n    V = torch.randn(B, h, L, d)\n    out_s = F.scaled_dot_product_attention(Q, K, V)\n    out_l = linear_attention(Q, K, V)\n    mse   = F.mse_loss(out_l, out_s).item()\n    maxe  = (out_l - out_s).abs().max().item()\n    verdict = \u0027Good\u0027 if mse \u003c 0.01 else (\u0027Moderate\u0027 if mse \u003c 0.1 else \u0027Poor\u0027)\n    print(f\u0027{L:\u003e6} {mse:\u003e14.6f} {maxe:\u003e16.4f} {verdict:\u003e18}\u0027)\nprint(\u0027\\nConclusion: linear attention quality degrades with L.\u0027)\nprint(\u0027For L\u003e2K, quality gap is significant for retrieval-heavy tasks.\u0027)"},{"type":"heading","level":2,"content":"Throughput at Scale"},{"type":"text","content":"Linear attention achieves its throughput advantage at large L where O(L²) memory causes softmax attention to OOM or thrash memory bandwidth. The crossover point — where linear attention becomes faster — depends on d and batch size. For d=64, the crossover is typically around L=1000–2000 on GPU. For d=256, the O(Ld²) cost of linear attention is higher and the crossover shifts to L≈4000. The Performer implementation avoids storing the L×L attention matrix entirely, making it memory-bounded by O(L×m) rather than O(L²)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\nimport time\n\ndef elu_feature_map(x):\n    return F.elu(x) + 1\n\ndef linear_attention(Q, K, V):\n    phi_Q, phi_K = elu_feature_map(Q), elu_feature_map(K)\n    KV = phi_K.transpose(-2,-1) @ V\n    Ksum = phi_K.sum(-2)\n    return (phi_Q @ KV) / ((phi_Q * Ksum.unsqueeze(-2)).sum(-1, keepdim=True) + 1e-6)\n\ndef bench(fn, *args, n=20):\n    for _ in range(3): fn(*args)  # warmup\n    t0 = time.perf_counter()\n    for _ in range(n): fn(*args)\n    return (time.perf_counter() - t0) / n * 1000\n\nB, h, d = 1, 4, 64\nprint(f\"{\u0027L\u0027:\u003e6} {\u0027Softmax ms\u0027:\u003e12} {\u0027Linear ms\u0027:\u003e12} {\u0027Speedup\u0027:\u003e10} {\u0027Softmax MB\u0027:\u003e12}\")\nfor L in [512, 1024, 2048, 4096, 8192]:\n    Q, K, V = [torch.randn(B, h, L, d) for _ in range(3)]\n    try:\n        t_s = bench(F.scaled_dot_product_attention, Q, K, V)\n        sm_mem = B * h * L * L * 2 / 1024**2\n    except RuntimeError:\n        t_s, sm_mem = float(\u0027inf\u0027), -1\n    t_l = bench(linear_attention, Q, K, V)\n    speedup = t_s / t_l if t_s != float(\u0027inf\u0027) else float(\u0027inf\u0027)\n    print(f\u0027{L:\u003e6} {t_s:\u003e12.2f} {t_l:\u003e12.2f} {speedup:\u003e10.2f} {sm_mem:\u003e12.1f}\u0027)"},{"type":"table","headers":["Method","Complexity","Memory","Quality","Parallelizable","Causal support","Notes"],"rows":[["Softmax attention","O(L²d)","O(L²)","Exact — best","Yes — batched matmul","Yes — causal mask","FlashAttention reduces memory to O(L)"],["Performer (FAVOR+)","O(Lmd)","O(Lm)","Good (m≥64), degrades at large L","Yes","Yes","Unbiased estimator; variance ∝ 1/m"],["Linear Transformer","O(Ld²)","O(Ld)","Moderate — quality gap at large L","Yes (non-causal); sequential (causal)","Yes — recurrent form","ELU+1 feature map; Katharopoulos 2020"],["RetNet","O(Ld²) train / O(d²) per step","O(d²) at inference","Competitive with Transformer","Yes (parallel training)","Yes — retention decay","Recurrent inference like RNN"],["RWKV","O(Ld) train / O(d) per step","O(d)","Strong on NLP benchmarks","Partially (WKV operator)","Yes — time-mixing","Hybrid RNN/Transformer design"]]},{"type":"heading","level":2,"content":"Practical Tradeoffs and Alternatives"},{"type":"text","content":"Linear attention is not a free lunch. The quality degradation at large L makes it unsuitable for tasks requiring precise attention over long contexts — retrieval-augmented generation, long-document QA, or code generation with large repos. The ELU+1 and FAVOR+ approximations are best suited to tasks with diffuse attention patterns where no single key dominates the distribution. Retentive Networks (RetNet) and RWKV take a different approach: they achieve linear complexity during inference (recurrent forward pass) while training in parallel — better practical quality than linear attention at the cost of a more complex architecture."},{"type":"callout","variant":"warning","title":"Linear Attention Quality Gap Is Real","content":"Do not use linear attention as a drop-in replacement for softmax attention without empirical validation on your task. The quality gap is small for diffuse attention tasks (summarisation, classification) but significant for retrieval-heavy tasks (document QA, multi-hop reasoning). On long-context language modelling (L=8192+), linear attention perplexity is typically 1–3 points higher than FlashAttention. Always measure on your downstream task before committing to a linear attention architecture."},{"type":"heading","level":2,"content":"Sub-Quadratic Architectures Beyond Linear Attention"},{"type":"text","content":"Several architectures achieve sub-quadratic complexity with better practical quality than kernel linear attention. Hyena (Nguyen et al. 2023) replaces attention with implicit long convolutions, achieving O(L log L) complexity with competitive language modelling quality. Mamba (Gu \u0026 Dao 2023) uses a selective state space model with O(L) complexity and hardware-aware parallel scan for training. S4 (Gu et al. 2021) parametrises the state space with HiPPO matrices for efficient long-sequence modelling. These models represent an active research frontier where architecture choice depends on the specific task, sequence length regime, and hardware constraints."},{"type":"list","ordered":false,"items":["Linear Transformer (Katharopoulos 2020): ELU+1 feature map, exact linear complexity, quality gap at L\u003e2K.","Performer (Choromanski 2021): FAVOR+ random features, unbiased softmax approximation, m controls quality-speed trade-off.","RetNet (Sun et al. 2023): training-time parallel, inference-time recurrent O(d²/step), competitive NLP quality.","RWKV (Peng et al. 2023): time-mixing replaces attention, O(d) inference, strong empirical results on NLP.","Mamba (Gu \u0026 Dao 2023): selective SSM with O(L) complexity and hardware-aware scan, state-of-the-art at time of publication.","Hyena (Nguyen et al. 2023): implicit convolution, O(L log L), promising for DNA/audio with very long sequences."]},{"type":"divider"}]"
---
# Linear Attention — Kernel Approximation of Softmax Attention

Softmax attention computes O = softmax(QKᵀ/√d) · V where the intermediate QKᵀ matrix has shape (B, h, L, L) — quadratic in sequence length. Linear attention replaces the softmax with a kernel function φ that factorises over query and key: attn(Q, K, V) ≈ φ(Q)(φ(K)ᵀV). Because matrix multiplication is associative, computing φ(K)ᵀV first (shape d × d) costs O(Ld²); then multiplying φ(Q) by this (shape L × d) costs O(Ld²) — total O(Ld²) independent of L. This eliminates the L² bottleneck at the cost of approximation error in the attention distribution.

## Softmax Attention is O(L²d)

The canonical derivation: softmax(QKᵀ/√d) is (L × L); multiplying by V is (L × L) × (L × d) = O(L²d) FLOPs and O(L²) memory. This cannot be factored without approximation because softmax is not a linear function: softmax(QKᵀ) ≠ Q · (Kᵀ · something). The key observation is that softmax(qᵢᵀkⱼ) can be viewed as a kernel function K(qᵢ, kⱼ) = exp(qᵢᵀkⱼ/√d) / Z — if K(q, k) = φ(q)ᵀφ(k) for some feature map φ, then the normalisation Z = Σⱼ φ(q)ᵀφ(kⱼ) = φ(q)ᵀ(Σⱼ φ(kⱼ)) can be computed in O(Ld) and the entire attention in O(Ld²).

## Linear Attention via the Kernel Trick

Katharopoulos et al. (2020) propose using the feature map φ(x) = elu(x) + 1, which is always positive and approximates the exponential kernel. The linear attention formula is: O_i = φ(Q_i)ᵀ (Σⱼ φ(Kⱼ)Vⱼᵀ) / (φ(Q_i)ᵀ Σⱼ φ(Kⱼ)). The denominator (the normalisation) is φ(Q)ᵀ · (Σ φ(K)) — a dot product after summing the feature maps. Both the numerator (the output) and denominator are computed in O(Ld²) total by first accumulating Σⱼ φ(Kⱼ)Vⱼᵀ (shape d × d) and Σⱼ φ(Kⱼ) (shape d), then multiplying each query's φ(Q_i) against these accumulators.

```python
import torch
import torch.nn.functional as F
import math

def elu_feature_map(x):
    """ELU+1 feature map: always positive, approximates exp kernel."""
    return F.elu(x) + 1

def linear_attention(Q, K, V):
    """Linear attention O(Ld^2) via kernel trick with ELU+1 feature map.
    Q, K, V: (B, h, L, d). Returns: (B, h, L, d).
    """
    phi_Q = elu_feature_map(Q)  # (B, h, L, d)
    phi_K = elu_feature_map(K)  # (B, h, L, d)
    # Accumulate: KV = sum_j phi(K_j) V_j^T  -- shape (B, h, d, d)
    KV = phi_K.transpose(-2, -1) @ V          # O(L * d^2)
    # Accumulate: Ksum = sum_j phi(K_j)       -- shape (B, h, d)
    Ksum = phi_K.sum(dim=-2)                  # O(L * d)
    # Numerator: phi(Q) @ KV                  -- shape (B, h, L, d)
    num = phi_Q @ KV                          # O(L * d^2)
    # Denominator: phi(Q) . Ksum              -- shape (B, h, L, 1)
    denom = (phi_Q * Ksum.unsqueeze(-2)).sum(dim=-1, keepdim=True)  # O(L*d)
    return num / (denom + 1e-6)

torch.manual_seed(42)
B, h, L, d = 1, 2, 32, 16
Q, K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d), torch.randn(B,h,L,d)
out_linear = linear_attention(Q, K, V)
out_softmax = F.scaled_dot_product_attention(Q, K, V)
print(f'Linear attention output: {out_linear.shape}')
print(f'Max absolute diff from softmax: {(out_linear - out_softmax).abs().max().item():.4f}')
print(f'Linear attention FLOPs: O(L*d^2) = {L * d**2} | Softmax: O(L^2*d) = {L**2 * d}')
```

## Performer: FAVOR+ Random Feature Approximation

Performer (Choromanski et al. 2021) approximates the softmax kernel exp(qᵢᵀkⱼ/√d) using the FAVOR+ (Fast Attention Via positive Orthogonal Random features) method. The idea: by the Johnson-Lindenstrauss lemma, exp(qᵢᵀkⱼ/√d) ≈ (1/√m) Σ_r cos(ωᵣᵀqᵢ) cos(ωᵣᵀkⱼ) + sin(ωᵣᵀqᵢ) sin(ωᵣᵀkⱼ) where ωᵣ are Gaussian random vectors. Using m random features, the feature map φ_FAVOR(x) ∈ ℝ^{2m} provides an unbiased estimate of the kernel with variance decreasing as 1/m. The FAVOR+ variant uses orthogonal random features (samples from the Stiefel manifold) to reduce variance further.

```python
import torch
import torch.nn.functional as F
import math

def favor_plus_features(x, omega):
    """FAVOR+ random feature map for softmax kernel approximation.
    x: (B, h, L, d)   omega: (d, m) random projections
    Returns: (B, h, L, 2m) -- exp-normalised trig features
    """
    d, m = omega.shape
    proj = x @ omega  # (B, h, L, m)
    # Normalise by exp(||x||^2 / 2) for unbiased softmax approximation
    x_norm_sq = (x ** 2).sum(dim=-1, keepdim=True) / 2  # (B, h, L, 1)
    scale = math.sqrt(1.0 / m)
    phi = scale * torch.exp(-x_norm_sq) * torch.cat([torch.cos(proj), torch.sin(proj)], dim=-1)
    return phi  # (B, h, L, 2m)

def performer_attention(Q, K, V, num_features=64):
    """Performer attention using FAVOR+ features. O(L * m * d)."""
    d = Q.shape[-1]
    omega = torch.randn(d, num_features) / math.sqrt(d)
    phi_Q = favor_plus_features(Q, omega)  # (B,h,L,2m)
    phi_K = favor_plus_features(K, omega)
    # KV accumulator: (B, h, 2m, d)
    KV   = phi_K.transpose(-2,-1) @ V
    Ksum = phi_K.sum(dim=-2)              # (B, h, 2m)
    num  = phi_Q @ KV
    denom = (phi_Q * Ksum.unsqueeze(-2)).sum(dim=-1, keepdim=True)
    return num / (denom + 1e-6)

torch.manual_seed(0)
B, h, d = 1, 1, 32
for L, m in [(64, 32), (256, 64), (1024, 128)]:
    Q, K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d), torch.randn(B,h,L,d)
    out_p = performer_attention(Q, K, V, m)
    out_s = F.scaled_dot_product_attention(Q, K, V)
    diff = (out_p - out_s).abs().mean().item()
    print(f'L={L:4d}, m={m:3d}: mean abs diff = {diff:.4f}')
```

## Quality: Linear vs Softmax

The quality gap between linear and softmax attention depends on sequence length and task. For short sequences (L < 256), the ELU+1 kernel and FAVOR+ both approximate softmax closely — differences in perplexity are negligible. For long sequences (L > 2048), approximation errors accumulate: the linear model may lose track of rare but important tokens that softmax would assign high attention weight. Perplexity gaps of 1–3 points are typical on language modelling benchmarks. Tasks requiring hard retrieval (find the one relevant sentence in a 16K document) show larger degradation; tasks with diffuse attention (summarisation) show less.

```python
import torch
import torch.nn.functional as F
import math

def elu_feature_map(x):
    return F.elu(x) + 1

def linear_attention(Q, K, V):
    phi_Q, phi_K = elu_feature_map(Q), elu_feature_map(K)
    KV = phi_K.transpose(-2,-1) @ V
    Ksum = phi_K.sum(-2)
    return (phi_Q @ KV) / ((phi_Q * Ksum.unsqueeze(-2)).sum(-1, keepdim=True) + 1e-6)

torch.manual_seed(7)
B, h, d = 1, 1, 32
print(f"{'L':>6} {'L-attn MSE':>14} {'L-attn MaxErr':>16} {'Quality verdict':>18}")
for L in [32, 128, 512, 2048, 8192]:
    Q = torch.randn(B, h, L, d)
    K = torch.randn(B, h, L, d)
    V = torch.randn(B, h, L, d)
    out_s = F.scaled_dot_product_attention(Q, K, V)
    out_l = linear_attention(Q, K, V)
    mse   = F.mse_loss(out_l, out_s).item()
    maxe  = (out_l - out_s).abs().max().item()
    verdict = 'Good' if mse < 0.01 else ('Moderate' if mse < 0.1 else 'Poor')
    print(f'{L:>6} {mse:>14.6f} {maxe:>16.4f} {verdict:>18}')
print('\nConclusion: linear attention quality degrades with L.')
print('For L>2K, quality gap is significant for retrieval-heavy tasks.')
```

## Throughput at Scale

Linear attention achieves its throughput advantage at large L where O(L²) memory causes softmax attention to OOM or thrash memory bandwidth. The crossover point — where linear attention becomes faster — depends on d and batch size. For d=64, the crossover is typically around L=1000–2000 on GPU. For d=256, the O(Ld²) cost of linear attention is higher and the crossover shifts to L≈4000. The Performer implementation avoids storing the L×L attention matrix entirely, making it memory-bounded by O(L×m) rather than O(L²).

```python
import torch
import torch.nn.functional as F
import math
import time

def elu_feature_map(x):
    return F.elu(x) + 1

def linear_attention(Q, K, V):
    phi_Q, phi_K = elu_feature_map(Q), elu_feature_map(K)
    KV = phi_K.transpose(-2,-1) @ V
    Ksum = phi_K.sum(-2)
    return (phi_Q @ KV) / ((phi_Q * Ksum.unsqueeze(-2)).sum(-1, keepdim=True) + 1e-6)

def bench(fn, *args, n=20):
    for _ in range(3): fn(*args)  # warmup
    t0 = time.perf_counter()
    for _ in range(n): fn(*args)
    return (time.perf_counter() - t0) / n * 1000

B, h, d = 1, 4, 64
print(f"{'L':>6} {'Softmax ms':>12} {'Linear ms':>12} {'Speedup':>10} {'Softmax MB':>12}")
for L in [512, 1024, 2048, 4096, 8192]:
    Q, K, V = [torch.randn(B, h, L, d) for _ in range(3)]
    try:
        t_s = bench(F.scaled_dot_product_attention, Q, K, V)
        sm_mem = B * h * L * L * 2 / 1024**2
    except RuntimeError:
        t_s, sm_mem = float('inf'), -1
    t_l = bench(linear_attention, Q, K, V)
    speedup = t_s / t_l if t_s != float('inf') else float('inf')
    print(f'{L:>6} {t_s:>12.2f} {t_l:>12.2f} {speedup:>10.2f} {sm_mem:>12.1f}')
```

| Method | Complexity | Memory | Quality | Parallelizable | Causal support | Notes |
| --- | --- | --- | --- | --- | --- | --- |
| Softmax attention | O(L²d) | O(L²) | Exact — best | Yes — batched matmul | Yes — causal mask | FlashAttention reduces memory to O(L) |
| Performer (FAVOR+) | O(Lmd) | O(Lm) | Good (m≥64), degrades at large L | Yes | Yes | Unbiased estimator; variance ∝ 1/m |
| Linear Transformer | O(Ld²) | O(Ld) | Moderate — quality gap at large L | Yes (non-causal); sequential (causal) | Yes — recurrent form | ELU+1 feature map; Katharopoulos 2020 |
| RetNet | O(Ld²) train / O(d²) per step | O(d²) at inference | Competitive with Transformer | Yes (parallel training) | Yes — retention decay | Recurrent inference like RNN |
| RWKV | O(Ld) train / O(d) per step | O(d) | Strong on NLP benchmarks | Partially (WKV operator) | Yes — time-mixing | Hybrid RNN/Transformer design |

## Practical Tradeoffs and Alternatives

Linear attention is not a free lunch. The quality degradation at large L makes it unsuitable for tasks requiring precise attention over long contexts — retrieval-augmented generation, long-document QA, or code generation with large repos. The ELU+1 and FAVOR+ approximations are best suited to tasks with diffuse attention patterns where no single key dominates the distribution. Retentive Networks (RetNet) and RWKV take a different approach: they achieve linear complexity during inference (recurrent forward pass) while training in parallel — better practical quality than linear attention at the cost of a more complex architecture.

> **Linear Attention Quality Gap Is Real**: Do not use linear attention as a drop-in replacement for softmax attention without empirical validation on your task. The quality gap is small for diffuse attention tasks (summarisation, classification) but significant for retrieval-heavy tasks (document QA, multi-hop reasoning). On long-context language modelling (L=8192+), linear attention perplexity is typically 1–3 points higher than FlashAttention. Always measure on your downstream task before committing to a linear attention architecture.

## Sub-Quadratic Architectures Beyond Linear Attention

Several architectures achieve sub-quadratic complexity with better practical quality than kernel linear attention. Hyena (Nguyen et al. 2023) replaces attention with implicit long convolutions, achieving O(L log L) complexity with competitive language modelling quality. Mamba (Gu & Dao 2023) uses a selective state space model with O(L) complexity and hardware-aware parallel scan for training. S4 (Gu et al. 2021) parametrises the state space with HiPPO matrices for efficient long-sequence modelling. These models represent an active research frontier where architecture choice depends on the specific task, sequence length regime, and hardware constraints.

- Linear Transformer (Katharopoulos 2020): ELU+1 feature map, exact linear complexity, quality gap at L>2K.
- Performer (Choromanski 2021): FAVOR+ random features, unbiased softmax approximation, m controls quality-speed trade-off.
- RetNet (Sun et al. 2023): training-time parallel, inference-time recurrent O(d²/step), competitive NLP quality.
- RWKV (Peng et al. 2023): time-mixing replaces attention, O(d) inference, strong empirical results on NLP.
- Mamba (Gu & Dao 2023): selective SSM with O(L) complexity and hardware-aware scan, state-of-the-art at time of publication.
- Hyena (Nguyen et al. 2023): implicit convolution, O(L log L), promising for DNA/audio with very long sequences.

---

