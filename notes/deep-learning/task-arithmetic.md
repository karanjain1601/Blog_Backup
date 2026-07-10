---
title: "Task Arithmetic — Adding and Negating Fine-Tuned Weight Deltas"
slug: "task-arithmetic"
description: "Task vectors encode task-specific knowledge as the weight difference between a fine-tuned and pretrained model. Covers task vector addition for multi-task capability, scaling with lambda, negation for capability removal, analogy operations, and orthogonality analysis explaining low interference."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Task arithmetic (Ilharco et al., 2023) defines a task vector τ = θ_fine-tuned − θ_pretrained: the element-wise difference between a task-specific fine-tuned model and the original pretrained checkpoint. These vectors live in the same weight space as the model parameters and can be combined algebraically. Adding a task vector to the pretrained model recovers (approximately) the fine-tuned model; adding multiple task vectors endows the pretrained model with multiple capabilities simultaneously; negating a task vector reduces that capability. The surprising finding is that these operations compose more cleanly than expected."},{"type":"heading","level":2,"content":"Task Vectors — Definition and Extraction"},{"type":"text","content":"For a pretrained model with parameters θ₀, and a model fine-tuned on task T with parameters θ_T, the task vector is τ_T = θ_T − θ₀. This is a vector of the same dimensionality as the model: if the model has 7B parameters, each task vector has 7B elements. Task vectors are dense (not sparse) over all parameter groups — encoder layers, attention projections, FFN weights, and layer norms all accumulate task-specific deltas during fine-tuning. The magnitude of the task vector (‖τ_T‖) reflects the total drift from pretrained to fine-tuned weights."},{"type":"code","language":"python","content":"import torch\nfrom collections import OrderedDict\n\ndef extract_task_vectors(base_state_dict, finetuned_state_dicts, names=None):\n    \"\"\"Compute tau_i = theta_ft_i - theta_base for each fine-tuned model.\"\"\"\n    task_vectors = []\n    for i, ft_sd in enumerate(finetuned_state_dicts):\n        tau = OrderedDict()\n        for key in base_state_dict:\n            tau[key] = ft_sd[key].float() - base_state_dict[key].float()\n        task_vectors.append(tau)\n    return task_vectors\n\ndef task_vector_stats(task_vectors, names=None):\n    for i, tv in enumerate(task_vectors):\n        name = names[i] if names else f\"Task {i+1}\"\n        total_norm = sum(v.norm().item() for v in tv.values())\n        max_delta = max(v.abs().max().item() for v in tv.values())\n        print(f\"{name}: total_norm={total_norm:.4f}, max_delta={max_delta:.4f}, layers={len(tv)}\")\n\ntorch.manual_seed(42)\nbase = {\"enc.w\": torch.zeros(8, 8), \"head.w\": torch.zeros(4, 8)}\nft_dicts = [\n    {\"enc.w\": base[\"enc.w\"] + torch.randn(8,8)*0.15, \"head.w\": base[\"head.w\"] + torch.randn(4,8)*0.2},\n    {\"enc.w\": base[\"enc.w\"] + torch.randn(8,8)*0.12, \"head.w\": base[\"head.w\"] + torch.randn(4,8)*0.18},\n    {\"enc.w\": base[\"enc.w\"] + torch.randn(8,8)*0.10, \"head.w\": base[\"head.w\"] + torch.randn(4,8)*0.22},\n]\ntvs = extract_task_vectors(base, ft_dicts)\ntask_vector_stats(tvs, names=[\"Sentiment\", \"NER\", \"QA\"])\nprint(\"Task vectors: each encodes task drift from the shared pretrained base.\")"},{"type":"heading","level":2,"content":"Task Vector Addition — Multi-Task Composition"},{"type":"text","content":"Adding task vectors combines capabilities: θ_multi = θ₀ + λ₁τ₁ + λ₂τ₂ + ... + λ_nτ_n. The scalar λ controls how strongly each task is incorporated. At λ=0 the base model is unchanged; at λ=1 the full task vector is applied; at λ\u003e1 the task is extrapolated beyond the fine-tuned optimum. In practice, λ in [0.5, 1.0] works well for most tasks; values above 1.5 often overshoot and degrade general capabilities. The key insight from Ilharco et al. is that task vectors for semantically distinct NLP tasks (sentiment, NER, QA) are approximately orthogonal, so their sum has low interference."},{"type":"code","language":"python","content":"import torch\nfrom collections import OrderedDict\n\ndef apply_task_arithmetic(base_sd, task_vectors, lambdas):\n    \"\"\"Apply task arithmetic: theta = theta_base + sum(lambda_i * tau_i).\"\"\"\n    assert len(task_vectors) == len(lambdas)\n    merged = OrderedDict()\n    for key in base_sd:\n        delta = sum(lam * tv[key].float() for lam, tv in zip(lambdas, task_vectors))\n        merged[key] = base_sd[key].float() + delta\n    return merged\n\ndef task_benchmark(model_sd, task_name, metric_fn):\n    score = metric_fn(model_sd)\n    print(f\"  [{task_name}]: {score:.4f}\")\n    return score\n\ntorch.manual_seed(0)\nbase = {\"w\": torch.zeros(6)}\ntau_code = {\"w\": torch.tensor([0.5, 0.3, -0.1, 0.2, 0.4, 0.1])}\ntau_math = {\"w\": torch.tensor([0.2, -0.1, 0.6, 0.3, -0.2, 0.4])}\n\nprint(\"Sweeping lambda for single-task addition:\")\nfor lam in [0.0, 0.25, 0.5, 1.0, 1.5]:\n    result = apply_task_arithmetic(base, [tau_code], [lam])\n    print(f\"  lambda={lam}: w={[round(v,3) for v in result[\u0027w\u0027].tolist()]}\")\n\nprint(\"\\nMulti-task addition (lambda=1.0 for both):\")\nmulti = apply_task_arithmetic(base, [tau_code, tau_math], [1.0, 1.0])\nprint(f\"  combined w={[round(v,3) for v in multi[\u0027w\u0027].tolist()]}\")\nprint(\"Sum of orthogonal task vectors composes with low interference.\")"},{"type":"heading","level":2,"content":"Scaling and Extrapolation"},{"type":"text","content":"The scalar λ is a continuous knob over task strength. At λ=0, the model is the pretrained base. At λ=1, the model equals the fine-tuned checkpoint (in the weight-space approximation). At λ\u003e1, the task is extrapolated: the model is pushed further along the direction of the task vector than the fine-tuned model itself reached. Extrapolation (λ\u003e1) sometimes yields better performance on in-distribution tasks than the fine-tuned model, because it amplifies the task-specific direction while suppressing generalist features. However, extrapolation degrades robustness on out-of-distribution inputs and is sensitive to λ."},{"type":"heading","level":2,"content":"Negation — Unlearning a Capability"},{"type":"text","content":"Subtracting a task vector removes the corresponding capability: θ_negated = θ₀ − λ · τ_harmful. This is useful for alignment: if a model has a harmful capability (e.g., producing toxic text), you can fine-tune a small dataset to extract the harmful task vector, then subtract it from the aligned model. The result reduces harmful outputs without requiring full retraining. The antidote approach adds a negated harmful task vector to an aligned model rather than retraining with filtered data. Ilharco et al. show that negating a task vector for sentiment classification reduces accuracy on sentiment benchmarks by 20–30% while leaving unrelated tasks largely unaffected."},{"type":"code","language":"python","content":"import torch\nfrom collections import OrderedDict\n\ndef negate_capability(base_sd, task_vector, scale=1.0):\n    \"\"\"Subtract task vector: theta = theta_base - scale * tau (capability removal).\"\"\"\n    negated = OrderedDict()\n    for key in base_sd:\n        negated[key] = base_sd[key].float() - scale * task_vector[key].float()\n    return negated\n\ndef measure_capability(model_sd, probe_key, probe_direction):\n    \"\"\"Proxy: dot product with probe direction measures task alignment.\"\"\"\n    w = model_sd[probe_key].float().flatten()\n    return (w * probe_direction).sum().item()\n\ntorch.manual_seed(7)\nbase = {\"w\": torch.randn(8)}\ntau_harmful = {\"w\": torch.randn(8) * 0.4}\nprobe = tau_harmful[\"w\"] / tau_harmful[\"w\"].norm()  # probe aligned with harmful direction\n\nprint(\"Capability score (higher = more harmful alignment):\")\nprint(f\"  Base model: {measure_capability(base, \u0027w\u0027, probe):.4f}\")\nfor scale in [0.5, 1.0, 1.5, 2.0]:\n    neg = negate_capability(base, tau_harmful, scale=scale)\n    print(f\"  After negation (scale={scale:.1f}): {measure_capability(neg, \u0027w\u0027, probe):.4f}\")\nprint(\"Negation progressively removes the capability; scale controls aggressiveness.\")"},{"type":"heading","level":2,"content":"Orthogonality Analysis — Why Addition Works"},{"type":"text","content":"Task arithmetic addition is interference-free when task vectors are orthogonal: if τ_A · τ_B = 0, then ‖τ_A + τ_B‖² = ‖τ_A‖² + ‖τ_B‖². In practice, task vectors for NLP tasks with different label spaces (sentiment vs NER vs QA) have pairwise cosine similarities below 0.1 — nearly orthogonal. This near-orthogonality breaks down for semantically related tasks (e.g., two different sentiment datasets) where vectors align strongly. Measuring pairwise cosine similarities before merging is a good diagnostic: high similarity (\u003e0.3) predicts low interference; low similarity (\u003c0.1) predicts effective composition."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef cosine_similarity_matrix(task_vectors, names=None):\n    \"\"\"Compute pairwise cosine similarity between flattened task vectors.\"\"\"\n    n = len(task_vectors)\n    flat = [\n        torch.cat([v.float().flatten() for v in tv.values()])\n        for tv in task_vectors\n    ]\n    sim = torch.zeros(n, n)\n    for i in range(n):\n        for j in range(n):\n            sim[i, j] = F.cosine_similarity(flat[i].unsqueeze(0), flat[j].unsqueeze(0))\n    if names:\n        header = f\"{\u0027\u0027:\u003e14}\" + \"\".join(f\"{name:\u003e14}\" for name in names)\n        print(header)\n        for i, name in enumerate(names):\n            row = f\"{name:\u003e14}\" + \"\".join(f\"{sim[i,j].item():\u003e14.3f}\" for j in range(n))\n            print(row)\n    off_diag = (sim.sum() - sim.trace()) / (n * (n - 1))\n    print(f\"Off-diagonal mean cosine similarity: {off_diag.item():.4f}\")\n    return sim\n\ntorch.manual_seed(99)\ntvs = [\n    {\"enc\": torch.randn(32, 32), \"head\": torch.randn(8, 32)}\n    for _ in range(4)\n]\nnames = [\"Sentiment\", \"NER\", \"QA\", \"Summarization\"]\nsim = cosine_similarity_matrix(tvs, names)\nprint(\"Low off-diagonal values confirm near-orthogonality =\u003e low addition interference.\")"},{"type":"heading","level":2,"content":"Limitations and Extensions"},{"type":"text","content":"Task arithmetic degrades as more task vectors are added. With 2–3 tasks, interference is typically below 2% absolute; with 8+ tasks, interference can exceed 10%. The degradation is worse when tasks share similar features — for example, adding 5 different code generation task vectors produces high mutual interference. TIES and DARE extend task arithmetic to reduce this interference. The analogy operation τ_A − τ_B + τ_C transfers task structure: if τ_A is \u0027English→French translation\u0027 and τ_B is \u0027English→Spanish translation\u0027, then τ_C = τ_A − τ_B + τ_Spanish-text captures the translation direction without Spanish-specific bias."},{"type":"list","ordered":false,"items":["Task vectors are dense over all parameter groups — not just LoRA-adapted layers; apply to full fine-tunes or merge LoRA BA products first.","Scaling range: λ ∈ [0.3, 1.0] is safe for most tasks; λ \u003e 1.5 risks degrading general capabilities.","Orthogonality diagnostic: measure pairwise cosine similarities before merging; \u003e0.3 means high interference risk.","Negation scale: λ=1.0 for full capability removal; λ=0.5 for partial reduction while preserving related capabilities.","Analogy (A-B+C): transfers relational task structure; requires τ_A and τ_B to encode the same type of transformation.","Extension: TIES/DARE improve upon simple task vector addition for cross-task merging with 4+ models."]},{"type":"heading","level":2,"content":"Task Arithmetic Operations Summary"},{"type":"table","headers":["Operation","Formula","Effect","λ Range","Interference Risk","Use Case"],"rows":[["Addition","θ₀ + λτ_A","Add task A capability to base","0.5–1.0","Low if orthogonal","Multi-task composition"],["Scaling","θ₀ + λτ_A (vary λ)","Tune task strength continuously","0–1.5","Low","Task strength control"],["Negation","θ₀ − λτ_harmful","Remove or reduce capability","0.5–1.5","Low (subtractive)","Alignment / capability removal"],["Multi-add","θ₀ + Σλᵢτᵢ","Combine N tasks simultaneously","0.3–0.8 each","Grows with N","Up to ~4 tasks cleanly"],["Analogy A-B+C","θ₀ + τ_A − τ_B + τ_C","Transfer relational structure","1.0 each","Moderate","Cross-lingual / domain transfer"]]},{"type":"callout","variant":"info","title":"Near-Orthogonality Explains Task Arithmetic\u0027s Low Interference","content":"Task vectors for different NLP tasks (sentiment, NER, QA) are approximately orthogonal (cosine similarity \u003c 0.1) — this near-orthogonality explains why task arithmetic addition is often interference-free for the first 2–3 added tasks, but degrades beyond that. Measure pairwise cosine similarities before merging: if any pair exceeds 0.25, expect measurable interference and prefer TIES or DARE instead of simple task arithmetic addition."},{"type":"divider"}]"
---
# Task Arithmetic — Adding and Negating Fine-Tuned Weight Deltas

Task arithmetic (Ilharco et al., 2023) defines a task vector τ = θ_fine-tuned − θ_pretrained: the element-wise difference between a task-specific fine-tuned model and the original pretrained checkpoint. These vectors live in the same weight space as the model parameters and can be combined algebraically. Adding a task vector to the pretrained model recovers (approximately) the fine-tuned model; adding multiple task vectors endows the pretrained model with multiple capabilities simultaneously; negating a task vector reduces that capability. The surprising finding is that these operations compose more cleanly than expected.

## Task Vectors — Definition and Extraction

For a pretrained model with parameters θ₀, and a model fine-tuned on task T with parameters θ_T, the task vector is τ_T = θ_T − θ₀. This is a vector of the same dimensionality as the model: if the model has 7B parameters, each task vector has 7B elements. Task vectors are dense (not sparse) over all parameter groups — encoder layers, attention projections, FFN weights, and layer norms all accumulate task-specific deltas during fine-tuning. The magnitude of the task vector (‖τ_T‖) reflects the total drift from pretrained to fine-tuned weights.

```python
import torch
from collections import OrderedDict

def extract_task_vectors(base_state_dict, finetuned_state_dicts, names=None):
    """Compute tau_i = theta_ft_i - theta_base for each fine-tuned model."""
    task_vectors = []
    for i, ft_sd in enumerate(finetuned_state_dicts):
        tau = OrderedDict()
        for key in base_state_dict:
            tau[key] = ft_sd[key].float() - base_state_dict[key].float()
        task_vectors.append(tau)
    return task_vectors

def task_vector_stats(task_vectors, names=None):
    for i, tv in enumerate(task_vectors):
        name = names[i] if names else f"Task {i+1}"
        total_norm = sum(v.norm().item() for v in tv.values())
        max_delta = max(v.abs().max().item() for v in tv.values())
        print(f"{name}: total_norm={total_norm:.4f}, max_delta={max_delta:.4f}, layers={len(tv)}")

torch.manual_seed(42)
base = {"enc.w": torch.zeros(8, 8), "head.w": torch.zeros(4, 8)}
ft_dicts = [
    {"enc.w": base["enc.w"] + torch.randn(8,8)*0.15, "head.w": base["head.w"] + torch.randn(4,8)*0.2},
    {"enc.w": base["enc.w"] + torch.randn(8,8)*0.12, "head.w": base["head.w"] + torch.randn(4,8)*0.18},
    {"enc.w": base["enc.w"] + torch.randn(8,8)*0.10, "head.w": base["head.w"] + torch.randn(4,8)*0.22},
]
tvs = extract_task_vectors(base, ft_dicts)
task_vector_stats(tvs, names=["Sentiment", "NER", "QA"])
print("Task vectors: each encodes task drift from the shared pretrained base.")
```

## Task Vector Addition — Multi-Task Composition

Adding task vectors combines capabilities: θ_multi = θ₀ + λ₁τ₁ + λ₂τ₂ + ... + λ_nτ_n. The scalar λ controls how strongly each task is incorporated. At λ=0 the base model is unchanged; at λ=1 the full task vector is applied; at λ>1 the task is extrapolated beyond the fine-tuned optimum. In practice, λ in [0.5, 1.0] works well for most tasks; values above 1.5 often overshoot and degrade general capabilities. The key insight from Ilharco et al. is that task vectors for semantically distinct NLP tasks (sentiment, NER, QA) are approximately orthogonal, so their sum has low interference.

```python
import torch
from collections import OrderedDict

def apply_task_arithmetic(base_sd, task_vectors, lambdas):
    """Apply task arithmetic: theta = theta_base + sum(lambda_i * tau_i)."""
    assert len(task_vectors) == len(lambdas)
    merged = OrderedDict()
    for key in base_sd:
        delta = sum(lam * tv[key].float() for lam, tv in zip(lambdas, task_vectors))
        merged[key] = base_sd[key].float() + delta
    return merged

def task_benchmark(model_sd, task_name, metric_fn):
    score = metric_fn(model_sd)
    print(f"  [{task_name}]: {score:.4f}")
    return score

torch.manual_seed(0)
base = {"w": torch.zeros(6)}
tau_code = {"w": torch.tensor([0.5, 0.3, -0.1, 0.2, 0.4, 0.1])}
tau_math = {"w": torch.tensor([0.2, -0.1, 0.6, 0.3, -0.2, 0.4])}

print("Sweeping lambda for single-task addition:")
for lam in [0.0, 0.25, 0.5, 1.0, 1.5]:
    result = apply_task_arithmetic(base, [tau_code], [lam])
    print(f"  lambda={lam}: w={[round(v,3) for v in result['w'].tolist()]}")

print("\nMulti-task addition (lambda=1.0 for both):")
multi = apply_task_arithmetic(base, [tau_code, tau_math], [1.0, 1.0])
print(f"  combined w={[round(v,3) for v in multi['w'].tolist()]}")
print("Sum of orthogonal task vectors composes with low interference.")
```

## Scaling and Extrapolation

The scalar λ is a continuous knob over task strength. At λ=0, the model is the pretrained base. At λ=1, the model equals the fine-tuned checkpoint (in the weight-space approximation). At λ>1, the task is extrapolated: the model is pushed further along the direction of the task vector than the fine-tuned model itself reached. Extrapolation (λ>1) sometimes yields better performance on in-distribution tasks than the fine-tuned model, because it amplifies the task-specific direction while suppressing generalist features. However, extrapolation degrades robustness on out-of-distribution inputs and is sensitive to λ.

## Negation — Unlearning a Capability

Subtracting a task vector removes the corresponding capability: θ_negated = θ₀ − λ · τ_harmful. This is useful for alignment: if a model has a harmful capability (e.g., producing toxic text), you can fine-tune a small dataset to extract the harmful task vector, then subtract it from the aligned model. The result reduces harmful outputs without requiring full retraining. The antidote approach adds a negated harmful task vector to an aligned model rather than retraining with filtered data. Ilharco et al. show that negating a task vector for sentiment classification reduces accuracy on sentiment benchmarks by 20–30% while leaving unrelated tasks largely unaffected.

```python
import torch
from collections import OrderedDict

def negate_capability(base_sd, task_vector, scale=1.0):
    """Subtract task vector: theta = theta_base - scale * tau (capability removal)."""
    negated = OrderedDict()
    for key in base_sd:
        negated[key] = base_sd[key].float() - scale * task_vector[key].float()
    return negated

def measure_capability(model_sd, probe_key, probe_direction):
    """Proxy: dot product with probe direction measures task alignment."""
    w = model_sd[probe_key].float().flatten()
    return (w * probe_direction).sum().item()

torch.manual_seed(7)
base = {"w": torch.randn(8)}
tau_harmful = {"w": torch.randn(8) * 0.4}
probe = tau_harmful["w"] / tau_harmful["w"].norm()  # probe aligned with harmful direction

print("Capability score (higher = more harmful alignment):")
print(f"  Base model: {measure_capability(base, 'w', probe):.4f}")
for scale in [0.5, 1.0, 1.5, 2.0]:
    neg = negate_capability(base, tau_harmful, scale=scale)
    print(f"  After negation (scale={scale:.1f}): {measure_capability(neg, 'w', probe):.4f}")
print("Negation progressively removes the capability; scale controls aggressiveness.")
```

## Orthogonality Analysis — Why Addition Works

Task arithmetic addition is interference-free when task vectors are orthogonal: if τ_A · τ_B = 0, then ‖τ_A + τ_B‖² = ‖τ_A‖² + ‖τ_B‖². In practice, task vectors for NLP tasks with different label spaces (sentiment vs NER vs QA) have pairwise cosine similarities below 0.1 — nearly orthogonal. This near-orthogonality breaks down for semantically related tasks (e.g., two different sentiment datasets) where vectors align strongly. Measuring pairwise cosine similarities before merging is a good diagnostic: high similarity (>0.3) predicts low interference; low similarity (<0.1) predicts effective composition.

```python
import torch
import torch.nn.functional as F

def cosine_similarity_matrix(task_vectors, names=None):
    """Compute pairwise cosine similarity between flattened task vectors."""
    n = len(task_vectors)
    flat = [
        torch.cat([v.float().flatten() for v in tv.values()])
        for tv in task_vectors
    ]
    sim = torch.zeros(n, n)
    for i in range(n):
        for j in range(n):
            sim[i, j] = F.cosine_similarity(flat[i].unsqueeze(0), flat[j].unsqueeze(0))
    if names:
        header = f"{'':>14}" + "".join(f"{name:>14}" for name in names)
        print(header)
        for i, name in enumerate(names):
            row = f"{name:>14}" + "".join(f"{sim[i,j].item():>14.3f}" for j in range(n))
            print(row)
    off_diag = (sim.sum() - sim.trace()) / (n * (n - 1))
    print(f"Off-diagonal mean cosine similarity: {off_diag.item():.4f}")
    return sim

torch.manual_seed(99)
tvs = [
    {"enc": torch.randn(32, 32), "head": torch.randn(8, 32)}
    for _ in range(4)
]
names = ["Sentiment", "NER", "QA", "Summarization"]
sim = cosine_similarity_matrix(tvs, names)
print("Low off-diagonal values confirm near-orthogonality => low addition interference.")
```

## Limitations and Extensions

Task arithmetic degrades as more task vectors are added. With 2–3 tasks, interference is typically below 2% absolute; with 8+ tasks, interference can exceed 10%. The degradation is worse when tasks share similar features — for example, adding 5 different code generation task vectors produces high mutual interference. TIES and DARE extend task arithmetic to reduce this interference. The analogy operation τ_A − τ_B + τ_C transfers task structure: if τ_A is 'English→French translation' and τ_B is 'English→Spanish translation', then τ_C = τ_A − τ_B + τ_Spanish-text captures the translation direction without Spanish-specific bias.

- Task vectors are dense over all parameter groups — not just LoRA-adapted layers; apply to full fine-tunes or merge LoRA BA products first.
- Scaling range: λ ∈ [0.3, 1.0] is safe for most tasks; λ > 1.5 risks degrading general capabilities.
- Orthogonality diagnostic: measure pairwise cosine similarities before merging; >0.3 means high interference risk.
- Negation scale: λ=1.0 for full capability removal; λ=0.5 for partial reduction while preserving related capabilities.
- Analogy (A-B+C): transfers relational task structure; requires τ_A and τ_B to encode the same type of transformation.
- Extension: TIES/DARE improve upon simple task vector addition for cross-task merging with 4+ models.

## Task Arithmetic Operations Summary

| Operation | Formula | Effect | λ Range | Interference Risk | Use Case |
| --- | --- | --- | --- | --- | --- |
| Addition | θ₀ + λτ_A | Add task A capability to base | 0.5–1.0 | Low if orthogonal | Multi-task composition |
| Scaling | θ₀ + λτ_A (vary λ) | Tune task strength continuously | 0–1.5 | Low | Task strength control |
| Negation | θ₀ − λτ_harmful | Remove or reduce capability | 0.5–1.5 | Low (subtractive) | Alignment / capability removal |
| Multi-add | θ₀ + Σλᵢτᵢ | Combine N tasks simultaneously | 0.3–0.8 each | Grows with N | Up to ~4 tasks cleanly |
| Analogy A-B+C | θ₀ + τ_A − τ_B + τ_C | Transfer relational structure | 1.0 each | Moderate | Cross-lingual / domain transfer |

> **Near-Orthogonality Explains Task Arithmetic's Low Interference**: Task vectors for different NLP tasks (sentiment, NER, QA) are approximately orthogonal (cosine similarity < 0.1) — this near-orthogonality explains why task arithmetic addition is often interference-free for the first 2–3 added tasks, but degrades beyond that. Measure pairwise cosine similarities before merging: if any pair exceeds 0.25, expect measurable interference and prefer TIES or DARE instead of simple task arithmetic addition.

---

