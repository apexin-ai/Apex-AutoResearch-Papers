# paper d031 framing core

**Depth Profiling: Classifying Recursive Generation Depth in Base-Model LLM Text** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 25
- **Recorded user turns:** 0
- **Tool calls:** 12
- **Original source:** `logs/chats/worker_paper_d031-framing-core_20260520T112415.jsonl`
- **Structured JSON:** [`f74512f1cdbfb35283c6.json`](../../sessions/f7/f74512f1cdbfb35283c6.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

25 recorded events

### Tool call

_source line 1 · 2026-05-20T11:25:26.418440+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-20T11:25:26.418760+00:00_

1	% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains
2	\begin{abstract}
3	Recursive LLM generation shifts \emph{where} text sits in distributional space but leaves \emph{how} it is shaped nearly unchanged, and this asymmetry is consistent across five model families spanning 0.6B to 8B parameters.
4	We term this \emph{differential depth response} (DDR): under standard decoding, mean entropy and lexical diversity drift monotonically with generation depth while entropy max and tail decay show an order-of-magnitude smaller effect size.
5	Prior work on iterative generation tracks aggregate convergence without separating what changes from what is preserved; DDR provides this decomposition and enables coarse depth classification (gen-0\,/\,gen-1\,/\,gen-2+): a 7-feature ensemble achieves leak-free binary F1\,=\,0.694 (95\% CI [.688, .700]) under leave-one-generator-out evaluation and 0.830 on cross-model chains (5-generator subset, LOGO; 95\% CI [.818, .841]), at lower cost than multi-detector alternatives.
6	Despite measurable distributional drift, equivalence testing (TOST $\pm$2\%, $p < 0.001$) suggests no downstream training quality degradation.
7	The depth signal degrades under instruction tuning; current applicability is restricted to base models.
8	\end{abstract}
9	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-20T11:25:26.418942+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-20T11:25:26.419106+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	When the output of a language model is fed back as input to another (or the same) model, the resulting generation chain defines a discrete dynamical system over text distributions.
5	How do the distributional properties of generated text evolve across successive steps of this recursion?
6	Understanding this evolution is fundamental to characterizing how language models transform distributions under iterative conditioning, with implications for model collapse theory \cite{curse_of_recursion,strong_model_collapse} and data provenance \cite{ccnet,dsir} as model outputs increasingly re-enter training corpora \cite{dolma,fineweb} (an estimated 7--17\% of recent scientific publications contain substantial LLM-modified content \cite{mapping_llm_science,monitoring_ai_review}).
7	Yet existing detection methods \cite{fast_detectgpt,binoculars,ld_score,detectgpt} provide only binary real-vs-synthetic decisions, conflating qualitatively different material: a first-generation continuation retains much of the source distribution's lexical properties, while deeper recursive text exhibits measurably reduced vocabulary diversity and compressed perplexity.
8	
9	We formulate \emph{generation depth classification}, classifying text by coarse ordinal depth (gen-0\,/\,gen-1\,/\,gen-2+) rather than a binary label, and refer to the overall framework as \emph{depth fingerprinting}.
10	Concurrent studies characterize convergence in paraphrastic and translation chains \cite{broken_telephone,markovian_chains}, but none decompose the drift into structurally distinct components; our work addresses this gap in non-paraphrastic continuation chains.
11	We restrict to base (pretrained) models to isolate the generation mechanism from alignment artifacts: instruction-tuning introduces confounds (length regulation, format constraints, safety-driven shaping) that obscure the distributional dynamics of recursive generation; preliminary experiments 
…[truncated 2593 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-20T11:25:26.419277+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-20T11:25:26.419437+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	The central finding is that recursive generation alters \emph{where} the token-level surprise distribution sits but not \emph{how} it is shaped: autoregressive sampling with fixed top-$p$ plausibly truncates the conditional distribution at a consistent shape regardless of input, while mean surprisal systematically decreases as the model conditions on its own increasingly typical outputs.
5	Permutation importance, Granger causality, and feature intervention analyses confirm that DDR features carry causal predictive power beyond correlation: drifting features contribute $5.5\times$ more to classification than near-stationary ones, and 6/7 features exhibit significant Granger causality across generation depths, with entropy\_min as the sole exception (Appendix~\ref{app:ddr-causality}).
6	This asymmetry is not intrinsic to recursion but parameter-dependent: at $t{=}1.0$, the location signal collapses ($\rho$ from $-0.60$ to $-0.002$; Appendix~\ref{app:sampling-sensitivity}), and semantic-preservation constraints attenuate drift (elaboration F1\,=\,0.730 vs.\ continuation 0.781; Appendix~\ref{app:prompt-type}), consistent with \citet{broken_telephone}; cross-type transfer remains viable (F1\,=\,0.753).
7	
8	Several boundary conditions constrain practical applicability.
9	Document-level gen-1 per-class F1\,=\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging ($O(1/\sqrt{n})$ error scaling); the primary difficulty is distinguishing gen-1 from gen-2+, consistent with DDR producing the smallest location shift at the first recursive step (86\% false negatives; Appendix~\ref{app:error-analysis}).
10	Cross-temperature transfer degrades when test-time temperature exceeds training ($t{=}0.7 \rightarrow 1.0$: overall 3-class F1 drops from 0.789 to 0.723; the most affected single generator, Qwen3-1.7B, drops to per-generator F1\,=\,0.418; Appendix~\ref{app:cross-temp}); depth fingerprinting ass
…[truncated 1884 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-20T11:25:26.419660+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
  "old_string": "Recursive LLM generation shifts \\emph{where} text sits in distributional space but leaves \\emph{how} it is shaped nearly unchanged, and this asymmetry is consistent across five model families spanning 0.6B to 8B parameters.",
  "new_string": "Recursive generation by base (pretrained) LLMs shifts \\emph{where} text sits in distributional space but leaves \\emph{how} it is shaped nearly unchanged, and this asymmetry is consistent across five model families spanning 0.6B to 8B parameters."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
    "old_string": "Recursive LLM generation shifts \\emph{where} text sits in distributional space but leaves \\emph{how} it is shaped nearly unchanged, and this asymmetry is consistent across five model families spanning 0.6B to 8B parameters.",
    "new_string": "Recursive generation by base (pretrained) LLMs shifts \\emph{where} text sits in distributional space but leaves \\emph{how} it is shaped nearly unchanged, and this asymmetry is consistent across five model families spanning 0.6B to 8B parameters."
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-20T11:25:26.419870+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-20T11:25:26.420005+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
  "old_string": "under standard decoding, mean entropy",
  "new_string": "under standard decoding (temperature $\\leq 0.7$, nucleus $p{=}0.9$), mean entropy"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
    "old_string": "under standard decoding, mean entropy",
    "new_string": "under standard decoding (temperature $\\leq 0.7$, nucleus $p{=}0.9$), mean entropy"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-20T11:25:26.420150+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-20T11:25:26.420272+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
  "old_string": "Despite measurable distributional drift, equivalence testing (TOST $\\pm$2\\%, $p < 0.001$) suggests no downstream training quality degradation.",
  "new_string": "Despite measurable distributional drift, preliminary equivalence testing (TOST $\\pm$2\\%, $p < 0.001$; $n{=}3$ seeds) suggests no downstream training quality degradation."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
    "old_string": "Despite measurable distributional drift, equivalence testing (TOST $\\pm$2\\%, $p < 0.001$) suggests no downstream training quality degradation.",
    "new_string": "Despite measurable distributional drift, preliminary equivalence testing (TOST $\\pm$2\\%, $p < 0.001$; $n{=}3$ seeds) suggests no downstream training quality degradation."
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-20T11:25:26.420411+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-20T11:25:26.420553+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex",
  "old_string": "\\begin{enumerate}[nosep,leftmargin=*]\n    \\item We formulate generation depth classification, moving beyond binary detection to ordinal depth estimation (gen-0\\,/\\,gen-1\\,/\\,gen-2+), and construct an evaluation suite of 37K texts from eight generators spanning five model families (0.6B--8B parameters).\n    \\item We decompose inference-chain drift into structurally distinct components: central-tendency features drift monotonically ($d = 0.76$--$1.17$) while shape features remain an order of magnitude more stable ($d < 0.10$), a decomposition absent from existing attractor dynamics and model collapse analyses. A 7-feature ensemble exploiting this \\emph{differential depth response} achieves binary F1\\,=\\,0.830 on cross-model chains.\n    \\item Comprehensive evaluation reveals that DDR is robust within $t \\in [0.5, 0.7]$ but degrades at $t{=}0.9$ ($-9.3$ to $-26.0$\\,pp), is prompt-type modulated (continuation $>$ elaboration), and is substantially attenuated under instruction tuning; equivalence testing (TOST $\\pm$2\\%, $p < 0.001$) suggests no downstream quality degradation (Appendix~\\ref{app:downstream}).\n\\end{enumerate}",
  "new_string": "\\begin{enumerate}[nosep,leftmargin=*]\n    \\item We decompose inference-chain drift into structurally distinct components: central-tendency features drift monotonically ($d = 0.76$--$1.17$) while shape features remain an order of magnitude more stable ($d < 0.10$), a decomposition absent from existing attractor dynamics and model collapse analyses.\n    \\item We formulate generation depth classification, moving beyond binary detection to ordinal depth estimation (gen-0\\,/\\,gen-1\\,/\\,gen-2+), and construct an evaluation suite of 37K texts from eight generators spanning five model families (0.6B--8B parameters).\n    \\item An interpretable 7-feature baseline exploiting this \\emph{differential depth response} achieves binary F1\\,=\\,0.830 on cross-model chains. Comprehensive evaluation reveals that DDR is robust within $t \\in [0.5, 0.7]$ but degrades at $t{=}0.9$ ($-9.3$ to $-26.0$\\,pp), is prompt-type modulated (continuation $>$ elaboration), and is substantially attenuated under instruction tuning; preliminary equivalence testing (TOST $\\pm$2\\%, $p < 0.001$; $n{=}3$ seeds) suggests no downstream quality degradation (Appendix~\\ref{app:downstream}).\n\\end{enumerate}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex",
    "old_string": "\\begin{enumerate}[nosep,leftmargin=*]\n    \\item We formulate generation depth classification, moving beyond binary detection to ordinal depth estimation (gen-0\\,/\\,gen-1\\,/\\,gen-2+), and construct an evaluation suite of 37K texts from eight generators spanning five model families (0.6B--8B parameters).\n    \\item We decompose inference-chain drift into structurally distinct components: central-tendency features drift monotonically ($d = 0.76$--$1.17$) while shape features remain an order of magnitude more stable ($d < 0.10$), a decomposition absent from existing attractor dynamics and model collapse analyses. A 7-feature ensemble exploiting this \\emph{differential depth response} achieves binary F1\\,=\\,0.830 on cross-model chains.\n    \\item Comprehensive evaluation reveals that DDR is robust within $t \\in [0.5, 0.7]$ but degrades at $t{=}0.9$ ($-9.3$ to $-26.0$\\,pp), is prompt-type modulated (continuation $>$ elaboration), and is substantially attenuated under instruction tuning; equivalence testing (TOST $\\pm$2\\%, $p < 0.001$) suggests no downstream quality degradation (Appendix~\\ref{app:downstream}).\n\\end{enumerate}",
    "new_string": "\\begin{enumerate}[nosep,leftmargin=*]\n    \\item We decompose inference-chain drift into structurally distinct components: central-tendency features drift monotonically ($d = 0.76$--$1.17$) while shape features remain an order of magnitude more stable ($d < 0.10$), a decomposition absent from existing attractor dynamics and model collapse analyses.\n    \\item We formulate generation depth classification, moving beyond binary detection to ordinal depth estimation (gen-0\\,/\\,gen-1\\,/\\,gen-2+), and construct an evaluation suite of 37K texts from eight generators spanning five model families (0.6B--8B parameters).\n    \\item An interpretable 7-feature baseline exploiting this \\emph{differential depth response} achieves binary F1\\,=\\,0.830 on cross-model chains. Comprehensive evaluation reveals that DDR is robust within $t \\in [0.5, 0.7]$ but degrades at $t{=}0.9$ ($-9.3$ to $-26.0$\\,pp), is prompt-type modulated (continuation $>$ elaboration), and is substantially attenuated under instruction tuning; preliminary equivalence testing (TOST $\\pm$2\\%, $p < 0.001$; $n{=}3$ seeds) suggests no downstream quality degradation (Appendix~\\ref{app:downstream}).\n\\end{enumerate}"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-20T11:25:26.420774+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-20T11:25:26.420923+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
  "old_string": "Instruction-tuned models show attenuated fingerprints (OLMo-Instruct LOGO F1\\,=\\,0.338 vs.\\ 0.763 base), but QLoRA on instruct data (F1\\,=\\,0.89--0.91 vs.\\ XGBoost 0.58--0.73; Appendix~\\ref{app:instruct}) indicates instruction tuning reorganizes rather than eliminates the signal, though this is demonstrated under within-model CV only; cross-generator instruct transfer (XGBoost LOGO F1\\,=\\,0.487) remains weak.",
  "new_string": "Instruction-tuned models show attenuated fingerprints (OLMo-Instruct LOGO F1\\,=\\,0.338 vs.\\ 0.763 base), but QLoRA on instruct data (F1\\,=\\,0.89--0.91 vs.\\ XGBoost 0.58--0.73; Appendix~\\ref{app:instruct}) indicates instruction tuning reorganizes rather than eliminates the signal, though this is demonstrated under within-model CV only; cross-generator instruct transfer (XGBoost LOGO F1\\,=\\,0.487) remains weak.\nThe direction reversal of Spearman correlations under instruction tuning (e.g., entropy mean $\\rho$ from $-0.60$ to $+0.23$; Appendix~\\ref{app:instruct}) suggests that alignment reshapes the generation attractor rather than eliminating depth-dependent structure; QLoRA's recovery to F1\\,=\\,0.89--0.91 confirms that token-level signal persists but aggregate summary statistics lose discriminative power under the reshaped distribution."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
    "old_string": "Instruction-tuned models show attenuated fingerprints (OLMo-Instruct LOGO F1\\,=\\,0.338 vs.\\ 0.763 base), but QLoRA on instruct data (F1\\,=\\,0.89--0.91 vs.\\ XGBoost 0.58--0.73; Appendix~\\ref{app:instruct}) indicates instruction tuning reorganizes rather than eliminates the signal, though this is demonstrated under within-model CV only; cross-generator instruct transfer (XGBoost LOGO F1\\,=\\,0.487) remains weak.",
    "new_string": "Instruction-tuned models show attenuated fingerprints (OLMo-Instruct LOGO F1\\,=\\,0.338 vs.\\ 0.763 base), but QLoRA on instruct data (F1\\,=\\,0.89--0.91 vs.\\ XGBoost 0.58--0.73; Appendix~\\ref{app:instruct}) indicates instruction tuning reorganizes rather than eliminates the signal, though this is demonstrated under within-model CV only; cross-generator instruct transfer (XGBoost LOGO F1\\,=\\,0.487) remains weak.\nThe direction reversal of Spearman correlations under instruction tuning (e.g., entropy mean $\\rho$ from $-0.60$ to $+0.23$; Appendix~\\ref{app:instruct}) suggests that alignment reshapes the generation attractor rather than eliminating depth-dependent structure; QLoRA's recovery to F1\\,=\\,0.89--0.91 confirms that token-level signal persists but aggregate summary statistics lose discriminative power under the reshaped distribution."
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-20T11:25:26.421076+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-20T11:25:26.421195+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
  "old_string": "Document-level gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging ($O(1/\\sqrt{n})$ error scaling); the primary difficulty is distinguishing gen-1 from gen-2+, consistent with DDR producing the smallest location shift at the first recursive step (86\\% false negatives; Appendix~\\ref{app:error-analysis}).",
  "new_string": "Document-level gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging ($O(1/\\sqrt{n})$ error scaling); the primary difficulty is distinguishing gen-1 from gen-2+, consistent with DDR producing the smallest location shift at the first recursive step (86\\% false negatives; Appendix~\\ref{app:error-analysis}).\nTwo diagnostic scenarios illustrate practical utility: (a)~training-data batch auditing, where batches exceeding a gen-2+ proportion threshold can be flagged for review; (b)~generation-chain provenance tracing, where known gen-0 seeds enable lineage reconstruction through successive depth predictions.\nIn generator-unknown deployment, the 9.1\\,pp per-generator spread (0.633--0.724) represents estimation uncertainty; the ensemble LOGO F1\\,=\\,0.694 provides a conservative lower bound."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
    "old_string": "Document-level gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging ($O(1/\\sqrt{n})$ error scaling); the primary difficulty is distinguishing gen-1 from gen-2+, consistent with DDR producing the smallest location shift at the first recursive step (86\\% false negatives; Appendix~\\ref{app:error-analysis}).",
    "new_string": "Document-level gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging ($O(1/\\sqrt{n})$ error scaling); the primary difficulty is distinguishing gen-1 from gen-2+, consistent with DDR producing the smallest location shift at the first recursive step (86\\% false negatives; Appendix~\\ref{app:error-analysis}).\nTwo diagnostic scenarios illustrate practical utility: (a)~training-data batch auditing, where batches exceeding a gen-2+ proportion threshold can be flagged for review; (b)~generation-chain provenance tracing, where known gen-0 seeds enable lineage reconstruction through successive depth predictions.\nIn generator-unknown deployment, the 9.1\\,pp per-generator spread (0.633--0.724) represents estimation uncertainty; the ensemble LOGO F1\\,=\\,0.694 provides a conservative lower bound."
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-20T11:25:26.421349+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-20T11:25:26.421483+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-20T11:25:26.421631+00:00_

1	% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains
2	\begin{abstract}
3	Recursive generation by base (pretrained) LLMs shifts \emph{where} text sits in distributional space but leaves \emph{how} it is shaped nearly unchanged, and this asymmetry is consistent across five model families spanning 0.6B to 8B parameters.
4	We term this \emph{differential depth response} (DDR): under standard decoding (temperature $\leq 0.7$, nucleus $p{=}0.9$), mean entropy and lexical diversity drift monotonically with generation depth while entropy max and tail decay show an order-of-magnitude smaller effect size.
5	Prior work on iterative generation tracks aggregate convergence without separating what changes from what is preserved; DDR provides this decomposition and enables coarse depth classification (gen-0\,/\,gen-1\,/\,gen-2+): a 7-feature ensemble achieves leak-free binary F1\,=\,0.694 (95\% CI [.688, .700]) under leave-one-generator-out evaluation and 0.830 on cross-model chains (5-generator subset, LOGO; 95\% CI [.818, .841]), at lower cost than multi-detector alternatives.
6	Despite measurable distributional drift, preliminary equivalence testing (TOST $\pm$2\%, $p < 0.001$; $n{=}3$ seeds) suggests no downstream training quality degradation.
7	The depth signal degrades under instruction tuning; current applicability is restricted to base models.
8	\end{abstract}
9	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-20T11:25:26.421772+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex",
  "offset": "18",
  "limit": "8"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex",
    "offset": "18",
    "limit": "8"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-20T11:25:26.421897+00:00_

18	Our contributions are threefold:
19	\begin{enumerate}[nosep,leftmargin=*]
20	    \item We decompose inference-chain drift into structurally distinct components: central-tendency features drift monotonically ($d = 0.76$--$1.17$) while shape features remain an order of magnitude more stable ($d < 0.10$), a decomposition absent from existing attractor dynamics and model collapse analyses.
21	    \item We formulate generation depth classification, moving beyond binary detection to ordinal depth estimation (gen-0\,/\,gen-1\,/\,gen-2+), and construct an evaluation suite of 37K texts from eight generators spanning five model families (0.6B--8B parameters).
22	    \item An interpretable 7-feature baseline exploiting this \emph{differential depth response} achieves binary F1\,=\,0.830 on cross-model chains. Comprehensive evaluation reveals that DDR is robust within $t \in [0.5, 0.7]$ but degrades at $t{=}0.9$ ($-9.3$ to $-26.0$\,pp), is prompt-type modulated (continuation $>$ elaboration), and is substantially attenuated under instruction tuning; preliminary equivalence testing (TOST $\pm$2\%, $p < 0.001$; $n{=}3$ seeds) suggests no downstream quality degradation (Appendix~\ref{app:downstream}).
23	\end{enumerate}
24	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-20T11:25:26.422024+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-20T11:25:26.422164+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	The central finding is that recursive generation alters \emph{where} the token-level surprise distribution sits but not \emph{how} it is shaped: autoregressive sampling with fixed top-$p$ plausibly truncates the conditional distribution at a consistent shape regardless of input, while mean surprisal systematically decreases as the model conditions on its own increasingly typical outputs.
5	Permutation importance, Granger causality, and feature intervention analyses confirm that DDR features carry causal predictive power beyond correlation: drifting features contribute $5.5\times$ more to classification than near-stationary ones, and 6/7 features exhibit significant Granger causality across generation depths, with entropy\_min as the sole exception (Appendix~\ref{app:ddr-causality}).
6	This asymmetry is not intrinsic to recursion but parameter-dependent: at $t{=}1.0$, the location signal collapses ($\rho$ from $-0.60$ to $-0.002$; Appendix~\ref{app:sampling-sensitivity}), and semantic-preservation constraints attenuate drift (elaboration F1\,=\,0.730 vs.\ continuation 0.781; Appendix~\ref{app:prompt-type}), consistent with \citet{broken_telephone}; cross-type transfer remains viable (F1\,=\,0.753).
7	
8	Several boundary conditions constrain practical applicability.
9	Document-level gen-1 per-class F1\,=\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging ($O(1/\sqrt{n})$ error scaling); the primary difficulty is distinguishing gen-1 from gen-2+, consistent with DDR producing the smallest location shift at the first recursive step (86\% false negatives; Appendix~\ref{app:error-analysis}).
10	Two diagnostic scenarios illustrate practical utility: (a)~training-data batch auditing, where batches exceeding a gen-2+ proportion threshold can be flagged for review; (b)~generation-chain provenance tracing, where known gen-0 seeds enable lineage reconstruction through successive depth predi
…[truncated 2815 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_d031-framing-core_20260520T112415",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 25 · 2026-05-20T11:25:26.422335+00:00_

全部 9 处修改完成：

**abstract.tex (3处)**
- **N1**: L3 — "Recursive LLM generation" → "Recursive generation by base (pretrained) LLMs"
- **W3**: L4 — "under standard decoding" → "under standard decoding (temperature $\leq 0.7$, nucleus $p{=}0.9$)"
- **N2**: L6 — "equivalence testing" → "preliminary equivalence testing (…; $n{=}3$ seeds)"

**introduction.tex (1处)**
- **N4**: L19-22 — 贡献列表重排为 DDR decomposition → task formulation → interpretable baseline + evaluation; 第3条同步加入 preliminary + n=3 seeds 限定

**discussion.tex (3处)**
- **W7**: L10 — 新增两个诊断场景 (batch auditing + provenance tracing)
- **W8**: L11 — 新增 generator-unknown 部署下的 conservative lower bound 说明
- **N1 instruct**: L21 — 新增 ρ 反转机制假说 + QLoRA recovery 解释

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_d031-framing-core_20260520T112415"
}
```

</details>

---
