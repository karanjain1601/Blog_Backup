---
title: "DeepSeek-R1: Reinforcement Learning for Reasoning"
slug: "deepseek-r1"
description: "How DeepSeek-R1 trains long chain-of-thought reasoning via RL — covering GRPO, cold-start SFT, the RL training pipeline, and distillation to smaller models."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"DeepSeek-R1 achieves o1-level performance on math and coding benchmarks using reinforcement learning with GRPO, without relying on human-labeled chain-of-thought data. R1-Zero demonstrates that complex reasoning behaviors — including self-verification and reflection — can emerge purely from reward signals, challenging the assumption that supervised CoT data is necessary."},{"type":"heading","content":"GRPO: Group Relative Policy Optimization"},{"type":"text","content":"GRPO replaces the actor-critic setup used in PPO with a group-based advantage estimation. For each prompt, K responses are sampled from the current policy; each receives a scalar reward. The advantage for each response is computed by subtracting the group mean and dividing by the group standard deviation — eliminating the need for a separate critic or value model."},{"type":"code","language":"python","content":"import torch\n\ndef grpo_loss(policy, ref_policy, prompts, K=8, beta=0.04, eps=0.2):\n    losses = []\n    for prompt in prompts:\n        completions = policy.sample(prompt, n=K, temperature=0.8)\n        r = torch.tensor([reward_fn(prompt, c) for c in completions])\n        adv = (r - r.mean()) / (r.std() + 1e-8)\n        logp = policy.log_prob(completions)\n        ref_logp = ref_policy.log_prob(completions)\n        ratio = (logp - ref_logp).exp()\n        clipped = torch.clamp(ratio, 1 - eps, 1 + eps)\n        pg = -torch.min(ratio * adv, clipped * adv).mean()\n        losses.append(pg + beta * (logp - ref_logp).mean())\n    return torch.stack(losses).mean()"},{"type":"heading","content":"Reward Functions"},{"type":"text","content":"DeepSeek-R1 uses two rule-based rewards: a correctness reward that checks the final answer against a ground-truth (using SymPy for symbolic math equality and unit tests for code), and a format reward that enforces the model produces \u003cthink\u003e...\u003c/think\u003e and \u003canswer\u003e...\u003c/answer\u003e tags. No learned reward model is needed, keeping the signal clean and verifiable."},{"type":"code","language":"python","content":"import re\nfrom sympy import simplify, sympify, SympifyError\n\ndef reward_fn(prompt, completion, expected):\n    has_think = bool(re.search(r\u0027\u003cthink\u003e.+\u003c/think\u003e\u0027, completion, re.S))\n    fmt_bonus = 0.1 if has_think else 0.0\n    m = re.search(r\u0027\u003canswer\u003e(.*?)\u003c/answer\u003e\u0027, completion, re.S)\n    if m is None:\n        return fmt_bonus * 0.5\n    predicted = m.group(1).strip()\n    try:\n        if simplify(sympify(predicted) - sympify(expected)) == 0:\n            return 1.0 + fmt_bonus\n    except SympifyError:\n        pass\n    return fmt_bonus if predicted != str(expected) else 1.0 + fmt_bonus"},{"type":"heading","content":"Cold-Start Problem and SFT Initialization"},{"type":"text","content":"R1-Zero (pure RL from base) produces emergent reasoning but suffers from language mixing and inconsistent output formatting. DeepSeek-R1 addresses this with a cold-start phase: a small set of human-curated long-CoT examples in the desired format are used to fine-tune the base model before RL begins, giving the policy a well-structured starting point."},{"type":"code","language":"python","content":"from transformers import AutoModelForCausalLM, AutoTokenizer, Trainer, TrainingArguments\n\ndef cold_start_sft(model_name, sft_dataset_path, output_dir):\n    model = AutoModelForCausalLM.from_pretrained(model_name)\n    tokenizer = AutoTokenizer.from_pretrained(model_name)\n    dataset = load_cot_dataset(sft_dataset_path)  # \u003cthink\u003e...\u003c/think\u003e\u003canswer\u003e...\u003c/answer\u003e\n    args = TrainingArguments(\n        output_dir=output_dir, num_train_epochs=1,\n        per_device_train_batch_size=4, learning_rate=1e-5,\n        lr_scheduler_type=\"cosine\", warmup_ratio=0.03,\n    )\n    trainer = Trainer(model=model, args=args,\n                      train_dataset=dataset, tokenizer=tokenizer)\n    trainer.train()"},{"type":"heading","content":"RL Training Pipeline"},{"type":"text","content":"The RL loop repeatedly samples completions from the current policy, scores them with the reward function, computes GRPO advantages, and updates policy weights. Training runs for thousands of steps with a KL-divergence penalty against a frozen reference policy to prevent the model from drifting too far from the pre-trained distribution."},{"type":"text","content":"After RL convergence, a second SFT pass is applied using rejection-sampled solutions from the RL model plus supervised data for general tasks. This round restores helpfulness on non-reasoning tasks, reduces repetition artifacts from RL training, and chat-aligns the final model while preserving the strong reasoning capability gained through GRPO."},{"type":"heading","content":"Distillation to Smaller Models"},{"type":"text","content":"Rather than running expensive RL on smaller models, DeepSeek distills reasoning by generating large quantities of long-CoT solution traces from the R1-671B teacher, then fine-tuning a smaller student (7B or 32B) on those traces using standard supervised learning. This is far cheaper than RL while achieving surprisingly strong benchmark results on reasoning tasks."},{"type":"code","language":"python","content":"from transformers import AutoModelForCausalLM, Trainer, TrainingArguments\nfrom datasets import load_dataset\n\ndef distill_from_r1(student_name, traces_path, output_dir, eval_dataset):\n    student = AutoModelForCausalLM.from_pretrained(student_name)\n    dataset = load_dataset(\"json\", data_files=traces_path)[\"train\"]\n    # Mask loss to answer tokens; CoT tokens are still fed as context\n    dataset = dataset.map(lambda x: mask_cot_tokens(x, answer_tag=\"\u003canswer\u003e\"))\n    args = TrainingArguments(\n        output_dir=output_dir, num_train_epochs=3,\n        per_device_train_batch_size=2, learning_rate=2e-5,\n        gradient_accumulation_steps=8,\n    )\n    trainer = Trainer(model=student, args=args, train_dataset=dataset)\n    trainer.train()\n    return evaluate_aime(student, eval_dataset)"},{"type":"text","content":"Distillation works because the student learns to reproduce the structure of long reasoning chains — including backtracking, self-correction, and verification steps — by imitating the teacher. Remarkably, a 7B model distilled from R1 outperforms much larger models trained without chain-of-thought distillation, achieving 55.5% on AIME 2024 and 92.8% on MATH-500."},{"type":"callout","calloutType":"info","content":"DeepSeek-R1-Zero trained purely via RL with no SFT spontaneously developed chain-of-thought reasoning, self-verification, and reflection behaviors — demonstrating that reasoning can emerge from reward signals alone without any human-labeled reasoning traces."},{"type":"table","headers":["Model","AIME 2024 (%)","MATH-500 (%)","Codeforces (%ile)","Params"],"rows":[["R1-Zero","71.0","90.0","58.0","671B"],["R1","79.8","97.3","96.3","671B"],["R1-Distill-7B","55.5","92.8","37.6","7B"],["R1-Distill-32B","72.6","94.3","72.6","32B"],["GPT-4o","9.3","76.6","43.4","-"]]},{"type":"text","content":"The benchmark numbers highlight a key insight: distillation transfers reasoning capability efficiently. R1-Distill-32B at 32B parameters vastly exceeds GPT-4o on AIME 2024 (72.6% vs 9.3%), and even R1-Distill-7B substantially outperforms GPT-4o. The gap between R1-Zero and R1 also shows the concrete value of cold-start SFT and the second alignment pass."},{"type":"divider"},{"type":"heading","content":"Key Takeaways"},{"type":"list","items":["GRPO eliminates the critic/value model by estimating advantages within a group of K sampled responses — reducing training complexity and GPU memory vs PPO.","R1-Zero proves reasoning can emerge from RL with rule-based rewards alone, with no SFT on CoT data — though output quality is inconsistent without cold-start initialization.","Cold-start SFT on a small set of human-curated CoT examples stabilizes formatting and language consistency before RL training begins.","Distillation via imitation of R1-671B traces gives 7B and 32B models strong reasoning at a fraction of the RL training cost — no RL required on the student model.","R1-Distill-32B scores 72.6% on AIME 2024, vastly exceeding GPT-4o (9.3%) — showing that distilled reasoning dramatically outperforms scale-only approaches.","Use distilled models (7B/32B) for production serving; use full R1-671B for generating high-quality reasoning traces for future distillation rounds."]},{"type":"text","content":"DeepSeek-R1\u0027s key contribution is a practical training recipe: grow strong reasoning with GRPO using rule-based rewards, then distill that capability into deployable smaller models via supervised imitation. The approach bypasses expensive human annotation of reasoning chains and demonstrates that outcome supervision at scale is sufficient to produce state-of-the-art reasoning."}]"
---
# DeepSeek-R1: Reinforcement Learning for Reasoning

DeepSeek-R1 achieves o1-level performance on math and coding benchmarks using reinforcement learning with GRPO, without relying on human-labeled chain-of-thought data. R1-Zero demonstrates that complex reasoning behaviors — including self-verification and reflection — can emerge purely from reward signals, challenging the assumption that supervised CoT data is necessary.

 GRPO: Group Relative Policy Optimization

GRPO replaces the actor-critic setup used in PPO with a group-based advantage estimation. For each prompt, K responses are sampled from the current policy; each receives a scalar reward. The advantage for each response is computed by subtracting the group mean and dividing by the group standard deviation — eliminating the need for a separate critic or value model.

```python
import torch

def grpo_loss(policy, ref_policy, prompts, K=8, beta=0.04, eps=0.2):
    losses = []
    for prompt in prompts:
        completions = policy.sample(prompt, n=K, temperature=0.8)
        r = torch.tensor([reward_fn(prompt, c) for c in completions])
        adv = (r - r.mean()) / (r.std() + 1e-8)
        logp = policy.log_prob(completions)
        ref_logp = ref_policy.log_prob(completions)
        ratio = (logp - ref_logp).exp()
        clipped = torch.clamp(ratio, 1 - eps, 1 + eps)
        pg = -torch.min(ratio * adv, clipped * adv).mean()
        losses.append(pg + beta * (logp - ref_logp).mean())
    return torch.stack(losses).mean()
```

 Reward Functions

DeepSeek-R1 uses two rule-based rewards: a correctness reward that checks the final answer against a ground-truth (using SymPy for symbolic math equality and unit tests for code), and a format reward that enforces the model produces <think>...</think> and <answer>...</answer> tags. No learned reward model is needed, keeping the signal clean and verifiable.

```python
import re
from sympy import simplify, sympify, SympifyError

def reward_fn(prompt, completion, expected):
    has_think = bool(re.search(r'<think>.+</think>', completion, re.S))
    fmt_bonus = 0.1 if has_think else 0.0
    m = re.search(r'<answer>(.*?)</answer>', completion, re.S)
    if m is None:
        return fmt_bonus * 0.5
    predicted = m.group(1).strip()
    try:
        if simplify(sympify(predicted) - sympify(expected)) == 0:
            return 1.0 + fmt_bonus
    except SympifyError:
        pass
    return fmt_bonus if predicted != str(expected) else 1.0 + fmt_bonus
```

 Cold-Start Problem and SFT Initialization

R1-Zero (pure RL from base) produces emergent reasoning but suffers from language mixing and inconsistent output formatting. DeepSeek-R1 addresses this with a cold-start phase: a small set of human-curated long-CoT examples in the desired format are used to fine-tune the base model before RL begins, giving the policy a well-structured starting point.

```python
from transformers import AutoModelForCausalLM, AutoTokenizer, Trainer, TrainingArguments

def cold_start_sft(model_name, sft_dataset_path, output_dir):
    model = AutoModelForCausalLM.from_pretrained(model_name)
    tokenizer = AutoTokenizer.from_pretrained(model_name)
    dataset = load_cot_dataset(sft_dataset_path)  # <think>...</think><answer>...</answer>
    args = TrainingArguments(
        output_dir=output_dir, num_train_epochs=1,
        per_device_train_batch_size=4, learning_rate=1e-5,
        lr_scheduler_type="cosine", warmup_ratio=0.03,
    )
    trainer = Trainer(model=model, args=args,
                      train_dataset=dataset, tokenizer=tokenizer)
    trainer.train()
```

 RL Training Pipeline

The RL loop repeatedly samples completions from the current policy, scores them with the reward function, computes GRPO advantages, and updates policy weights. Training runs for thousands of steps with a KL-divergence penalty against a frozen reference policy to prevent the model from drifting too far from the pre-trained distribution.

After RL convergence, a second SFT pass is applied using rejection-sampled solutions from the RL model plus supervised data for general tasks. This round restores helpfulness on non-reasoning tasks, reduces repetition artifacts from RL training, and chat-aligns the final model while preserving the strong reasoning capability gained through GRPO.

 Distillation to Smaller Models

Rather than running expensive RL on smaller models, DeepSeek distills reasoning by generating large quantities of long-CoT solution traces from the R1-671B teacher, then fine-tuning a smaller student (7B or 32B) on those traces using standard supervised learning. This is far cheaper than RL while achieving surprisingly strong benchmark results on reasoning tasks.

```python
from transformers import AutoModelForCausalLM, Trainer, TrainingArguments
from datasets import load_dataset

def distill_from_r1(student_name, traces_path, output_dir, eval_dataset):
    student = AutoModelForCausalLM.from_pretrained(student_name)
    dataset = load_dataset("json", data_files=traces_path)["train"]
    # Mask loss to answer tokens; CoT tokens are still fed as context
    dataset = dataset.map(lambda x: mask_cot_tokens(x, answer_tag="<answer>"))
    args = TrainingArguments(
        output_dir=output_dir, num_train_epochs=3,
        per_device_train_batch_size=2, learning_rate=2e-5,
        gradient_accumulation_steps=8,
    )
    trainer = Trainer(model=student, args=args, train_dataset=dataset)
    trainer.train()
    return evaluate_aime(student, eval_dataset)
```

Distillation works because the student learns to reproduce the structure of long reasoning chains — including backtracking, self-correction, and verification steps — by imitating the teacher. Remarkably, a 7B model distilled from R1 outperforms much larger models trained without chain-of-thought distillation, achieving 55.5% on AIME 2024 and 92.8% on MATH-500.

> ****: DeepSeek-R1-Zero trained purely via RL with no SFT spontaneously developed chain-of-thought reasoning, self-verification, and reflection behaviors — demonstrating that reasoning can emerge from reward signals alone without any human-labeled reasoning traces.

| Model | AIME 2024 (%) | MATH-500 (%) | Codeforces (%ile) | Params |
| --- | --- | --- | --- | --- |
| R1-Zero | 71.0 | 90.0 | 58.0 | 671B |
| R1 | 79.8 | 97.3 | 96.3 | 671B |
| R1-Distill-7B | 55.5 | 92.8 | 37.6 | 7B |
| R1-Distill-32B | 72.6 | 94.3 | 72.6 | 32B |
| GPT-4o | 9.3 | 76.6 | 43.4 | - |

The benchmark numbers highlight a key insight: distillation transfers reasoning capability efficiently. R1-Distill-32B at 32B parameters vastly exceeds GPT-4o on AIME 2024 (72.6% vs 9.3%), and even R1-Distill-7B substantially outperforms GPT-4o. The gap between R1-Zero and R1 also shows the concrete value of cold-start SFT and the second alignment pass.

---

 Key Takeaways

- GRPO eliminates the critic/value model by estimating advantages within a group of K sampled responses — reducing training complexity and GPU memory vs PPO.
- R1-Zero proves reasoning can emerge from RL with rule-based rewards alone, with no SFT on CoT data — though output quality is inconsistent without cold-start initialization.
- Cold-start SFT on a small set of human-curated CoT examples stabilizes formatting and language consistency before RL training begins.
- Distillation via imitation of R1-671B traces gives 7B and 32B models strong reasoning at a fraction of the RL training cost — no RL required on the student model.
- R1-Distill-32B scores 72.6% on AIME 2024, vastly exceeding GPT-4o (9.3%) — showing that distilled reasoning dramatically outperforms scale-only approaches.
- Use distilled models (7B/32B) for production serving; use full R1-671B for generating high-quality reasoning traces for future distillation rounds.

DeepSeek-R1's key contribution is a practical training recipe: grow strong reasoning with GRPO using rule-based rewards, then distill that capability into deployable smaller models via supervised imitation. The approach bypasses expensive human annotation of reasoning chains and demonstrates that outcome supervision at scale is sufficient to produce state-of-the-art reasoning.

