---
title: "Pretraining on Code — Code Understanding, Math Reasoning, and Transfer Benefits"
slug: "pretraining-on-code"
description: "How including code in LLM pretraining improves reasoning, structured generation, and math benchmarks — covering quality filtering, language distribution, mixed training strategies, and transfer evidence."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"One of the most surprising findings in LLM research is that pretraining on code dramatically improves performance on tasks that have nothing to do with programming — mathematical reasoning, multi-step logic, and structured instruction following. GPT-4, LLaMA-3, and DeepSeek all include substantial code in their pretraining mixtures, and ablation studies consistently show that removing code hurts NL reasoning benchmarks. Phi-2, a 2.7B parameter model trained almost entirely on code and synthetic textbook data, outperformed 13B models trained on natural language at the time of its release. Understanding why code helps — and how to incorporate it effectively — is essential for pretraining practitioners."},{"type":"heading","level":2,"content":"Why Code Pretraining Improves Reasoning"},{"type":"text","content":"Code has structural properties that natural language lacks. Every function has an explicit input-output contract enforced by execution. Control flow (loops, conditionals, recursion) teaches the model to reason about state across multiple steps. Type systems enforce precision about what operations are valid. Comments explain the reasoning behind the code, not just what it does — teaching the model to articulate intermediate reasoning steps. These properties align closely with what is needed for chain-of-thought reasoning on math and logic problems: precise step sequencing, state tracking, and explicit intermediate computation."},{"type":"list","ordered":false,"items":["Precise syntax: exact token sequences required for valid programs — forces structured generation","Step-by-step computation: loops and recursion teach multi-step state tracking","Comments and docstrings: models learn to explain logic in natural language adjacent to code","Function signatures: teach abstraction — separating interface from implementation","Test cases: examples of input-output pairs that demonstrate intended behavior"]},{"type":"heading","level":2,"content":"Evidence From Major Pretraining Experiments"},{"type":"text","content":"Multiple independent lines of evidence confirm that code transfer is real and substantial. CodeX (GPT-3 fine-tuned on 100B tokens of code) achieved 28% pass@1 on HumanEval — far above GPT-3\u0027s near-zero — demonstrating that code data is the primary driver of code capability, not model size alone. Phi-2 (2.7B parameters) was trained on ~250B tokens of code and synthetic textbook-quality data and achieved GSM8K accuracy of 57.2% — competitive with LLaMA-2 13B despite having 5× fewer parameters. DeepSeek-Coder-V2 uses 87% code tokens and achieves math reasoning benchmarks competitive with much larger general models, confirming that code reasoning transfers to math."},{"type":"list","ordered":false,"items":["CodeX (GPT-3 + code FT): HumanEval 28% pass@1 vs GPT-3 near-zero — code data drives capability","Phi-2 2.7B (65% code + textbook): GSM8K 57.2%, MMLU 57.4% — SOTA at size at release","LLaMA-3 (25% code mix): strong code + math reasoning despite mostly NL training","DeepSeek-Coder 7B (87% code): HumanEval 65.2%, transfers to math (GSM8K 74.4%)","StarCoder (80+ languages, 1T tokens): multilingual code reasoning, strong NL transfer reported"]},{"type":"heading","level":2,"content":"Code Quality Filtering Pipeline"},{"type":"text","content":"Raw code from GitHub or Common Crawl contains auto-generated boilerplate, minified JavaScript, binary-encoded data, and files with credentials or private keys. Quality filtering removes these before including code in pretraining. The StarCoder project (The Stack dataset) applied filters including file size limits, average line length caps, and repository star count thresholds. Language-specific filters remove files that are almost certainly auto-generated (protobuf outputs, ANTLR parsers). Personal data and credential detection (regex-based API key detection) is an essential safety step."},{"type":"code","language":"python","content":"import re\n\nAUTO_GEN_PATTERNS = [\n    r\u0027# generated by\u0027, r\u0027# auto-generated\u0027, r\u0027# do not edit\u0027,\n    r\u0027this file was generated\u0027, r\u0027@generated\u0027, r\u0027generated code\u0027\n]\nCREDENTIAL_PATTERNS = [\n    r\u0027(?i)(api[_-]?key|secret[_-]?key|password|token)\\s*=\\s*[\"\\\u0027][A-Za-z0-9+/]{20,}\u0027,\n    r\u0027(?i)aws[_-]?secret\u0027,\n    r\u0027-----BEGIN (RSA |EC )?PRIVATE KEY-----\u0027,\n]\n\ndef code_quality_score(code, min_lines=5, max_avg_line_len=200):\n    \"\"\"Return (score, reason): score=None means filtered out.\"\"\"\n    if any(re.search(p, code, re.IGNORECASE) for p in CREDENTIAL_PATTERNS):\n        return None, \u0027credentials\u0027\n    lines = [l for l in code.splitlines() if l.strip()]\n    if len(lines) \u003c min_lines:\n        return None, \u0027too_short\u0027\n    avg_len = sum(len(l) for l in lines) / len(lines)\n    if avg_len \u003e max_avg_line_len:\n        return None, \u0027minified\u0027\n    if any(p in code.lower() for p in AUTO_GEN_PATTERNS):\n        return None, \u0027auto_generated\u0027\n    comment_lines = sum(1 for l in lines if l.strip().startswith((\u0027#\u0027, \u0027//\u0027, \u0027/*\u0027, \u0027*\u0027)))\n    comment_ratio = comment_lines / max(len(lines), 1)\n    score = min(1.0, 0.3 + comment_ratio * 0.5 + min(len(lines), 100) / 200)\n    return round(score, 3), \u0027ok\u0027\n\nsamples = [\n    (\u0027good\u0027, \u0027import numpy as np\\n# Compute pairwise cosine similarity\\ndef cosine_sim(a, b):\\n    return np.dot(a,b)/(np.linalg.norm(a)*np.linalg.norm(b))\\nprint(cosine_sim([1,0],[0,1]))\u0027),\n    (\u0027auto_gen\u0027, \u0027# Generated by protoc-gen-python\\n# Do not edit manually\\nclass Proto:\\n    pass\\n\u0027),\n    (\u0027minified\u0027, (\u0027a=1;b=2;c=a+b;\u0027 * 30)),\n    (\u0027credential\u0027, \u0027API_KEY = \"sk-abc123XYZlong_secret_token_value_here\"\\nprint(API_KEY)\u0027),\n]\nfor name, code in samples:\n    score, reason = code_quality_score(code)\n    print(f\"{name:12s}: score={score}  reason={reason}\")"},{"type":"heading","level":2,"content":"Programming Language Detection and Distribution"},{"type":"text","content":"Python dominates code pretraining datasets at 40–60% of tokens, followed by JavaScript (~15%), Java (~10%), C/C++ (~8%), and TypeScript (~5%). Python\u0027s dominance reflects both its prevalence on GitHub and its high information density per line — Python code tends to have many readable function calls with named arguments and docstrings. Multilingual code training (80+ languages in StarCoder) provides robustness and helps the model generalize across syntactic families. Language detection from file extensions is reliable but must be supplemented with content-based detection for files without extensions or with misleading names."},{"type":"code","language":"python","content":"import re\nfrom collections import Counter\n\nLANG_PATTERNS = {\n    \u0027python\u0027:     [r\u0027import \\w+\u0027, r\u0027def \\w+\\(\u0027, r\u0027:\\s*$\u0027, r\u0027elif \u0027, r\u0027print\\(\u0027],\n    \u0027javascript\u0027: [r\u0027const |let |var \u0027, r\u0027=\u003e\u0027, r\u0027function\\s+\\w+\\(\u0027, r\u0027===\u0027, r\u0027console\\.log\u0027],\n    \u0027java\u0027:       [r\u0027public class \u0027, r\u0027System\\.out\u0027, r\u0027@Override\u0027, r\u0027public static void main\u0027],\n    \u0027cpp\u0027:        [r\u0027#include \u003c\u0027, r\u0027std::\u0027, r\u0027int main\\(\u0027, r\u0027cout \u003c\u003c\u0027, r\u0027-\u003e\u0027],\n    \u0027rust\u0027:       [r\u0027fn main\\(\\)\u0027, r\u0027let mut \u0027, r\u0027impl \u0027, r\u0027use std::\u0027, r\u0027println!\u0027],\n    \u0027typescript\u0027: [r\u0027: string\u0027, r\u0027: number\u0027, r\u0027: boolean\u0027, r\u0027interface \u0027, r\u0027type \\w+ =\u0027],\n}\n\ndef detect_language(code):\n    scores = {lang: sum(bool(re.search(p, code)) for p in pats)\n              for lang, pats in LANG_PATTERNS.items()}\n    best = max(scores, key=scores.get)\n    return best if scores[best] \u003e 0 else \u0027other\u0027\n\n# Simulate language distribution in a hypothetical code corpus\nimport random; random.seed(42)\nweights = {\u0027python\u0027: 48, \u0027javascript\u0027: 20, \u0027java\u0027: 11, \u0027cpp\u0027: 9, \u0027rust\u0027: 5, \u0027typescript\u0027: 4, \u0027other\u0027: 3}\nsampled = random.choices(list(weights.keys()), weights=list(weights.values()), k=2000)\ndist    = Counter(sampled)\nprint(\"Simulated code corpus language distribution (N=2000 files):\")\nfor lang, count in dist.most_common():\n    bar = \u0027|\u0027 * (count // 20)\n    print(f\"  {lang:12s}: {count/20:5.1f}%  {bar}\")"},{"type":"heading","level":2,"content":"Code-Text Mixed Training"},{"type":"text","content":"Simply concatenating code and natural language data and sampling randomly underrepresents or overrepresents code depending on token counts. A controlled mixed batch sampler explicitly sets a target code ratio (typically 15–25% of tokens) and ensures that each training batch contains the right proportion of code and NL documents. The ratio is a hyperparameter: too little code and reasoning transfer is weak; too much code and the model under-learns natural language fluency and knowledge. Most production recipes use 20% code for general-purpose LLMs, rising to 60–90% for code-specialized models."},{"type":"code","language":"python","content":"import random\n\ndef mixed_batch_sampler(code_dataset, text_dataset, code_ratio=0.20, batch_size=8, seed=42):\n    \"\"\"\n    Yield batches with code_ratio fraction code samples and (1-code_ratio) text samples.\n    Shuffles within each batch to prevent domain clustering.\n    \"\"\"\n    rng    = random.Random(seed)\n    n_code = max(1, round(batch_size * code_ratio))\n    n_text = batch_size - n_code\n    code_iter = iter(code_dataset)\n    text_iter = iter(text_dataset)\n    while True:\n        try:\n            code_batch = [next(code_iter) for _ in range(n_code)]\n            text_batch = [next(text_iter) for _ in range(n_text)]\n        except StopIteration:\n            break\n        batch = code_batch + text_batch\n        rng.shuffle(batch)\n        yield batch\n\n# Simulate with 200 code and 800 text documents\ncode_data = [{\u0027text\u0027: f\u0027def func_{i}(x): return x ** {i}\u0027, \u0027domain\u0027: \u0027code\u0027} for i in range(200)]\ntext_data = [{\u0027text\u0027: f\u0027Natural language passage number {i} about science.\u0027, \u0027domain\u0027: \u0027text\u0027} for i in range(800)]\n\nbatches   = list(mixed_batch_sampler(code_data, text_data, code_ratio=0.20, batch_size=8))\nall_items = [item for batch in batches for item in batch]\ncode_pct  = sum(1 for x in all_items if x[\u0027domain\u0027] == \u0027code\u0027) / len(all_items) * 100\nprint(f\"Total batches: {len(batches)}, Total samples: {len(all_items)}\")\nprint(f\"Code: {code_pct:.1f}%  Text: {100-code_pct:.1f}%  (target code_ratio=20%)\")"},{"type":"callout","variant":"tip","title":"Tip","content":"Even 15–20% code in the pretraining mixture significantly improves mathematical reasoning and structured thinking for NL tasks — the mechanism is learning precise syntax and step-by-step execution from code rather than memorizing math facts."},{"type":"heading","level":2,"content":"Evaluating Reasoning Improvement from Code Pretraining"},{"type":"code","language":"python","content":"import re\n\ndef extract_numeric_answer(output):\n    \"\"\"Extract the last numeric value from model output (GSM8K-style answer extraction).\"\"\"\n    cleaned = output.replace(\u0027,\u0027, \u0027\u0027)\n    numbers = re.findall(r\u0027-?\\d+(?:\\.\\d+)?\u0027, cleaned)\n    return numbers[-1] if numbers else None\n\ndef evaluate_gsm8k(model_outputs, ground_truths):\n    \"\"\"Evaluate GSM8K accuracy by matching final numeric answer.\"\"\"\n    correct, total = 0, len(ground_truths)\n    results = []\n    for output, truth in zip(model_outputs, ground_truths):\n        predicted = extract_numeric_answer(output)\n        is_correct = (predicted == str(truth))\n        correct += int(is_correct)\n        results.append({\u0027predicted\u0027: predicted, \u0027truth\u0027: truth, \u0027correct\u0027: is_correct})\n    return {\u0027accuracy\u0027: correct / total, \u0027correct\u0027: correct, \u0027total\u0027: total, \u0027details\u0027: results}\n\n# Simulated outputs: model WITHOUT code pretraining vs model WITH code pretraining\nground_truths = [42, 15, 100, 7, 256, 33, 8, 12, 90, 144]\n\nno_code_outputs = [\n    \u0027I estimate the answer is around 42.\u0027, \u0027Approximately 20 items remain.\u0027,\n    \u0027The total comes to 100.\u0027, \u0027About 5 parts needed.\u0027, \u0027Result is 256.\u0027,\n    \u0027The answer should be roughly 30.\u0027, \u0027Eight units in total: 8.\u0027,\n    \u0027I calculate about 15.\u0027, \u0027Ninety percent means 90.\u0027, \u0027Total: 144.\u0027\n]\n\ncode_outputs = [\n    \u0027Step 1: 6 * 7 = 42. Final answer: 42.\u0027, \u0027Step 1: 3 * 5 = 15. Answer: 15.\u0027,\n    \u002710 * 10 = 100. The answer is 100.\u0027, \u0027Counting: 7 items total. Answer: 7.\u0027,\n    \u00272 ** 8 = 256. Answer: 256.\u0027, \u0027Step: 3 * 11 = 33. Answer: 33.\u0027,\n    \u0027Loop 8 times: answer = 8.\u0027, \u0027Step: 4 * 3 = 12. Final: 12.\u0027,\n    \u0027Percentage: 90 out of 100 = 90.\u0027, \u002712 squared = 144. Answer: 144.\u0027\n]\n\nres_no_code = evaluate_gsm8k(no_code_outputs, ground_truths)\nres_code    = evaluate_gsm8k(code_outputs,    ground_truths)\nprint(f\"Without code pretraining: GSM8K = {res_no_code[\u0027accuracy\u0027]:.1%} ({res_no_code[\u0027correct\u0027]}/{res_no_code[\u0027total\u0027]})\")\nprint(f\"With code pretraining:    GSM8K = {res_code[\u0027accuracy\u0027]:.1%} ({res_code[\u0027correct\u0027]}/{res_code[\u0027total\u0027]})\")\nprint(f\"Improvement: +{(res_code[\u0027accuracy\u0027] - res_no_code[\u0027accuracy\u0027]):.1%}\")"},{"type":"heading","level":2,"content":"Code Data Impact on Downstream Tasks"},{"type":"table","headers":["Model","Code %","HumanEval pass@1","GSM8K","MMLU","Notes"],"rows":[["Phi-2 2.7B","~65%","59.1%","57.2%","57.4%","Code + textbook data; SOTA at size on release"],["LLaMA-3 8B","~25%","33.5%","79.6%","66.6%","General pretraining with code, strong transfer"],["LLaMA-3 70B","~25%","54.8%","93.0%","79.5%","Scale amplifies code reasoning transfer"],["DeepSeek-Coder 7B","~87%","65.2%","74.4%","49.2%","Code-focused; strong math, weaker general NL"],["CodeX (GPT-3 FT)","~100%","28.0%","N/A","N/A","Code fine-tune only; limited NL capability"]]},{"type":"heading","level":2,"content":"Code Data Sources and Licensing"},{"type":"text","content":"The largest source of code training data is GitHub, but licensing is a significant constraint. Only repositories with permissive licenses (MIT, Apache 2.0, BSD) are suitable for unrestricted model training. The Stack dataset (BigCode project) applied license filtering to 358M+ GitHub files, retaining approximately 3TB of permissively licensed code across 350+ programming languages. Stack Exchange data (programming questions and answers) is valuable because it includes natural language explanations alongside code. Kaggle notebooks and arXiv LaTeX provide scientific computing code with mathematical context, particularly useful for math reasoning transfer."},{"type":"list","ordered":false,"items":["GitHub (permissive licenses only): MIT, Apache 2.0, BSD — largest volume source","The Stack (BigCode): 3TB permissively licensed code, 350+ languages, deduped","Stack Overflow: code + natural language explanations — high reasoning density","Kaggle notebooks: scientific Python with inline prose — bridges code and NL reasoning","arXiv LaTeX: math equations with code implementations — math-code co-training signal","Synthetic code: LLM-generated problems and solutions (used by Phi series) — scalable quality"]}]"
---
# Pretraining on Code — Code Understanding, Math Reasoning, and Transfer Benefits

One of the most surprising findings in LLM research is that pretraining on code dramatically improves performance on tasks that have nothing to do with programming — mathematical reasoning, multi-step logic, and structured instruction following. GPT-4, LLaMA-3, and DeepSeek all include substantial code in their pretraining mixtures, and ablation studies consistently show that removing code hurts NL reasoning benchmarks. Phi-2, a 2.7B parameter model trained almost entirely on code and synthetic textbook data, outperformed 13B models trained on natural language at the time of its release. Understanding why code helps — and how to incorporate it effectively — is essential for pretraining practitioners.

## Why Code Pretraining Improves Reasoning

Code has structural properties that natural language lacks. Every function has an explicit input-output contract enforced by execution. Control flow (loops, conditionals, recursion) teaches the model to reason about state across multiple steps. Type systems enforce precision about what operations are valid. Comments explain the reasoning behind the code, not just what it does — teaching the model to articulate intermediate reasoning steps. These properties align closely with what is needed for chain-of-thought reasoning on math and logic problems: precise step sequencing, state tracking, and explicit intermediate computation.

- Precise syntax: exact token sequences required for valid programs — forces structured generation
- Step-by-step computation: loops and recursion teach multi-step state tracking
- Comments and docstrings: models learn to explain logic in natural language adjacent to code
- Function signatures: teach abstraction — separating interface from implementation
- Test cases: examples of input-output pairs that demonstrate intended behavior

## Evidence From Major Pretraining Experiments

Multiple independent lines of evidence confirm that code transfer is real and substantial. CodeX (GPT-3 fine-tuned on 100B tokens of code) achieved 28% pass@1 on HumanEval — far above GPT-3's near-zero — demonstrating that code data is the primary driver of code capability, not model size alone. Phi-2 (2.7B parameters) was trained on ~250B tokens of code and synthetic textbook-quality data and achieved GSM8K accuracy of 57.2% — competitive with LLaMA-2 13B despite having 5× fewer parameters. DeepSeek-Coder-V2 uses 87% code tokens and achieves math reasoning benchmarks competitive with much larger general models, confirming that code reasoning transfers to math.

- CodeX (GPT-3 + code FT): HumanEval 28% pass@1 vs GPT-3 near-zero — code data drives capability
- Phi-2 2.7B (65% code + textbook): GSM8K 57.2%, MMLU 57.4% — SOTA at size at release
- LLaMA-3 (25% code mix): strong code + math reasoning despite mostly NL training
- DeepSeek-Coder 7B (87% code): HumanEval 65.2%, transfers to math (GSM8K 74.4%)
- StarCoder (80+ languages, 1T tokens): multilingual code reasoning, strong NL transfer reported

## Code Quality Filtering Pipeline

Raw code from GitHub or Common Crawl contains auto-generated boilerplate, minified JavaScript, binary-encoded data, and files with credentials or private keys. Quality filtering removes these before including code in pretraining. The StarCoder project (The Stack dataset) applied filters including file size limits, average line length caps, and repository star count thresholds. Language-specific filters remove files that are almost certainly auto-generated (protobuf outputs, ANTLR parsers). Personal data and credential detection (regex-based API key detection) is an essential safety step.

```python
import re

AUTO_GEN_PATTERNS = [
    r'# generated by', r'# auto-generated', r'# do not edit',
    r'this file was generated', r'@generated', r'generated code'
]
CREDENTIAL_PATTERNS = [
    r'(?i)(api[_-]?key|secret[_-]?key|password|token)\s*=\s*["\'][A-Za-z0-9+/]{20,}',
    r'(?i)aws[_-]?secret',
    r'-----BEGIN (RSA |EC )?PRIVATE KEY-----',
]

def code_quality_score(code, min_lines=5, max_avg_line_len=200):
    """Return (score, reason): score=None means filtered out."""
    if any(re.search(p, code, re.IGNORECASE) for p in CREDENTIAL_PATTERNS):
        return None, 'credentials'
    lines = [l for l in code.splitlines() if l.strip()]
    if len(lines) < min_lines:
        return None, 'too_short'
    avg_len = sum(len(l) for l in lines) / len(lines)
    if avg_len > max_avg_line_len:
        return None, 'minified'
    if any(p in code.lower() for p in AUTO_GEN_PATTERNS):
        return None, 'auto_generated'
    comment_lines = sum(1 for l in lines if l.strip().startswith(('#', '//', '/*', '*')))
    comment_ratio = comment_lines / max(len(lines), 1)
    score = min(1.0, 0.3 + comment_ratio * 0.5 + min(len(lines), 100) / 200)
    return round(score, 3), 'ok'

samples = [
    ('good', 'import numpy as np\n# Compute pairwise cosine similarity\ndef cosine_sim(a, b):\n    return np.dot(a,b)/(np.linalg.norm(a)*np.linalg.norm(b))\nprint(cosine_sim([1,0],[0,1]))'),
    ('auto_gen', '# Generated by protoc-gen-python\n# Do not edit manually\nclass Proto:\n    pass\n'),
    ('minified', ('a=1;b=2;c=a+b;' * 30)),
    ('credential', 'API_KEY = "sk-abc123XYZlong_secret_token_value_here"\nprint(API_KEY)'),
]
for name, code in samples:
    score, reason = code_quality_score(code)
    print(f"{name:12s}: score={score}  reason={reason}")
```

## Programming Language Detection and Distribution

Python dominates code pretraining datasets at 40–60% of tokens, followed by JavaScript (~15%), Java (~10%), C/C++ (~8%), and TypeScript (~5%). Python's dominance reflects both its prevalence on GitHub and its high information density per line — Python code tends to have many readable function calls with named arguments and docstrings. Multilingual code training (80+ languages in StarCoder) provides robustness and helps the model generalize across syntactic families. Language detection from file extensions is reliable but must be supplemented with content-based detection for files without extensions or with misleading names.

```python
import re
from collections import Counter

LANG_PATTERNS = {
    'python':     [r'import \w+', r'def \w+\(', r':\s*$', r'elif ', r'print\('],
    'javascript': [r'const |let |var ', r'=>', r'function\s+\w+\(', r'===', r'console\.log'],
    'java':       [r'public class ', r'System\.out', r'@Override', r'public static void main'],
    'cpp':        [r'#include <', r'std::', r'int main\(', r'cout <<', r'->'],
    'rust':       [r'fn main\(\)', r'let mut ', r'impl ', r'use std::', r'println!'],
    'typescript': [r': string', r': number', r': boolean', r'interface ', r'type \w+ ='],
}

def detect_language(code):
    scores = {lang: sum(bool(re.search(p, code)) for p in pats)
              for lang, pats in LANG_PATTERNS.items()}
    best = max(scores, key=scores.get)
    return best if scores[best] > 0 else 'other'

# Simulate language distribution in a hypothetical code corpus
import random; random.seed(42)
weights = {'python': 48, 'javascript': 20, 'java': 11, 'cpp': 9, 'rust': 5, 'typescript': 4, 'other': 3}
sampled = random.choices(list(weights.keys()), weights=list(weights.values()), k=2000)
dist    = Counter(sampled)
print("Simulated code corpus language distribution (N=2000 files):")
for lang, count in dist.most_common():
    bar = '|' * (count // 20)
    print(f"  {lang:12s}: {count/20:5.1f}%  {bar}")
```

## Code-Text Mixed Training

Simply concatenating code and natural language data and sampling randomly underrepresents or overrepresents code depending on token counts. A controlled mixed batch sampler explicitly sets a target code ratio (typically 15–25% of tokens) and ensures that each training batch contains the right proportion of code and NL documents. The ratio is a hyperparameter: too little code and reasoning transfer is weak; too much code and the model under-learns natural language fluency and knowledge. Most production recipes use 20% code for general-purpose LLMs, rising to 60–90% for code-specialized models.

```python
import random

def mixed_batch_sampler(code_dataset, text_dataset, code_ratio=0.20, batch_size=8, seed=42):
    """
    Yield batches with code_ratio fraction code samples and (1-code_ratio) text samples.
    Shuffles within each batch to prevent domain clustering.
    """
    rng    = random.Random(seed)
    n_code = max(1, round(batch_size * code_ratio))
    n_text = batch_size - n_code
    code_iter = iter(code_dataset)
    text_iter = iter(text_dataset)
    while True:
        try:
            code_batch = [next(code_iter) for _ in range(n_code)]
            text_batch = [next(text_iter) for _ in range(n_text)]
        except StopIteration:
            break
        batch = code_batch + text_batch
        rng.shuffle(batch)
        yield batch

# Simulate with 200 code and 800 text documents
code_data = [{'text': f'def func_{i}(x): return x ** {i}', 'domain': 'code'} for i in range(200)]
text_data = [{'text': f'Natural language passage number {i} about science.', 'domain': 'text'} for i in range(800)]

batches   = list(mixed_batch_sampler(code_data, text_data, code_ratio=0.20, batch_size=8))
all_items = [item for batch in batches for item in batch]
code_pct  = sum(1 for x in all_items if x['domain'] == 'code') / len(all_items) * 100
print(f"Total batches: {len(batches)}, Total samples: {len(all_items)}")
print(f"Code: {code_pct:.1f}%  Text: {100-code_pct:.1f}%  (target code_ratio=20%)")
```

> **Tip**: Even 15–20% code in the pretraining mixture significantly improves mathematical reasoning and structured thinking for NL tasks — the mechanism is learning precise syntax and step-by-step execution from code rather than memorizing math facts.

## Evaluating Reasoning Improvement from Code Pretraining

```python
import re

def extract_numeric_answer(output):
    """Extract the last numeric value from model output (GSM8K-style answer extraction)."""
    cleaned = output.replace(',', '')
    numbers = re.findall(r'-?\d+(?:\.\d+)?', cleaned)
    return numbers[-1] if numbers else None

def evaluate_gsm8k(model_outputs, ground_truths):
    """Evaluate GSM8K accuracy by matching final numeric answer."""
    correct, total = 0, len(ground_truths)
    results = []
    for output, truth in zip(model_outputs, ground_truths):
        predicted = extract_numeric_answer(output)
        is_correct = (predicted == str(truth))
        correct += int(is_correct)
        results.append({'predicted': predicted, 'truth': truth, 'correct': is_correct})
    return {'accuracy': correct / total, 'correct': correct, 'total': total, 'details': results}

# Simulated outputs: model WITHOUT code pretraining vs model WITH code pretraining
ground_truths = [42, 15, 100, 7, 256, 33, 8, 12, 90, 144]

no_code_outputs = [
    'I estimate the answer is around 42.', 'Approximately 20 items remain.',
    'The total comes to 100.', 'About 5 parts needed.', 'Result is 256.',
    'The answer should be roughly 30.', 'Eight units in total: 8.',
    'I calculate about 15.', 'Ninety percent means 90.', 'Total: 144.'
]

code_outputs = [
    'Step 1: 6 * 7 = 42. Final answer: 42.', 'Step 1: 3 * 5 = 15. Answer: 15.',
    '10 * 10 = 100. The answer is 100.', 'Counting: 7 items total. Answer: 7.',
    '2 ** 8 = 256. Answer: 256.', 'Step: 3 * 11 = 33. Answer: 33.',
    'Loop 8 times: answer = 8.', 'Step: 4 * 3 = 12. Final: 12.',
    'Percentage: 90 out of 100 = 90.', '12 squared = 144. Answer: 144.'
]

res_no_code = evaluate_gsm8k(no_code_outputs, ground_truths)
res_code    = evaluate_gsm8k(code_outputs,    ground_truths)
print(f"Without code pretraining: GSM8K = {res_no_code['accuracy']:.1%} ({res_no_code['correct']}/{res_no_code['total']})")
print(f"With code pretraining:    GSM8K = {res_code['accuracy']:.1%} ({res_code['correct']}/{res_code['total']})")
print(f"Improvement: +{(res_code['accuracy'] - res_no_code['accuracy']):.1%}")
```

## Code Data Impact on Downstream Tasks

| Model | Code % | HumanEval pass@1 | GSM8K | MMLU | Notes |
| --- | --- | --- | --- | --- | --- |
| Phi-2 2.7B | ~65% | 59.1% | 57.2% | 57.4% | Code + textbook data; SOTA at size on release |
| LLaMA-3 8B | ~25% | 33.5% | 79.6% | 66.6% | General pretraining with code, strong transfer |
| LLaMA-3 70B | ~25% | 54.8% | 93.0% | 79.5% | Scale amplifies code reasoning transfer |
| DeepSeek-Coder 7B | ~87% | 65.2% | 74.4% | 49.2% | Code-focused; strong math, weaker general NL |
| CodeX (GPT-3 FT) | ~100% | 28.0% | N/A | N/A | Code fine-tune only; limited NL capability |

## Code Data Sources and Licensing

The largest source of code training data is GitHub, but licensing is a significant constraint. Only repositories with permissive licenses (MIT, Apache 2.0, BSD) are suitable for unrestricted model training. The Stack dataset (BigCode project) applied license filtering to 358M+ GitHub files, retaining approximately 3TB of permissively licensed code across 350+ programming languages. Stack Exchange data (programming questions and answers) is valuable because it includes natural language explanations alongside code. Kaggle notebooks and arXiv LaTeX provide scientific computing code with mathematical context, particularly useful for math reasoning transfer.

- GitHub (permissive licenses only): MIT, Apache 2.0, BSD — largest volume source
- The Stack (BigCode): 3TB permissively licensed code, 350+ languages, deduped
- Stack Overflow: code + natural language explanations — high reasoning density
- Kaggle notebooks: scientific Python with inline prose — bridges code and NL reasoning
- arXiv LaTeX: math equations with code implementations — math-code co-training signal
- Synthetic code: LLM-generated problems and solutions (used by Phi series) — scalable quality

