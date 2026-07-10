---
title: "QLoRA — 4-bit NF4 Quantization with LoRA for Memory-Efficient Fine-Tuning"
slug: "qlora"
description: "Complete guide to QLoRA (Dettmers et al., 2023): NF4 information-theoretically optimal 4-bit quantization, double quantization of scaling constants, paged Adam optimizer, and how to fine-tune 70B+ LLMs on a single GPU using bitsandbytes and HuggingFace PEFT."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"QLoRA (Dettmers et al., 2023) combines 4-bit NF4 (NormalFloat4) quantization of the frozen base model with full-precision LoRA adapters to achieve unprecedented memory efficiency for LLM fine-tuning. A 65B LLaMA model requires ~130GB in fp16 — requiring multiple A100 80GB GPUs. QLoRA reduces this to ~35GB by quantizing frozen base weights to 4-bit NF4, enabling single-GPU fine-tuning of 65B models on an A100 80GB and 7B fine-tuning on a consumer RTX 3090 24GB."},{"type":"heading","level":2,"content":"The Memory Wall in LLM Fine-Tuning"},{"type":"text","content":"LLM fine-tuning memory consumption comes from four sources: model weights, gradient tensors (same size as weights), Adam optimizer states (momentum + variance, each fp32 = 2× weight size), and activation memory for backpropagation. For a 7B model in fp16: weights = 14GB, gradients = 14GB, Adam states = 56GB (fp32) — totaling ~84GB before activations. QLoRA\u0027s insight: the base weights only need high precision during the LoRA adapter computation, not for storage. Store in 4-bit, dequantize on-the-fly only for the forward and backward pass."},{"type":"list","ordered":false,"items":["fp32 full fine-tune: ~24 bytes/param — 168GB for 7B, 1.7TB for 70B","fp16/bf16 full fine-tune: ~16 bytes/param — 112GB for 7B, 1.1TB for 70B","LoRA (fp16 base): ~14GB weights + ~2GB adapter + ~4GB optimizer = ~20GB for 7B","QLoRA (NF4 4-bit base): ~3.5GB weights + ~2GB adapter + ~4GB optimizer = ~9.5GB for 7B","QLoRA with double quantization: ~3.25GB weights + adapters + optimizer ≈ 9GB for 7B"]},{"type":"heading","level":2,"content":"NF4 — Information-Theoretically Optimal 4-bit Quantization"},{"type":"text","content":"Standard INT4 quantization places 16 quantization levels at equal intervals in [min, max], assuming weights are uniformly distributed. LLM weights are near-Gaussian N(0, σ²). NF4 (NormalFloat4) exploits this: quantization levels are placed at the quantiles of N(0,1), spacing them closer together where the density is highest (near zero) and further apart in the tails. This is information-theoretically optimal — each 4-bit codeword carries equal information under the Gaussian prior. The result is lower reconstruction error than INT4 at the same bit width."},{"type":"math","content":"q_i = Q_{N(0,1)}\\!\\left(\\frac{i + 0.5}{2^k}\\right),\\quad i = 0, 1, \\ldots, 2^k - 1,\\quad k = 4","display":true},{"type":"heading","level":2,"content":"QLoRA Setup — 4-bit NF4 Model with LoRA Adapters"},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoModelForCausalLM, AutoTokenizer, BitsAndBytesConfig\nfrom peft import LoraConfig, get_peft_model, TaskType, prepare_model_for_kbit_training\n\n# Step 1: Configure 4-bit NF4 quantization with double quantization\nbnb_config = BitsAndBytesConfig(\n    load_in_4bit=True,\n    bnb_4bit_quant_type=\"nf4\",           # NF4 optimal for Gaussian weights\n    bnb_4bit_compute_dtype=torch.bfloat16,  # Dequantize to bf16 for matmul\n    bnb_4bit_use_double_quant=True,      # Quantize the scaling constants too\n)\n\n# Step 2: Load model quantized to 4-bit NF4\nmodel = AutoModelForCausalLM.from_pretrained(\n    \"meta-llama/Llama-2-7b-hf\",\n    quantization_config=bnb_config,\n    device_map=\"auto\",\n)\ntokenizer = AutoTokenizer.from_pretrained(\"meta-llama/Llama-2-7b-hf\")\ntokenizer.pad_token = tokenizer.eos_token\n\n# Step 3: Prepare for k-bit training — enables gradient checkpointing\nmodel = prepare_model_for_kbit_training(model)\n\n# Step 4: Add LoRA adapters in bf16 on top of frozen 4-bit base\nlora_config = LoraConfig(\n    task_type=TaskType.CAUSAL_LM,\n    r=16, lora_alpha=32,\n    target_modules=[\"q_proj\", \"v_proj\", \"k_proj\", \"o_proj\"],\n    lora_dropout=0.05, bias=\"none\",\n)\npeft_model = get_peft_model(model, lora_config)\npeft_model.print_trainable_parameters()"},{"type":"text","content":"During the forward pass, each 4-bit NF4 weight block is dequantized to bf16 on-the-fly, the matrix multiplication runs in bf16, and the dequantized values are immediately discarded. Only the 4-bit integers and their scaling constants remain in GPU memory for the base model. LoRA adapter weights stay in bf16/fp32 throughout training. Gradients flow only through the adapter parameters — the quantized base weights have no gradients."},{"type":"heading","level":2,"content":"NF4 Quantization Mechanics"},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom scipy.stats import norm\n\ndef compute_nf4_levels(num_bits: int = 4) -\u003e torch.Tensor:\n    \"\"\"Compute NF4 quantization levels: midpoints of equal-prob intervals of N(0,1).\"\"\"\n    num_levels = 2 ** num_bits  # 16 levels for 4-bit\n    quantile_pos = np.linspace(0, 1, num_levels + 1)\n    midpoints = (quantile_pos[:-1] + quantile_pos[1:]) / 2\n    levels = torch.tensor(norm.ppf(midpoints), dtype=torch.float32)\n    return levels / levels.abs().max()  # normalize to [-1, 1]\n\ndef nf4_quantize(weight: torch.Tensor, block_size: int = 64) -\u003e tuple:\n    \"\"\"Quantize weight tensor to NF4 with per-block absmax scaling.\"\"\"\n    nf4_lvls = compute_nf4_levels(4).to(weight.device)\n    blocks = weight.reshape(-1, block_size)\n    scales = blocks.abs().max(dim=1, keepdim=True).values.clamp(min=1e-8)\n    normalized = blocks / scales\n    diffs = (normalized.unsqueeze(-1) - nf4_lvls).abs()\n    indices = diffs.argmin(dim=-1).to(torch.uint8)  # 4-bit indices (0-15)\n    return indices, scales\n\ndef nf4_dequantize(indices: torch.Tensor,\n                   scales: torch.Tensor, block_size: int = 64) -\u003e torch.Tensor:\n    \"\"\"Reconstruct fp32 weights from NF4 indices and per-block scales.\"\"\"\n    nf4_lvls = compute_nf4_levels(4).to(scales.device)\n    reconstructed = nf4_lvls[indices.long()]\n    return (reconstructed * scales).reshape(-1)\nw = torch.randn(256, 256)\nnf4_lvls = compute_nf4_levels()\nprint(f\"NF4 levels (central 8): {nf4_lvls[4:12].tolist()}\")\nidx, sc = nf4_quantize(w)\nw_recon = nf4_dequantize(idx, sc).reshape(256, 256)\nrmse = (w - w_recon).pow(2).mean().sqrt().item()\nprint(f\"NF4 RMSE: {rmse:.5f}  |  Compression: {w.numel()*32/(idx.numel()*4+sc.numel()*32):.1f}x\")"},{"type":"text","content":"NF4 allocates 8 of its 16 levels to the central region where most LLM weight mass resides, vs INT4 which allocates 4. For a weight distribution with σ=0.02, approximately 68% of values fall within ±σ of zero — NF4 covers this dense region with double the resolution of INT4. This density matching reduces reconstruction MSE by 25–30% compared to INT4 at the same bit width, which translates to measurable quality improvements for downstream task performance."},{"type":"heading","level":2,"content":"Double Quantization — Quantizing the Quantization Constants"},{"type":"code","language":"python","content":"import torch\n\ndef double_quantize(weight: torch.Tensor,\n                    inner_block: int = 64,\n                    outer_block: int = 256) -\u003e dict:\n    \"\"\"\n    Two-level quantization: NF4 for weights (4 bits), INT8 for scales (8 bits).\n    Reduces per-weight scale overhead from 0.5 to 0.125 bits.\n    \"\"\"\n    # Level 1: per-inner-block fp32 scales for NF4 quantization\n    blocks = weight.reshape(-1, inner_block)\n    scales_fp32 = blocks.abs().max(dim=1).values       # [N] fp32, 32 bits each\n\n    # Level 2: quantize fp32 scales to INT8 per outer_block\n    n_groups = (scales_fp32.numel() + outer_block // inner_block - 1) // (outer_block // inner_block)\n    group_size = outer_block // inner_block\n    padded = torch.cat([scales_fp32, scales_fp32.new_zeros(n_groups * group_size - scales_fp32.numel())])\n    groups = padded.reshape(n_groups, group_size)\n    super_scales = groups.abs().max(dim=1, keepdim=True).values.clamp(1e-8)\n    scales_int8 = (groups / super_scales * 127).round().clamp(-127, 127).to(torch.int8)\n\n    # Bit-cost analysis\n    bits_fp32 = 32 / inner_block           # 0.500 bits/weight for fp32 scales\n    bits_int8 = 8 / inner_block            # 0.125 bits/weight for int8 scales\n    bits_super = 32 / outer_block          # 0.125 bits/weight for super-scales\n    print(f\"Scale overhead: fp32={bits_fp32:.3f} -\u003e int8={bits_int8:.3f} bits/weight\")\n    print(f\"Total NF4 + double quant: {4 + bits_int8 + bits_super:.3f} bits/weight\")\n    return {\"scales_int8\": scales_int8, \"super_scales\": super_scales}\n\nresult = double_quantize(torch.randn(4096, 4096))"},{"type":"text","content":"Double quantization reduces the storage overhead of quantization constants from 0.5 bits/weight (fp32 scale per 64 weights) to approximately 0.127 bits/weight (int8 scale per 64 + fp32 super-scale per 256). Combined with NF4\u0027s 4 bits per weight, the total is ~4.127 bits/weight. For a 70B model, double quantization saves approximately 3.5GB of GPU memory — enough to fit on a 40GB A100 that would otherwise require a 80GB variant."},{"type":"heading","level":2,"content":"Memory Profiling — fp16 vs LoRA vs QLoRA"},{"type":"code","language":"python","content":"import torch\n\ndef estimate_training_memory_gb(n_params: float, mode: str,\n                                adapter_frac: float = 0.01) -\u003e float:\n    \"\"\"Estimate peak GPU training memory (GB) for a model by size and mode.\"\"\"\n    n = n_params * 1e9\n    if mode == \"fp16_full\":\n        # Weights fp16 + grads fp16 + Adam fp32 momentum + Adam fp32 variance\n        return n * (2 + 2 + 4 + 4) / 1e9\n    elif mode == \"lora_fp16\":\n        # Frozen fp16 base weights + adapter fp16 + Adam fp32 on adapter only\n        adapter_n = n * adapter_frac\n        return (n * 2 + adapter_n * 2 + adapter_n * (4 + 4)) / 1e9\n    elif mode == \"qlora_nf4\":\n        # NF4 base (0.5 bytes/param) + adapter bf16 + Adam fp32 on adapter only\n        adapter_n = n * adapter_frac\n        return (n * 0.5 + adapter_n * 2 + adapter_n * (4 + 4)) / 1e9\n    return 0.0\n\nprint(f\"{\u0027Size\u0027:\u003c6} {\u0027Mode\u0027:\u003c14} {\u0027Peak GPU (GB)\u0027:\u003e14}\")\nprint(\"-\" * 36)\nfor n_b, label in [(7, \"7B\"), (13, \"13B\"), (70, \"70B\")]:\n    for mode in [\"fp16_full\", \"lora_fp16\", \"qlora_nf4\"]:\n        gb = estimate_training_memory_gb(n_b, mode)\n        print(f\"{label:\u003c6} {mode:\u003c14} {gb:\u003e14.1f}\")"},{"type":"text","content":"Estimated peak GPU memory on A100: 7B fp16 full = 84GB (needs 2× A100 80GB), 7B LoRA = 18GB, 7B QLoRA = 9GB. For 70B: fp16 full = 840GB (11× A100 80GB), LoRA = 154GB, QLoRA = 80GB (fits on a single A100 80GB with some room for activations). QLoRA throughput is approximately 70-75% of LoRA due to the overhead of on-the-fly dequantization during the forward pass."},{"type":"table","headers":["Quantization","Bits/Param","Memory (7B)","Quality vs fp16","Speed vs fp16","Max Model on 80GB A100"],"rows":[["fp16 Full FT","16","~84 GB","Baseline","1.00×","~5B"],["LoRA fp16","16 + adapter","~18 GB","≈99%","0.95×","~30B"],["8-bit INT8","8","~14 GB","~98-99%","0.85×","~45B"],["4-bit INT4","4","~7 GB","~94-96%","0.80×","~130B"],["4-bit NF4 (QLoRA)","~4.5","~9 GB","~98-99%","0.75×","~70B"],["NF4 + Double Quant","~4.13","~8.5 GB","~98-99%","0.75×","~75B"]]},{"type":"heading","level":2,"content":"Paged Optimizer and Training Tips"},{"type":"text","content":"The paged optimizer is a QLoRA-specific technique using NVIDIA unified memory to automatically page Adam optimizer states (momentum and variance tensors) from GPU VRAM to CPU RAM when the GPU runs out of memory, and page them back when needed for gradient updates. This prevents OOM crashes during long training runs without requiring manual memory management. Use paged_adamw_8bit from bitsandbytes for maximum savings; paged_adamw_32bit for training stability on sensitive tasks."},{"type":"list","ordered":false,"items":["Use paged_adamw_8bit for maximum GPU memory savings; paged_adamw_32bit for numerical stability","Set bnb_4bit_compute_dtype=torch.bfloat16 (not float16) — bf16 has better dynamic range and avoids NaN instability","Enable gradient checkpointing via prepare_model_for_kbit_training() — trades 30% throughput for large activation memory savings","Set max_grad_norm=0.3 and warmup_ratio=0.03 for stable QLoRA training runs","Use per_device_train_batch_size=1 or 2 with gradient_accumulation_steps=16 to maintain effective batch of 16-32","LoRA adapters remain in bf16/fp32 throughout training — only the frozen base model is in 4-bit NF4"]},{"type":"callout","variant":"tip","title":"NF4 + Double Quantization Memory Math","content":"QLoRA with NF4 + double quantization uses ~0.5 bits/parameter for the quantization constants (vs 0.125 bits for NF4 weights), bringing total memory to ~4.5 bits/param — allowing a 70B model to fit in a single 40GB A100 with 4-bit quantization. Specifically: 70B × 4.5 bits / 8 bits_per_byte = 39.4GB for weights, leaving room for activations and LoRA adapter states within 40GB VRAM."},{"type":"text","content":"QLoRA democratized LLM fine-tuning by making it feasible on consumer hardware. A 7B model can be fine-tuned on an RTX 3090 24GB — a task that previously required multiple enterprise A100 GPUs. Combined with open datasets (Alpaca, FLAN, OpenAssistant) and the Guanaco training recipe from the QLoRA paper, this enabled a generation of competitive open-source fine-tuned models trained by individuals and small teams with modest GPU budgets."}]"
---
# QLoRA — 4-bit NF4 Quantization with LoRA for Memory-Efficient Fine-Tuning

QLoRA (Dettmers et al., 2023) combines 4-bit NF4 (NormalFloat4) quantization of the frozen base model with full-precision LoRA adapters to achieve unprecedented memory efficiency for LLM fine-tuning. A 65B LLaMA model requires ~130GB in fp16 — requiring multiple A100 80GB GPUs. QLoRA reduces this to ~35GB by quantizing frozen base weights to 4-bit NF4, enabling single-GPU fine-tuning of 65B models on an A100 80GB and 7B fine-tuning on a consumer RTX 3090 24GB.

## The Memory Wall in LLM Fine-Tuning

LLM fine-tuning memory consumption comes from four sources: model weights, gradient tensors (same size as weights), Adam optimizer states (momentum + variance, each fp32 = 2× weight size), and activation memory for backpropagation. For a 7B model in fp16: weights = 14GB, gradients = 14GB, Adam states = 56GB (fp32) — totaling ~84GB before activations. QLoRA's insight: the base weights only need high precision during the LoRA adapter computation, not for storage. Store in 4-bit, dequantize on-the-fly only for the forward and backward pass.

- fp32 full fine-tune: ~24 bytes/param — 168GB for 7B, 1.7TB for 70B
- fp16/bf16 full fine-tune: ~16 bytes/param — 112GB for 7B, 1.1TB for 70B
- LoRA (fp16 base): ~14GB weights + ~2GB adapter + ~4GB optimizer = ~20GB for 7B
- QLoRA (NF4 4-bit base): ~3.5GB weights + ~2GB adapter + ~4GB optimizer = ~9.5GB for 7B
- QLoRA with double quantization: ~3.25GB weights + adapters + optimizer ≈ 9GB for 7B

## NF4 — Information-Theoretically Optimal 4-bit Quantization

Standard INT4 quantization places 16 quantization levels at equal intervals in [min, max], assuming weights are uniformly distributed. LLM weights are near-Gaussian N(0, σ²). NF4 (NormalFloat4) exploits this: quantization levels are placed at the quantiles of N(0,1), spacing them closer together where the density is highest (near zero) and further apart in the tails. This is information-theoretically optimal — each 4-bit codeword carries equal information under the Gaussian prior. The result is lower reconstruction error than INT4 at the same bit width.

$$q_i = Q_{N(0,1)}\!\left(\frac{i + 0.5}{2^k}\right),\quad i = 0, 1, \ldots, 2^k - 1,\quad k = 4$$

## QLoRA Setup — 4-bit NF4 Model with LoRA Adapters

```python
import torch
from transformers import AutoModelForCausalLM, AutoTokenizer, BitsAndBytesConfig
from peft import LoraConfig, get_peft_model, TaskType, prepare_model_for_kbit_training

# Step 1: Configure 4-bit NF4 quantization with double quantization
bnb_config = BitsAndBytesConfig(
    load_in_4bit=True,
    bnb_4bit_quant_type="nf4",           # NF4 optimal for Gaussian weights
    bnb_4bit_compute_dtype=torch.bfloat16,  # Dequantize to bf16 for matmul
    bnb_4bit_use_double_quant=True,      # Quantize the scaling constants too
)

# Step 2: Load model quantized to 4-bit NF4
model = AutoModelForCausalLM.from_pretrained(
    "meta-llama/Llama-2-7b-hf",
    quantization_config=bnb_config,
    device_map="auto",
)
tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-2-7b-hf")
tokenizer.pad_token = tokenizer.eos_token

# Step 3: Prepare for k-bit training — enables gradient checkpointing
model = prepare_model_for_kbit_training(model)

# Step 4: Add LoRA adapters in bf16 on top of frozen 4-bit base
lora_config = LoraConfig(
    task_type=TaskType.CAUSAL_LM,
    r=16, lora_alpha=32,
    target_modules=["q_proj", "v_proj", "k_proj", "o_proj"],
    lora_dropout=0.05, bias="none",
)
peft_model = get_peft_model(model, lora_config)
peft_model.print_trainable_parameters()
```

During the forward pass, each 4-bit NF4 weight block is dequantized to bf16 on-the-fly, the matrix multiplication runs in bf16, and the dequantized values are immediately discarded. Only the 4-bit integers and their scaling constants remain in GPU memory for the base model. LoRA adapter weights stay in bf16/fp32 throughout training. Gradients flow only through the adapter parameters — the quantized base weights have no gradients.

## NF4 Quantization Mechanics

```python
import torch
import numpy as np
from scipy.stats import norm

def compute_nf4_levels(num_bits: int = 4) -> torch.Tensor:
    """Compute NF4 quantization levels: midpoints of equal-prob intervals of N(0,1)."""
    num_levels = 2 ** num_bits  # 16 levels for 4-bit
    quantile_pos = np.linspace(0, 1, num_levels + 1)
    midpoints = (quantile_pos[:-1] + quantile_pos[1:]) / 2
    levels = torch.tensor(norm.ppf(midpoints), dtype=torch.float32)
    return levels / levels.abs().max()  # normalize to [-1, 1]

def nf4_quantize(weight: torch.Tensor, block_size: int = 64) -> tuple:
    """Quantize weight tensor to NF4 with per-block absmax scaling."""
    nf4_lvls = compute_nf4_levels(4).to(weight.device)
    blocks = weight.reshape(-1, block_size)
    scales = blocks.abs().max(dim=1, keepdim=True).values.clamp(min=1e-8)
    normalized = blocks / scales
    diffs = (normalized.unsqueeze(-1) - nf4_lvls).abs()
    indices = diffs.argmin(dim=-1).to(torch.uint8)  # 4-bit indices (0-15)
    return indices, scales

def nf4_dequantize(indices: torch.Tensor,
                   scales: torch.Tensor, block_size: int = 64) -> torch.Tensor:
    """Reconstruct fp32 weights from NF4 indices and per-block scales."""
    nf4_lvls = compute_nf4_levels(4).to(scales.device)
    reconstructed = nf4_lvls[indices.long()]
    return (reconstructed * scales).reshape(-1)
w = torch.randn(256, 256)
nf4_lvls = compute_nf4_levels()
print(f"NF4 levels (central 8): {nf4_lvls[4:12].tolist()}")
idx, sc = nf4_quantize(w)
w_recon = nf4_dequantize(idx, sc).reshape(256, 256)
rmse = (w - w_recon).pow(2).mean().sqrt().item()
print(f"NF4 RMSE: {rmse:.5f}  |  Compression: {w.numel()*32/(idx.numel()*4+sc.numel()*32):.1f}x")
```

NF4 allocates 8 of its 16 levels to the central region where most LLM weight mass resides, vs INT4 which allocates 4. For a weight distribution with σ=0.02, approximately 68% of values fall within ±σ of zero — NF4 covers this dense region with double the resolution of INT4. This density matching reduces reconstruction MSE by 25–30% compared to INT4 at the same bit width, which translates to measurable quality improvements for downstream task performance.

## Double Quantization — Quantizing the Quantization Constants

```python
import torch

def double_quantize(weight: torch.Tensor,
                    inner_block: int = 64,
                    outer_block: int = 256) -> dict:
    """
    Two-level quantization: NF4 for weights (4 bits), INT8 for scales (8 bits).
    Reduces per-weight scale overhead from 0.5 to 0.125 bits.
    """
    # Level 1: per-inner-block fp32 scales for NF4 quantization
    blocks = weight.reshape(-1, inner_block)
    scales_fp32 = blocks.abs().max(dim=1).values       # [N] fp32, 32 bits each

    # Level 2: quantize fp32 scales to INT8 per outer_block
    n_groups = (scales_fp32.numel() + outer_block // inner_block - 1) // (outer_block // inner_block)
    group_size = outer_block // inner_block
    padded = torch.cat([scales_fp32, scales_fp32.new_zeros(n_groups * group_size - scales_fp32.numel())])
    groups = padded.reshape(n_groups, group_size)
    super_scales = groups.abs().max(dim=1, keepdim=True).values.clamp(1e-8)
    scales_int8 = (groups / super_scales * 127).round().clamp(-127, 127).to(torch.int8)

    # Bit-cost analysis
    bits_fp32 = 32 / inner_block           # 0.500 bits/weight for fp32 scales
    bits_int8 = 8 / inner_block            # 0.125 bits/weight for int8 scales
    bits_super = 32 / outer_block          # 0.125 bits/weight for super-scales
    print(f"Scale overhead: fp32={bits_fp32:.3f} -> int8={bits_int8:.3f} bits/weight")
    print(f"Total NF4 + double quant: {4 + bits_int8 + bits_super:.3f} bits/weight")
    return {"scales_int8": scales_int8, "super_scales": super_scales}

result = double_quantize(torch.randn(4096, 4096))
```

Double quantization reduces the storage overhead of quantization constants from 0.5 bits/weight (fp32 scale per 64 weights) to approximately 0.127 bits/weight (int8 scale per 64 + fp32 super-scale per 256). Combined with NF4's 4 bits per weight, the total is ~4.127 bits/weight. For a 70B model, double quantization saves approximately 3.5GB of GPU memory — enough to fit on a 40GB A100 that would otherwise require a 80GB variant.

## Memory Profiling — fp16 vs LoRA vs QLoRA

```python
import torch

def estimate_training_memory_gb(n_params: float, mode: str,
                                adapter_frac: float = 0.01) -> float:
    """Estimate peak GPU training memory (GB) for a model by size and mode."""
    n = n_params * 1e9
    if mode == "fp16_full":
        # Weights fp16 + grads fp16 + Adam fp32 momentum + Adam fp32 variance
        return n * (2 + 2 + 4 + 4) / 1e9
    elif mode == "lora_fp16":
        # Frozen fp16 base weights + adapter fp16 + Adam fp32 on adapter only
        adapter_n = n * adapter_frac
        return (n * 2 + adapter_n * 2 + adapter_n * (4 + 4)) / 1e9
    elif mode == "qlora_nf4":
        # NF4 base (0.5 bytes/param) + adapter bf16 + Adam fp32 on adapter only
        adapter_n = n * adapter_frac
        return (n * 0.5 + adapter_n * 2 + adapter_n * (4 + 4)) / 1e9
    return 0.0

print(f"{'Size':<6} {'Mode':<14} {'Peak GPU (GB)':>14}")
print("-" * 36)
for n_b, label in [(7, "7B"), (13, "13B"), (70, "70B")]:
    for mode in ["fp16_full", "lora_fp16", "qlora_nf4"]:
        gb = estimate_training_memory_gb(n_b, mode)
        print(f"{label:<6} {mode:<14} {gb:>14.1f}")
```

Estimated peak GPU memory on A100: 7B fp16 full = 84GB (needs 2× A100 80GB), 7B LoRA = 18GB, 7B QLoRA = 9GB. For 70B: fp16 full = 840GB (11× A100 80GB), LoRA = 154GB, QLoRA = 80GB (fits on a single A100 80GB with some room for activations). QLoRA throughput is approximately 70-75% of LoRA due to the overhead of on-the-fly dequantization during the forward pass.

| Quantization | Bits/Param | Memory (7B) | Quality vs fp16 | Speed vs fp16 | Max Model on 80GB A100 |
| --- | --- | --- | --- | --- | --- |
| fp16 Full FT | 16 | ~84 GB | Baseline | 1.00× | ~5B |
| LoRA fp16 | 16 + adapter | ~18 GB | ≈99% | 0.95× | ~30B |
| 8-bit INT8 | 8 | ~14 GB | ~98-99% | 0.85× | ~45B |
| 4-bit INT4 | 4 | ~7 GB | ~94-96% | 0.80× | ~130B |
| 4-bit NF4 (QLoRA) | ~4.5 | ~9 GB | ~98-99% | 0.75× | ~70B |
| NF4 + Double Quant | ~4.13 | ~8.5 GB | ~98-99% | 0.75× | ~75B |

## Paged Optimizer and Training Tips

The paged optimizer is a QLoRA-specific technique using NVIDIA unified memory to automatically page Adam optimizer states (momentum and variance tensors) from GPU VRAM to CPU RAM when the GPU runs out of memory, and page them back when needed for gradient updates. This prevents OOM crashes during long training runs without requiring manual memory management. Use paged_adamw_8bit from bitsandbytes for maximum savings; paged_adamw_32bit for training stability on sensitive tasks.

- Use paged_adamw_8bit for maximum GPU memory savings; paged_adamw_32bit for numerical stability
- Set bnb_4bit_compute_dtype=torch.bfloat16 (not float16) — bf16 has better dynamic range and avoids NaN instability
- Enable gradient checkpointing via prepare_model_for_kbit_training() — trades 30% throughput for large activation memory savings
- Set max_grad_norm=0.3 and warmup_ratio=0.03 for stable QLoRA training runs
- Use per_device_train_batch_size=1 or 2 with gradient_accumulation_steps=16 to maintain effective batch of 16-32
- LoRA adapters remain in bf16/fp32 throughout training — only the frozen base model is in 4-bit NF4

> **NF4 + Double Quantization Memory Math**: QLoRA with NF4 + double quantization uses ~0.5 bits/parameter for the quantization constants (vs 0.125 bits for NF4 weights), bringing total memory to ~4.5 bits/param — allowing a 70B model to fit in a single 40GB A100 with 4-bit quantization. Specifically: 70B × 4.5 bits / 8 bits_per_byte = 39.4GB for weights, leaving room for activations and LoRA adapter states within 40GB VRAM.

QLoRA democratized LLM fine-tuning by making it feasible on consumer hardware. A 7B model can be fine-tuned on an RTX 3090 24GB — a task that previously required multiple enterprise A100 GPUs. Combined with open datasets (Alpaca, FLAN, OpenAssistant) and the Guanaco training recipe from the QLoRA paper, this enabled a generation of competitive open-source fine-tuned models trained by individuals and small teams with modest GPU budgets.

