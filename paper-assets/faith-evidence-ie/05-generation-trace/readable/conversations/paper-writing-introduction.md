# paper writing introduction

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 21
- **Recorded user turns:** 0
- **Tool calls:** 10
- **Original source:** `logs/chats/worker_paper_writing_introduction_20260517T164308.jsonl`
- **Structured JSON:** [`de78051e890c3ae09a59.json`](../../sessions/de/de78051e890c3ae09a59.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

21 recorded events

### Tool call

_source line 1 · 2026-05-17T16:44:54.565285+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/ 2>/dev/null || echo \"DIR_NOT_FOUND\"",
  "description": "Check if output directory exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/ 2>/dev/null || echo \"DIR_NOT_FOUND\"",
    "description": "Check if output directory exists"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-17T16:44:54.565657+00:00_

experiments.tex
method.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-17T16:44:54.565864+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "content": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent LLM-based approaches have closed this gap: \\citet{wan2024genres} recast DocRE as constrained generation, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.\nWhen a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nWithout machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth improve extraction quality \\emph{and} produce evidence annotations.\nHowever, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference between evidence in encoder and generative frameworks.\nIn SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.\nThe evidence signal \\emph{regularizes} the encoder and improves extraction.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nEvidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.\nThe fundamental asymmetry is clear: encoder evidence helps extraction; generative evidence costs extraction capacity.\nThis distinction motivates a systematic investigation of how to produce faithful evidence within LLM-based DocRE without sacrificing the extraction gains that make these models attractive.\n\nWe formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via GRPO \\citep{shao2024deepseekmath}, offline preference optimization via DPO \\citep{rafailov2023direct}, and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR \\citep{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 8B), two model families, and two datasets, reveal three principal findings.\n\\textbf{First}, we identify a \\emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.\nGRPO with QLoRA \\citep{hu2022lora} produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.\nQLoRA acts as a catastrophic amplifier of the underlying optimization conflict rather than its root cause.\n\\textbf{Second}, we discover a \\emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations follows a non-monotonic pattern across model scales.\nAt 1.7B parameters, evidence supervision provides an implicit regularization benefit of +8 percentage points (pp) in Rel-F1; at 4B, it imposes a $-$7.5pp penalty; at 8B, the tax approaches zero.\nThis non-linear pattern overturns the naive assumption that evidence generation uniformly harms extraction.\n\\textbf{Third}, RSFT with NLI-based Claim-Evidence Decomposition (CED) scoring emerges as the only effective optimization route.\nBy selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We formalize \\textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs, defining structured output formats that jointly produce relation triplets and their supporting evidence sentences.\n\n    \\item We characterize a \\textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We introduce the EDCR diagnostic metric, which captures this relationship with method-level $\\rho = -0.965$.\n\n    \\item We identify a \\textbf{scale-dependent evidence tax}: a non-monotonic cost pattern across 1.7B, 4B, and 8B parameters that overturns the assumption that evidence production uniformly degrades extraction quality.\n\n    \\item We establish \\textbf{RSFT with NLI-based CED scoring} as an effective solution, achieving +4.92pp Ign-F1 over SFT at 4B scale. Our 1.7B RSFT model (50.50 Ign-F1) matches 8B SFT performance (50.51), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.\n\n    \\item We present a \\textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms, providing the first systematic analysis of evidence production in generative DocRE.\n\\end{enumerate}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "content": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent LLM-based approaches have closed this gap: \\citet{wan2024genres} recast DocRE as constrained generation, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.\nWhen a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nWithout machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth improve extraction quality \\emph{and} produce evidence annotations.\nHowever, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference between evidence in encoder and generative frameworks.\nIn SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.\nThe evidence signal \\emph{regularizes} the encoder and improves extraction.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nEvidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.\nThe fundamental asymmetry is clear: encoder evidence helps extraction; generative evidence costs extraction capacity.\nThis distinction motivates a systematic investigation of how to produce faithful evidence within LLM-based DocRE without sacrificing the extraction gains that make these models attractive.\n\nWe formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via GRPO \\citep{shao2024deepseekmath}, offline preference optimization via DPO \\citep{rafailov2023direct}, and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR \\citep{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 8B), two model families, and two datasets, reveal three principal findings.\n\\textbf{First}, we identify a \\emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.\nGRPO with QLoRA \\citep{hu2022lora} produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.\nQLoRA acts as a catastrophic amplifier of the underlying optimization conflict rather than its root cause.\n\\textbf{Second}, we discover a \\emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations follows a non-monotonic pattern across model scales.\nAt 1.7B parameters, evidence supervision provides an implicit regularization benefit of +8 percentage points (pp) in Rel-F1; at 4B, it imposes a $-$7.5pp penalty; at 8B, the tax approaches zero.\nThis non-linear pattern overturns the naive assumption that evidence generation uniformly harms extraction.\n\\textbf{Third}, RSFT with NLI-based Claim-Evidence Decomposition (CED) scoring emerges as the only effective optimization route.\nBy selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We formalize \\textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs, defining structured output formats that jointly produce relation triplets and their supporting evidence sentences.\n\n    \\item We characterize a \\textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We introduce the EDCR diagnostic metric, which captures this relationship with method-level $\\rho = -0.965$.\n\n    \\item We identify a \\textbf{scale-dependent evidence tax}: a non-monotonic cost pattern across 1.7B, 4B, and 8B parameters that overturns the assumption that evidence production uniformly degrades extraction quality.\n\n    \\item We establish \\textbf{RSFT with NLI-based CED scoring} as an effective solution, achieving +4.92pp Ign-F1 over SFT at 4B scale. Our 1.7B RSFT model (50.50 Ign-F1) matches 8B SFT performance (50.51), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.\n\n    \\item We present a \\textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms, providing the first systematic analysis of evidence production in generative DocRE.\n\\end{enumerate}\n"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-17T16:44:54.566083+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-17T16:44:54.566264+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "—",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "tool_args": {
    "pattern": "—",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-17T16:44:54.566452+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-17T16:44:54.566586+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": " – ",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "tool_args": {
    "pattern": " – ",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-17T16:44:54.566713+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-17T16:44:54.566832+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "ing[,.]?\\s*$",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "tool_args": {
    "pattern": "ing[,.]?\\s*$",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-17T16:44:54.566948+00:00_

28:\textbf{First}, we identify a \emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-17T16:44:54.567077+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "offset": "27",
  "limit": "3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "offset": "27",
    "limit": "3"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-17T16:44:54.567196+00:00_

27	Our experiments across 85+ configurations, spanning four model scales (1.7B to 8B), two model families, and two datasets, reveal three principal findings.
28	\textbf{First}, we identify a \emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.
29	GRPO with QLoRA \citep{hu2022lora} produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-17T16:44:54.567355+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "Furthermore|Moreover|Additionally",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "tool_args": {
    "pattern": "Furthermore|Moreover|Additionally",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-17T16:44:54.567470+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-17T16:44:54.567579+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "delve|leverage|utilize|myriad|plethora",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "tool_args": {
    "pattern": "delve|leverage|utilize|myriad|plethora",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-17T16:44:54.567687+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-17T16:44:54.567804+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__register_artifact",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-17T16:44:54.567914+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-17T16:44:54.568036+00:00_

called mcp__agent-ml-research__register_artifact

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact</summary>

```json
{
  "name": "introduction.tex",
  "type": "paper",
  "description": "Introduction section for EMNLP 2026 paper \"Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction\"",
  "project": "faith-evidence-ie",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "tags": "['paper', 'introduction', 'emnlp2026']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "mcp__agent-ml-research__register_artifact",
  "tool_args": {
    "name": "introduction.tex",
    "type": "paper",
    "description": "Introduction section for EMNLP 2026 paper \"Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction\"",
    "project": "faith-evidence-ie",
    "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "tags": "['paper', 'introduction', 'emnlp2026']"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-17T16:44:54.568176+00:00_

{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260517_0dbdd7\", \"name\": \"introduction.tex\", \"type\": \"paper\", \"description\": \"Introduction section for EMNLP 2026 paper \\\"Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction\\\"\", \"path\": \"projects/faith-evidence-ie/artifacts/_project/paper/introduction.tex\", \"url\": null, \"project\": \"faith-evidence-ie\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-17T16:44:41.685535+00:00\", \"tags\": [\"paper\", \"introduction\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_introduction_20260517T164308",
  "tool": "mcp__agent-ml-research__register_artifact",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-17T16:44:54.568365+00:00_

Introduction 已写入 `docs/paper/sections/introduction.tex`，约 1200 words，5 段结构：

1. **P1** — LLM DocRE 进展但无证据：GenRES/LMRC/DocKS-RAG 逼近 encoder SOTA，但只输出裸三元组，部署场景无法验证
2. **P2** — 可验证证据的必要性：RE 输出进入 KG 和决策流程，encoder 方法 (SAIS/DREEAM) 有证据但精度已落后
3. **P3** — Encoder retrieval ≠ generative production：encoder 证据是辅助信号（helps extraction），生成式证据是额外负担（costs capacity）
4. **P4** — 核心发现：decoupling spectrum、scale-dependent evidence tax、RSFT+CED 方案
5. **P5** — 5 条贡献列表（enumerate 格式）

风格检查通过：无 em-dash、无解释性 en-dash、无 -ing 短语结尾、无连续过渡词、无黑名单用词。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_introduction_20260517T164308"
}
```

</details>

---
