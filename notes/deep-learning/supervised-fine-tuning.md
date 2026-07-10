---
title: "Supervised Fine-Tuning — Instruction Format, Conversation Templates, and SFT Training"
slug: "supervised-fine-tuning"
description: "Covers supervised fine-tuning of pretrained LLMs on curated instruction-response pairs: instruction format with chat templates, CLM loss masking on instruction tokens, LoRA-based SFT to prevent catastrophic forgetting, multi-turn conversation collation, data scale findings from LIMA, and key SFT configurations across LLaMA-3, Mistral, Phi-3, Gemma, and Qwen2."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Supervised fine-tuning (SFT) adapts a pretrained LLM to follow instructions by training on curated (instruction, response) pairs using causal language modelling loss restricted to the response tokens. The pretrained model already encodes world knowledge and language structure; SFT reshapes its output distribution toward helpful, formatted responses without relearning facts from scratch. Understanding the exact mechanics — chat template formatting, loss masking, gradient accumulation, and regularisation with LoRA — is prerequisite for building instruction-tuned models that generalise beyond the training distribution."},{"type":"heading","level":2,"content":"Instruction Format and Chat Templates"},{"type":"text","content":"Modern instruction-tuned models use a structured conversation format: a system prompt establishes the assistant persona, a user turn provides the instruction, and an assistant turn contains the expected response. Each model family defines a chat template that serialises this structure into a flat string with special tokens. LLaMA-3 uses \u003c|begin_of_text|\u003e, \u003c|start_header_id|\u003erole\u003c|end_header_id|\u003e\\n\\ncontent\u003c|eot_id|\u003e markers. Mistral uses [INST] ... [/INST] wrapping. Phi-3 uses \u003c|system|\u003e, \u003c|user|\u003e, \u003c|assistant|\u003e sentinels. The template is baked into the tokeniser and applied via tokenizer.apply_chat_template(). Mixing templates across models is a common bug that degrades instruction following silently."},{"type":"heading","level":2,"content":"Tokenisation and Loss Masking"},{"type":"text","content":"CLM loss is computed over all tokens by default, but for SFT only the assistant response tokens should contribute to the loss — the model is not being trained to predict the instruction. The standard approach: apply the chat template to the full conversation to get input_ids, separately tokenise the instruction portion to determine its length, then set labels[:instruction_len] = -100. HuggingFace\u0027s Trainer ignores positions with label -100 when computing cross-entropy. Getting this masking right is critical: if instruction tokens leak into the loss, the model learns to reproduce system and user turns rather than follow them."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\nimport torch\n\ndef format_sft_example(tokenizer, system, user, assistant, max_length=1024):\n    \"\"\"Apply chat template and mask instruction tokens from CLM loss.\"\"\"\n    messages = [\n        {\"role\": \"system\", \"content\": system},\n        {\"role\": \"user\", \"content\": user},\n        {\"role\": \"assistant\", \"content\": assistant},\n    ]\n    # Full conversation text (including assistant response)\n    full_text = tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=False)\n    # Instruction-only text to compute mask boundary\n    instr_text = tokenizer.apply_chat_template(messages[:2], tokenize=False, add_generation_prompt=True)\n    enc = tokenizer(full_text, max_length=max_length, truncation=True, return_tensors=\"pt\")\n    input_ids = enc.input_ids[0]\n    instr_len = len(tokenizer(instr_text, add_special_tokens=False).input_ids)\n    labels = input_ids.clone()\n    labels[:instr_len] = -100  # no loss on instruction tokens\n    return {\"input_ids\": input_ids, \"labels\": labels, \"attention_mask\": enc.attention_mask[0]}\n\n# Demo\ntokenizer = AutoTokenizer.from_pretrained(\"meta-llama/Llama-3-8B-Instruct\")\nexample = format_sft_example(\n    tokenizer,\n    system=\"You are a helpful assistant.\",\n    user=\"Explain backpropagation in one paragraph.\",\n    assistant=\"Backpropagation applies the chain rule in reverse through the computational graph to compute gradients of the loss wrt every parameter.\",\n)\nprint(f\"input_ids shape : {example[\u0027input_ids\u0027].shape}\")\nprint(f\"Masked tokens   : {(example[\u0027labels\u0027] == -100).sum().item()} (instruction)\")\nprint(f\"Loss tokens     : {(example[\u0027labels\u0027] != -100).sum().item()} (assistant response)\")"},{"type":"heading","level":2,"content":"SFT Training Details — LR, Epochs, and Batch Size"},{"type":"text","content":"SFT uses small learning rates (1e-5 to 5e-5) to prevent overwriting pretrained representations. Training runs for 1–3 epochs on small datasets (few thousand examples) to avoid overfitting; on larger datasets (50K+) a single epoch may suffice. Cosine learning rate decay with a short warm-up (5–10% of steps) is standard. Effective batch size is typically 128–256 sequences achieved via gradient accumulation across 8–32 physical batches, improving gradient quality on small SFT datasets. AdamW with weight decay 0.01 is the default optimizer. Unlike pretraining, SFT datasets are small enough that training time is dominated by data preprocessing and tokenisation rather than compute."},{"type":"code","language":"python","content":"from transformers import AutoModelForCausalLM, AutoTokenizer, get_cosine_schedule_with_warmup\nfrom peft import LoraConfig, get_peft_model\nimport torch\nfrom torch.optim import AdamW\n\ndef sft_train_step(model, batch, optimizer, scheduler):\n    \"\"\"Single SFT gradient step with LoRA; loss computed only on response tokens.\"\"\"\n    input_ids = batch[\"input_ids\"].to(model.device)\n    labels = batch[\"labels\"].to(model.device)\n    attention_mask = batch[\"attention_mask\"].to(model.device)\n    # HuggingFace CausalLM ignores label=-100 positions automatically\n    outputs = model(input_ids=input_ids, attention_mask=attention_mask, labels=labels)\n    loss = outputs.loss\n    optimizer.zero_grad()\n    loss.backward()\n    torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=1.0)\n    optimizer.step()\n    scheduler.step()\n    return loss.item()\n\n# Attach LoRA to base model\nbase = AutoModelForCausalLM.from_pretrained(\"meta-llama/Llama-3-8B\", torch_dtype=torch.bfloat16)\nlora_cfg = LoraConfig(\n    r=16, lora_alpha=32,\n    target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\"],\n    lora_dropout=0.05, bias=\"none\", task_type=\"CAUSAL_LM\"\n)\nmodel = get_peft_model(base, lora_cfg)\nmodel.print_trainable_parameters()  # ~0.5% of params for r=16\n\noptimizer = AdamW(model.parameters(), lr=2e-5, weight_decay=0.01)\nscheduler = get_cosine_schedule_with_warmup(optimizer, num_warmup_steps=100, num_training_steps=3000)\nprint(\"LoRA SFT setup complete — only adapter weights update during training\")"},{"type":"heading","level":2,"content":"Multi-Turn Conversation SFT"},{"type":"text","content":"For multi-turn conversations, the SFT example includes multiple user and assistant exchanges. The training objective applies teacher-forcing cumulatively: given all previous turns, predict the next assistant turn. Only assistant turns contribute to the loss; all user and system turns are masked with -100. This cumulative structure means the model learns to condition its response on the full conversation history, enabling in-context coherence across turns. Packing multiple conversations into a single sequence (with document boundaries marked by end-of-sequence tokens) is common for efficiency on GPU memory."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\nimport torch\n\ndef collate_multiturn(tokenizer, conversation, max_length=2048):\n    \"\"\"Pack multi-turn conversation; compute loss only on assistant turns.\"\"\"\n    input_ids, labels = [], []\n    for turn in conversation:\n        text = tokenizer.apply_chat_template([turn], tokenize=False, add_generation_prompt=False)\n        ids = tokenizer(text, add_special_tokens=False).input_ids\n        if turn[\"role\"] == \"assistant\":\n            labels.extend(ids)          # include in loss\n        else:\n            labels.extend([-100] * len(ids))  # mask system/user turns\n        input_ids.extend(ids)\n    input_ids = torch.tensor(input_ids[:max_length])\n    labels = torch.tensor(labels[:max_length])\n    return {\"input_ids\": input_ids, \"labels\": labels,\n            \"attention_mask\": torch.ones_like(input_ids)}\n\n# Example: 3-turn conversation\ntokenizer = AutoTokenizer.from_pretrained(\"meta-llama/Llama-3-8B-Instruct\")\nconv = [\n    {\"role\": \"system\",    \"content\": \"You are a coding assistant.\"},\n    {\"role\": \"user\",      \"content\": \"What is a gradient?\"},\n    {\"role\": \"assistant\", \"content\": \"A gradient is the vector of partial derivatives of a scalar function.\"},\n    {\"role\": \"user\",      \"content\": \"How is it used in training?\"},\n    {\"role\": \"assistant\", \"content\": \"The gradient of the loss wrt parameters drives the parameter update in gradient descent.\"},\n]\nbatch = collate_multiturn(tokenizer, conv)\nprint(f\"Total tokens : {batch[\u0027input_ids\u0027].shape[0]}\")\nprint(f\"Masked tokens: {(batch[\u0027labels\u0027] == -100).sum().item()} (system+user)\")\nprint(f\"Loss tokens  : {(batch[\u0027labels\u0027] != -100).sum().item()} (assistant turns)\")"},{"type":"heading","level":2,"content":"Data Scale — LIMA and the Less-is-More Principle"},{"type":"text","content":"The LIMA paper (2023) demonstrated that 1,000 carefully curated, diverse examples produce an SFT model competitive with models trained on 52,000 Alpaca examples. The key insight: a pretrained model already has the knowledge and language ability; SFT is merely teaching it the surface format of helpfulness. Raw data volume matters far less than diversity (covering different task types, domains, lengths) and quality (correct, well-structured responses). The FLAN approach goes the opposite direction — fine-tuning on 1,000+ NLP tasks in instruction format — showing that breadth generalises zero-shot. Both findings point to the same conclusion: the instruction distribution, not its size, determines SFT quality."},{"type":"code","language":"python","content":"from datasets import load_dataset\nfrom transformers import AutoTokenizer, DataCollatorForSeq2Seq\nfrom torch.utils.data import DataLoader\n\ntokenizer = AutoTokenizer.from_pretrained(\"meta-llama/Llama-3-8B-Instruct\")\ntokenizer.pad_token = tokenizer.eos_token\n\ndataset = load_dataset(\"tatsu-lab/alpaca\", split=\"train\")\n\ndef preprocess(example):\n    user_content = example[\"instruction\"]\n    if example.get(\"input\"):\n        user_content += \"\\n\" + example[\"input\"]\n    messages = [\n        {\"role\": \"user\",      \"content\": user_content},\n        {\"role\": \"assistant\", \"content\": example[\"output\"]},\n    ]\n    full = tokenizer.apply_chat_template(messages, tokenize=False)\n    enc  = tokenizer(full, max_length=512, truncation=True, padding=False)\n    instr = tokenizer.apply_chat_template(messages[:1], tokenize=False, add_generation_prompt=True)\n    instr_len = len(tokenizer(instr, add_special_tokens=False).input_ids)\n    labels = enc[\"input_ids\"][:]\n    labels[:instr_len] = [-100] * instr_len\n    enc[\"labels\"] = labels\n    return enc\n\ntokenized = dataset.map(preprocess, remove_columns=dataset.column_names, num_proc=4)\ncollator  = DataCollatorForSeq2Seq(tokenizer, padding=True, pad_to_multiple_of=8)\nloader    = DataLoader(tokenized, batch_size=4, collate_fn=collator, shuffle=True)\nprint(f\"Dataset size: {len(tokenized)}, steps per epoch: {len(loader)}\")"},{"type":"heading","level":2,"content":"Instruction Diversity and Catastrophic Forgetting"},{"type":"text","content":"Instruction diversity — spanning reasoning, coding, summarisation, QA, creative writing, and dialogue — determines whether the SFT model generalises or overfits to a narrow format. Models fine-tuned on homogeneous datasets (e.g., only coding instructions) lose performance on other task types. Catastrophic forgetting is a related problem: SFT with full parameter updates can degrade base model capabilities, particularly on tasks not represented in the SFT dataset. LoRA mitigates this by keeping base weights frozen and training only low-rank adapter matrices, acting as a regulariser. Early stopping (monitor validation loss on a held-out diverse eval set) is essential for small datasets where overfitting can happen within a single epoch."},{"type":"list","ordered":false,"items":["Task types to cover: question answering, summarisation, code generation, translation, creative writing, reasoning chains, dialogue, data extraction.","Length diversity: short factual answers (1–2 sentences), medium explanations (1–3 paragraphs), long structured outputs (lists, tables, code).","Difficulty spectrum: simple lookup, multi-step reasoning, constraint satisfaction, open-ended generation.","Format diversity: prose, bullet lists, markdown with headers, JSON, code with explanation.","LoRA hyperparameters: rank r=8–64; larger r captures more capacity but risks overfitting; alpha/r ratio of 2 is a safe default.","Catastrophic forgetting check: evaluate on MMLU/HellaSwag before and after SFT to detect knowledge degradation."]},{"type":"heading","level":2,"content":"SFT Configurations in Notable Models"},{"type":"table","headers":["Model","Dataset Size","Epochs","Learning Rate","LoRA","Data Source"],"rows":[["LLaMA-3-8B-Instruct","~10M tokens","2–3","1e-5","No (full FT)","Internal curated + public mix"],["Mistral-7B-Instruct-v0.2","~1M examples","3","2e-5","No (full FT)","UltraChat + public open-source"],["Phi-3-mini-Instruct","~3.3T pretrain + SFT stage","3","1e-5","No","Synthetic GPT-4-generated instructions"],["Gemma-7B-Instruct","~2M examples","2","5e-6","No","FLAN subset + proprietary dialogue"],["Qwen2-7B-Instruct","~1.5M pairs","2","7e-6","No","Proprietary multilingual instruction data"]]},{"type":"callout","variant":"info","title":"LIMA: Less Is More for Alignment","content":"LIMA showed that 1,000 carefully curated examples outperform 52,000 noisy Alpaca examples — instruction diversity (covering different task types) matters more than raw count for SFT quality. A pretrained LLM already has the knowledge; SFT merely teaches the format. Invest in curation and diversity, not data volume."},{"type":"text","content":"SFT is the foundational alignment step — it converts a next-token predictor into an instruction follower. The key implementation decisions (chat template, loss masking, LoRA vs full FT, data diversity) compound: a model with correct masking, diverse data, and LoRA regularisation will generalise far better than one trained with larger but homogeneous data and full-parameter updates. SFT alone is insufficient for safety and helpfulness optimisation; it is typically followed by preference learning (RLHF or DPO) trained on reward signals from human or AI feedback."},{"type":"divider"}]"
---
# Supervised Fine-Tuning — Instruction Format, Conversation Templates, and SFT Training

Supervised fine-tuning (SFT) adapts a pretrained LLM to follow instructions by training on curated (instruction, response) pairs using causal language modelling loss restricted to the response tokens. The pretrained model already encodes world knowledge and language structure; SFT reshapes its output distribution toward helpful, formatted responses without relearning facts from scratch. Understanding the exact mechanics — chat template formatting, loss masking, gradient accumulation, and regularisation with LoRA — is prerequisite for building instruction-tuned models that generalise beyond the training distribution.

## Instruction Format and Chat Templates

Modern instruction-tuned models use a structured conversation format: a system prompt establishes the assistant persona, a user turn provides the instruction, and an assistant turn contains the expected response. Each model family defines a chat template that serialises this structure into a flat string with special tokens. LLaMA-3 uses <|begin_of_text|>, <|start_header_id|>role<|end_header_id|>\n\ncontent<|eot_id|> markers. Mistral uses [INST] ... [/INST] wrapping. Phi-3 uses <|system|>, <|user|>, <|assistant|> sentinels. The template is baked into the tokeniser and applied via tokenizer.apply_chat_template(). Mixing templates across models is a common bug that degrades instruction following silently.

## Tokenisation and Loss Masking

CLM loss is computed over all tokens by default, but for SFT only the assistant response tokens should contribute to the loss — the model is not being trained to predict the instruction. The standard approach: apply the chat template to the full conversation to get input_ids, separately tokenise the instruction portion to determine its length, then set labels[:instruction_len] = -100. HuggingFace's Trainer ignores positions with label -100 when computing cross-entropy. Getting this masking right is critical: if instruction tokens leak into the loss, the model learns to reproduce system and user turns rather than follow them.

```python
from transformers import AutoTokenizer
import torch

def format_sft_example(tokenizer, system, user, assistant, max_length=1024):
    """Apply chat template and mask instruction tokens from CLM loss."""
    messages = [
        {"role": "system", "content": system},
        {"role": "user", "content": user},
        {"role": "assistant", "content": assistant},
    ]
    # Full conversation text (including assistant response)
    full_text = tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=False)
    # Instruction-only text to compute mask boundary
    instr_text = tokenizer.apply_chat_template(messages[:2], tokenize=False, add_generation_prompt=True)
    enc = tokenizer(full_text, max_length=max_length, truncation=True, return_tensors="pt")
    input_ids = enc.input_ids[0]
    instr_len = len(tokenizer(instr_text, add_special_tokens=False).input_ids)
    labels = input_ids.clone()
    labels[:instr_len] = -100  # no loss on instruction tokens
    return {"input_ids": input_ids, "labels": labels, "attention_mask": enc.attention_mask[0]}

# Demo
tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-3-8B-Instruct")
example = format_sft_example(
    tokenizer,
    system="You are a helpful assistant.",
    user="Explain backpropagation in one paragraph.",
    assistant="Backpropagation applies the chain rule in reverse through the computational graph to compute gradients of the loss wrt every parameter.",
)
print(f"input_ids shape : {example['input_ids'].shape}")
print(f"Masked tokens   : {(example['labels'] == -100).sum().item()} (instruction)")
print(f"Loss tokens     : {(example['labels'] != -100).sum().item()} (assistant response)")
```

## SFT Training Details — LR, Epochs, and Batch Size

SFT uses small learning rates (1e-5 to 5e-5) to prevent overwriting pretrained representations. Training runs for 1–3 epochs on small datasets (few thousand examples) to avoid overfitting; on larger datasets (50K+) a single epoch may suffice. Cosine learning rate decay with a short warm-up (5–10% of steps) is standard. Effective batch size is typically 128–256 sequences achieved via gradient accumulation across 8–32 physical batches, improving gradient quality on small SFT datasets. AdamW with weight decay 0.01 is the default optimizer. Unlike pretraining, SFT datasets are small enough that training time is dominated by data preprocessing and tokenisation rather than compute.

```python
from transformers import AutoModelForCausalLM, AutoTokenizer, get_cosine_schedule_with_warmup
from peft import LoraConfig, get_peft_model
import torch
from torch.optim import AdamW

def sft_train_step(model, batch, optimizer, scheduler):
    """Single SFT gradient step with LoRA; loss computed only on response tokens."""
    input_ids = batch["input_ids"].to(model.device)
    labels = batch["labels"].to(model.device)
    attention_mask = batch["attention_mask"].to(model.device)
    # HuggingFace CausalLM ignores label=-100 positions automatically
    outputs = model(input_ids=input_ids, attention_mask=attention_mask, labels=labels)
    loss = outputs.loss
    optimizer.zero_grad()
    loss.backward()
    torch.nn.utils.clip_grad_norm_(model.parameters(), max_norm=1.0)
    optimizer.step()
    scheduler.step()
    return loss.item()

# Attach LoRA to base model
base = AutoModelForCausalLM.from_pretrained("meta-llama/Llama-3-8B", torch_dtype=torch.bfloat16)
lora_cfg = LoraConfig(
    r=16, lora_alpha=32,
    target_modules=["q_proj", "k_proj", "v_proj", "o_proj"],
    lora_dropout=0.05, bias="none", task_type="CAUSAL_LM"
)
model = get_peft_model(base, lora_cfg)
model.print_trainable_parameters()  # ~0.5% of params for r=16

optimizer = AdamW(model.parameters(), lr=2e-5, weight_decay=0.01)
scheduler = get_cosine_schedule_with_warmup(optimizer, num_warmup_steps=100, num_training_steps=3000)
print("LoRA SFT setup complete — only adapter weights update during training")
```

## Multi-Turn Conversation SFT

For multi-turn conversations, the SFT example includes multiple user and assistant exchanges. The training objective applies teacher-forcing cumulatively: given all previous turns, predict the next assistant turn. Only assistant turns contribute to the loss; all user and system turns are masked with -100. This cumulative structure means the model learns to condition its response on the full conversation history, enabling in-context coherence across turns. Packing multiple conversations into a single sequence (with document boundaries marked by end-of-sequence tokens) is common for efficiency on GPU memory.

```python
from transformers import AutoTokenizer
import torch

def collate_multiturn(tokenizer, conversation, max_length=2048):
    """Pack multi-turn conversation; compute loss only on assistant turns."""
    input_ids, labels = [], []
    for turn in conversation:
        text = tokenizer.apply_chat_template([turn], tokenize=False, add_generation_prompt=False)
        ids = tokenizer(text, add_special_tokens=False).input_ids
        if turn["role"] == "assistant":
            labels.extend(ids)          # include in loss
        else:
            labels.extend([-100] * len(ids))  # mask system/user turns
        input_ids.extend(ids)
    input_ids = torch.tensor(input_ids[:max_length])
    labels = torch.tensor(labels[:max_length])
    return {"input_ids": input_ids, "labels": labels,
            "attention_mask": torch.ones_like(input_ids)}

# Example: 3-turn conversation
tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-3-8B-Instruct")
conv = [
    {"role": "system",    "content": "You are a coding assistant."},
    {"role": "user",      "content": "What is a gradient?"},
    {"role": "assistant", "content": "A gradient is the vector of partial derivatives of a scalar function."},
    {"role": "user",      "content": "How is it used in training?"},
    {"role": "assistant", "content": "The gradient of the loss wrt parameters drives the parameter update in gradient descent."},
]
batch = collate_multiturn(tokenizer, conv)
print(f"Total tokens : {batch['input_ids'].shape[0]}")
print(f"Masked tokens: {(batch['labels'] == -100).sum().item()} (system+user)")
print(f"Loss tokens  : {(batch['labels'] != -100).sum().item()} (assistant turns)")
```

## Data Scale — LIMA and the Less-is-More Principle

The LIMA paper (2023) demonstrated that 1,000 carefully curated, diverse examples produce an SFT model competitive with models trained on 52,000 Alpaca examples. The key insight: a pretrained model already has the knowledge and language ability; SFT is merely teaching it the surface format of helpfulness. Raw data volume matters far less than diversity (covering different task types, domains, lengths) and quality (correct, well-structured responses). The FLAN approach goes the opposite direction — fine-tuning on 1,000+ NLP tasks in instruction format — showing that breadth generalises zero-shot. Both findings point to the same conclusion: the instruction distribution, not its size, determines SFT quality.

```python
from datasets import load_dataset
from transformers import AutoTokenizer, DataCollatorForSeq2Seq
from torch.utils.data import DataLoader

tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-3-8B-Instruct")
tokenizer.pad_token = tokenizer.eos_token

dataset = load_dataset("tatsu-lab/alpaca", split="train")

def preprocess(example):
    user_content = example["instruction"]
    if example.get("input"):
        user_content += "\n" + example["input"]
    messages = [
        {"role": "user",      "content": user_content},
        {"role": "assistant", "content": example["output"]},
    ]
    full = tokenizer.apply_chat_template(messages, tokenize=False)
    enc  = tokenizer(full, max_length=512, truncation=True, padding=False)
    instr = tokenizer.apply_chat_template(messages[:1], tokenize=False, add_generation_prompt=True)
    instr_len = len(tokenizer(instr, add_special_tokens=False).input_ids)
    labels = enc["input_ids"][:]
    labels[:instr_len] = [-100] * instr_len
    enc["labels"] = labels
    return enc

tokenized = dataset.map(preprocess, remove_columns=dataset.column_names, num_proc=4)
collator  = DataCollatorForSeq2Seq(tokenizer, padding=True, pad_to_multiple_of=8)
loader    = DataLoader(tokenized, batch_size=4, collate_fn=collator, shuffle=True)
print(f"Dataset size: {len(tokenized)}, steps per epoch: {len(loader)}")
```

## Instruction Diversity and Catastrophic Forgetting

Instruction diversity — spanning reasoning, coding, summarisation, QA, creative writing, and dialogue — determines whether the SFT model generalises or overfits to a narrow format. Models fine-tuned on homogeneous datasets (e.g., only coding instructions) lose performance on other task types. Catastrophic forgetting is a related problem: SFT with full parameter updates can degrade base model capabilities, particularly on tasks not represented in the SFT dataset. LoRA mitigates this by keeping base weights frozen and training only low-rank adapter matrices, acting as a regulariser. Early stopping (monitor validation loss on a held-out diverse eval set) is essential for small datasets where overfitting can happen within a single epoch.

- Task types to cover: question answering, summarisation, code generation, translation, creative writing, reasoning chains, dialogue, data extraction.
- Length diversity: short factual answers (1–2 sentences), medium explanations (1–3 paragraphs), long structured outputs (lists, tables, code).
- Difficulty spectrum: simple lookup, multi-step reasoning, constraint satisfaction, open-ended generation.
- Format diversity: prose, bullet lists, markdown with headers, JSON, code with explanation.
- LoRA hyperparameters: rank r=8–64; larger r captures more capacity but risks overfitting; alpha/r ratio of 2 is a safe default.
- Catastrophic forgetting check: evaluate on MMLU/HellaSwag before and after SFT to detect knowledge degradation.

## SFT Configurations in Notable Models

| Model | Dataset Size | Epochs | Learning Rate | LoRA | Data Source |
| --- | --- | --- | --- | --- | --- |
| LLaMA-3-8B-Instruct | ~10M tokens | 2–3 | 1e-5 | No (full FT) | Internal curated + public mix |
| Mistral-7B-Instruct-v0.2 | ~1M examples | 3 | 2e-5 | No (full FT) | UltraChat + public open-source |
| Phi-3-mini-Instruct | ~3.3T pretrain + SFT stage | 3 | 1e-5 | No | Synthetic GPT-4-generated instructions |
| Gemma-7B-Instruct | ~2M examples | 2 | 5e-6 | No | FLAN subset + proprietary dialogue |
| Qwen2-7B-Instruct | ~1.5M pairs | 2 | 7e-6 | No | Proprietary multilingual instruction data |

> **LIMA: Less Is More for Alignment**: LIMA showed that 1,000 carefully curated examples outperform 52,000 noisy Alpaca examples — instruction diversity (covering different task types) matters more than raw count for SFT quality. A pretrained LLM already has the knowledge; SFT merely teaches the format. Invest in curation and diversity, not data volume.

SFT is the foundational alignment step — it converts a next-token predictor into an instruction follower. The key implementation decisions (chat template, loss masking, LoRA vs full FT, data diversity) compound: a model with correct masking, diverse data, and LoRA regularisation will generalise far better than one trained with larger but homogeneous data and full-parameter updates. SFT alone is insufficient for safety and helpfulness optimisation; it is typically followed by preference learning (RLHF or DPO) trained on reward signals from human or AI feedback.

---

