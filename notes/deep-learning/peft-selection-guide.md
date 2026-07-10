---
title: "PEFT Selection Guide — Choosing the Right Method by Task, Data, and Constraints"
slug: "peft-selection-guide"
description: "Decision framework for choosing the right PEFT method. Covers key selection dimensions, a Python decision function, parameter efficiency vs quality benchmarks, inference latency comparison, multi-task adapter serving, and a comprehensive method comparison table for LoRA, QLoRA, DoRA, LoRA+, VeRA, Prefix Tuning, Adapters, and IA3."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"With a growing zoo of PEFT methods — LoRA, QLoRA, DoRA, LoRA+, VeRA, Prefix Tuning, Adapters, IA3 — choosing the right one requires reasoning about five dimensions simultaneously: data size, task type, GPU memory budget, inference latency requirement, and whether you need to merge or swap adapters at runtime. No single method dominates all dimensions; the right choice depends on which constraints are binding in your setting."},{"type":"heading","level":2,"content":"Key Decision Dimensions"},{"type":"list","ordered":false,"items":["Data size: \u003c 100 examples → IA3; 100–10K → LoRA or LoRA+; 10K–100K → LoRA+/DoRA; \u003e 100K → DoRA or full fine-tune with LoRA regularization.","Task type: understanding (classification, NER) → LoRA rank 4–16; generation → LoRA rank 16–64; alignment (RLHF/DPO) → LoRA + DPO is standard.","GPU memory: \u003c 16 GB → QLoRA (4-bit base); 16–40 GB → LoRA or DoRA in bf16; \u003e 40 GB → DoRA full precision.","Inference latency: zero overhead required → merge LoRA into base weights; can tolerate extra layers → Adapters or Prefix Tuning; extreme few-shot → IA3 (3 rescaling vectors per layer).","Multi-task serving: hot-swap without reloading → Adapters or non-merged LoRA; single task at a time → merge LoRA for zero latency.","Merging / task arithmetic: only LoRA and DoRA produce mergeable delta matrices; Adapters and Prefix Tuning cannot be merged into base weights cleanly."]},{"type":"heading","level":2,"content":"PEFT Selection Decision Tree"},{"type":"text","content":"A systematic decision function removes the guesswork. The tree below checks binding constraints in priority order: memory first (QLoRA), then extreme few-shot (IA3), then multi-task inference (Adapters), then quality priority (DoRA), and defaults to LoRA+ for the general case. LoRA+ is a free improvement over standard LoRA — it sets different learning rates for the A and B matrices — and should always be preferred over vanilla LoRA when there is no other constraint."},{"type":"code","language":"python","content":"from dataclasses import dataclass\nfrom typing import Optional\n\n@dataclass\nclass PEFTRecommendation:\n    method: str\n    reason: str\n    lora_rank: Optional[int] = None\n    notes: str = \"\"\n\ndef select_peft_method(\n    data_size: int,\n    gpu_memory_gb: float,\n    task_type: str = \"generation\",\n    multi_task_inference: bool = False,\n    need_merge: bool = False,\n    quality_priority: bool = False,\n) -\u003e PEFTRecommendation:\n    \"\"\"Return the recommended PEFT method given task constraints.\"\"\"\n    if data_size \u003c 100:\n        return PEFTRecommendation(\"IA3\", \"Extreme few-shot: IA3 has fewest trainable params\",\n                                  notes=\"Only ~3 vectors per layer; no rank to tune\")\n    if gpu_memory_gb \u003c 16:\n        return PEFTRecommendation(\"QLoRA\", \"Memory constrained: 4-bit base + bf16 adapters\",\n                                  lora_rank=16, notes=\"Use bitsandbytes NF4 + paged optimizer\")\n    if multi_task_inference and not need_merge:\n        return PEFTRecommendation(\"Adapters\", \"Hot-swap at inference without reloading base\",\n                                  notes=\"Use PEFT AdapterHub; swap by task_id\")\n    if need_merge and quality_priority:\n        return PEFTRecommendation(\"LoRA+ + DoRA\", \"Best quality, merges to zero latency\",\n                                  lora_rank=32, notes=\"DoRA: separate magnitude/direction learning\")\n    if need_merge:\n        return PEFTRecommendation(\"LoRA+\", \"Mergeable, free LR improvement over LoRA\",\n                                  lora_rank=16, notes=\"Set lr_ratio=16 for B matrix\")\n    return PEFTRecommendation(\"LoRA+\", \"Best general-purpose default\",\n                              lora_rank=16, notes=\"Start here; add DoRA if quality is insufficient\")\n\ntest_cases = [\n    (50,   24, \"classification\", False, False, False),\n    (500,  12, \"generation\",     False, True,  False),\n    (5000, 24, \"generation\",     False, True,  True),\n    (50000,80, \"alignment\",      False, True,  True),\n    (2000, 40, \"generation\",     True,  False, False),\n]\nfor args in test_cases:\n    r = select_peft_method(*args)\n    print(f\"data={args[0]:\u003e6}, gpu={args[1]:\u003e2}GB -\u003e {r.method}: {r.reason}\")"},{"type":"heading","level":2,"content":"Parameter Efficiency vs Quality Tradeoff"},{"type":"text","content":"The efficiency-quality Pareto frontier varies by method. IA3 sits at the extreme-efficiency end (\u003c 0.02% trainable parameters) but requires large base models to shine — on GPT-3 scale it matches LoRA, but on 1B-scale models it underperforms. LoRA at rank 16 is the sweet spot for most 1–7B models: enough capacity for generation tasks, negligible inference overhead when merged. DoRA adds ~1% overhead over LoRA in training time but consistently outperforms LoRA by 1–3% absolute on generation benchmarks. VeRA uses shared random matrices with learnable rescaling vectors, achieving LoRA-comparable quality with 10× fewer trainable parameters but cannot be merged cleanly."},{"type":"code","language":"python","content":"from dataclasses import dataclass, field\nfrom typing import List\n\n@dataclass\nclass BenchmarkResult:\n    method: str\n    trainable_params_pct: float\n    train_time_relative: float  # relative to LoRA=1.0\n    eval_score: float           # normalized: LoRA=0.871\n    peak_memory_gb: float\n    merge_to_base: bool\n\ndef run_peft_benchmark(model_params: int = 7_000_000_000) -\u003e List[BenchmarkResult]:\n    \"\"\"Simulated benchmark results (from published papers and internal evals).\"\"\"\n    results = [\n        BenchmarkResult(\"LoRA r=16\",    0.050, 1.00, 0.871, 14.2, True),\n        BenchmarkResult(\"LoRA+ r=16\",   0.050, 0.99, 0.876, 14.2, True),\n        BenchmarkResult(\"DoRA r=16\",    0.051, 1.04, 0.882, 14.6, True),\n        BenchmarkResult(\"QLoRA r=16\",   0.050, 1.18, 0.868,  8.1, True),\n        BenchmarkResult(\"IA3\",          0.002, 0.80, 0.841, 13.8, False),\n        BenchmarkResult(\"Adapters\",     0.120, 1.13, 0.874, 15.1, False),\n        BenchmarkResult(\"PrefixTuning\", 0.010, 0.95, 0.843, 14.0, False),\n        BenchmarkResult(\"VeRA r=256\",   0.005, 1.02, 0.869, 14.3, False),\n    ]\n    return results\n\nresults = run_peft_benchmark()\nprint(f\"{\u0027Method\u0027:\u003e16} {\u0027Params%\u0027:\u003e8} {\u0027Time\u0027:\u003e6} {\u0027Score\u0027:\u003e7} {\u0027Mem(GB)\u0027:\u003e8} {\u0027Merge\u0027:\u003e6}\")\nprint(\"-\" * 58)\nfor r in results:\n    merge_str = \"Yes\" if r.merge_to_base else \"No\"\n    print(f\"{r.method:\u003e16} {r.trainable_params_pct:\u003e7.3f}% {r.train_time_relative:\u003e6.2f}x \"\n          f\"{r.eval_score:\u003e7.3f} {r.peak_memory_gb:\u003e8.1f} {merge_str:\u003e6}\")"},{"type":"heading","level":2,"content":"Inference Overhead Comparison"},{"type":"text","content":"Inference latency is where methods diverge most sharply. Merged LoRA is identical to the base model at inference — the adapter matrices are absorbed into the base weights, adding zero latency. Non-merged LoRA adds two extra matmuls (Ax and Bx) per adapted layer, roughly 3–8% overhead on GPU for rank 16. Adapter layers insert a bottleneck MLP (down-project → activation → up-project) adding 5–15% overhead depending on rank and model size. Prefix Tuning prepends k virtual tokens to the key-value cache, increasing attention computation by k/seq_len — for k=50 tokens on a 512-token sequence, overhead is ~10%. IA3 rescales by learned vectors: the overhead is a single element-wise multiply per layer, \u003c 1%."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\ndef measure_latency(model: nn.Module, x: torch.Tensor,\n                    n_warmup: int = 20, n_runs: int = 100) -\u003e float:\n    \"\"\"Return average forward-pass latency in milliseconds.\"\"\"\n    model.eval()\n    with torch.no_grad():\n        for _ in range(n_warmup):\n            model(x)\n    t0 = time.perf_counter()\n    with torch.no_grad():\n        for _ in range(n_runs):\n            model(x)\n    return (time.perf_counter() - t0) * 1000 / n_runs\n\nD = 512\n# Merged LoRA: same as base model\nbase = nn.Sequential(nn.Linear(D, D), nn.ReLU(), nn.Linear(D, D))\n# Non-merged LoRA: extra matmul per layer (simulated as extra small linear)\nnon_merged_lora = nn.Sequential(\n    nn.Linear(D, D), nn.ReLU(), nn.Linear(D, D),\n    nn.Linear(D, 16, bias=False), nn.Linear(16, D, bias=False)  # LoRA A+B\n)\n# Adapter: extra bottleneck layers\nadapter = nn.Sequential(\n    nn.Linear(D, D), nn.ReLU(),\n    nn.Linear(D, 64), nn.ReLU(), nn.Linear(64, D),  # adapter bottleneck\n    nn.Linear(D, D)\n)\nx = torch.randn(16, D)\nfor name, model in [(\"Base/MergedLoRA\", base), (\"NonMergedLoRA\", non_merged_lora), (\"Adapter\", adapter)]:\n    lat = measure_latency(model, x)\n    params = sum(p.numel() for p in model.parameters())\n    print(f\"{name:\u003e16}: {lat:.3f} ms/batch  ({params:,} params)\")"},{"type":"heading","level":2,"content":"Multi-Task Serving with Adapter Swap"},{"type":"text","content":"When serving multiple tasks from one deployment, non-merged adapters offer hot-swap: load the base model once and swap the adapter weights per request without reloading the full model. This is efficient when tasks share a common base and differ only in the adapter. The overhead is the adapter forward pass (5–15%) plus the time to copy adapter weights to GPU (negligible for rank 16–64 LoRA: \u003c 1 MB). Libraries like PEFT\u0027s load_adapter and set_adapter enable runtime task switching. For LoRA, non-merged mode keeps the A and B matrices separate from the base weights, enabling swap; merged mode fuses them and cannot be unswapped without the original adapter."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom typing import Dict\n\nclass MultiTaskLoRAServer:\n    \"\"\"Serve multiple tasks by swapping LoRA adapters on a shared base model.\"\"\"\n\n    def __init__(self, base_model: nn.Module, lora_rank: int = 16):\n        self.base = base_model\n        self.rank = lora_rank\n        self.adapters: Dict[str, Dict[str, torch.Tensor]] = {}\n        self.active_task: str = None\n\n    def register_adapter(self, task_name: str, lora_A: torch.Tensor, lora_B: torch.Tensor):\n        self.adapters[task_name] = {\"A\": lora_A, \"B\": lora_B}\n        size_kb = (lora_A.numel() + lora_B.numel()) * 4 / 1024\n        print(f\"Registered \u0027{task_name}\u0027: rank={self.rank}, size={size_kb:.1f} KB\")\n\n    def activate(self, task_name: str):\n        if task_name not in self.adapters:\n            raise ValueError(f\"Unknown task: {task_name}\")\n        self.active_task = task_name\n        # In real PEFT: model.set_adapter(task_name)\n        print(f\"Activated adapter: \u0027{task_name}\u0027 (no base reload required)\")\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        out = self.base(x)\n        if self.active_task:\n            adapter = self.adapters[self.active_task]\n            # Apply LoRA delta: out += x @ A.T @ B.T * (1/rank)\n            lora_out = (x @ adapter[\"A\"].T) @ adapter[\"B\"].T / self.rank\n            out = out + lora_out\n        return out\n\nbase = nn.Linear(64, 64)\nserver = MultiTaskLoRAServer(base, lora_rank=8)\nfor task in [\"sentiment\", \"ner\", \"qa\"]:\n    A = torch.randn(8, 64) * 0.02\n    B = torch.zeros(64, 8)\n    server.register_adapter(task, A, B)\nx = torch.randn(4, 64)\nfor task in [\"sentiment\", \"ner\", \"qa\"]:\n    server.activate(task)\n    out = server.forward(x)\n    print(f\"  {task} output norm: {out.norm():.4f}\")"},{"type":"heading","level":2,"content":"Method Strengths and Weaknesses"},{"type":"text","content":"No PEFT method dominates all dimensions. LoRA+ is the safest default: it improves over LoRA at zero cost, merges cleanly, and is supported by every major library. QLoRA is essential when GPU memory is the binding constraint — it enables 7B fine-tuning on a single 16 GB GPU at modest quality cost. DoRA is worth adding when squeezing maximum quality from a fixed rank and compute budget. Prefix Tuning and Adapter layers shine only in multi-task inference settings where hot-swap is required and latency overhead is acceptable. IA3 is the right choice for true few-shot scenarios (\u003c 100 examples) where LoRA would overfit. VeRA is for settings with extreme numbers of tasks to store (thousands of adapters) where per-task storage is the bottleneck."},{"type":"heading","level":2,"content":"PEFT Method Comparison Table"},{"type":"table","headers":["Method","Trainable Params","Merge to Base","Memory Reduction","Best Data Size","Best Use Case"],"rows":[["LoRA r=16","~0.05% of 7B","Yes — zero latency","Minimal (bf16 adapters)","1K–100K","General-purpose fine-tuning"],["LoRA+","~0.05% of 7B","Yes — zero latency","Same as LoRA","1K–100K","Free upgrade over LoRA, always prefer"],["DoRA","~0.051% of 7B","Yes — zero latency","Same as LoRA","5K–100K","Maximum quality at same rank"],["QLoRA","~0.05% of 7B","Yes (dequant first)","50–75% vs bf16","1K–50K","16 GB GPU fine-tuning"],["VeRA","~0.005% of 7B","No (shared random)","Same as LoRA","5K–50K","Storing thousands of task adapters"],["Prefix Tuning","~0.01% of 7B","No (virtual tokens)","Minimal","10K+ (scale needed)","Multi-task hot-swap, large models only"],["Adapters","~0.1–1% of 7B","No (extra layers)","Minimal","5K–100K","Hot-swap multi-task serving"],["IA3","~0.002% of 7B","No (rescaling only)","Minimal","\u003c 100 (few-shot)","Extreme few-shot, GPT-3 scale models"]]},{"type":"callout","variant":"tip","title":"Production Fine-Tuning Default Stack","content":"For most production fine-tuning: start with LoRA+ (free improvement over LoRA) + DoRA if you need maximum quality. Add QLoRA only if GPU memory is the binding constraint. Use adapter layers or prefix tuning only if you need hot-swap multi-task inference without reloading. VeRA is worth considering only when you need to store more than 100 different task adapters — for fewer tasks, LoRA\u0027s storage is manageable."},{"type":"list","ordered":false,"items":["LoRA rank selection: rank 4–8 for classification/NER; rank 16–32 for generation; rank 64 for alignment tasks.","LoRA target modules: always include q_proj, v_proj at minimum; add k_proj, o_proj, gate_proj for higher quality.","QLoRA: use NF4 quantization (not INT8) for best quality; add double quantization to save another ~0.5 GB.","DoRA: available in Hugging Face PEFT \u003e= 0.9.0 via use_dora=True in LoraConfig; no other changes needed.","Merging: call model.merge_and_unload() after training to absorb LoRA into base weights before deployment.","Adapter swap timing: swapping a rank-16 LoRA adapter takes \u003c 5 ms including CPU-to-GPU transfer for 7B models."]},{"type":"divider"}]"
---
# PEFT Selection Guide — Choosing the Right Method by Task, Data, and Constraints

With a growing zoo of PEFT methods — LoRA, QLoRA, DoRA, LoRA+, VeRA, Prefix Tuning, Adapters, IA3 — choosing the right one requires reasoning about five dimensions simultaneously: data size, task type, GPU memory budget, inference latency requirement, and whether you need to merge or swap adapters at runtime. No single method dominates all dimensions; the right choice depends on which constraints are binding in your setting.

## Key Decision Dimensions

- Data size: < 100 examples → IA3; 100–10K → LoRA or LoRA+; 10K–100K → LoRA+/DoRA; > 100K → DoRA or full fine-tune with LoRA regularization.
- Task type: understanding (classification, NER) → LoRA rank 4–16; generation → LoRA rank 16–64; alignment (RLHF/DPO) → LoRA + DPO is standard.
- GPU memory: < 16 GB → QLoRA (4-bit base); 16–40 GB → LoRA or DoRA in bf16; > 40 GB → DoRA full precision.
- Inference latency: zero overhead required → merge LoRA into base weights; can tolerate extra layers → Adapters or Prefix Tuning; extreme few-shot → IA3 (3 rescaling vectors per layer).
- Multi-task serving: hot-swap without reloading → Adapters or non-merged LoRA; single task at a time → merge LoRA for zero latency.
- Merging / task arithmetic: only LoRA and DoRA produce mergeable delta matrices; Adapters and Prefix Tuning cannot be merged into base weights cleanly.

## PEFT Selection Decision Tree

A systematic decision function removes the guesswork. The tree below checks binding constraints in priority order: memory first (QLoRA), then extreme few-shot (IA3), then multi-task inference (Adapters), then quality priority (DoRA), and defaults to LoRA+ for the general case. LoRA+ is a free improvement over standard LoRA — it sets different learning rates for the A and B matrices — and should always be preferred over vanilla LoRA when there is no other constraint.

```python
from dataclasses import dataclass
from typing import Optional

@dataclass
class PEFTRecommendation:
    method: str
    reason: str
    lora_rank: Optional[int] = None
    notes: str = ""

def select_peft_method(
    data_size: int,
    gpu_memory_gb: float,
    task_type: str = "generation",
    multi_task_inference: bool = False,
    need_merge: bool = False,
    quality_priority: bool = False,
) -> PEFTRecommendation:
    """Return the recommended PEFT method given task constraints."""
    if data_size < 100:
        return PEFTRecommendation("IA3", "Extreme few-shot: IA3 has fewest trainable params",
                                  notes="Only ~3 vectors per layer; no rank to tune")
    if gpu_memory_gb < 16:
        return PEFTRecommendation("QLoRA", "Memory constrained: 4-bit base + bf16 adapters",
                                  lora_rank=16, notes="Use bitsandbytes NF4 + paged optimizer")
    if multi_task_inference and not need_merge:
        return PEFTRecommendation("Adapters", "Hot-swap at inference without reloading base",
                                  notes="Use PEFT AdapterHub; swap by task_id")
    if need_merge and quality_priority:
        return PEFTRecommendation("LoRA+ + DoRA", "Best quality, merges to zero latency",
                                  lora_rank=32, notes="DoRA: separate magnitude/direction learning")
    if need_merge:
        return PEFTRecommendation("LoRA+", "Mergeable, free LR improvement over LoRA",
                                  lora_rank=16, notes="Set lr_ratio=16 for B matrix")
    return PEFTRecommendation("LoRA+", "Best general-purpose default",
                              lora_rank=16, notes="Start here; add DoRA if quality is insufficient")

test_cases = [
    (50,   24, "classification", False, False, False),
    (500,  12, "generation",     False, True,  False),
    (5000, 24, "generation",     False, True,  True),
    (50000,80, "alignment",      False, True,  True),
    (2000, 40, "generation",     True,  False, False),
]
for args in test_cases:
    r = select_peft_method(*args)
    print(f"data={args[0]:>6}, gpu={args[1]:>2}GB -> {r.method}: {r.reason}")
```

## Parameter Efficiency vs Quality Tradeoff

The efficiency-quality Pareto frontier varies by method. IA3 sits at the extreme-efficiency end (< 0.02% trainable parameters) but requires large base models to shine — on GPT-3 scale it matches LoRA, but on 1B-scale models it underperforms. LoRA at rank 16 is the sweet spot for most 1–7B models: enough capacity for generation tasks, negligible inference overhead when merged. DoRA adds ~1% overhead over LoRA in training time but consistently outperforms LoRA by 1–3% absolute on generation benchmarks. VeRA uses shared random matrices with learnable rescaling vectors, achieving LoRA-comparable quality with 10× fewer trainable parameters but cannot be merged cleanly.

```python
from dataclasses import dataclass, field
from typing import List

@dataclass
class BenchmarkResult:
    method: str
    trainable_params_pct: float
    train_time_relative: float  # relative to LoRA=1.0
    eval_score: float           # normalized: LoRA=0.871
    peak_memory_gb: float
    merge_to_base: bool

def run_peft_benchmark(model_params: int = 7_000_000_000) -> List[BenchmarkResult]:
    """Simulated benchmark results (from published papers and internal evals)."""
    results = [
        BenchmarkResult("LoRA r=16",    0.050, 1.00, 0.871, 14.2, True),
        BenchmarkResult("LoRA+ r=16",   0.050, 0.99, 0.876, 14.2, True),
        BenchmarkResult("DoRA r=16",    0.051, 1.04, 0.882, 14.6, True),
        BenchmarkResult("QLoRA r=16",   0.050, 1.18, 0.868,  8.1, True),
        BenchmarkResult("IA3",          0.002, 0.80, 0.841, 13.8, False),
        BenchmarkResult("Adapters",     0.120, 1.13, 0.874, 15.1, False),
        BenchmarkResult("PrefixTuning", 0.010, 0.95, 0.843, 14.0, False),
        BenchmarkResult("VeRA r=256",   0.005, 1.02, 0.869, 14.3, False),
    ]
    return results

results = run_peft_benchmark()
print(f"{'Method':>16} {'Params%':>8} {'Time':>6} {'Score':>7} {'Mem(GB)':>8} {'Merge':>6}")
print("-" * 58)
for r in results:
    merge_str = "Yes" if r.merge_to_base else "No"
    print(f"{r.method:>16} {r.trainable_params_pct:>7.3f}% {r.train_time_relative:>6.2f}x "
          f"{r.eval_score:>7.3f} {r.peak_memory_gb:>8.1f} {merge_str:>6}")
```

## Inference Overhead Comparison

Inference latency is where methods diverge most sharply. Merged LoRA is identical to the base model at inference — the adapter matrices are absorbed into the base weights, adding zero latency. Non-merged LoRA adds two extra matmuls (Ax and Bx) per adapted layer, roughly 3–8% overhead on GPU for rank 16. Adapter layers insert a bottleneck MLP (down-project → activation → up-project) adding 5–15% overhead depending on rank and model size. Prefix Tuning prepends k virtual tokens to the key-value cache, increasing attention computation by k/seq_len — for k=50 tokens on a 512-token sequence, overhead is ~10%. IA3 rescales by learned vectors: the overhead is a single element-wise multiply per layer, < 1%.

```python
import torch
import torch.nn as nn
import time

def measure_latency(model: nn.Module, x: torch.Tensor,
                    n_warmup: int = 20, n_runs: int = 100) -> float:
    """Return average forward-pass latency in milliseconds."""
    model.eval()
    with torch.no_grad():
        for _ in range(n_warmup):
            model(x)
    t0 = time.perf_counter()
    with torch.no_grad():
        for _ in range(n_runs):
            model(x)
    return (time.perf_counter() - t0) * 1000 / n_runs

D = 512
# Merged LoRA: same as base model
base = nn.Sequential(nn.Linear(D, D), nn.ReLU(), nn.Linear(D, D))
# Non-merged LoRA: extra matmul per layer (simulated as extra small linear)
non_merged_lora = nn.Sequential(
    nn.Linear(D, D), nn.ReLU(), nn.Linear(D, D),
    nn.Linear(D, 16, bias=False), nn.Linear(16, D, bias=False)  # LoRA A+B
)
# Adapter: extra bottleneck layers
adapter = nn.Sequential(
    nn.Linear(D, D), nn.ReLU(),
    nn.Linear(D, 64), nn.ReLU(), nn.Linear(64, D),  # adapter bottleneck
    nn.Linear(D, D)
)
x = torch.randn(16, D)
for name, model in [("Base/MergedLoRA", base), ("NonMergedLoRA", non_merged_lora), ("Adapter", adapter)]:
    lat = measure_latency(model, x)
    params = sum(p.numel() for p in model.parameters())
    print(f"{name:>16}: {lat:.3f} ms/batch  ({params:,} params)")
```

## Multi-Task Serving with Adapter Swap

When serving multiple tasks from one deployment, non-merged adapters offer hot-swap: load the base model once and swap the adapter weights per request without reloading the full model. This is efficient when tasks share a common base and differ only in the adapter. The overhead is the adapter forward pass (5–15%) plus the time to copy adapter weights to GPU (negligible for rank 16–64 LoRA: < 1 MB). Libraries like PEFT's load_adapter and set_adapter enable runtime task switching. For LoRA, non-merged mode keeps the A and B matrices separate from the base weights, enabling swap; merged mode fuses them and cannot be unswapped without the original adapter.

```python
import torch
import torch.nn as nn
from typing import Dict

class MultiTaskLoRAServer:
    """Serve multiple tasks by swapping LoRA adapters on a shared base model."""

    def __init__(self, base_model: nn.Module, lora_rank: int = 16):
        self.base = base_model
        self.rank = lora_rank
        self.adapters: Dict[str, Dict[str, torch.Tensor]] = {}
        self.active_task: str = None

    def register_adapter(self, task_name: str, lora_A: torch.Tensor, lora_B: torch.Tensor):
        self.adapters[task_name] = {"A": lora_A, "B": lora_B}
        size_kb = (lora_A.numel() + lora_B.numel()) * 4 / 1024
        print(f"Registered '{task_name}': rank={self.rank}, size={size_kb:.1f} KB")

    def activate(self, task_name: str):
        if task_name not in self.adapters:
            raise ValueError(f"Unknown task: {task_name}")
        self.active_task = task_name
        # In real PEFT: model.set_adapter(task_name)
        print(f"Activated adapter: '{task_name}' (no base reload required)")

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        out = self.base(x)
        if self.active_task:
            adapter = self.adapters[self.active_task]
            # Apply LoRA delta: out += x @ A.T @ B.T * (1/rank)
            lora_out = (x @ adapter["A"].T) @ adapter["B"].T / self.rank
            out = out + lora_out
        return out

base = nn.Linear(64, 64)
server = MultiTaskLoRAServer(base, lora_rank=8)
for task in ["sentiment", "ner", "qa"]:
    A = torch.randn(8, 64) * 0.02
    B = torch.zeros(64, 8)
    server.register_adapter(task, A, B)
x = torch.randn(4, 64)
for task in ["sentiment", "ner", "qa"]:
    server.activate(task)
    out = server.forward(x)
    print(f"  {task} output norm: {out.norm():.4f}")
```

## Method Strengths and Weaknesses

No PEFT method dominates all dimensions. LoRA+ is the safest default: it improves over LoRA at zero cost, merges cleanly, and is supported by every major library. QLoRA is essential when GPU memory is the binding constraint — it enables 7B fine-tuning on a single 16 GB GPU at modest quality cost. DoRA is worth adding when squeezing maximum quality from a fixed rank and compute budget. Prefix Tuning and Adapter layers shine only in multi-task inference settings where hot-swap is required and latency overhead is acceptable. IA3 is the right choice for true few-shot scenarios (< 100 examples) where LoRA would overfit. VeRA is for settings with extreme numbers of tasks to store (thousands of adapters) where per-task storage is the bottleneck.

## PEFT Method Comparison Table

| Method | Trainable Params | Merge to Base | Memory Reduction | Best Data Size | Best Use Case |
| --- | --- | --- | --- | --- | --- |
| LoRA r=16 | ~0.05% of 7B | Yes — zero latency | Minimal (bf16 adapters) | 1K–100K | General-purpose fine-tuning |
| LoRA+ | ~0.05% of 7B | Yes — zero latency | Same as LoRA | 1K–100K | Free upgrade over LoRA, always prefer |
| DoRA | ~0.051% of 7B | Yes — zero latency | Same as LoRA | 5K–100K | Maximum quality at same rank |
| QLoRA | ~0.05% of 7B | Yes (dequant first) | 50–75% vs bf16 | 1K–50K | 16 GB GPU fine-tuning |
| VeRA | ~0.005% of 7B | No (shared random) | Same as LoRA | 5K–50K | Storing thousands of task adapters |
| Prefix Tuning | ~0.01% of 7B | No (virtual tokens) | Minimal | 10K+ (scale needed) | Multi-task hot-swap, large models only |
| Adapters | ~0.1–1% of 7B | No (extra layers) | Minimal | 5K–100K | Hot-swap multi-task serving |
| IA3 | ~0.002% of 7B | No (rescaling only) | Minimal | < 100 (few-shot) | Extreme few-shot, GPT-3 scale models |

> **Production Fine-Tuning Default Stack**: For most production fine-tuning: start with LoRA+ (free improvement over LoRA) + DoRA if you need maximum quality. Add QLoRA only if GPU memory is the binding constraint. Use adapter layers or prefix tuning only if you need hot-swap multi-task inference without reloading. VeRA is worth considering only when you need to store more than 100 different task adapters — for fewer tasks, LoRA's storage is manageable.

- LoRA rank selection: rank 4–8 for classification/NER; rank 16–32 for generation; rank 64 for alignment tasks.
- LoRA target modules: always include q_proj, v_proj at minimum; add k_proj, o_proj, gate_proj for higher quality.
- QLoRA: use NF4 quantization (not INT8) for best quality; add double quantization to save another ~0.5 GB.
- DoRA: available in Hugging Face PEFT >= 0.9.0 via use_dora=True in LoraConfig; no other changes needed.
- Merging: call model.merge_and_unload() after training to absorb LoRA into base weights before deployment.
- Adapter swap timing: swapping a rank-16 LoRA adapter takes < 5 ms including CPU-to-GPU transfer for 7B models.

---

