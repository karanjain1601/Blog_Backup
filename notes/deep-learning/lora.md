---
title: "LoRA — Low-Rank Adaptation for Parameter-Efficient LLM Fine-Tuning"
slug: "lora"
description: "Deep dive into LoRA (Hu et al., 2021): freeze pretrained weights W0, inject low-rank perturbation ΔW=BA, scale by α/r, and merge at inference for zero overhead. Covers math, scratch implementation, PEFT integration, weight merging, and rank ablation."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"LoRA (Low-Rank Adaptation, Hu et al. 2021) is the dominant parameter-efficient fine-tuning (PEFT) method for LLMs. Instead of updating all 7B+ parameters of a pretrained model, LoRA freezes the original weights W₀ and injects a trainable low-rank perturbation ΔW = BA into each target layer. The entire update is parameterized by two small matrices — B ∈ ℝ^(d×r) and A ∈ ℝ^(r×k) — where r ≪ min(d, k). This yields a 10,000× reduction in trainable parameters with near-zero quality loss on most tasks."},{"type":"heading","level":2,"content":"Motivation and Background"},{"type":"text","content":"Full fine-tuning a 7B model requires storing a separate 14GB checkpoint per task — infeasible at scale. LoRA\u0027s key hypothesis (supported by Aghajanyan et al. 2020) is that weight updates during fine-tuning have a low intrinsic rank: the delta ΔW lives in a low-dimensional subspace even though W₀ is high-dimensional. LoRA makes this explicit by constraining ΔW = BA where rank(BA) ≤ r. At inference, BA can be merged into W₀ eliminating all adapter overhead: W_merged = W₀ + (α/r)·BA."},{"type":"math","content":"h = W_0 x + \\Delta W x = W_0 x + \\frac{\\alpha}{r} B A x,\\quad B \\in \\mathbb{R}^{d \\times r},\\ A \\in \\mathbb{R}^{r \\times k},\\ r \\ll \\min(d,k)","display":true},{"type":"heading","level":2,"content":"LoRA Architecture and Key Parameters"},{"type":"text","content":"The forward pass runs the frozen base W₀ and the low-rank branch BA in parallel, then sums their outputs scaled by α/r. Initialization: A ~ N(0, σ²) (Kaiming uniform in practice), B = 0 — so ΔW = 0 at the start of training, preserving the pretrained model\u0027s behavior exactly. The scaling α/r decouples rank from effective learning rate: keeping α fixed while searching over r makes rank a pure capacity knob."},{"type":"list","ordered":false,"items":["rank r: expressivity of the adapter — r=4,8,16,32 cover most tasks; diminishing returns after r=32","alpha α: scaling constant; setting α=2r keeps the effective step size of ΔW constant across rank choices","target_modules: which weight matrices to adapt — Q and V projections are the default; adding K, O, up, down, gate improves performance at higher param cost","lora_dropout: regularization applied to adapter inputs — 0.05 to 0.1 is typical; helps with smaller datasets","bias: whether to train bias parameters alongside adapters — \u0027none\u0027 is the standard default for LoRA"]},{"type":"heading","level":2,"content":"LoRA Layer — Implementation from Scratch"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\nclass LoRALayer(nn.Module):\n    \"\"\"Low-Rank Adaptation: h = W0 @ x + (alpha/r) * B @ A @ x.\"\"\"\n\n    def __init__(self, in_features: int, out_features: int,\n                 rank: int = 4, alpha: float = 16.0, dropout: float = 0.0):\n        super().__init__()\n        self.rank = rank\n        self.alpha = alpha\n        self.scaling = alpha / rank\n\n        # A ~ Kaiming uniform, B = 0 guarantees delta_W = 0 at training start\n        self.lora_A = nn.Parameter(torch.empty(rank, in_features))\n        self.lora_B = nn.Parameter(torch.zeros(out_features, rank))\n        self.dropout = nn.Dropout(p=dropout)\n        nn.init.kaiming_uniform_(self.lora_A, a=math.sqrt(5))\n\n    def forward(self, x: torch.Tensor, pretrained_weight: torch.Tensor) -\u003e torch.Tensor:\n        # Frozen base path: W0 @ x\n        base_out = x @ pretrained_weight.T\n        # LoRA branch: (alpha/r) * B @ A @ x\n        lora_out = self.dropout(x) @ self.lora_A.T @ self.lora_B.T\n        return base_out + self.scaling * lora_out\n\n# Test with a typical attention Q-projection (d_model=768)\nlayer = LoRALayer(in_features=768, out_features=768, rank=8, alpha=16)\nx = torch.randn(2, 10, 768)  # batch=2, seq_len=10, d_model=768\nW0 = nn.Linear(768, 768, bias=False).weight.data\noutput = layer(x, W0)\nprint(f\"Output shape: {output.shape}\")\nprint(f\"Trainable params: {sum(p.numel() for p in layer.parameters()):,}\")"},{"type":"text","content":"B = 0 at initialization is non-negotiable: it ensures the adapted model is identical to the pretrained model before any gradient updates, making the fine-tuning stable and predictable. A is initialized with Kaiming uniform rather than pure Gaussian to match PyTorch\u0027s Linear layer initialization, which provides better gradient flow in early training steps."},{"type":"heading","level":2,"content":"LoRA with HuggingFace PEFT"},{"type":"code","language":"python","content":"from transformers import AutoModelForCausalLM, AutoTokenizer\nfrom peft import LoraConfig, get_peft_model, TaskType\nimport torch\n\nmodel_name = \"meta-llama/Llama-2-7b-hf\"\nmodel = AutoModelForCausalLM.from_pretrained(\n    model_name,\n    torch_dtype=torch.float16,\n    device_map=\"auto\",\n)\n\n# LoRA configuration targeting Q, K, V, O attention projections\nlora_config = LoraConfig(\n    task_type=TaskType.CAUSAL_LM,\n    r=16,                    # Rank of the update matrices\n    lora_alpha=32,           # Scaling: effective factor alpha/r = 2.0\n    target_modules=[\"q_proj\", \"v_proj\", \"k_proj\", \"o_proj\"],\n    lora_dropout=0.05,\n    bias=\"none\",\n)\n\npeft_model = get_peft_model(model, lora_config)\n\n# Report parameter efficiency\ntotal = sum(p.numel() for p in peft_model.parameters())\ntrainable = sum(p.numel() for p in peft_model.parameters() if p.requires_grad)\nprint(f\"Total parameters:     {total:,}\")\nprint(f\"Trainable parameters: {trainable:,}\")\nprint(f\"Trainable fraction:   {100 * trainable / total:.4f}%\")\npeft_model.print_trainable_parameters()"},{"type":"text","content":"For a 7B LLaMA model with r=16 targeting Q, K, V, O across 32 transformer layers: trainable params ≈ 4 × 2 × 4096 × 16 × 32 = 134M, roughly 1.9% of 7B total. Targeting only Q and V halves this to ~67M (0.96%). The PEFT library handles adapter injection, weight freezing, and checkpoint management automatically via get_peft_model()."},{"type":"heading","level":2,"content":"Weight Merging for Zero-Overhead Inference"},{"type":"code","language":"python","content":"import torch\nfrom peft import PeftModel\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\n# Load base model and LoRA adapter separately\nbase_model = AutoModelForCausalLM.from_pretrained(\n    \"meta-llama/Llama-2-7b-hf\",\n    torch_dtype=torch.float16,\n    device_map=\"auto\",\n)\npeft_model = PeftModel.from_pretrained(base_model, \"./lora-adapter-checkpoint\")\n\n# Measure outputs before merging\ntokenizer = AutoTokenizer.from_pretrained(\"meta-llama/Llama-2-7b-hf\")\ninputs = tokenizer(\"Hello, world!\", return_tensors=\"pt\").to(\"cuda\")\nwith torch.no_grad():\n    out_peft = peft_model(**inputs).logits\n\n# Merge: W_merged = W0 + (alpha/r) * B @ A  (done offline once)\nmerged_model = peft_model.merge_and_unload()\nwith torch.no_grad():\n    out_merged = merged_model(**inputs).logits\n\n# Outputs are numerically identical within fp16 rounding\ndiff = (out_peft - out_merged).abs().max().item()\nprint(f\"Max logit difference after merge: {diff:.2e}\")  # ~1e-5\nmerged_model.save_pretrained(\"./merged-model\")\nprint(\"Merged model saved - inference has zero LoRA overhead\")"},{"type":"text","content":"merge_and_unload() iterates over all LoRA layers and computes W_merged = W₀ + (α/r)·BA in place, then removes the adapter modules. The resulting model has identical architecture to the original pretrained model — no extra parameters, no extra compute, no latency penalty. The ~1e-5 maximum logit difference is pure fp16 rounding noise, not a correctness issue."},{"type":"heading","level":2,"content":"Rank Ablation Study"},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\nfrom peft import LoraConfig, get_peft_model, TaskType\nfrom datasets import load_dataset\n\ndef count_trainable(model):\n    return sum(p.numel() for p in model.parameters() if p.requires_grad)\n\ndef run_rank_ablation(base_model_name: str, ranks: list) -\u003e dict:\n    \"\"\"Train LoRA at different ranks; report trainable params and eval metrics.\"\"\"\n    results = {}\n    tokenizer = AutoTokenizer.from_pretrained(base_model_name)\n    tokenizer.pad_token = tokenizer.eos_token\n\n    for r in ranks:\n        model = AutoModelForCausalLM.from_pretrained(\n            base_model_name, torch_dtype=torch.float16, device_map=\"auto\"\n        )\n        config = LoraConfig(\n            task_type=TaskType.CAUSAL_LM, r=r, lora_alpha=r * 2,\n            target_modules=[\"q_proj\", \"v_proj\"], lora_dropout=0.05,\n        )\n        peft_model = get_peft_model(model, config)\n        trainable = count_trainable(peft_model)\n        # ... training and evaluation on downstream task omitted ...\n        print(f\"rank={r:2d} | trainable={trainable:\u003e8,} | eval_loss=\u003crun training\u003e\")\n        results[r] = {\"trainable_params\": trainable}\n    return results\n\nranks = [1, 2, 4, 8, 16, 32]\nresults = run_rank_ablation(\"meta-llama/Llama-2-7b-hf\", ranks)\nfor r, info in results.items():\n    print(f\"r={r:2d}: {info[\u0027trainable_params\u0027]:,} trainable params\")"},{"type":"text","content":"Empirical findings across instruction-following benchmarks: r=1 is often sufficient for simple style transfer tasks. r=8 to r=16 is the sweet spot for general instruction following. r=32 helps for complex reasoning (code, math) where the update subspace is larger. Beyond r=64, LoRA approaches the cost of full fine-tuning with diminishing returns — at that point, full fine-tuning or large-rank PEFT alternatives are worth considering."},{"type":"table","headers":["Rank (r)","Trainable Params (M)","% of 7B Total","Typical Task Suitability"],"rows":[["4","8.4","0.12%","Narrow domain adaptation, small datasets (\u003c5K examples)"],["8","16.8","0.24%","General instruction following, chat — balanced default"],["16","33.6","0.48%","Multi-task, instruction + chat — recommended starting point"],["32","67.1","0.96%","Complex reasoning, coding, math — larger datasets (\u003e50K)"],["64","134.2","1.92%","Near-full-finetune quality — use with large datasets (100K+)"]]},{"type":"heading","level":2,"content":"Practical Guidelines and Best Practices"},{"type":"text","content":"Start with r=16, alpha=32, target Q and V projections, learning rate 2e-4 with cosine decay, and 3 epochs. If the model underfits (eval loss plateaus high), increase rank or add K, O, and FFN target modules. If it overfits (train loss falls but eval loss rises), reduce rank or add dropout. Always inspect the adapter checkpoint size — it should be under 100MB for r=16 on a 7B model."},{"type":"list","ordered":false,"items":["Start small: r=16 covers most tasks — scale up only when downstream performance plateaus","Set alpha=2*rank to keep the adapter update scale constant across rank sweeps","Use a learning rate 5-10x higher than full fine-tuning (2e-4 vs 2e-5) — the adapter is randomly initialized","Save only adapter weights with peft_model.save_pretrained() — saves ~100x storage vs full model checkpoints","For multi-task serving: store separate LoRA adapters (few MB each) and hot-swap them at inference time","Merge and unload before deployment to eliminate all runtime overhead"]},{"type":"callout","variant":"info","title":"Alpha/r Scaling Insight","content":"LoRA\u0027s α/r scaling factor is crucial — keeping α constant while varying r ensures the effective learning rate of ΔW = (α/r)BA stays consistent regardless of rank, making rank hyperparameter searches more interpretable. For example, with α=16: r=4 → scaling=4.0, r=8 → scaling=2.0, r=16 → scaling=1.0. Using α=2r keeps scaling=2.0 across all ranks, decoupling rank from effective step size and making rank a pure capacity knob."},{"type":"text","content":"LoRA remains the gold standard PEFT method because of its simplicity, zero inference overhead after merging, and strong empirical performance across NLP benchmarks. Extensions like QLoRA (4-bit quantization + LoRA), DoRA (weight decomposition into magnitude and direction), and LoRA+ (asymmetric learning rates for A vs B) have pushed the Pareto frontier further, but vanilla LoRA is still the first tool to reach for when adapting a pretrained LLM to a new task."}]"
---
# LoRA — Low-Rank Adaptation for Parameter-Efficient LLM Fine-Tuning

LoRA (Low-Rank Adaptation, Hu et al. 2021) is the dominant parameter-efficient fine-tuning (PEFT) method for LLMs. Instead of updating all 7B+ parameters of a pretrained model, LoRA freezes the original weights W₀ and injects a trainable low-rank perturbation ΔW = BA into each target layer. The entire update is parameterized by two small matrices — B ∈ ℝ^(d×r) and A ∈ ℝ^(r×k) — where r ≪ min(d, k). This yields a 10,000× reduction in trainable parameters with near-zero quality loss on most tasks.

## Motivation and Background

Full fine-tuning a 7B model requires storing a separate 14GB checkpoint per task — infeasible at scale. LoRA's key hypothesis (supported by Aghajanyan et al. 2020) is that weight updates during fine-tuning have a low intrinsic rank: the delta ΔW lives in a low-dimensional subspace even though W₀ is high-dimensional. LoRA makes this explicit by constraining ΔW = BA where rank(BA) ≤ r. At inference, BA can be merged into W₀ eliminating all adapter overhead: W_merged = W₀ + (α/r)·BA.

$$h = W_0 x + \Delta W x = W_0 x + \frac{\alpha}{r} B A x,\quad B \in \mathbb{R}^{d \times r},\ A \in \mathbb{R}^{r \times k},\ r \ll \min(d,k)$$

## LoRA Architecture and Key Parameters

The forward pass runs the frozen base W₀ and the low-rank branch BA in parallel, then sums their outputs scaled by α/r. Initialization: A ~ N(0, σ²) (Kaiming uniform in practice), B = 0 — so ΔW = 0 at the start of training, preserving the pretrained model's behavior exactly. The scaling α/r decouples rank from effective learning rate: keeping α fixed while searching over r makes rank a pure capacity knob.

- rank r: expressivity of the adapter — r=4,8,16,32 cover most tasks; diminishing returns after r=32
- alpha α: scaling constant; setting α=2r keeps the effective step size of ΔW constant across rank choices
- target_modules: which weight matrices to adapt — Q and V projections are the default; adding K, O, up, down, gate improves performance at higher param cost
- lora_dropout: regularization applied to adapter inputs — 0.05 to 0.1 is typical; helps with smaller datasets
- bias: whether to train bias parameters alongside adapters — 'none' is the standard default for LoRA

## LoRA Layer — Implementation from Scratch

```python
import torch
import torch.nn as nn
import math

class LoRALayer(nn.Module):
    """Low-Rank Adaptation: h = W0 @ x + (alpha/r) * B @ A @ x."""

    def __init__(self, in_features: int, out_features: int,
                 rank: int = 4, alpha: float = 16.0, dropout: float = 0.0):
        super().__init__()
        self.rank = rank
        self.alpha = alpha
        self.scaling = alpha / rank

        # A ~ Kaiming uniform, B = 0 guarantees delta_W = 0 at training start
        self.lora_A = nn.Parameter(torch.empty(rank, in_features))
        self.lora_B = nn.Parameter(torch.zeros(out_features, rank))
        self.dropout = nn.Dropout(p=dropout)
        nn.init.kaiming_uniform_(self.lora_A, a=math.sqrt(5))

    def forward(self, x: torch.Tensor, pretrained_weight: torch.Tensor) -> torch.Tensor:
        # Frozen base path: W0 @ x
        base_out = x @ pretrained_weight.T
        # LoRA branch: (alpha/r) * B @ A @ x
        lora_out = self.dropout(x) @ self.lora_A.T @ self.lora_B.T
        return base_out + self.scaling * lora_out

# Test with a typical attention Q-projection (d_model=768)
layer = LoRALayer(in_features=768, out_features=768, rank=8, alpha=16)
x = torch.randn(2, 10, 768)  # batch=2, seq_len=10, d_model=768
W0 = nn.Linear(768, 768, bias=False).weight.data
output = layer(x, W0)
print(f"Output shape: {output.shape}")
print(f"Trainable params: {sum(p.numel() for p in layer.parameters()):,}")
```

B = 0 at initialization is non-negotiable: it ensures the adapted model is identical to the pretrained model before any gradient updates, making the fine-tuning stable and predictable. A is initialized with Kaiming uniform rather than pure Gaussian to match PyTorch's Linear layer initialization, which provides better gradient flow in early training steps.

## LoRA with HuggingFace PEFT

```python
from transformers import AutoModelForCausalLM, AutoTokenizer
from peft import LoraConfig, get_peft_model, TaskType
import torch

model_name = "meta-llama/Llama-2-7b-hf"
model = AutoModelForCausalLM.from_pretrained(
    model_name,
    torch_dtype=torch.float16,
    device_map="auto",
)

# LoRA configuration targeting Q, K, V, O attention projections
lora_config = LoraConfig(
    task_type=TaskType.CAUSAL_LM,
    r=16,                    # Rank of the update matrices
    lora_alpha=32,           # Scaling: effective factor alpha/r = 2.0
    target_modules=["q_proj", "v_proj", "k_proj", "o_proj"],
    lora_dropout=0.05,
    bias="none",
)

peft_model = get_peft_model(model, lora_config)

# Report parameter efficiency
total = sum(p.numel() for p in peft_model.parameters())
trainable = sum(p.numel() for p in peft_model.parameters() if p.requires_grad)
print(f"Total parameters:     {total:,}")
print(f"Trainable parameters: {trainable:,}")
print(f"Trainable fraction:   {100 * trainable / total:.4f}%")
peft_model.print_trainable_parameters()
```

For a 7B LLaMA model with r=16 targeting Q, K, V, O across 32 transformer layers: trainable params ≈ 4 × 2 × 4096 × 16 × 32 = 134M, roughly 1.9% of 7B total. Targeting only Q and V halves this to ~67M (0.96%). The PEFT library handles adapter injection, weight freezing, and checkpoint management automatically via get_peft_model().

## Weight Merging for Zero-Overhead Inference

```python
import torch
from peft import PeftModel
from transformers import AutoModelForCausalLM, AutoTokenizer

# Load base model and LoRA adapter separately
base_model = AutoModelForCausalLM.from_pretrained(
    "meta-llama/Llama-2-7b-hf",
    torch_dtype=torch.float16,
    device_map="auto",
)
peft_model = PeftModel.from_pretrained(base_model, "./lora-adapter-checkpoint")

# Measure outputs before merging
tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-2-7b-hf")
inputs = tokenizer("Hello, world!", return_tensors="pt").to("cuda")
with torch.no_grad():
    out_peft = peft_model(**inputs).logits

# Merge: W_merged = W0 + (alpha/r) * B @ A  (done offline once)
merged_model = peft_model.merge_and_unload()
with torch.no_grad():
    out_merged = merged_model(**inputs).logits

# Outputs are numerically identical within fp16 rounding
diff = (out_peft - out_merged).abs().max().item()
print(f"Max logit difference after merge: {diff:.2e}")  # ~1e-5
merged_model.save_pretrained("./merged-model")
print("Merged model saved - inference has zero LoRA overhead")
```

merge_and_unload() iterates over all LoRA layers and computes W_merged = W₀ + (α/r)·BA in place, then removes the adapter modules. The resulting model has identical architecture to the original pretrained model — no extra parameters, no extra compute, no latency penalty. The ~1e-5 maximum logit difference is pure fp16 rounding noise, not a correctness issue.

## Rank Ablation Study

```python
import torch
from transformers import AutoModelForCausalLM, AutoTokenizer
from peft import LoraConfig, get_peft_model, TaskType
from datasets import load_dataset

def count_trainable(model):
    return sum(p.numel() for p in model.parameters() if p.requires_grad)

def run_rank_ablation(base_model_name: str, ranks: list) -> dict:
    """Train LoRA at different ranks; report trainable params and eval metrics."""
    results = {}
    tokenizer = AutoTokenizer.from_pretrained(base_model_name)
    tokenizer.pad_token = tokenizer.eos_token

    for r in ranks:
        model = AutoModelForCausalLM.from_pretrained(
            base_model_name, torch_dtype=torch.float16, device_map="auto"
        )
        config = LoraConfig(
            task_type=TaskType.CAUSAL_LM, r=r, lora_alpha=r * 2,
            target_modules=["q_proj", "v_proj"], lora_dropout=0.05,
        )
        peft_model = get_peft_model(model, config)
        trainable = count_trainable(peft_model)
        # ... training and evaluation on downstream task omitted ...
        print(f"rank={r:2d} | trainable={trainable:>8,} | eval_loss=<run training>")
        results[r] = {"trainable_params": trainable}
    return results

ranks = [1, 2, 4, 8, 16, 32]
results = run_rank_ablation("meta-llama/Llama-2-7b-hf", ranks)
for r, info in results.items():
    print(f"r={r:2d}: {info['trainable_params']:,} trainable params")
```

Empirical findings across instruction-following benchmarks: r=1 is often sufficient for simple style transfer tasks. r=8 to r=16 is the sweet spot for general instruction following. r=32 helps for complex reasoning (code, math) where the update subspace is larger. Beyond r=64, LoRA approaches the cost of full fine-tuning with diminishing returns — at that point, full fine-tuning or large-rank PEFT alternatives are worth considering.

| Rank (r) | Trainable Params (M) | % of 7B Total | Typical Task Suitability |
| --- | --- | --- | --- |
| 4 | 8.4 | 0.12% | Narrow domain adaptation, small datasets (<5K examples) |
| 8 | 16.8 | 0.24% | General instruction following, chat — balanced default |
| 16 | 33.6 | 0.48% | Multi-task, instruction + chat — recommended starting point |
| 32 | 67.1 | 0.96% | Complex reasoning, coding, math — larger datasets (>50K) |
| 64 | 134.2 | 1.92% | Near-full-finetune quality — use with large datasets (100K+) |

## Practical Guidelines and Best Practices

Start with r=16, alpha=32, target Q and V projections, learning rate 2e-4 with cosine decay, and 3 epochs. If the model underfits (eval loss plateaus high), increase rank or add K, O, and FFN target modules. If it overfits (train loss falls but eval loss rises), reduce rank or add dropout. Always inspect the adapter checkpoint size — it should be under 100MB for r=16 on a 7B model.

- Start small: r=16 covers most tasks — scale up only when downstream performance plateaus
- Set alpha=2*rank to keep the adapter update scale constant across rank sweeps
- Use a learning rate 5-10x higher than full fine-tuning (2e-4 vs 2e-5) — the adapter is randomly initialized
- Save only adapter weights with peft_model.save_pretrained() — saves ~100x storage vs full model checkpoints
- For multi-task serving: store separate LoRA adapters (few MB each) and hot-swap them at inference time
- Merge and unload before deployment to eliminate all runtime overhead

> **Alpha/r Scaling Insight**: LoRA's α/r scaling factor is crucial — keeping α constant while varying r ensures the effective learning rate of ΔW = (α/r)BA stays consistent regardless of rank, making rank hyperparameter searches more interpretable. For example, with α=16: r=4 → scaling=4.0, r=8 → scaling=2.0, r=16 → scaling=1.0. Using α=2r keeps scaling=2.0 across all ranks, decoupling rank from effective step size and making rank a pure capacity knob.

LoRA remains the gold standard PEFT method because of its simplicity, zero inference overhead after merging, and strong empirical performance across NLP benchmarks. Extensions like QLoRA (4-bit quantization + LoRA), DoRA (weight decomposition into magnitude and direction), and LoRA+ (asymmetric learning rates for A vs B) have pushed the Pareto frontier further, but vanilla LoRA is still the first tool to reach for when adapting a pretrained LLM to a new task.

