---
title: "Prompt Tuning — Soft Prompts at Input Embeddings and Scale-Dependent Behavior"
slug: "prompt-tuning"
description: "Prompt tuning (Lester et al., 2021) prepends P learned soft prompt tokens only at the input embedding layer. Covers the embedding math, scale dependence (competitive with full fine-tuning only at 10B+ params), initialization strategies, multi-task inference, and comparison with prefix tuning."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Prompt tuning (Lester et al., 2021) is a parameter-efficient fine-tuning method that prepends P learned soft prompt token embeddings to the input embedding sequence. Unlike discrete prompts (manually written text), soft prompts are continuous vectors in the embedding space that are optimized directly by gradient descent. The entire transformer is frozen; only the P×d_emb prompt embedding matrix is trained. This makes prompt tuning one of the most minimal PEFT approaches: no new layers, no weight decompositions, just a small learned prefix appended to every input."},{"type":"heading","level":2,"content":"Soft Prompt Embedding Math"},{"type":"text","content":"Let E_input ∈ ℝ^(L×d_emb) be the token embeddings for an input sequence of length L. Prompt tuning introduces a learnable matrix E_prompt ∈ ℝ^(P×d_emb) where P is the prompt length (typically 1–100 tokens). The full input to the transformer is concat(E_prompt, E_input) ∈ ℝ^((P+L)×d_emb). The transformer processes this concatenated sequence with its frozen weights. Backpropagation flows through the frozen transformer layers back to E_prompt. The gradient ∂L/∂E_prompt is well-defined and dense — every forward pass updates all P×d_emb values."},{"type":"text","content":"Trainable parameter count: for P=100 and d_emb=1024 (T5-Large), the prompt matrix contains 100×1024 = 102,400 parameters — roughly 0.01% of T5-Large\u0027s 770M parameters. This is 10–100× fewer trainable parameters than prefix tuning, which inserts learned key-value pairs at every attention layer. Prompt tuning is input-only; prefix tuning is per-layer. The reduction in trainable parameters comes at a cost: with only input-layer influence, the soft prompts must encode all task-specific information through the frozen model\u0027s own representational capacity."},{"type":"heading","level":2,"content":"Soft Prompt Embedding Implementation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import AutoModel, AutoTokenizer\n\nclass SoftPromptModel(nn.Module):\n    \"\"\"Wraps a frozen transformer with a learnable soft prompt prefix.\"\"\"\n\n    def __init__(self, model_name: str, prompt_length: int = 20):\n        super().__init__()\n        self.backbone = AutoModel.from_pretrained(model_name)\n        for param in self.backbone.parameters():\n            param.requires_grad = False\n        d_emb = self.backbone.config.hidden_size\n        self.prompt_length = prompt_length\n        # Learnable soft prompt embeddings: shape (P, d_emb)\n        self.soft_prompt = nn.Parameter(\n            torch.randn(prompt_length, d_emb) * 0.02\n        )\n\n    def forward(self, input_ids: torch.Tensor,\n                attention_mask: torch.Tensor) -\u003e torch.Tensor:\n        bsz = input_ids.shape[0]\n        token_embeds = self.backbone.get_input_embeddings()(input_ids)\n        prompt_embeds = self.soft_prompt.unsqueeze(0).expand(bsz, -1, -1)\n        full_embeds = torch.cat([prompt_embeds, token_embeds], dim=1)\n        prompt_mask = torch.ones(bsz, self.prompt_length,\n                                 device=attention_mask.device)\n        full_mask = torch.cat([prompt_mask, attention_mask], dim=1)\n        outputs = self.backbone(inputs_embeds=full_embeds,\n                                attention_mask=full_mask)\n        return outputs.last_hidden_state\n\n    def trainable_params(self):\n        return sum(p.numel() for p in self.parameters() if p.requires_grad)\n\nmodel = SoftPromptModel(\u0027bert-base-uncased\u0027, prompt_length=20)\nprint(f\u0027Trainable params: {model.trainable_params():,}\u0027)  # only soft prompt\nprint(f\u0027Soft prompt shape: {model.soft_prompt.shape}\u0027)    # (20, 768)"},{"type":"heading","level":2,"content":"Prompt Tuning with T5 via PEFT"},{"type":"code","language":"python","content":"import torch\nfrom transformers import T5ForConditionalGeneration, T5Tokenizer\nfrom peft import PromptTuningConfig, PromptTuningInit, get_peft_model, TaskType\n\ndef setup_t5_prompt_tuning(model_name: str = \u0027t5-large\u0027,\n                           num_virtual_tokens: int = 100,\n                           init_text: str = \u0027Classify sentiment:\u0027):\n    \"\"\"Configure T5 for prompt tuning on a classification task.\"\"\"\n    base_model = T5ForConditionalGeneration.from_pretrained(model_name)\n    peft_config = PromptTuningConfig(\n        task_type=TaskType.SEQ_2_SEQ_LM,\n        prompt_tuning_init=PromptTuningInit.TEXT,\n        num_virtual_tokens=num_virtual_tokens,\n        prompt_tuning_init_text=init_text,\n        tokenizer_name_or_path=model_name,\n    )\n    model = get_peft_model(base_model, peft_config)\n    model.print_trainable_parameters()  # ~102K / 770M for T5-Large\n    return model\n\ndef run_prompt_tuning_demo():\n    model = setup_t5_prompt_tuning(num_virtual_tokens=50)\n    tokenizer = T5Tokenizer.from_pretrained(\u0027t5-large\u0027)\n    sample = \u0027The movie was absolutely fantastic and I loved every moment.\u0027\n    inputs = tokenizer(sample, return_tensors=\u0027pt\u0027, truncation=True, max_length=128)\n    with torch.no_grad():\n        output_ids = model.generate(**inputs, max_new_tokens=5)\n    print(f\u0027Input: {sample}\u0027)\n    print(f\u0027Output: {tokenizer.decode(output_ids[0], skip_special_tokens=True)}\u0027)\n\nprint(\u0027Prompt tuning config ready — only soft_prompt params receive gradients.\u0027)"},{"type":"heading","level":2,"content":"Initialization Strategies"},{"type":"text","content":"The initial values of E_prompt significantly affect convergence speed. Three strategies are compared: (1) random initialization from N(0, 0.02) — high variance across runs; (2) vocabulary token initialization — sample P tokens from the model\u0027s vocabulary embedding matrix, providing meaningful starting points; (3) class label initialization — for classification tasks, initialize from embeddings of target class label strings (e.g., \u0027positive\u0027, \u0027negative\u0027). Class label init converges fastest and shows lowest variance, particularly at sub-1B scale."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import AutoTokenizer, AutoModel\n\ndef initialize_soft_prompt(model_name: str, prompt_length: int,\n                           strategy: str = \u0027random\u0027,\n                           class_labels: list = None) -\u003e nn.Parameter:\n    \"\"\"\n    Initialize soft prompt embeddings with three strategies.\n    strategy: \u0027random\u0027 | \u0027vocab\u0027 | \u0027class_label\u0027\n    \"\"\"\n    tokenizer = AutoTokenizer.from_pretrained(model_name)\n    model = AutoModel.from_pretrained(model_name)\n    embed_layer = model.get_input_embeddings()\n    d_emb = embed_layer.embedding_dim\n    vocab_embeddings = embed_layer.weight.data  # (V, d_emb)\n\n    if strategy == \u0027random\u0027:\n        init = torch.randn(prompt_length, d_emb) * 0.02\n        print(f\u0027Random init: std={init.std().item():.4f}\u0027)\n    elif strategy == \u0027vocab\u0027:\n        vocab_size = vocab_embeddings.shape[0]\n        idx = torch.randint(0, vocab_size, (prompt_length,))\n        init = vocab_embeddings[idx].clone().detach()\n        print(f\u0027Vocab init: sampled indices {idx[:5].tolist()}\u0027)\n    elif strategy == \u0027class_label\u0027:\n        assert class_labels, \u0027Provide class_labels for class_label strategy\u0027\n        label_embeds = []\n        for label in class_labels:\n            ids = tokenizer(label, return_tensors=\u0027pt\u0027).input_ids[0]\n            embs = vocab_embeddings[ids].mean(0)\n            label_embeds.append(embs)\n        base = torch.stack(label_embeds)\n        idx = torch.arange(prompt_length) % len(class_labels)\n        init = base[idx].clone().detach()\n        print(f\u0027Class label init: {class_labels} tiled over {prompt_length} tokens\u0027)\n    return nn.Parameter(init)\n\nfor strat, kwargs in [(\u0027random\u0027, {}), (\u0027vocab\u0027, {}),\n                      (\u0027class_label\u0027, {\u0027class_labels\u0027: [\u0027positive\u0027, \u0027negative\u0027, \u0027neutral\u0027]})]:\n    param = initialize_soft_prompt(\u0027bert-base-uncased\u0027, 30, strat, **kwargs)\n    print(f\u0027  -\u003e shape={param.shape}, norm={param.data.norm().item():.3f}\u0027)"},{"type":"heading","level":2,"content":"Scale Sensitivity Analysis"},{"type":"code","language":"python","content":"import numpy as np\n\n# Reproduced from Lester et al. (2021) -- SuperGLUE average score by model size\nmodel_sizes_B = [0.06, 0.25, 0.77, 3.0, 11.0]  # billions of parameters\nmodel_labels  = [\u0027T5-Small\u0027, \u0027T5-Base\u0027, \u0027T5-Large\u0027, \u0027T5-XL\u0027, \u0027T5-XXL\u0027]\nfull_ft_score     = [83.1, 86.4, 88.9, 90.3, 91.2]\nprompt_tune_score = [53.2, 63.1, 72.4, 81.5, 90.8]  # P=100 tokens\nmodel_tune_score  = [78.3, 82.1, 85.6, 88.2, 89.9]  # freeze all, tune head only\n\nprint(f\u0027{\"Model\":\u003c12} {\"Params (B)\":\u003e11} {\"Full FT\":\u003e9} {\"Prompt\":\u003e9} {\"Gap\":\u003e9}\u0027)\nprint(\u0027-\u0027 * 55)\nfor label, size, fft, pt in zip(model_labels, model_sizes_B,\n                                 full_ft_score, prompt_tune_score):\n    gap = pt - fft\n    print(f\u0027{label:\u003c12} {size:\u003e11.2f} {fft:\u003e9.1f} {pt:\u003e9.1f} {gap:\u003e+9.1f}\u0027)\n\nprint()\nfor label, size, fft, pt in zip(model_labels, model_sizes_B,\n                                 full_ft_score, prompt_tune_score):\n    if abs(pt - fft) \u003c= 2.0:\n        print(f\u0027Prompt tuning within 2 pts of full FT at: {label} ({size}B params)\u0027)\n        break"},{"type":"heading","level":2,"content":"Prompt Tuning vs Prefix Tuning"},{"type":"table","headers":["Dimension","Prompt Tuning","Prefix Tuning"],"rows":[["Where adaptation occurs","Input embedding layer only","Every transformer layer (K, V pairs)"],["Layers affected","1 (embedding)","All N layers"],["Trainable params (100-token, T5-Large)","~102K (100×1024)","~13M (100×1024×2×24 layers)"],["Context length consumed","P tokens from input budget","P tokens from input budget per layer"],["Scale threshold for competitive perf","≥10B parameters","Competitive at ~1B+ parameters"],["Implementation complexity","Very simple — one parameter matrix","Moderate — hook into each attention layer"],["Multi-task inference","Swap E_prompt at inference","Swap per-layer KV prefixes at inference"]]},{"type":"heading","level":2,"content":"Multi-Task Inference and Ensembling"},{"type":"text","content":"One practical advantage of prompt tuning is multi-task serving: a single frozen backbone can serve multiple tasks simultaneously by swapping the soft prompt matrix at inference. Each task requires storing only P×d_emb floats. For T5-Large and P=100, that is 102K×2 bytes = 204KB per task — trivial compared to the 3GB backbone. An ensemble of soft prompts can be constructed by averaging their logits: run the same input through the backbone with K different soft prompts and aggregate predictions. This prompt ensemble reliably outperforms a single prompt without changing the backbone."},{"type":"text","content":"In production, the serving architecture is: one backbone instance loaded in GPU memory (shared across tasks), a task router that selects the correct soft prompt matrix, and a prompt-prepend step before the backbone forward pass. Switching tasks has zero latency beyond the tiny prompt embedding lookup. This is fundamentally different from full fine-tuning, which requires loading a separate full model copy per task."},{"type":"heading","level":2,"content":"Scale Dependence and Method Selection"},{"type":"callout","variant":"info","title":"Scale Dependence","content":"Prompt tuning is scale-dependent — it only matches full fine-tuning quality at 10B+ parameters. For smaller models (1–7B), the signal from P soft tokens at the input cannot sufficiently condition a shallower network, making LoRA or adapters preferable."},{"type":"heading","level":2,"content":"Practical Recommendations"},{"type":"text","content":"Prompt length P=100 is a reliable default; gains plateau beyond 100 tokens and longer prompts consume input context budget. For models below 1B parameters, the gap between prompt tuning and full fine-tuning is too large for production use — LoRA (r=8) or Pfeiffer adapters close that gap at comparable parameter budgets. For 10B+ models, prompt tuning is a practical choice when backbone sharing across tasks is required and memory is the primary constraint."},{"type":"list","ordered":false,"items":["Use prompt length P=100; gains diminish beyond 100 and longer prompts consume input context budget.","Initialize from class label embeddings — converges faster and with lower variance than random init.","For models below 1B parameters, prefer LoRA (r=8) or Pfeiffer adapters over prompt tuning.","At T5-XXL or LLaMA-13B+ scale, prompt tuning achieves full fine-tuning accuracy at a fraction of the compute.","For multi-task serving, store one soft prompt matrix (≤1MB) per task — swap at inference with zero backbone reload.","Prompt tuning is incompatible with models that lack a standard token embedding lookup (e.g., some vision models)."]},{"type":"divider"}]"
---
# Prompt Tuning — Soft Prompts at Input Embeddings and Scale-Dependent Behavior

Prompt tuning (Lester et al., 2021) is a parameter-efficient fine-tuning method that prepends P learned soft prompt token embeddings to the input embedding sequence. Unlike discrete prompts (manually written text), soft prompts are continuous vectors in the embedding space that are optimized directly by gradient descent. The entire transformer is frozen; only the P×d_emb prompt embedding matrix is trained. This makes prompt tuning one of the most minimal PEFT approaches: no new layers, no weight decompositions, just a small learned prefix appended to every input.

## Soft Prompt Embedding Math

Let E_input ∈ ℝ^(L×d_emb) be the token embeddings for an input sequence of length L. Prompt tuning introduces a learnable matrix E_prompt ∈ ℝ^(P×d_emb) where P is the prompt length (typically 1–100 tokens). The full input to the transformer is concat(E_prompt, E_input) ∈ ℝ^((P+L)×d_emb). The transformer processes this concatenated sequence with its frozen weights. Backpropagation flows through the frozen transformer layers back to E_prompt. The gradient ∂L/∂E_prompt is well-defined and dense — every forward pass updates all P×d_emb values.

Trainable parameter count: for P=100 and d_emb=1024 (T5-Large), the prompt matrix contains 100×1024 = 102,400 parameters — roughly 0.01% of T5-Large's 770M parameters. This is 10–100× fewer trainable parameters than prefix tuning, which inserts learned key-value pairs at every attention layer. Prompt tuning is input-only; prefix tuning is per-layer. The reduction in trainable parameters comes at a cost: with only input-layer influence, the soft prompts must encode all task-specific information through the frozen model's own representational capacity.

## Soft Prompt Embedding Implementation

```python
import torch
import torch.nn as nn
from transformers import AutoModel, AutoTokenizer

class SoftPromptModel(nn.Module):
    """Wraps a frozen transformer with a learnable soft prompt prefix."""

    def __init__(self, model_name: str, prompt_length: int = 20):
        super().__init__()
        self.backbone = AutoModel.from_pretrained(model_name)
        for param in self.backbone.parameters():
            param.requires_grad = False
        d_emb = self.backbone.config.hidden_size
        self.prompt_length = prompt_length
        # Learnable soft prompt embeddings: shape (P, d_emb)
        self.soft_prompt = nn.Parameter(
            torch.randn(prompt_length, d_emb) * 0.02
        )

    def forward(self, input_ids: torch.Tensor,
                attention_mask: torch.Tensor) -> torch.Tensor:
        bsz = input_ids.shape[0]
        token_embeds = self.backbone.get_input_embeddings()(input_ids)
        prompt_embeds = self.soft_prompt.unsqueeze(0).expand(bsz, -1, -1)
        full_embeds = torch.cat([prompt_embeds, token_embeds], dim=1)
        prompt_mask = torch.ones(bsz, self.prompt_length,
                                 device=attention_mask.device)
        full_mask = torch.cat([prompt_mask, attention_mask], dim=1)
        outputs = self.backbone(inputs_embeds=full_embeds,
                                attention_mask=full_mask)
        return outputs.last_hidden_state

    def trainable_params(self):
        return sum(p.numel() for p in self.parameters() if p.requires_grad)

model = SoftPromptModel('bert-base-uncased', prompt_length=20)
print(f'Trainable params: {model.trainable_params():,}')  # only soft prompt
print(f'Soft prompt shape: {model.soft_prompt.shape}')    # (20, 768)
```

## Prompt Tuning with T5 via PEFT

```python
import torch
from transformers import T5ForConditionalGeneration, T5Tokenizer
from peft import PromptTuningConfig, PromptTuningInit, get_peft_model, TaskType

def setup_t5_prompt_tuning(model_name: str = 't5-large',
                           num_virtual_tokens: int = 100,
                           init_text: str = 'Classify sentiment:'):
    """Configure T5 for prompt tuning on a classification task."""
    base_model = T5ForConditionalGeneration.from_pretrained(model_name)
    peft_config = PromptTuningConfig(
        task_type=TaskType.SEQ_2_SEQ_LM,
        prompt_tuning_init=PromptTuningInit.TEXT,
        num_virtual_tokens=num_virtual_tokens,
        prompt_tuning_init_text=init_text,
        tokenizer_name_or_path=model_name,
    )
    model = get_peft_model(base_model, peft_config)
    model.print_trainable_parameters()  # ~102K / 770M for T5-Large
    return model

def run_prompt_tuning_demo():
    model = setup_t5_prompt_tuning(num_virtual_tokens=50)
    tokenizer = T5Tokenizer.from_pretrained('t5-large')
    sample = 'The movie was absolutely fantastic and I loved every moment.'
    inputs = tokenizer(sample, return_tensors='pt', truncation=True, max_length=128)
    with torch.no_grad():
        output_ids = model.generate(**inputs, max_new_tokens=5)
    print(f'Input: {sample}')
    print(f'Output: {tokenizer.decode(output_ids[0], skip_special_tokens=True)}')

print('Prompt tuning config ready — only soft_prompt params receive gradients.')
```

## Initialization Strategies

The initial values of E_prompt significantly affect convergence speed. Three strategies are compared: (1) random initialization from N(0, 0.02) — high variance across runs; (2) vocabulary token initialization — sample P tokens from the model's vocabulary embedding matrix, providing meaningful starting points; (3) class label initialization — for classification tasks, initialize from embeddings of target class label strings (e.g., 'positive', 'negative'). Class label init converges fastest and shows lowest variance, particularly at sub-1B scale.

```python
import torch
import torch.nn as nn
from transformers import AutoTokenizer, AutoModel

def initialize_soft_prompt(model_name: str, prompt_length: int,
                           strategy: str = 'random',
                           class_labels: list = None) -> nn.Parameter:
    """
    Initialize soft prompt embeddings with three strategies.
    strategy: 'random' | 'vocab' | 'class_label'
    """
    tokenizer = AutoTokenizer.from_pretrained(model_name)
    model = AutoModel.from_pretrained(model_name)
    embed_layer = model.get_input_embeddings()
    d_emb = embed_layer.embedding_dim
    vocab_embeddings = embed_layer.weight.data  # (V, d_emb)

    if strategy == 'random':
        init = torch.randn(prompt_length, d_emb) * 0.02
        print(f'Random init: std={init.std().item():.4f}')
    elif strategy == 'vocab':
        vocab_size = vocab_embeddings.shape[0]
        idx = torch.randint(0, vocab_size, (prompt_length,))
        init = vocab_embeddings[idx].clone().detach()
        print(f'Vocab init: sampled indices {idx[:5].tolist()}')
    elif strategy == 'class_label':
        assert class_labels, 'Provide class_labels for class_label strategy'
        label_embeds = []
        for label in class_labels:
            ids = tokenizer(label, return_tensors='pt').input_ids[0]
            embs = vocab_embeddings[ids].mean(0)
            label_embeds.append(embs)
        base = torch.stack(label_embeds)
        idx = torch.arange(prompt_length) % len(class_labels)
        init = base[idx].clone().detach()
        print(f'Class label init: {class_labels} tiled over {prompt_length} tokens')
    return nn.Parameter(init)

for strat, kwargs in [('random', {}), ('vocab', {}),
                      ('class_label', {'class_labels': ['positive', 'negative', 'neutral']})]:
    param = initialize_soft_prompt('bert-base-uncased', 30, strat, **kwargs)
    print(f'  -> shape={param.shape}, norm={param.data.norm().item():.3f}')
```

## Scale Sensitivity Analysis

```python
import numpy as np

# Reproduced from Lester et al. (2021) -- SuperGLUE average score by model size
model_sizes_B = [0.06, 0.25, 0.77, 3.0, 11.0]  # billions of parameters
model_labels  = ['T5-Small', 'T5-Base', 'T5-Large', 'T5-XL', 'T5-XXL']
full_ft_score     = [83.1, 86.4, 88.9, 90.3, 91.2]
prompt_tune_score = [53.2, 63.1, 72.4, 81.5, 90.8]  # P=100 tokens
model_tune_score  = [78.3, 82.1, 85.6, 88.2, 89.9]  # freeze all, tune head only

print(f'{"Model":<12} {"Params (B)":>11} {"Full FT":>9} {"Prompt":>9} {"Gap":>9}')
print('-' * 55)
for label, size, fft, pt in zip(model_labels, model_sizes_B,
                                 full_ft_score, prompt_tune_score):
    gap = pt - fft
    print(f'{label:<12} {size:>11.2f} {fft:>9.1f} {pt:>9.1f} {gap:>+9.1f}')

print()
for label, size, fft, pt in zip(model_labels, model_sizes_B,
                                 full_ft_score, prompt_tune_score):
    if abs(pt - fft) <= 2.0:
        print(f'Prompt tuning within 2 pts of full FT at: {label} ({size}B params)')
        break
```

## Prompt Tuning vs Prefix Tuning

| Dimension | Prompt Tuning | Prefix Tuning |
| --- | --- | --- |
| Where adaptation occurs | Input embedding layer only | Every transformer layer (K, V pairs) |
| Layers affected | 1 (embedding) | All N layers |
| Trainable params (100-token, T5-Large) | ~102K (100×1024) | ~13M (100×1024×2×24 layers) |
| Context length consumed | P tokens from input budget | P tokens from input budget per layer |
| Scale threshold for competitive perf | ≥10B parameters | Competitive at ~1B+ parameters |
| Implementation complexity | Very simple — one parameter matrix | Moderate — hook into each attention layer |
| Multi-task inference | Swap E_prompt at inference | Swap per-layer KV prefixes at inference |

## Multi-Task Inference and Ensembling

One practical advantage of prompt tuning is multi-task serving: a single frozen backbone can serve multiple tasks simultaneously by swapping the soft prompt matrix at inference. Each task requires storing only P×d_emb floats. For T5-Large and P=100, that is 102K×2 bytes = 204KB per task — trivial compared to the 3GB backbone. An ensemble of soft prompts can be constructed by averaging their logits: run the same input through the backbone with K different soft prompts and aggregate predictions. This prompt ensemble reliably outperforms a single prompt without changing the backbone.

In production, the serving architecture is: one backbone instance loaded in GPU memory (shared across tasks), a task router that selects the correct soft prompt matrix, and a prompt-prepend step before the backbone forward pass. Switching tasks has zero latency beyond the tiny prompt embedding lookup. This is fundamentally different from full fine-tuning, which requires loading a separate full model copy per task.

## Scale Dependence and Method Selection

> **Scale Dependence**: Prompt tuning is scale-dependent — it only matches full fine-tuning quality at 10B+ parameters. For smaller models (1–7B), the signal from P soft tokens at the input cannot sufficiently condition a shallower network, making LoRA or adapters preferable.

## Practical Recommendations

Prompt length P=100 is a reliable default; gains plateau beyond 100 tokens and longer prompts consume input context budget. For models below 1B parameters, the gap between prompt tuning and full fine-tuning is too large for production use — LoRA (r=8) or Pfeiffer adapters close that gap at comparable parameter budgets. For 10B+ models, prompt tuning is a practical choice when backbone sharing across tasks is required and memory is the primary constraint.

- Use prompt length P=100; gains diminish beyond 100 and longer prompts consume input context budget.
- Initialize from class label embeddings — converges faster and with lower variance than random init.
- For models below 1B parameters, prefer LoRA (r=8) or Pfeiffer adapters over prompt tuning.
- At T5-XXL or LLaMA-13B+ scale, prompt tuning achieves full fine-tuning accuracy at a fraction of the compute.
- For multi-task serving, store one soft prompt matrix (≤1MB) per task — swap at inference with zero backbone reload.
- Prompt tuning is incompatible with models that lack a standard token embedding lookup (e.g., some vision models).

---

