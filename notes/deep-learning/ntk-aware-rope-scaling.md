---
title: "NTK-Aware RoPE Scaling"
slug: "ntk-aware-rope-scaling"
description: "Adapting the RoPE base frequency (θ) using neural tangent kernel theory so that high-frequency dimensions remain useful at extended context lengths, outperforming linear interpolation without requiring fine-tuning."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"NTK-aware RoPE scaling addresses the core weakness of linear interpolation: uniform compression destroys the high-frequency RoPE dimensions that encode local syntactic structure. Instead of dividing position indices by s, NTK-aware scaling rescales the RoPE base frequency (theta, typically 10000) to a new value that distributes the ‘interpolation burden’ across dimensions according to their natural frequency. Dimensions with short wavelengths (high-frequency, encoding local patterns) receive little or no interpolation, while dimensions with long wavelengths (low-frequency, encoding document-level structure) receive strong interpolation. The result is a frequency spectrum that is distorted as little as possible from the training distribution, giving better zero-shot performance at the same scale factor."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"NTK-aware scaling (Reddit, bloc97, 2023; subsequently studied by Xiong et al., 2023) modifies the RoPE base from 10000 to a new value b* = 10000 * s^(d/(d-2)), where s is the desired scale factor and d is the head dimension. This formula derives from the requirement that the highest-frequency RoPE dimension completes the same number of full rotations over the extended context as it did over the training context — preventing aliasing. In practice, for s=4 and d=128 (Llama-2-7B), the new base is approximately 10000 * 4^(128/126) ≈ 40497. With this larger base, all RoPE frequencies are reduced proportionally to their dimension index, with higher-indexed (lower-frequency) dimensions receiving the most rescaling. The method requires no fine-tuning for s ≤ 4 and outperforms linear interpolation at the same scale factor on most benchmarks."},{"type":"heading","level":2,"content":"The NTK Perspective on RoPE"},{"type":"text","content":"The NTK (neural tangent kernel) perspective treats the RoPE features as a Fourier-like basis. Each RoPE dimension pair i contributes a feature of the form (cos(theta_i * m), sin(theta_i * m)) — a sinusoidal basis function at frequency theta_i. For the model to generalise to longer sequences, these basis functions must cover the new sequence length adequately. With linear interpolation, all basis functions are rescaled uniformly by 1/s, which compresses high-frequency components into a narrower band and wastes their representational capacity. NTK-aware scaling instead increases the base frequency b so that the wavelength of each RoPE component scales proportionally to its own natural period. This preserves the relative spacing between frequency components, maintaining the original Fourier structure of the position encoding while still fitting within the trained distribution."},{"type":"math","display":true,"content":"b^{*} = b_0 \\cdot s^{\\,d/(d-2)}, \\qquad \\theta_i^{*} = \\frac{1}{(b^{*})^{\\,2i/d}} = \\frac{1}{b_0^{\\,2i/d} \\cdot s^{\\,2i/(d-2)}}"},{"type":"text","content":"The exponent d/(d-2) ensures that the highest-frequency pair (i=0, where theta_0 = 1/b^0 = 1) is unchanged: 1/(b*)^0 = 1 regardless of b*. The lowest-frequency pair (i = d/2-1, where theta ≈ 1/b^{(d-2)/d}) is rescaled by exactly 1/s, equivalent to linear interpolation. All intermediate dimensions receive a fractional rescaling between 0 and 1/s. This graduated interpolation is the NTK insight: high-frequency dimensions extrapolate (no rescaling), low-frequency dimensions interpolate (full 1/s rescaling), and mid-frequency dimensions lie on a smooth continuum between these extremes."},{"type":"heading","level":2,"content":"Base Frequency Scaling"},{"type":"text","content":"To implement NTK-aware static scaling, compute b* = 10000 * s^(d/(d-2)) once at model load time and use it everywhere instead of 10000. For Llama-2-7B (d=128, s=4), b* = 10000 * 4^(128/126) ≈ 40497. For s=8, b* ≈ 10000 * 8^(128/126) ≈ 161979. The computation is a single scalar multiply — no per-layer or per-position overhead. The base b* is then used in the standard RoPE formula: inv_freq_i = 1 / (b*)^(2i/d). All subsequent operations (outer product with positions, sin/cos, rotation) are identical to standard RoPE. The only change is the value of the base."},{"type":"code","language":"python","content":"import torch\nimport math\nimport numpy as np\n\ndef ntk_new_base(original_base: int, scale: float, dim: int) -\u003e float:\n    \"\"\"Compute NTK-aware new base: b* = base * s^(d / (d-2)).\n    Keeps the per-dimension wavelength ratio invariant across scales.\"\"\"\n    return original_base * (scale ** (dim / (dim - 2)))\n\ndef rope_with_base(dim: int, seq_len: int, base: float) -\u003e torch.Tensor:\n    \"\"\"Standard RoPE embeddings with a configurable base frequency.\"\"\"\n    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))\n    t = torch.arange(seq_len, dtype=torch.float32)\n    freqs = torch.outer(t, inv_freq)\n    return torch.cat([freqs, freqs], dim=-1)\n\ndef compare_spectra(dim: int = 128, seq_len: int = 8192, scale: float = 4.0):\n    \"\"\"Compare rotation angle spectra: original vs linear vs NTK-scaled.\"\"\"\n    orig_base = 10000\n    ntk_base  = ntk_new_base(orig_base, scale, dim)\n    print(f\"Original base : {orig_base}\")\n    print(f\"NTK new base  : {ntk_base:.1f}  (scale={scale}, dim={dim})\")\n\n    emb_orig = rope_with_base(dim, seq_len, orig_base)\n    emb_ntk  = rope_with_base(dim, seq_len, ntk_base)\n\n    # Compare high-frequency (dim pair 0) and low-frequency (pair dim//2-1)\n    hi, lo = 0, dim // 2 - 1\n    for label, emb in [(\"Original\", emb_orig), (\"NTK\", emb_ntk)]:\n        print(f\"{label:10s}  hi@pos={seq_len-1}: {emb[-1, hi]:.3f}  \"\n              f\"lo@pos={seq_len-1}: {emb[-1, lo]:.5f}\")\n\ncompare_spectra()"},{"type":"heading","level":2,"content":"Dynamic NTK Scaling"},{"type":"text","content":"Static NTK scaling computes a fixed b* for the target context length ahead of time. Dynamic NTK scaling (Peng et al., 2023) instead recomputes the effective base on-the-fly based on the actual sequence length seen at each forward pass. If seq_len ≤ train_len, the original base (10000) is used unmodified. If seq_len \u003e train_len, the base is recomputed as b* = 10000 * (seq_len / train_len)^(d/(d-2)). This means a model serving mixed-length inputs applies no modification for short sequences and automatically adapts to any longer sequence without requiring a pre-specified target length. Dynamic NTK is the default rope_scaling={\u0027type\u0027: \u0027dynamic\u0027, \u0027factor\u0027: s} in HuggingFace and is the recommended zero-shot approach for variable-length inference pipelines."},{"type":"code","language":"python","content":"import torch\nimport math\n\nclass DynamicNTKRoPE(torch.nn.Module):\n    \"\"\"Recomputes the RoPE base on-the-fly as sequence length grows.\"\"\"\n\n    def __init__(self, dim: int, max_train_len: int, base: int = 10000):\n        super().__init__()\n        self.dim, self.max_train_len, self.base = dim, max_train_len, base\n        self._cache: dict = {}\n\n    def _get_base(self, seq_len: int) -\u003e float:\n        \"\"\"Return effective base: original for short seqs, NTK-scaled for long.\"\"\"\n        if seq_len \u003c= self.max_train_len:\n            return float(self.base)\n        s = seq_len / self.max_train_len\n        return self.base * (s ** (self.dim / (self.dim - 2)))\n\n    def forward(self, seq_len: int) -\u003e torch.Tensor:\n        if seq_len not in self._cache:\n            b = self._get_base(seq_len)\n            inv_freq = 1.0 / (b ** (torch.arange(0, self.dim, 2).float() / self.dim))\n            t = torch.arange(seq_len, dtype=torch.float32)\n            freqs = torch.outer(t, inv_freq)\n            self._cache[seq_len] = torch.cat([freqs, freqs], dim=-1)\n        return self._cache[seq_len]\n\n# Test: base grows automatically as sequence length increases\nrope = DynamicNTKRoPE(dim=128, max_train_len=4096)\nfor L in [2048, 4096, 8192, 16384, 32768]:\n    b = rope._get_base(L)\n    f = rope(L)\n    print(f\"L={L:6d}  eff_base={b:\u003e10.1f}  max_angle={f.max().item():.3f}\")"},{"type":"heading","level":2,"content":"Frequency Bands and Dimension Distribution"},{"type":"text","content":"A key diagnostic for any RoPE extension method is how the per-dimension rotation angle at the maximum sequence position compares to training. Ideally, every dimension pair should have a rotation angle at position N that is within the range seen during training. Under linear scaling with s=4, all dimensions are uniformly compressed: dimension pair 0 (high-frequency) sees position N/4 instead of N, reducing its rotation angle by 4x. Under NTK scaling, dimension pair 0 is essentially unchanged (the exponent 2*0/d = 0 means inv_freq_0 is unaffected by the base change), while dimension pair d/2-1 (low-frequency) is reduced by approximately 1/s. This graduated treatment — no change for high-frequency, full interpolation for low-frequency — is why NTK outperforms linear scaling at the same scale factor."},{"type":"code","language":"python","content":"import torch\nimport math\nimport numpy as np\n\ndef per_dim_angles(dim: int, pos: int, base: float) -\u003e np.ndarray:\n    \"\"\"Return rotation angle theta_i * pos for each dimension pair i.\"\"\"\n    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))\n    return (pos * inv_freq).numpy()\n\ndim, pos, scale = 128, 4096, 4.0\nntk_base = 10000 * (scale ** (dim / (dim - 2)))\n\norig_angles   = per_dim_angles(dim, pos, base=10000)\nlinear_angles = per_dim_angles(dim, pos // int(scale), base=10000)  # linear: pos/s\nntk_angles    = per_dim_angles(dim, pos, base=ntk_base)\n\nprint(f\"{\u0027Pair\u0027:\u003e6} {\u0027Original\u0027:\u003e12} {\u0027Linear/4\u0027:\u003e12} {\u0027NTK\u0027:\u003e12} {\u0027Lo-freq?\u0027:\u003e10}\")\nfor i, (o, l, n) in enumerate(zip(orig_angles, linear_angles, ntk_angles)):\n    lo_freq_label = \"yes\" if o \u003c 0.1 else \"no\"\n    if i % 6 == 0:\n        print(f\"{i:\u003e6} {o:\u003e12.4f} {l:\u003e12.4f} {n:\u003e12.4f} {lo_freq_label:\u003e10}\")"},{"type":"heading","level":2,"content":"NTK vs Linear Interpolation"},{"type":"text","content":"On standard long-context benchmarks (Scrolls, LongBench, passkey retrieval), NTK-aware scaling consistently outperforms linear interpolation at the same scale factor when no fine-tuning is applied. The gap is largest at high scale factors (s=4–8) and on tasks that require precise local token relationships, such as code completion and structured extraction. The reason is that linear interpolation degrades high-frequency dimensions that are critical for distinguishing adjacent tokens. NTK scaling leaves these dimensions intact. For s=2, the difference is small (both methods are near-lossless). For s=8, NTK scaling can give 5–10 PPL improvement over linear interpolation zero-shot. With fine-tuning, both methods converge to similar quality, though NTK requires fewer fine-tuning steps to converge."},{"type":"table","headers":["RoPE variant","Base change","High-freq dims","Fine-tuning needed","PPL at 16K","Notes"],"rows":[["Original (4K)","None (b=10000)","Intact","N/A","147+ (OOD)","Fails completely beyond training window"],["Linear scale (s=4)","None (b=10000)","Compressed 4x","Recommended","8.2","Uniform position compression"],["NTK static (s=4)","b*=40497","Intact (pair 0)","Not required","7.4","Graduated per-dim interpolation"],["NTK dynamic (s=4)","b* computed per seq_len","Intact","Not required","7.1","Adapts to actual sequence length"],["YaRN (s=4)","Piecewise per-dim","Fully intact","400 steps","6.9","Best quality; adds temperature correction"]]},{"type":"callout","variant":"info","title":"Zero-Shot Context Extension","content":"NTK scaling is the recommended zero-shot context extension method for 2–4x extensions. It prevents the aliasing of low-frequency RoPE dimensions that linear interpolation causes, and leaves high-frequency dimensions untouched. Use rope_scaling={\u0027type\u0027: \u0027dynamic\u0027, \u0027factor\u0027: s} in HuggingFace to get dynamic NTK scaling with no fine-tuning required."},{"type":"heading","level":2,"content":"Implementation"},{"type":"text","content":"In HuggingFace Transformers, NTK-aware scaling is available via two rope_scaling types: \u0027dynamic\u0027 (recomputes base per sequence length, recommended) and, in some model configurations, a static variant. The factor parameter sets the maximum scale factor s; the actual base is computed as 10000 * s^(d/(d-2)) using the model’s head dimension d. For models not yet supporting rope_scaling natively, it is straightforward to monkey-patch the rotary embedding module: subclass LlamaRotaryEmbedding (or equivalent), override the __init__ to recompute inv_freq with the new base, and replace the module in-place on the loaded model. The patch is 10–15 lines of Python and requires no retraining."},{"type":"code","language":"python","content":"import torch\nfrom transformers import LlamaConfig, LlamaForCausalLM, AutoTokenizer\n\ndef load_llama_ntk_dynamic(\n        model_id: str = \"meta-llama/Llama-2-7b-hf\",\n        factor: float = 4.0,\n        max_ctx: int = 16384) -\u003e tuple:\n    \"\"\"Load Llama-2 with HuggingFace dynamic NTK RoPE scaling.\"\"\"\n    config = LlamaConfig.from_pretrained(model_id)\n    config.rope_scaling = {\"type\": \"dynamic\", \"factor\": factor}\n    config.max_position_embeddings = max_ctx\n    model = LlamaForCausalLM.from_pretrained(\n        model_id, config=config,\n        torch_dtype=torch.float16, device_map=\"auto\"\n    )\n    tokenizer = AutoTokenizer.from_pretrained(model_id)\n    return model, tokenizer\n\n# Compare PPL at 16K: linear vs NTK-static vs NTK-dynamic (simulated)\nresults = [\n    (\"No scaling\",        147.3),\n    (\"Linear (s=4)\",        8.2),\n    (\"NTK-static (s=4)\",    7.4),\n    (\"NTK-dynamic (s=4)\",   7.1),\n]\nfor method, ppl in results:\n    print(f\"{method:\u003c25} PPL@16K = {ppl:.1f}\")"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"NTK-aware RoPE scaling is the recommended zero-shot context extension method when fine-tuning is not an option. By rescaling the RoPE base frequency rather than the position indices, it applies graduated interpolation: none for high-frequency dimensions and full 1/s for low-frequency dimensions. This preserves local syntactic structure while extending long-range positional coverage. The dynamic variant (rope_scaling type=\u0027dynamic\u0027) is strictly better than the static variant because it does not perturb short-sequence behaviour. For production use, set factor to the maximum expected context ratio; the base will be computed automatically. When fine-tuning is available, NTK-aware scaling converges faster than linear interpolation and serves as the starting point for YaRN."},{"type":"list","ordered":false,"items":["Scale the base b via b* = 10000 * s^(d/(d-2)); do not change the position indices","Dynamic NTK recomputes b* at each forward pass; safe for variable-length inference","High-frequency RoPE dimensions (pair 0) are unaffected; low-frequency dims get full 1/s rescaling","Works zero-shot for s ≤ 4; outperforms linear interpolation by 0.8–1.1 PPL at 16K","HuggingFace: rope_scaling={\u0027type\u0027: \u0027dynamic\u0027, \u0027factor\u0027: 4.0} — one config line","YaRN extends NTK by adding piecewise mid-frequency handling and temperature correction"]}]"
---
# NTK-Aware RoPE Scaling

NTK-aware RoPE scaling addresses the core weakness of linear interpolation: uniform compression destroys the high-frequency RoPE dimensions that encode local syntactic structure. Instead of dividing position indices by s, NTK-aware scaling rescales the RoPE base frequency (theta, typically 10000) to a new value that distributes the ‘interpolation burden’ across dimensions according to their natural frequency. Dimensions with short wavelengths (high-frequency, encoding local patterns) receive little or no interpolation, while dimensions with long wavelengths (low-frequency, encoding document-level structure) receive strong interpolation. The result is a frequency spectrum that is distorted as little as possible from the training distribution, giving better zero-shot performance at the same scale factor.

## Overview

NTK-aware scaling (Reddit, bloc97, 2023; subsequently studied by Xiong et al., 2023) modifies the RoPE base from 10000 to a new value b* = 10000 * s^(d/(d-2)), where s is the desired scale factor and d is the head dimension. This formula derives from the requirement that the highest-frequency RoPE dimension completes the same number of full rotations over the extended context as it did over the training context — preventing aliasing. In practice, for s=4 and d=128 (Llama-2-7B), the new base is approximately 10000 * 4^(128/126) ≈ 40497. With this larger base, all RoPE frequencies are reduced proportionally to their dimension index, with higher-indexed (lower-frequency) dimensions receiving the most rescaling. The method requires no fine-tuning for s ≤ 4 and outperforms linear interpolation at the same scale factor on most benchmarks.

## The NTK Perspective on RoPE

The NTK (neural tangent kernel) perspective treats the RoPE features as a Fourier-like basis. Each RoPE dimension pair i contributes a feature of the form (cos(theta_i * m), sin(theta_i * m)) — a sinusoidal basis function at frequency theta_i. For the model to generalise to longer sequences, these basis functions must cover the new sequence length adequately. With linear interpolation, all basis functions are rescaled uniformly by 1/s, which compresses high-frequency components into a narrower band and wastes their representational capacity. NTK-aware scaling instead increases the base frequency b so that the wavelength of each RoPE component scales proportionally to its own natural period. This preserves the relative spacing between frequency components, maintaining the original Fourier structure of the position encoding while still fitting within the trained distribution.

$$b^{*} = b_0 \cdot s^{\,d/(d-2)}, \qquad \theta_i^{*} = \frac{1}{(b^{*})^{\,2i/d}} = \frac{1}{b_0^{\,2i/d} \cdot s^{\,2i/(d-2)}}$$

The exponent d/(d-2) ensures that the highest-frequency pair (i=0, where theta_0 = 1/b^0 = 1) is unchanged: 1/(b*)^0 = 1 regardless of b*. The lowest-frequency pair (i = d/2-1, where theta ≈ 1/b^{(d-2)/d}) is rescaled by exactly 1/s, equivalent to linear interpolation. All intermediate dimensions receive a fractional rescaling between 0 and 1/s. This graduated interpolation is the NTK insight: high-frequency dimensions extrapolate (no rescaling), low-frequency dimensions interpolate (full 1/s rescaling), and mid-frequency dimensions lie on a smooth continuum between these extremes.

## Base Frequency Scaling

To implement NTK-aware static scaling, compute b* = 10000 * s^(d/(d-2)) once at model load time and use it everywhere instead of 10000. For Llama-2-7B (d=128, s=4), b* = 10000 * 4^(128/126) ≈ 40497. For s=8, b* ≈ 10000 * 8^(128/126) ≈ 161979. The computation is a single scalar multiply — no per-layer or per-position overhead. The base b* is then used in the standard RoPE formula: inv_freq_i = 1 / (b*)^(2i/d). All subsequent operations (outer product with positions, sin/cos, rotation) are identical to standard RoPE. The only change is the value of the base.

```python
import torch
import math
import numpy as np

def ntk_new_base(original_base: int, scale: float, dim: int) -> float:
    """Compute NTK-aware new base: b* = base * s^(d / (d-2)).
    Keeps the per-dimension wavelength ratio invariant across scales."""
    return original_base * (scale ** (dim / (dim - 2)))

def rope_with_base(dim: int, seq_len: int, base: float) -> torch.Tensor:
    """Standard RoPE embeddings with a configurable base frequency."""
    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))
    t = torch.arange(seq_len, dtype=torch.float32)
    freqs = torch.outer(t, inv_freq)
    return torch.cat([freqs, freqs], dim=-1)

def compare_spectra(dim: int = 128, seq_len: int = 8192, scale: float = 4.0):
    """Compare rotation angle spectra: original vs linear vs NTK-scaled."""
    orig_base = 10000
    ntk_base  = ntk_new_base(orig_base, scale, dim)
    print(f"Original base : {orig_base}")
    print(f"NTK new base  : {ntk_base:.1f}  (scale={scale}, dim={dim})")

    emb_orig = rope_with_base(dim, seq_len, orig_base)
    emb_ntk  = rope_with_base(dim, seq_len, ntk_base)

    # Compare high-frequency (dim pair 0) and low-frequency (pair dim//2-1)
    hi, lo = 0, dim // 2 - 1
    for label, emb in [("Original", emb_orig), ("NTK", emb_ntk)]:
        print(f"{label:10s}  hi@pos={seq_len-1}: {emb[-1, hi]:.3f}  "
              f"lo@pos={seq_len-1}: {emb[-1, lo]:.5f}")

compare_spectra()
```

## Dynamic NTK Scaling

Static NTK scaling computes a fixed b* for the target context length ahead of time. Dynamic NTK scaling (Peng et al., 2023) instead recomputes the effective base on-the-fly based on the actual sequence length seen at each forward pass. If seq_len ≤ train_len, the original base (10000) is used unmodified. If seq_len > train_len, the base is recomputed as b* = 10000 * (seq_len / train_len)^(d/(d-2)). This means a model serving mixed-length inputs applies no modification for short sequences and automatically adapts to any longer sequence without requiring a pre-specified target length. Dynamic NTK is the default rope_scaling={'type': 'dynamic', 'factor': s} in HuggingFace and is the recommended zero-shot approach for variable-length inference pipelines.

```python
import torch
import math

class DynamicNTKRoPE(torch.nn.Module):
    """Recomputes the RoPE base on-the-fly as sequence length grows."""

    def __init__(self, dim: int, max_train_len: int, base: int = 10000):
        super().__init__()
        self.dim, self.max_train_len, self.base = dim, max_train_len, base
        self._cache: dict = {}

    def _get_base(self, seq_len: int) -> float:
        """Return effective base: original for short seqs, NTK-scaled for long."""
        if seq_len <= self.max_train_len:
            return float(self.base)
        s = seq_len / self.max_train_len
        return self.base * (s ** (self.dim / (self.dim - 2)))

    def forward(self, seq_len: int) -> torch.Tensor:
        if seq_len not in self._cache:
            b = self._get_base(seq_len)
            inv_freq = 1.0 / (b ** (torch.arange(0, self.dim, 2).float() / self.dim))
            t = torch.arange(seq_len, dtype=torch.float32)
            freqs = torch.outer(t, inv_freq)
            self._cache[seq_len] = torch.cat([freqs, freqs], dim=-1)
        return self._cache[seq_len]

# Test: base grows automatically as sequence length increases
rope = DynamicNTKRoPE(dim=128, max_train_len=4096)
for L in [2048, 4096, 8192, 16384, 32768]:
    b = rope._get_base(L)
    f = rope(L)
    print(f"L={L:6d}  eff_base={b:>10.1f}  max_angle={f.max().item():.3f}")
```

## Frequency Bands and Dimension Distribution

A key diagnostic for any RoPE extension method is how the per-dimension rotation angle at the maximum sequence position compares to training. Ideally, every dimension pair should have a rotation angle at position N that is within the range seen during training. Under linear scaling with s=4, all dimensions are uniformly compressed: dimension pair 0 (high-frequency) sees position N/4 instead of N, reducing its rotation angle by 4x. Under NTK scaling, dimension pair 0 is essentially unchanged (the exponent 2*0/d = 0 means inv_freq_0 is unaffected by the base change), while dimension pair d/2-1 (low-frequency) is reduced by approximately 1/s. This graduated treatment — no change for high-frequency, full interpolation for low-frequency — is why NTK outperforms linear scaling at the same scale factor.

```python
import torch
import math
import numpy as np

def per_dim_angles(dim: int, pos: int, base: float) -> np.ndarray:
    """Return rotation angle theta_i * pos for each dimension pair i."""
    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))
    return (pos * inv_freq).numpy()

dim, pos, scale = 128, 4096, 4.0
ntk_base = 10000 * (scale ** (dim / (dim - 2)))

orig_angles   = per_dim_angles(dim, pos, base=10000)
linear_angles = per_dim_angles(dim, pos // int(scale), base=10000)  # linear: pos/s
ntk_angles    = per_dim_angles(dim, pos, base=ntk_base)

print(f"{'Pair':>6} {'Original':>12} {'Linear/4':>12} {'NTK':>12} {'Lo-freq?':>10}")
for i, (o, l, n) in enumerate(zip(orig_angles, linear_angles, ntk_angles)):
    lo_freq_label = "yes" if o < 0.1 else "no"
    if i % 6 == 0:
        print(f"{i:>6} {o:>12.4f} {l:>12.4f} {n:>12.4f} {lo_freq_label:>10}")
```

## NTK vs Linear Interpolation

On standard long-context benchmarks (Scrolls, LongBench, passkey retrieval), NTK-aware scaling consistently outperforms linear interpolation at the same scale factor when no fine-tuning is applied. The gap is largest at high scale factors (s=4–8) and on tasks that require precise local token relationships, such as code completion and structured extraction. The reason is that linear interpolation degrades high-frequency dimensions that are critical for distinguishing adjacent tokens. NTK scaling leaves these dimensions intact. For s=2, the difference is small (both methods are near-lossless). For s=8, NTK scaling can give 5–10 PPL improvement over linear interpolation zero-shot. With fine-tuning, both methods converge to similar quality, though NTK requires fewer fine-tuning steps to converge.

| RoPE variant | Base change | High-freq dims | Fine-tuning needed | PPL at 16K | Notes |
| --- | --- | --- | --- | --- | --- |
| Original (4K) | None (b=10000) | Intact | N/A | 147+ (OOD) | Fails completely beyond training window |
| Linear scale (s=4) | None (b=10000) | Compressed 4x | Recommended | 8.2 | Uniform position compression |
| NTK static (s=4) | b*=40497 | Intact (pair 0) | Not required | 7.4 | Graduated per-dim interpolation |
| NTK dynamic (s=4) | b* computed per seq_len | Intact | Not required | 7.1 | Adapts to actual sequence length |
| YaRN (s=4) | Piecewise per-dim | Fully intact | 400 steps | 6.9 | Best quality; adds temperature correction |

> **Zero-Shot Context Extension**: NTK scaling is the recommended zero-shot context extension method for 2–4x extensions. It prevents the aliasing of low-frequency RoPE dimensions that linear interpolation causes, and leaves high-frequency dimensions untouched. Use rope_scaling={'type': 'dynamic', 'factor': s} in HuggingFace to get dynamic NTK scaling with no fine-tuning required.

## Implementation

In HuggingFace Transformers, NTK-aware scaling is available via two rope_scaling types: 'dynamic' (recomputes base per sequence length, recommended) and, in some model configurations, a static variant. The factor parameter sets the maximum scale factor s; the actual base is computed as 10000 * s^(d/(d-2)) using the model’s head dimension d. For models not yet supporting rope_scaling natively, it is straightforward to monkey-patch the rotary embedding module: subclass LlamaRotaryEmbedding (or equivalent), override the __init__ to recompute inv_freq with the new base, and replace the module in-place on the loaded model. The patch is 10–15 lines of Python and requires no retraining.

```python
import torch
from transformers import LlamaConfig, LlamaForCausalLM, AutoTokenizer

def load_llama_ntk_dynamic(
        model_id: str = "meta-llama/Llama-2-7b-hf",
        factor: float = 4.0,
        max_ctx: int = 16384) -> tuple:
    """Load Llama-2 with HuggingFace dynamic NTK RoPE scaling."""
    config = LlamaConfig.from_pretrained(model_id)
    config.rope_scaling = {"type": "dynamic", "factor": factor}
    config.max_position_embeddings = max_ctx
    model = LlamaForCausalLM.from_pretrained(
        model_id, config=config,
        torch_dtype=torch.float16, device_map="auto"
    )
    tokenizer = AutoTokenizer.from_pretrained(model_id)
    return model, tokenizer

# Compare PPL at 16K: linear vs NTK-static vs NTK-dynamic (simulated)
results = [
    ("No scaling",        147.3),
    ("Linear (s=4)",        8.2),
    ("NTK-static (s=4)",    7.4),
    ("NTK-dynamic (s=4)",   7.1),
]
for method, ppl in results:
    print(f"{method:<25} PPL@16K = {ppl:.1f}")
```

## Key Takeaways

NTK-aware RoPE scaling is the recommended zero-shot context extension method when fine-tuning is not an option. By rescaling the RoPE base frequency rather than the position indices, it applies graduated interpolation: none for high-frequency dimensions and full 1/s for low-frequency dimensions. This preserves local syntactic structure while extending long-range positional coverage. The dynamic variant (rope_scaling type='dynamic') is strictly better than the static variant because it does not perturb short-sequence behaviour. For production use, set factor to the maximum expected context ratio; the base will be computed automatically. When fine-tuning is available, NTK-aware scaling converges faster than linear interpolation and serves as the starting point for YaRN.

- Scale the base b via b* = 10000 * s^(d/(d-2)); do not change the position indices
- Dynamic NTK recomputes b* at each forward pass; safe for variable-length inference
- High-frequency RoPE dimensions (pair 0) are unaffected; low-frequency dims get full 1/s rescaling
- Works zero-shot for s ≤ 4; outperforms linear interpolation by 0.8–1.1 PPL at 16K
- HuggingFace: rope_scaling={'type': 'dynamic', 'factor': 4.0} — one config line
- YaRN extends NTK by adding piecewise mid-frequency handling and temperature correction

