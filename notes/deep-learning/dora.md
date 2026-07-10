---
title: "DoRA — Weight-Decomposed LoRA with Magnitude and Direction Adaptation"
slug: "dora"
description: "In-depth guide to DoRA (Liu et al., 2024): decompose pretrained weights W0 = m·(V/‖V‖), separately adapt magnitude m with a learned scalar and direction V with LoRA, yielding consistent 1-3% improvements over same-rank LoRA across commonsense reasoning benchmarks."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"DoRA (Weight-Decomposed Low-Rank Adaptation, Liu et al. 2024) identifies a structural limitation of LoRA: LoRA adapts only the column space (direction) of weight updates, with no explicit control over magnitude changes. DoRA decomposes each pretrained weight matrix W₀ = m·(V/‖V‖) into a magnitude vector m ∈ ℝ^(out_features) and a direction matrix V/‖V‖ (unit norm). It then learns Δm (magnitude change) directly as a scalar vector and ΔV (direction change) via a standard LoRA branch — separately optimizing both components for better approximation of full fine-tuning."},{"type":"heading","level":2,"content":"LoRA\u0027s Structural Limitation"},{"type":"text","content":"Analysis of full fine-tuning updates shows that pretrained LLM weights undergo both magnitude and direction changes: some neurons scale up (magnitude increases) while pivoting in weight space (direction changes). LoRA injects ΔW = (α/r)BA which is a rank-r matrix — it changes the effective column space but cannot independently control row magnitudes. In practice, LoRA implicitly changes magnitudes as a side effect of the direction update, but this coupling makes optimization harder. DoRA decouples them: the magnitude vector is trained independently from the direction LoRA branch."},{"type":"math","content":"W_0 = m \\cdot \\frac{V}{\\|V\\|},\\quad W_{\\text{DoRA}} = (m + \\Delta m) \\cdot \\frac{V + \\Delta V_{\\text{LoRA}}}{\\|V + \\Delta V_{\\text{LoRA}}\\|}","display":true},{"type":"heading","level":2,"content":"DoRA — Weight Decomposition and Separate Adaptation"},{"type":"text","content":"DoRA initialization: given pretrained W₀ ∈ ℝ^(d×k), compute the row-wise L2 norms m = ‖W₀‖_row ∈ ℝ^d and the unit-direction matrix V = W₀ / m. The magnitude vector m is stored as a learnable parameter (initialized to the actual row norms of W₀). The direction V is stored as a buffer (non-learnable base) and adapted via a standard LoRA branch ΔV = (α/r)BA. At each forward pass: compute adapted direction V + ΔV, normalize it to unit vectors, then scale by m + Δm where Δm is also learned."},{"type":"list","ordered":false,"items":["Magnitude m ∈ R^d: learnable vector, initialized to row-wise L2 norms of W0 — controls \u0027how much\u0027 each output neuron activates","Direction V/||V||: unit-norm weight matrix, adapted via LoRA branch (alpha/r)*B@A — controls \u0027which features\u0027 the neuron detects","LoRA branch: same A, B matrices as standard LoRA; updated through gradient descent with the same rank hyperparameter","Extra parameters: only d magnitude scalars per weight matrix (768 for 7B LLaMA Q-proj) — completely negligible overhead","HuggingFace PEFT support: enabled by use_dora=True in LoraConfig — no architectural changes needed beyond the flag"]},{"type":"heading","level":2,"content":"DoRA Layer — Implementation from Scratch"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\nclass DoRALayer(nn.Module):\n    \"\"\"DoRA: W = magnitude * normalize(direction + LoRA_delta).\"\"\"\n    def __init__(self, in_feat: int, out_feat: int,\n                 rank: int = 4, alpha: float = 16.0):\n        super().__init__()\n        self.scaling = alpha / rank\n        W0 = torch.randn(out_feat, in_feat) * 0.02\n        row_norms = W0.norm(dim=1, keepdim=True).clamp(min=1e-8)\n        # Learnable magnitude: initialized to row-wise L2 norms of W0\n        self.magnitude = nn.Parameter(row_norms.squeeze(1))  # [out_feat]\n        # Frozen unit-direction matrix (non-learnable base)\n        self.register_buffer(\"direction\", (W0 / row_norms).half())\n        # LoRA matrices for direction adaptation: A ~ N(0,sigma), B = 0\n        self.lora_A = nn.Parameter(torch.empty(rank, in_feat))\n        self.lora_B = nn.Parameter(torch.zeros(out_feat, rank))\n        nn.init.kaiming_uniform_(self.lora_A, a=math.sqrt(5))\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        # Perturb the direction with the LoRA branch\n        dir_delta = self.scaling * (self.lora_B @ self.lora_A)\n        adapted_dir = self.direction.float() + dir_delta\n        # Re-normalize each row to unit vector\n        unit_dir = adapted_dir / adapted_dir.norm(dim=1, keepdim=True).clamp(1e-8)\n        # Reconstruct weight: magnitude * unit_direction\n        W = self.magnitude.unsqueeze(1) * unit_dir\n        return x @ W.T\n\nlayer = DoRALayer(in_feat=768, out_feat=768, rank=8, alpha=16)\nx = torch.randn(2, 10, 768)\nprint(f\"Output shape: {layer(x).shape}\")\ntrainable = sum(p.numel() for p in layer.parameters())\nprint(f\"Trainable params: {trainable:,}\")  # 768 magnitude + 12288 LoRA = 13056"},{"type":"text","content":"The normalization step (unit_dir = adapted_dir / norm) ensures that gradient updates to lora_A and lora_B affect only the direction of the weight, not its magnitude — because magnitude changes are separately handled by the self.magnitude parameter. This decoupling is the core of DoRA\u0027s improvement over LoRA: the optimizer can independently tune how large each neuron\u0027s response is versus which features it responds to."},{"type":"heading","level":2,"content":"Magnitude vs Direction Analysis"},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef analyze_weight_update(W_base: torch.Tensor,\n                          W_adapted: torch.Tensor) -\u003e dict:\n    \"\"\"Decompose weight update into magnitude vs direction components.\"\"\"\n    # Row-wise L2 magnitude for each output neuron\n    mag_base = W_base.norm(dim=1)             # [out_features]\n    mag_adapted = W_adapted.norm(dim=1)\n    # Relative magnitude change: |delta_m| / m_base\n    rel_mag = ((mag_adapted - mag_base) / mag_base.clamp(1e-8)).abs().mean().item()\n\n    # Row-wise direction: normalize to unit vectors\n    dir_base = F.normalize(W_base, dim=1)\n    dir_adapted = F.normalize(W_adapted, dim=1)\n    # Direction change: 1 - cosine_sim (0=identical, 1=orthogonal)\n    cos_sim = (dir_base * dir_adapted).sum(dim=1).clamp(-1, 1)\n    dir_change = (1 - cos_sim).mean().item()\n    return {\"mag_change\": rel_mag, \"dir_change\": dir_change}\n\nW0 = torch.randn(768, 768) * 0.02\n# Simulate LoRA: rank-r additive perturbation (direction change, implicit magnitude shift)\nr = 8\nB_mat = torch.randn(768, r) * 0.001\nA_mat = torch.randn(r, 768) * 0.001\nW_lora = W0 + B_mat @ A_mat\n# Simulate DoRA: explicit magnitude shift + LoRA direction change\nW_dora = W0 * (1 + 0.05 * torch.randn(768, 1))  # explicit magnitude adaptation\nW_dora = W_dora + 0.0005 * torch.randn(768, 768)  # LoRA direction change\n\nlora_stats = analyze_weight_update(W0, W_lora)\ndora_stats = analyze_weight_update(W0, W_dora)\nprint(f\"LoRA -\u003e mag: {lora_stats[\u0027mag_change\u0027]:.5f}, dir: {lora_stats[\u0027dir_change\u0027]:.5f}\")\nprint(f\"DoRA -\u003e mag: {dora_stats[\u0027mag_change\u0027]:.5f}, dir: {dora_stats[\u0027dir_change\u0027]:.5f}\")\nprint(\"DoRA controls magnitude explicitly; LoRA changes it only as a side effect.\")"},{"type":"text","content":"The analysis reveals that LoRA updates produce similar magnitude and direction changes (tightly coupled), while DoRA allows independent control — the magnitude vector can change significantly while the direction changes only slightly, or vice versa. This matches the pattern observed in full fine-tuning where different layers undergo different magnitudes of magnitude vs direction change depending on the task."},{"type":"heading","level":2,"content":"DoRA with HuggingFace PEFT"},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoModelForCausalLM, AutoTokenizer, TrainingArguments\nfrom peft import LoraConfig, get_peft_model, TaskType\nfrom trl import SFTTrainer\nfrom datasets import load_dataset\n\nmodel = AutoModelForCausalLM.from_pretrained(\n    \"meta-llama/Llama-2-7b-hf\",\n    torch_dtype=torch.bfloat16,\n    device_map=\"auto\",\n)\ntokenizer = AutoTokenizer.from_pretrained(\"meta-llama/Llama-2-7b-hf\")\ntokenizer.pad_token = tokenizer.eos_token\n\n# DoRA: identical to LoraConfig but with use_dora=True\ndora_config = LoraConfig(\n    task_type=TaskType.CAUSAL_LM,\n    r=16, lora_alpha=32,\n    target_modules=[\"q_proj\", \"v_proj\", \"k_proj\", \"o_proj\"],\n    lora_dropout=0.05, bias=\"none\",\n    use_dora=True,   # Enable weight decomposition into magnitude + direction\n)\n\npeft_model = get_peft_model(model, dora_config)\npeft_model.print_trainable_parameters()  # ~67M LoRA + ~13K magnitude scalars\ndataset = load_dataset(\"tatsu-lab/alpaca\", split=\"train[:5000]\")\nargs = TrainingArguments(\n    output_dir=\"./dora-llama2-7b\", per_device_train_batch_size=4,\n    gradient_accumulation_steps=4, num_train_epochs=3,\n    learning_rate=2e-4, bf16=True, logging_steps=10,\n)\ntrainer = SFTTrainer(model=peft_model, args=args,\n                     train_dataset=dataset, tokenizer=tokenizer)\ntrainer.train()\npeft_model.save_pretrained(\"./dora-adapter\")"},{"type":"text","content":"The only difference from standard LoRA training in PEFT is the use_dora=True flag. The magnitude vectors are stored as additional parameters in the adapter checkpoint — for a 7B model targeting Q, K, V, O across 32 layers, this adds only 4 × 32 × 4096 = 524,288 extra float32 values (~2MB) — completely negligible compared to the 100MB+ LoRA adapter weights. Training time is nearly identical to LoRA because the magnitude update is just a vector addition."},{"type":"heading","level":2,"content":"DoRA vs LoRA Benchmark"},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoModelForCausalLM\nfrom peft import LoraConfig, get_peft_model, TaskType\nfrom lm_eval import evaluator\nfrom lm_eval.models.huggingface import HFLM\n\ndef run_peft_eval(model_name: str, use_dora: bool, rank: int = 16) -\u003e dict:\n    \"\"\"Evaluate LoRA vs DoRA at equal rank on commonsense reasoning tasks.\"\"\"\n    model = AutoModelForCausalLM.from_pretrained(\n        model_name, torch_dtype=torch.bfloat16, device_map=\"auto\"\n    )\n    config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM, r=rank, lora_alpha=rank * 2,\n        target_modules=[\"q_proj\", \"v_proj\", \"k_proj\", \"o_proj\"],\n        lora_dropout=0.05, use_dora=use_dora,\n    )\n    peft_model = get_peft_model(model, config)\n    trainable = sum(p.numel() for p in peft_model.parameters() if p.requires_grad)\n    # Evaluate using lm-evaluation-harness\n    lm = HFLM(pretrained=peft_model)\n    results = evaluator.simple_evaluate(lm, tasks=[\"hellaswag\", \"arc_easy\"])\n    hs = results[\"results\"][\"hellaswag\"][\"acc_norm,none\"]\n    arc = results[\"results\"][\"arc_easy\"][\"acc,none\"]\n    method = \"DoRA\" if use_dora else \"LoRA\"\n    print(f\"{method} r={rank}: params={trainable:,}, HellaSwag={hs:.3f}, ARC-Easy={arc:.3f}\")\n    return {\"method\": method, \"trainable\": trainable, \"hellaswag\": hs, \"arc_easy\": arc}\n\nfor use_dora in [False, True]:\n    run_peft_eval(\"meta-llama/Llama-2-7b-hf\", use_dora=use_dora, rank=16)"},{"type":"text","content":"Empirical results from Liu et al. (2024): at equal rank (r=16), DoRA consistently outperforms LoRA by 1-3% on commonsense reasoning benchmarks (HellaSwag, ARC, BoolQ, WinoGrande). The gap is larger for tasks requiring nuanced factual recall and smaller for tasks where simple instruction following suffices. DoRA matches full fine-tuning quality at lower ranks than LoRA, making r=16 DoRA roughly equivalent to r=32 LoRA on most benchmarks."},{"type":"table","headers":["Method","Trainable Params","Adapts Magnitude","Adapts Direction","Extra Parameters","Performance vs Full FT"],"rows":[["Full Fine-Tuning","100%","Yes — explicit","Yes — explicit","None","Baseline"],["LoRA","~0.5-2%","Implicitly (side effect)","Yes — primary adaptation","None","95-99%"],["DoRA","~0.5-2% + tiny","Yes — explicit Δm vector","Yes — via LoRA branch","d scalars/layer (~2MB total)","97-99.5%"],["QLoRA (LoRA on 4-bit)","~0.5-2%","Implicitly","Yes","None","95-98%"],["QDoRA (DoRA on 4-bit)","~0.5-2% + tiny","Yes — explicit","Yes — via LoRA branch","d scalars/layer","96-98.5%"]]},{"type":"heading","level":2,"content":"When to Use DoRA over LoRA"},{"type":"text","content":"DoRA is most beneficial when: (1) the target task requires significant shift from pretrained behavior (commonsense reasoning, complex instruction following), where the pretrained weight magnitudes and directions both need to change substantially; (2) you are constrained to a low rank budget (r=4 to r=16) and need maximum quality per trainable parameter; (3) you are fine-tuning from a strong pretrained checkpoint where the pretrained magnitudes carry meaningful information worth preserving and adapting separately."},{"type":"list","ordered":false,"items":["Use DoRA when LoRA underperforms: if r=32 LoRA still lags behind full fine-tuning by more than 3%, try DoRA at r=16","DoRA is nearly free: the extra magnitude parameters add ~2MB per 7B model — checkpoint size and training time are virtually unchanged","Combine DoRA with QLoRA: set use_dora=True alongside BitsAndBytesConfig for maximum memory efficiency + quality","Avoid DoRA for simple style transfer or domain adaptation tasks where LoRA already matches full fine-tuning at r=8","DoRA and LoRA+ (asymmetric learning rates for A vs B) are orthogonal improvements and can be combined","Benchmark before committing: run a quick r=16 LoRA vs r=16 DoRA comparison on a validation set — if gap is less than 0.5%, stick with LoRA"]},{"type":"callout","variant":"info","title":"DoRA\u0027s Key Insight","content":"DoRA\u0027s key insight is that pretrained weights undergo different magnitude vs direction changes during fine-tuning — LoRA only adapts direction (via column space of BA), while DoRA explicitly models both, better approximating full fine-tuning\u0027s update pattern. The magnitude vector m adds only d=4096 extra float32 values per target weight matrix in a 7B model — a completely negligible cost (~2MB total) for a consistent 1-3% benchmark improvement over same-rank LoRA."},{"type":"text","content":"DoRA represents the current state-of-the-art for single-adapter PEFT methods, consistently outperforming LoRA on commonsense reasoning, instruction following, and multi-task benchmarks with negligible additional cost. Its compatibility with QLoRA (use_dora=True + BitsAndBytesConfig) and native HuggingFace PEFT support makes it a drop-in replacement for LoRA in most training scripts. For new fine-tuning projects targeting quality-critical tasks, DoRA is the recommended default over vanilla LoRA."}]"
---
# DoRA — Weight-Decomposed LoRA with Magnitude and Direction Adaptation

DoRA (Weight-Decomposed Low-Rank Adaptation, Liu et al. 2024) identifies a structural limitation of LoRA: LoRA adapts only the column space (direction) of weight updates, with no explicit control over magnitude changes. DoRA decomposes each pretrained weight matrix W₀ = m·(V/‖V‖) into a magnitude vector m ∈ ℝ^(out_features) and a direction matrix V/‖V‖ (unit norm). It then learns Δm (magnitude change) directly as a scalar vector and ΔV (direction change) via a standard LoRA branch — separately optimizing both components for better approximation of full fine-tuning.

## LoRA's Structural Limitation

Analysis of full fine-tuning updates shows that pretrained LLM weights undergo both magnitude and direction changes: some neurons scale up (magnitude increases) while pivoting in weight space (direction changes). LoRA injects ΔW = (α/r)BA which is a rank-r matrix — it changes the effective column space but cannot independently control row magnitudes. In practice, LoRA implicitly changes magnitudes as a side effect of the direction update, but this coupling makes optimization harder. DoRA decouples them: the magnitude vector is trained independently from the direction LoRA branch.

$$W_0 = m \cdot \frac{V}{\|V\|},\quad W_{\text{DoRA}} = (m + \Delta m) \cdot \frac{V + \Delta V_{\text{LoRA}}}{\|V + \Delta V_{\text{LoRA}}\|}$$

## DoRA — Weight Decomposition and Separate Adaptation

DoRA initialization: given pretrained W₀ ∈ ℝ^(d×k), compute the row-wise L2 norms m = ‖W₀‖_row ∈ ℝ^d and the unit-direction matrix V = W₀ / m. The magnitude vector m is stored as a learnable parameter (initialized to the actual row norms of W₀). The direction V is stored as a buffer (non-learnable base) and adapted via a standard LoRA branch ΔV = (α/r)BA. At each forward pass: compute adapted direction V + ΔV, normalize it to unit vectors, then scale by m + Δm where Δm is also learned.

- Magnitude m ∈ R^d: learnable vector, initialized to row-wise L2 norms of W0 — controls 'how much' each output neuron activates
- Direction V/||V||: unit-norm weight matrix, adapted via LoRA branch (alpha/r)*B@A — controls 'which features' the neuron detects
- LoRA branch: same A, B matrices as standard LoRA; updated through gradient descent with the same rank hyperparameter
- Extra parameters: only d magnitude scalars per weight matrix (768 for 7B LLaMA Q-proj) — completely negligible overhead
- HuggingFace PEFT support: enabled by use_dora=True in LoraConfig — no architectural changes needed beyond the flag

## DoRA Layer — Implementation from Scratch

```python
import torch
import torch.nn as nn
import math

class DoRALayer(nn.Module):
    """DoRA: W = magnitude * normalize(direction + LoRA_delta)."""
    def __init__(self, in_feat: int, out_feat: int,
                 rank: int = 4, alpha: float = 16.0):
        super().__init__()
        self.scaling = alpha / rank
        W0 = torch.randn(out_feat, in_feat) * 0.02
        row_norms = W0.norm(dim=1, keepdim=True).clamp(min=1e-8)
        # Learnable magnitude: initialized to row-wise L2 norms of W0
        self.magnitude = nn.Parameter(row_norms.squeeze(1))  # [out_feat]
        # Frozen unit-direction matrix (non-learnable base)
        self.register_buffer("direction", (W0 / row_norms).half())
        # LoRA matrices for direction adaptation: A ~ N(0,sigma), B = 0
        self.lora_A = nn.Parameter(torch.empty(rank, in_feat))
        self.lora_B = nn.Parameter(torch.zeros(out_feat, rank))
        nn.init.kaiming_uniform_(self.lora_A, a=math.sqrt(5))
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # Perturb the direction with the LoRA branch
        dir_delta = self.scaling * (self.lora_B @ self.lora_A)
        adapted_dir = self.direction.float() + dir_delta
        # Re-normalize each row to unit vector
        unit_dir = adapted_dir / adapted_dir.norm(dim=1, keepdim=True).clamp(1e-8)
        # Reconstruct weight: magnitude * unit_direction
        W = self.magnitude.unsqueeze(1) * unit_dir
        return x @ W.T

layer = DoRALayer(in_feat=768, out_feat=768, rank=8, alpha=16)
x = torch.randn(2, 10, 768)
print(f"Output shape: {layer(x).shape}")
trainable = sum(p.numel() for p in layer.parameters())
print(f"Trainable params: {trainable:,}")  # 768 magnitude + 12288 LoRA = 13056
```

The normalization step (unit_dir = adapted_dir / norm) ensures that gradient updates to lora_A and lora_B affect only the direction of the weight, not its magnitude — because magnitude changes are separately handled by the self.magnitude parameter. This decoupling is the core of DoRA's improvement over LoRA: the optimizer can independently tune how large each neuron's response is versus which features it responds to.

## Magnitude vs Direction Analysis

```python
import torch
import torch.nn.functional as F

def analyze_weight_update(W_base: torch.Tensor,
                          W_adapted: torch.Tensor) -> dict:
    """Decompose weight update into magnitude vs direction components."""
    # Row-wise L2 magnitude for each output neuron
    mag_base = W_base.norm(dim=1)             # [out_features]
    mag_adapted = W_adapted.norm(dim=1)
    # Relative magnitude change: |delta_m| / m_base
    rel_mag = ((mag_adapted - mag_base) / mag_base.clamp(1e-8)).abs().mean().item()

    # Row-wise direction: normalize to unit vectors
    dir_base = F.normalize(W_base, dim=1)
    dir_adapted = F.normalize(W_adapted, dim=1)
    # Direction change: 1 - cosine_sim (0=identical, 1=orthogonal)
    cos_sim = (dir_base * dir_adapted).sum(dim=1).clamp(-1, 1)
    dir_change = (1 - cos_sim).mean().item()
    return {"mag_change": rel_mag, "dir_change": dir_change}

W0 = torch.randn(768, 768) * 0.02
# Simulate LoRA: rank-r additive perturbation (direction change, implicit magnitude shift)
r = 8
B_mat = torch.randn(768, r) * 0.001
A_mat = torch.randn(r, 768) * 0.001
W_lora = W0 + B_mat @ A_mat
# Simulate DoRA: explicit magnitude shift + LoRA direction change
W_dora = W0 * (1 + 0.05 * torch.randn(768, 1))  # explicit magnitude adaptation
W_dora = W_dora + 0.0005 * torch.randn(768, 768)  # LoRA direction change

lora_stats = analyze_weight_update(W0, W_lora)
dora_stats = analyze_weight_update(W0, W_dora)
print(f"LoRA -> mag: {lora_stats['mag_change']:.5f}, dir: {lora_stats['dir_change']:.5f}")
print(f"DoRA -> mag: {dora_stats['mag_change']:.5f}, dir: {dora_stats['dir_change']:.5f}")
print("DoRA controls magnitude explicitly; LoRA changes it only as a side effect.")
```

The analysis reveals that LoRA updates produce similar magnitude and direction changes (tightly coupled), while DoRA allows independent control — the magnitude vector can change significantly while the direction changes only slightly, or vice versa. This matches the pattern observed in full fine-tuning where different layers undergo different magnitudes of magnitude vs direction change depending on the task.

## DoRA with HuggingFace PEFT

```python
import torch
from transformers import AutoModelForCausalLM, AutoTokenizer, TrainingArguments
from peft import LoraConfig, get_peft_model, TaskType
from trl import SFTTrainer
from datasets import load_dataset

model = AutoModelForCausalLM.from_pretrained(
    "meta-llama/Llama-2-7b-hf",
    torch_dtype=torch.bfloat16,
    device_map="auto",
)
tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-2-7b-hf")
tokenizer.pad_token = tokenizer.eos_token

# DoRA: identical to LoraConfig but with use_dora=True
dora_config = LoraConfig(
    task_type=TaskType.CAUSAL_LM,
    r=16, lora_alpha=32,
    target_modules=["q_proj", "v_proj", "k_proj", "o_proj"],
    lora_dropout=0.05, bias="none",
    use_dora=True,   # Enable weight decomposition into magnitude + direction
)

peft_model = get_peft_model(model, dora_config)
peft_model.print_trainable_parameters()  # ~67M LoRA + ~13K magnitude scalars
dataset = load_dataset("tatsu-lab/alpaca", split="train[:5000]")
args = TrainingArguments(
    output_dir="./dora-llama2-7b", per_device_train_batch_size=4,
    gradient_accumulation_steps=4, num_train_epochs=3,
    learning_rate=2e-4, bf16=True, logging_steps=10,
)
trainer = SFTTrainer(model=peft_model, args=args,
                     train_dataset=dataset, tokenizer=tokenizer)
trainer.train()
peft_model.save_pretrained("./dora-adapter")
```

The only difference from standard LoRA training in PEFT is the use_dora=True flag. The magnitude vectors are stored as additional parameters in the adapter checkpoint — for a 7B model targeting Q, K, V, O across 32 layers, this adds only 4 × 32 × 4096 = 524,288 extra float32 values (~2MB) — completely negligible compared to the 100MB+ LoRA adapter weights. Training time is nearly identical to LoRA because the magnitude update is just a vector addition.

## DoRA vs LoRA Benchmark

```python
import torch
from transformers import AutoModelForCausalLM
from peft import LoraConfig, get_peft_model, TaskType
from lm_eval import evaluator
from lm_eval.models.huggingface import HFLM

def run_peft_eval(model_name: str, use_dora: bool, rank: int = 16) -> dict:
    """Evaluate LoRA vs DoRA at equal rank on commonsense reasoning tasks."""
    model = AutoModelForCausalLM.from_pretrained(
        model_name, torch_dtype=torch.bfloat16, device_map="auto"
    )
    config = LoraConfig(
        task_type=TaskType.CAUSAL_LM, r=rank, lora_alpha=rank * 2,
        target_modules=["q_proj", "v_proj", "k_proj", "o_proj"],
        lora_dropout=0.05, use_dora=use_dora,
    )
    peft_model = get_peft_model(model, config)
    trainable = sum(p.numel() for p in peft_model.parameters() if p.requires_grad)
    # Evaluate using lm-evaluation-harness
    lm = HFLM(pretrained=peft_model)
    results = evaluator.simple_evaluate(lm, tasks=["hellaswag", "arc_easy"])
    hs = results["results"]["hellaswag"]["acc_norm,none"]
    arc = results["results"]["arc_easy"]["acc,none"]
    method = "DoRA" if use_dora else "LoRA"
    print(f"{method} r={rank}: params={trainable:,}, HellaSwag={hs:.3f}, ARC-Easy={arc:.3f}")
    return {"method": method, "trainable": trainable, "hellaswag": hs, "arc_easy": arc}

for use_dora in [False, True]:
    run_peft_eval("meta-llama/Llama-2-7b-hf", use_dora=use_dora, rank=16)
```

Empirical results from Liu et al. (2024): at equal rank (r=16), DoRA consistently outperforms LoRA by 1-3% on commonsense reasoning benchmarks (HellaSwag, ARC, BoolQ, WinoGrande). The gap is larger for tasks requiring nuanced factual recall and smaller for tasks where simple instruction following suffices. DoRA matches full fine-tuning quality at lower ranks than LoRA, making r=16 DoRA roughly equivalent to r=32 LoRA on most benchmarks.

| Method | Trainable Params | Adapts Magnitude | Adapts Direction | Extra Parameters | Performance vs Full FT |
| --- | --- | --- | --- | --- | --- |
| Full Fine-Tuning | 100% | Yes — explicit | Yes — explicit | None | Baseline |
| LoRA | ~0.5-2% | Implicitly (side effect) | Yes — primary adaptation | None | 95-99% |
| DoRA | ~0.5-2% + tiny | Yes — explicit Δm vector | Yes — via LoRA branch | d scalars/layer (~2MB total) | 97-99.5% |
| QLoRA (LoRA on 4-bit) | ~0.5-2% | Implicitly | Yes | None | 95-98% |
| QDoRA (DoRA on 4-bit) | ~0.5-2% + tiny | Yes — explicit | Yes — via LoRA branch | d scalars/layer | 96-98.5% |

## When to Use DoRA over LoRA

DoRA is most beneficial when: (1) the target task requires significant shift from pretrained behavior (commonsense reasoning, complex instruction following), where the pretrained weight magnitudes and directions both need to change substantially; (2) you are constrained to a low rank budget (r=4 to r=16) and need maximum quality per trainable parameter; (3) you are fine-tuning from a strong pretrained checkpoint where the pretrained magnitudes carry meaningful information worth preserving and adapting separately.

- Use DoRA when LoRA underperforms: if r=32 LoRA still lags behind full fine-tuning by more than 3%, try DoRA at r=16
- DoRA is nearly free: the extra magnitude parameters add ~2MB per 7B model — checkpoint size and training time are virtually unchanged
- Combine DoRA with QLoRA: set use_dora=True alongside BitsAndBytesConfig for maximum memory efficiency + quality
- Avoid DoRA for simple style transfer or domain adaptation tasks where LoRA already matches full fine-tuning at r=8
- DoRA and LoRA+ (asymmetric learning rates for A vs B) are orthogonal improvements and can be combined
- Benchmark before committing: run a quick r=16 LoRA vs r=16 DoRA comparison on a validation set — if gap is less than 0.5%, stick with LoRA

> **DoRA's Key Insight**: DoRA's key insight is that pretrained weights undergo different magnitude vs direction changes during fine-tuning — LoRA only adapts direction (via column space of BA), while DoRA explicitly models both, better approximating full fine-tuning's update pattern. The magnitude vector m adds only d=4096 extra float32 values per target weight matrix in a 7B model — a completely negligible cost (~2MB total) for a consistent 1-3% benchmark improvement over same-rank LoRA.

DoRA represents the current state-of-the-art for single-adapter PEFT methods, consistently outperforming LoRA on commonsense reasoning, instruction following, and multi-task benchmarks with negligible additional cost. Its compatibility with QLoRA (use_dora=True + BitsAndBytesConfig) and native HuggingFace PEFT support makes it a drop-in replacement for LoRA in most training scripts. For new fine-tuning projects targeting quality-critical tasks, DoRA is the recommended default over vanilla LoRA.

