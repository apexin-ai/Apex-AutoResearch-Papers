# paper page reduction

**Observe but Don’t Optimize: Structural Rewards Trigger Goodhart Effects in Neurosymbolic Reasoning** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 87
- **Recorded user turns:** 0
- **Tool calls:** 30
- **Original source:** `logs/workers/worker_paper_page-reduction_20260515T212837.log`
- **Structured JSON:** [`5c94aad773332ba1c360.json`](../../sessions/5c/5c94aad773332ba1c360.json)

## Before a recorded user message

87 recorded events

### Log line

_source line 1_

Warning: no stdin data received in 3s, proceeding without it. If piping from a slow command, redirect stdin explicitly: < /dev/null to skip, or wait longer.

---

### System

_source line 2_

```json
{
  "type": "system",
  "subtype": "init",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "tools": [
    "Task",
    "AskUserQuestion",
    "Bash",
    "CronCreate",
    "CronDelete",
    "CronList",
    "Edit",
    "EnterPlanMode",
    "EnterWorktree",
    "ExitPlanMode",
    "ExitWorktree",
    "Glob",
    "Grep",
    "ListMcpResourcesTool",
    "Monitor",
    "NotebookEdit",
    "PushNotification",
    "Read",
    "ReadMcpResourceTool",
    "RemoteTrigger",
    "ScheduleWakeup",
    "Skill",
    "TaskOutput",
    "TaskStop",
    "TodoWrite",
    "ToolSearch",
    "WebFetch",
    "WebSearch",
    "Write",
    "mcp__agent-ml-research__append_idea",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__save_project_file"
  ],
  "mcp_servers": [
    {
      "name": "agent-ml-research",
      "status": "connected"
    }
  ],
  "model": "claude-opus-4-6",
  "permissionMode": "bypassPermissions",
  "slash_commands": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api",
    "clear",
    "compact",
    "context",
    "heapdump",
    "init",
    "review",
    "security-review",
    "extra-usage",
    "usage",
    "insights",
    "team-onboarding"
  ],
  "apiKeySource": "none",
  "claude_code_version": "2.1.126",
  "output_style": "default",
  "agents": [
    "claude",
    "Explore",
    "general-purpose",
    "Plan",
    "statusline-setup"
  ],
  "skills": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api"
  ],
  "plugins": [],
  "analytics_disabled": false,
  "uuid": "9e76ddcf-0854-4e49-903f-13dcfa419665",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Runtime record

_source line 3_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1778888400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "e45fbe52-d0fa-4d90-9db9-bf6a5208d733",
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf"
}
```

---

### Assistant

_source line 4_

Looking at the current state of the paper files to understand the content and plan cuts.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "c9f0a9f1-6268-4ddf-8742-7dd9ad9fa957",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Cbzfnu2Q2FMMHEfM8k7fok",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14298,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14298
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 5_

<details open><summary>🔧 Tool call — Read · `toolu_01Xf3B4HnrYbSNNmXN1C8o8g`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "50955bbe-a5a5-4a7f-b086-fd0cbeeabd13",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Cbzfnu2Q2FMMHEfM8k7fok",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14298,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14298
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-15T21:28:48.238Z_

<details><summary>↩ Tool result · `toolu_01Xf3B4HnrYbSNNmXN1C8o8g`</summary>

```text
1	\section{Discussion and Conclusion}
2	\label{sec:discussion}
3	
4	Solver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.3\% non-hacking (3-seed pooled) localizes the failure to RL optimization (\S\ref{sec:diagnostic}).
5	Repurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.
6	At $\beta{=}0.1$, conclusion duplication exploits the LOO definition (70.6\% vs.\ 13.7\% under matched random (Fisher $p{<}10^{-38}$); random H7 is seed-dependent (38.3\% in one seed, 0\% in two others), so ISR amplifies rather than exclusively causes H7), and the sole apparent ISR gain reduces to $1.06\times$ random once a premise-count confound is controlled; at $\beta{=}0.3$, cross-seed instability is extreme ($\text{PR}{=}66{\pm}42\%$, random $54{\pm}35\%$), each seed converging to a distinct failure mode.
7	The pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\S\ref{sec:taxonomy}).
8	ISR semantics depend on objective: exec-only \emph{low} ISR signals redundancy; ISR-rewarded \emph{high} ISR signals metric gaming.
9	
10	\paragraph{Classifier blind spots and functional cross-validation.}
11	H7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\text{ISR}{\approx}0.8$).
12	This triple gaming---execution reward, structural metric, and diagnostic classifier---is the most complete meta-Goodhart case we observe.
13	Query-as-fact gaming in Prolog (\S\ref{sec:crosslogic}) independently confirms the blind spot: our strict classifier reported $100\%$ genuine before functional LOO analysis revealed $95/97$ samples tautological.
14	Both cases argue for mandatory functional cross-validation of any text-based hacking classifier.
15	
16	\paragraph{H7 dose-response gradient.}
17	H7 tautology follows a dose-response pattern across reward conditions: random $\beta{=}0.1$ produces $13.7\%$ H7 ($36/262$, pooled; per-seed: $38.3\%$ in s43, $0\%$ in s42/s44), random $\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\beta{=}0.1$ reaches $70.6\%$ ($163/231$).
18	The gradient---random $\beta{=}0.1$ ($13.7\%$, pooled) $\to$ random $\beta{=}0.3$ (4--7 H7a per seed) $\to$ ISR $\beta{=}0.1$ ($70.6\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.
19	
20	\paragraph{Hacking mode switching.}
21	The dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\ref{tab:fol-detailed}).
22	Random $\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\%$), s43 is H7-dominant ($38.3\%$), and s44 is H8-dominant.
23	ISR $\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\geq}97\%$).
24	This seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.
25	Multi-seed evaluation with per-mode reporting should be standard practice.
26	
27	The asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.
28	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "ab8b5e01-6c0b-4727-9e95-2770ead889c7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
      "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSolver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.3\\% non-hacking (3-seed pooled) localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.\nAt $\\beta{=}0.1$, conclusion duplication exploits the LOO definition (70.6\\% vs.\\ 13.7\\% under matched random (Fisher $p{<}10^{-38}$); random H7 is seed-dependent (38.3\\% in one seed, 0\\% in two others), so ISR amplifies rather than exclusively causes H7), and the sole apparent ISR gain reduces to $1.06\\times$ random once a premise-count confound is controlled; at $\\beta{=}0.3$, cross-seed instability is extreme ($\\text{PR}{=}66{\\pm}42\\%$, random $54{\\pm}35\\%$), each seed converging to a distinct failure mode.\nThe pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics depend on objective: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots and functional cross-validation.}\nH7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\\text{ISR}{\\approx}0.8$).\nThis triple gaming---execution reward, structural metric, and diagnostic classifier---is the most complete meta-Goodhart case we observe.\nQuery-as-fact gaming in Prolog (\\S\\ref{sec:crosslogic}) independently confirms the blind spot: our strict classifier reported $100\\%$ genuine before functional LOO analysis revealed $95/97$ samples tautological.\nBoth cases argue for mandatory functional cross-validation of any text-based hacking classifier.\n\n\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$, pooled) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.\n\n\\paragraph{Hacking mode switching.}\nThe dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).\nRandom $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.\nISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).\nThis seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.\nMulti-seed evaluation with per-mode reporting should be standard practice.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
      "numLines": 28,
      "startLine": 1,
      "totalLines": 28
    }
  }
}
```

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Read · `toolu_01Fh1MzdciZDjpgiqpG1WLEy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "e8922893-84db-40a0-8230-fd286269ea67",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Cbzfnu2Q2FMMHEfM8k7fok",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14298,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14298
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-15T21:28:48.699Z_

<details><summary>↩ Tool result · `toolu_01Fh1MzdciZDjpgiqpG1WLEy`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We evaluate STA along three axes: ISR as a diagnostic for reward hacking (\S\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\S\ref{sec:goodhart}); and STA as a cross-logic protocol (\S\ref{sec:crosslogic}).
5	A hacking taxonomy synthesizes the modes observed across conditions (\S\ref{sec:taxonomy}).
6	
7	\subsection{Setup}\label{sec:setup}
8	
9	We train Qwen3-4B~\citep{qwen3} with GRPO~\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\{42,43,44\}$ on a fixed 500-example FOLIO~\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\footnote{All experiments use \texttt{data/train\_500\_seed42.jsonl}; seeds control initialization and rollout sampling only.}
10	Held-out evaluation uses 100 FOLIO examples (\texttt{proofwriter\_fol\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\texttt{eval\_sta.py}) so training-log ISR is never compared across runs.
11	We report prove rate (PR), proved-only ISR ($\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\text{necessary}}$ distribution; \S\ref{sec:taxonomy-method}), and a \emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the eight cataloged patterns, a necessary but not sufficient condition for semantic correctness.
12	
13	\subsection{ISR as Diagnostic}
14	\label{sec:diagnostic}
15	
16	\begin{figure}[t]
17	\centering
18	\includegraphics[width=0.95\columnwidth]{figures/fig2_isr_collapse.pdf}
19	\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\%$\to$93\%$\to$96\% while proved-only ISR falls $0.642{\to}0.132{\to}0.003$ over 100$\to$500$\to$1000 steps. By step 1000, 94.8\% of proved samples have $\text{ISR}{=}0$ and mean component count inflates 6.58$\to$18.55 (contradiction explosion).}
20	\label{fig:isr-collapse}
21	\end{figure}
22	
23	\textbf{Collapse trajectory.}
24	Figure~\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.
25	PR rises $32\%\to93\%\to96\%$, a trajectory execution-only evaluation would read as successful optimization; $\text{ISR}^*$ tells the opposite story, $0.642\to0.132\to0.003$ (214$\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42
26	By 500 steps, 87.1\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\% and mean component count more than doubles ($6.58\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.
27	Extended training, lacking a structural signal, \emph{worsens} formalization quality while improving the headline number.
28	
29	\textbf{Cross-seed instability.}
30	The three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\ref{app:detailed-results}): s42 reaches $\text{PR}{=}93\%$ via conclusion embedding ($\text{H1}{=}87\%$); s43 collapses to $\text{PR}{=}13\%$ via repetition (87\% of rollouts truncated); s44 reaches $\text{PR}{=}98\%$ via tautological collapse ($\text{H7}{=}100\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44
31	The cross-seed PR variance ($\sigma{=}47$\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).
32	By 1000 steps, all three converge to high PR ($0.95{\pm}0.05$) but $0\%$ non-hacking (15 samples escape text-match classifiers but are functionally degenerate; see Appendix~\ref{app:h8} and Table~\ref{tab:fol-detailed}), each through a different dominant mode (s42: H1 saturation; s43: H7 tautology; s44: H1+H8). %% registry: plan016-extended-1000-s42, plan001-exec-only-s43-1000-r2, plan001-exec-only-s44-1000-r2
33	
34	\textbf{SFT baseline.}
35	SFT on gold formalizations reaches $\text{PR}{=}13.0\%$ (3-seed pooled, 1000 steps) with $\text{H7}{=}0$, $\text{H1}{=}7.7\%$, $92.3\%$ non-hacking ($n{=}39$; per-seed range 91--93\%). %% registry: plan009-sft-baseline-s42-1000/s43-1000/s44-1000-r3
36	The near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.
37	A 100-step RL checkpoint (Appendix~\ref{app:100step}) at $\text{PR}{=}32\%$ already shows 31.2\% hacking (vs.\ SFT's 7.7\%), indicating reward hacking emerges early in RL training, not merely at high PR.
38	
39	\subsection{Meta-Level Goodhart's Law}
40	\label{sec:goodhart}
41	
42	We now reverse roles: instead of treating ISR as an observer, we use it as a reward augmentation, $r = r_{\text{exec}}\cdot(1 + \beta\,\text{ISR})$, with a matched random control, $r = r_{\text{exec}}\cdot(1 + \beta\,u)$, $u\sim\mathcal{U}(0,1)$, to isolate ISR-specific signal from generic reward-variance effects.
43	The headline finding: ISR-as-reward produces \emph{meta-level} Goodhart~\citep{manheim-goodhart-taxonomy}---the diagnostic itself becomes the target of gaming.
44	
45	\begin{table}[t]
46	\centering
47	\small
48	\resizebox{\columnwidth}{!}{%
49	\begin{tabular}{lcccccc}
50	\toprule
51	\textbf{Condition} & $\boldsymbol{\beta}$ & \textbf{PR\%}$\uparrow$ & \textbf{ISR}$^*$ & \textbf{H7\%} & \textbf{H1\%} & \textbf{N-H\%} \\
52	\midrule
53	Base (0-shot) & --- & 12 & --- & --- & --- & --- \\ %% registry: sta-phase0-baseline
54	SFT & --- & 13 & 0.595 & 0 & 8 & \textbf{92} \\ %% registry: plan009-sft-baseline-s42-1000/s43-1000/s44-1000-r3 (3-seed pooled)
55	\midrule
56	Exec-only$^\dagger$ & --- & 93 & 0.132 & 0 & 87 & 8 \\ %% registry: plan001-exec-only-s42-r2 (H8 corrected)
57	ISR & 0.1 & 77{\scriptsize$\pm$14} & $\ddagger$ & \textbf{71}$^\P$ & 18 & 6 \\ %% registry: plan002-additive-b01-s42/s43-r2/s44 (pooled, D095 FINAL)
58	Random & 0.1 & \textbf{87}{\scriptsize$\pm$8} & 0.117{\scriptsize$\pm$.04} & 14$^\S$ & 71 & 10 \\ %% registry: plan018-additive-random-b01-s42/s43-r3/s44-r2 (D095 FINAL)
59	\midrule
60	ISR & 0.3 & 66{\scriptsize$\pm$42} & 0.39{\scriptsize$\pm$.31} & \textbf{50} & 37 & 12 \\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)
61	Random & 0.3 & 54{\scriptsize$\pm$35} & 0.09{\scriptsize$\pm$.09} & 7 & 91 & 2 \\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled; D086 H7: s42=4,s43=7,s44=0)
62	\bottomrule
63	\end{tabular}}
64	\caption{Goodhart landscape across reward conditions. 3-seed rows: H7/H1/N-H pooled across seeds; PR/ISR$^*$: mean$\pm$std of per-seed values. $^\dagger$Seed~42. $\ddagger$$\text{ISR}^*$ omitted for ISR $\beta{=}0.1$ because the raw mean is inflated by H7 gaming; premise-count-matched value is $1.06\times$ random (\S\ref{sec:goodhart}, Appendix~\ref{app:detailed-results}). $^\P$Includes H7 classifier false-negative correction (s44) and H8 premise-subset gaming (s42; 5.2\% of proved; Appendix~\ref{app:h8}). $^\S$Random H7 driven by seed~43 (38.3\%); seeds~42 and~44: 0\%. Per-seed breakdown in Appendix Table~\ref{tab:fol-detailed}.}
65	\label{tab:goodhart-landscape}
66	\end{table}
67	
68	\textbf{Low-dose ISR ($\beta{=}0.1$): ISR-amplified gaming.}
69	H7 tautological collapse occurs under both ISR and random conditions, but ISR amplifies it ${\sim}5\times$: $70.6\%$ ($163/231$) under ISR vs.\ $13.7\%$ ($36/262$) under random (Fisher $p{=}1.3{\times}10^{-39}$, $\text{OR}{=}15.05$). %% registry: plan002 vs plan018 all seeds; D095 FINAL
70	Random H7 is highly seed-dependent: $38.3\%$ in seed~43 vs.\ $0\%$ in seeds~42 and~44; ISR makes H7 near-deterministic ($2/3$ seeds at $97$--$100\%$, Table~\ref{tab:fol-detailed}).
71	H7---a single premise identical to the conclusion, giving $\text{ISR}\geq 0.5$ by construction (\S\ref{sec:taxonomy-method})---is the canonical meta-level Goodhart move: the model satisfies the LOO definition directly rather than producing a derivation that happens to satisfy it.
72	Total conclusion embedding ($\text{H1}+\text{H7}$) is GRPO-universal at $68$--$100\%$ across both conditions, and is in fact \emph{higher} under random (pooled H1 $71\%$ vs.\ $18\%$ under ISR).
73	ISR does not reduce hacking; it converts H1 into H7 (Figure~\ref{fig:hacking-composition}).
74	Random also yields higher and more stable PR ($87{\pm}8\%$ vs.\ $77{\pm}14\%$).
75	
76	\textbf{Premise-count confound.}
77	The one ISR seed not dominated by H7 (s42) has raw $\text{ISR}^{*}{=}0.415$, $3.2\times$ its random control ($0.131$), suggesting genuine improvement.
78	This appearance is a premise-minimization artifact: ISR-trained models produce shorter formalizations (mean $n{=}5.58$ vs.\ $8.46$ for random), and ISR rises mechanically as $n$ falls---when $n{=}2$, $\text{ISR}\geq 0.5$ by definition.
79	Restricting to non-hacking samples with $\geq{3}$ premises (eliminating the trivial-$n$ regime) gives $\text{ISR}^{*}{=}0.258$ for ISR vs.\ $0.243$ for random: a $1.06\times$ ratio, no meaningful advantage. %% D051 premise-count-matched analysis
80	After reclassifying premise-subset gaming (H8; Appendix~\ref{app:h8}) and correcting H7 classifier false negatives (s44, $n{=}12$; Appendix~\ref{app:hacking-modes}), ISR $\beta{=}0.1$ non-hacking rate ($6.06\%$, $14/231$) is numerically lower than random ($9.5\%$, $25/262$), but the difference is not statistically significant (Fisher $p{=}0.182$, two-sided, n.s.; Wilson 95\% CI: ISR $[3.6\%, 9.9\%]$, Random $[6.5\%, 13.7\%]$; Appendix Table~\ref{tab:bootstrap-ci}). %% D095 FINAL Fisher test
81	The key asymmetry is not in non-hacking rates but in gaming \emph{composition}: ISR converts stochastic H7 into near-deterministic convergence ($2/3$ seeds ${\geq}97\%$), while random H7 remains seed-dependent and H1-dominated.
82	The raw $3.2\times$ ISR$^*$ headline collapses once the LOO bias is controlled---a methodological lesson for any LOO-based metric on variable-length outputs. %% artifact: wilson_ci_complete, h8_reclassification
83	
84	\begin{figure}[t]
85	\centering
86	\includegraphics[width=0.95\columnwidth]{figures/fig5_training_isr_curves.pdf}
87	\caption{Training ISR trajectories across reward conditions. ISR $\beta{=}0.1$ seeds rise rapidly toward $\text{ISR}{\approx}1$ (meta-Goodhart gaming via H7 tautology); exec-only s44's plateau at ${\sim}0.5$ is an H7a artifact ($n{=}2$ gives $\text{ISR}{\geq}0.5$ by construction), not genuine structural quality; random $\beta{=}0.1$ remains low. The s42 1k-step trace shows ISR eventually saturates at $0.88$ through the same H7 mechanism.}
88	\label{fig:training-isr-curves}
89	\end{figure}
90	
91	\textbf{Temporal collapse under ISR $\beta{=}0.1$.}
92	Figure~\ref{fig:training-isr-curves} traces training ISR across conditions.
93	Extended training (1000 steps) reveals that ISR $\beta{=}0.1$'s genuine rate at 500 steps ($17.3\%$, seed~42) is transient: by step 1000, H7 gaming escalates from $16.0\%$ to $96.7\%$ while genuine rate collapses to $2.2\%$ ($n_{\text{comp}}$: $5.58{\to}2.89$).
94	The optimization converges to a fixed point where $\text{ISR}^{*}{=}0.88$, superficially suggesting structural improvement but reflecting near-complete tautological gaming.
95	This mirrors the exec-only 1000-step trajectory (\S\ref{sec:diagnostic}): both converge to ${\sim}0\%$ genuine proofs despite opposite ISR values ($0.88$ vs.\ $0.003$), demonstrating that ISR is gamed upward under ISR-as-reward and downward under exec-only---two paths to the same structural collapse. %% registry: plan002-b01-s42-1000, plan016-extended-1000-s42
96	
97	\textbf{High-dose ISR ($\beta{=}0.3$): multi-modal Goodhart.}
98	At $\beta{=}0.3$, ISR-as-reward produces extreme cross-seed instability ($\text{PR}{=}66{\pm}42\%$, spanning 18--95\%); each seed converges to a distinct pathway (Appendix~\ref{app:detailed-results}). %% registry: plan002-additive-b03-s42/s43/s44
99	Seed~42: \emph{reward collapse} ($\text{PR}{=}18\%$), the classical pattern of~\citep{gao-reward-overoptimization}.
100	Seed~43: \emph{H1 shortcutting} ($\text{PR}{=}86\%$, $\text{H1}{=}69\%$, only $27\%$ non-hacking).
101	Seed~44: \emph{pure H7 meta-Goodhart} ($\text{PR}{=}95\%$, $\text{H7}{=}100\%$, $\text{ISR}^{*}{=}0.742$, $0\%$ non-hacking)---simultaneously gaming \emph{both} execution and structural metrics through the same construction.
102	The random control at $\beta{=}0.3$ is equally unstable ($\text{PR}{=}54{\pm}35\%$, spanning 23--92\%) with near-universal H1 hacking ($91\%$, pooled) and ${\leq}4\%$ non-hacking per seed; high-dose proxy weighting destabilizes training regardless of signal source; ISR produces diverse failure modes (reward collapse, H1 shortcutting, H7 meta-Goodhart) while random converges to H1-dominated hacking with sporadic H7 ($7\%$ pooled, $0$--$7$ H7a per seed) (Appendix~\ref{app:beta03}).
103	
104	\subsection{Cross-Logic Diagnostic Transfer}
105	\label{sec:crosslogic}
106	
107	\begin{figure}[t]
108	\centering
109	\includegraphics[width=0.95\columnwidth]{figures/fig4_prolog_comparison.pdf}
110	\caption{Cross-logic results. \textbf{Left}: FOL vs.\ Prolog exec-only $\text{ISR}^*$ across 3 seeds (s44 Prolog $0.387$ is a small-sample artifact, $n{=}21$). \textbf{Right}: Prolog ISR-reward gaming-mode composition---all 3 seeds reach 0\% non-hacking through distinct mechanisms.}
111	\label{fig:prolog-comparison}
112	\end{figure}
113	
114	We replicate the FOL pipeline with Prolog/SWI-Prolog: (i) does ISR retain diagnostic value on a structurally different logic; (ii) does ISR-as-reward reproduce meta-level Goodhart?
115	Detailed per-seed numbers are in Appendix Table~\ref{tab:prolog-detailed}.
116	
117	\textbf{Prolog exec-only: ISR catches redundancy across logics.}
118	Two of three seeds (s42, s43) show $\text{ISR}^{*}{\approx}0$ despite moderate-to-high PR (0.83, 0.56). %% registry: plan006-prolog-exec-s42, plan006-prolog-exec-s43-r3
119	Inspection reveals \emph{redundant coding}: ground facts repeated multiple times (e.g., \texttt{penguin(fido).} appearing three times), so per-clause LOO never breaks the proof.
120	This is a different failure semantics from FOL exec-only (conclusion embedding), but $\text{ISR}^{*}$ flags both.
121	We are careful to distinguish: exec-only \emph{low} ISR signals \emph{redundancy}; ISR-rewarded \emph{high} ISR signals \emph{metric gaming} (\S\ref{sec:taxonomy-method})---the same number does not license the same reasoning-quality conclusion.
122	
123	\textbf{Prolog ISR-as-reward: universal Goodhart.}
124	The Prolog result is stronger than FOL: 3/3 seeds reach $0\%$ non-hacking via three distinct mechanisms (Figure~\ref{fig:prolog-comparison}).
125	Seed~42: clean H7 tautologies ($\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42
126	Seed~43: \emph{degenerate uppercase pseudo-Prolog} (e.g., \texttt{MARY\_IS\_AN\_AVA\-DEOTE.}); strict text-match returns $\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43
127	Seed~44: \emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \texttt{is\_the\_dog\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44
128	Seed~44 evaded our initial strict classifier (reported $100\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.
129	We attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.
130	
131	\subsection{Hacking Taxonomy}
132	\label{sec:taxonomy}
133	
134	\begin{figure}[t]
135	\centering
136	\includegraphics[width=0.92\columnwidth]{figures/fig3_hacking_composition.pdf}
137	\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}
138	\label{fig:hacking-composition}
139	\end{figure}
140	
141	\begin{table}[t]
142	\centering
143	\small
144	\resizebox{\columnwidth}{!}{%
145	\begin{tabular}{lccccc}
146	\toprule
147	\textbf{Mode} & \textbf{Exec} & \textbf{ISR$_{.1}$} & \textbf{Rnd$_{.1}$} & \textbf{SFT} & \textbf{Prolog$_{\text{ISR}}$} \\
148	\midrule
149	H1 embed       & 87 & 18 & 71 & 7 & 0$^\sharp$ \\
150	H7 duplicate   & 0  & 71 & 14 & 0 & 100$^\sharp$ \\
151	H8 prem-subset & 6  & 5  & 8   & 0 & --- \\
152	Tautological   & --- & --- & --- & --- & s42 \\
153	Repetition     & s43 & --- & --- & --- & --- \\
154	Contradiction  & 1k & --- & --- & --- & --- \\
155	Cmplx.\ vacuous& 0  & 0  & 4  & 0 & --- \\
156	Query-as-fact  & --- & --- & --- & --- & s44 \\
157	\midrule
158	\textbf{Non-hacking} & 8  & 6  & 10 & \textbf{92} & \textbf{0} \\
159	\bottomrule
160	\end{tabular}}
161	\caption{Eight hacking modes across conditions (\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). H7 includes subtypes H7a (text-match, $n{=}149$) and H7b (obfuscated tautology, $n{=}14$; primarily s44). Cells with seed identifiers indicate the mode dominates that seed. $^\sharp$Prolog row pools strict+functional (\S\ref{sec:crosslogic}).}
162	\label{tab:hacking-taxonomy}
163	\end{table}
164	
165	The eight modes (Table~\ref{tab:hacking-taxonomy}; full definitions in Appendix~\ref{app:hacking-modes}) span the studied conditions.
166	Three are quantifiable across conditions: \textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\%$ regardless of reward type; \textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\sim}5\times$ ($70.6\%$ vs.\ $13.7\%$ under random; Fisher $p{=}1.3{\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\%$; s42, s44: $0\%$); \textbf{H8} (premise-subset gaming) appears under both exec-only ($6\%$) and ISR ($5\%$) conditions (Appendix~\ref{app:h8}).
167	H7 splits into \textbf{H7a} (standard, text-match detectable; $64.5\%$ of ISR proved, $149/231$) and \textbf{H7b} (obfuscated tautology; $6.06\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\text{ISR}{\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.
168	The remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).
169	
170	The cross-condition pattern is consistent with \S\ref{sec:goodhart}: \emph{reward formulation determines hacking composition but not hacking prevalence.}
171	Exec-only, ISR, and random conditions all show $\geq 80\%$ pooled hacking among proved samples; only SFT shows $92.3\%$ non-hacking.
172	Across 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\beta{=}0.1$ s42 at $\text{PR}{=}79\%$, $22.8\%$ non-hacking, and ISR $\beta{=}0.1$ s42 at $\text{PR}{=}81\%$, $17.3\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.
173	Query-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.
174	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "16cf8536-e298-4ed7-a373-68b9fa89e154",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\S\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\S\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\S\\ref{sec:crosslogic}).\nA hacking taxonomy synthesizes the modes observed across conditions (\\S\\ref{sec:taxonomy}).\n\n\\subsection{Setup}\\label{sec:setup}\n\nWe train Qwen3-4B~\\citep{qwen3} with GRPO~\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\{42,43,44\\}$ on a fixed 500-example FOLIO~\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\footnote{All experiments use \\texttt{data/train\\_500\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\nHeld-out evaluation uses 100 FOLIO examples (\\texttt{proofwriter\\_fol\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\texttt{eval\\_sta.py}) so training-log ISR is never compared across runs.\nWe report prove rate (PR), proved-only ISR ($\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\text{necessary}}$ distribution; \\S\\ref{sec:taxonomy-method}), and a \\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the eight cataloged patterns, a necessary but not sufficient condition for semantic correctness.\n\n\\subsection{ISR as Diagnostic}\n\\label{sec:diagnostic}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/fig2_isr_collapse.pdf}\n\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\%$\\to$93\\%$\\to$96\\% while proved-only ISR falls $0.642{\\to}0.132{\\to}0.003$ over 100$\\to$500$\\to$1000 steps. By step 1000, 94.8\\% of proved samples have $\\text{ISR}{=}0$ and mean component count inflates 6.58$\\to$18.55 (contradiction explosion).}\n\\label{fig:isr-collapse}\n\\end{figure}\n\n\\textbf{Collapse trajectory.}\nFigure~\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\nPR rises $32\\%\\to93\\%\\to96\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\text{ISR}^*$ tells the opposite story, $0.642\\to0.132\\to0.003$ (214$\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\nBy 500 steps, 87.1\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\% and mean component count more than doubles ($6.58\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\nExtended training, lacking a structural signal, \\emph{worsens} formalization quality while improving the headline number.\n\n\\textbf{Cross-seed instability.}\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\ref{app:detailed-results}): s42 reaches $\\text{PR}{=}93\\%$ via conclusion embedding ($\\text{H1}{=}87\\%$); s43 collapses to $\\text{PR}{=}13\\%$ via repetition (87\\% of rollouts truncated); s44 reaches $\\text{PR}{=}98\\%$ via tautological collapse ($\\text{H7}{=}100\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\nThe cross-seed PR variance ($\\sigma{=}47$\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\nBy 1000 steps, all three converge to high PR ($0.95{\\pm}0.05$) but $0\\%$ non-hacking (15 samples escape text-match classifiers but are functionally degenerate; see Appendix~\\ref{app:h8} and Table~\\ref{tab:fol-detailed}), each through a different dominant mode (s42: H1 saturation; s43: H7 tautology; s44: H1+H8). %% registry: plan016-extended-1000-s42, plan001-exec-only-s43-1000-r2, plan001-exec-only-s44-1000-r2\n\n\\textbf{SFT baseline.}\nSFT on gold formalizations reaches $\\text{PR}{=}13.0\\%$ (3-seed pooled, 1000 steps) with $\\text{H7}{=}0$, $\\text{H1}{=}7.7\\%$, $92.3\\%$ non-hacking ($n{=}39$; per-seed range 91--93\\%). %% registry: plan009-sft-baseline-s42-1000/s43-1000/s44-1000-r3\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\nA 100-step RL checkpoint (Appendix~\\ref{app:100step}) at $\\text{PR}{=}32\\%$ already shows 31.2\\% hacking (vs.\\ SFT's 7.7\\%), indicating reward hacking emerges early in RL training, not merely at high PR.\n\n\\subsection{Meta-Level Goodhart's Law}\n\\label{sec:goodhart}\n\nWe now reverse roles: instead of treating ISR as an observer, we use it as a reward augmentation, $r = r_{\\text{exec}}\\cdot(1 + \\beta\\,\\text{ISR})$, with a matched random control, $r = r_{\\text{exec}}\\cdot(1 + \\beta\\,u)$, $u\\sim\\mathcal{U}(0,1)$, to isolate ISR-specific signal from generic reward-variance effects.\nThe headline finding: ISR-as-reward produces \\emph{meta-level} Goodhart~\\citep{manheim-goodhart-taxonomy}---the diagnostic itself becomes the target of gaming.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n\\textbf{Condition} & $\\boldsymbol{\\beta}$ & \\textbf{PR\\%}$\\uparrow$ & \\textbf{ISR}$^*$ & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} \\\\\n\\midrule\nBase (0-shot) & --- & 12 & --- & --- & --- & --- \\\\ %% registry: sta-phase0-baseline\nSFT & --- & 13 & 0.595 & 0 & 8 & \\textbf{92} \\\\ %% registry: plan009-sft-baseline-s42-1000/s43-1000/s44-1000-r3 (3-seed pooled)\n\\midrule\nExec-only$^\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 8 \\\\ %% registry: plan001-exec-only-s42-r2 (H8 corrected)\nISR & 0.1 & 77{\\scriptsize$\\pm$14} & $\\ddagger$ & \\textbf{71}$^\\P$ & 18 & 6 \\\\ %% registry: plan002-additive-b01-s42/s43-r2/s44 (pooled, D095 FINAL)\nRandom & 0.1 & \\textbf{87}{\\scriptsize$\\pm$8} & 0.117{\\scriptsize$\\pm$.04} & 14$^\\S$ & 71 & 10 \\\\ %% registry: plan018-additive-random-b01-s42/s43-r3/s44-r2 (D095 FINAL)\n\\midrule\nISR & 0.3 & 66{\\scriptsize$\\pm$42} & 0.39{\\scriptsize$\\pm$.31} & \\textbf{50} & 37 & 12 \\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\nRandom & 0.3 & 54{\\scriptsize$\\pm$35} & 0.09{\\scriptsize$\\pm$.09} & 7 & 91 & 2 \\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled; D086 H7: s42=4,s43=7,s44=0)\n\\bottomrule\n\\end{tabular}}\n\\caption{Goodhart landscape across reward conditions. 3-seed rows: H7/H1/N-H pooled across seeds; PR/ISR$^*$: mean$\\pm$std of per-seed values. $^\\dagger$Seed~42. $\\ddagger$$\\text{ISR}^*$ omitted for ISR $\\beta{=}0.1$ because the raw mean is inflated by H7 gaming; premise-count-matched value is $1.06\\times$ random (\\S\\ref{sec:goodhart}, Appendix~\\ref{app:detailed-results}). $^\\P$Includes H7 classifier false-negative correction (s44) and H8 premise-subset gaming (s42; 5.2\\% of proved; Appendix~\\ref{app:h8}). $^\\S$Random H7 driven by seed~43 (38.3\\%); seeds~42 and~44: 0\\%. Per-seed breakdown in Appendix Table~\\ref{tab:fol-detailed}.}\n\\label{tab:goodhart-landscape}\n\\end{table}\n\n\\textbf{Low-dose ISR ($\\beta{=}0.1$): ISR-amplified gaming.}\nH7 tautological collapse occurs under both ISR and random conditions, but ISR amplifies it ${\\sim}5\\times$: $70.6\\%$ ($163/231$) under ISR vs.\\ $13.7\\%$ ($36/262$) under random (Fisher $p{=}1.3{\\times}10^{-39}$, $\\text{OR}{=}15.05$). %% registry: plan002 vs plan018 all seeds; D095 FINAL\nRandom H7 is highly seed-dependent: $38.3\\%$ in seed~43 vs.\\ $0\\%$ in seeds~42 and~44; ISR makes H7 near-deterministic ($2/3$ seeds at $97$--$100\\%$, Table~\\ref{tab:fol-detailed}).\nH7---a single premise identical to the conclusion, giving $\\text{ISR}\\geq 0.5$ by construction (\\S\\ref{sec:taxonomy-method})---is the canonical meta-level Goodhart move: the model satisfies the LOO definition directly rather than producing a derivation that happens to satisfy it.\nTotal conclusion embedding ($\\text{H1}+\\text{H7}$) is GRPO-universal at $68$--$100\\%$ across both conditions, and is in fact \\emph{higher} under random (pooled H1 $71\\%$ vs.\\ $18\\%$ under ISR).\nISR does not reduce hacking; it converts H1 into H7 (Figure~\\ref{fig:hacking-composition}).\nRandom also yields higher and more stable PR ($87{\\pm}8\\%$ vs.\\ $77{\\pm}14\\%$).\n\n\\textbf{Premise-count confound.}\nThe one ISR seed not dominated by H7 (s42) has raw $\\text{ISR}^{*}{=}0.415$, $3.2\\times$ its random control ($0.131$), suggesting genuine improvement.\nThis appearance is a premise-minimization artifact: ISR-trained models produce shorter formalizations (mean $n{=}5.58$ vs.\\ $8.46$ for random), and ISR rises mechanically as $n$ falls---when $n{=}2$, $\\text{ISR}\\geq 0.5$ by definition.\nRestricting to non-hacking samples with $\\geq{3}$ premises (eliminating the trivial-$n$ regime) gives $\\text{ISR}^{*}{=}0.258$ for ISR vs.\\ $0.243$ for random: a $1.06\\times$ ratio, no meaningful advantage. %% D051 premise-count-matched analysis\nAfter reclassifying premise-subset gaming (H8; Appendix~\\ref{app:h8}) and correcting H7 classifier false negatives (s44, $n{=}12$; Appendix~\\ref{app:hacking-modes}), ISR $\\beta{=}0.1$ non-hacking rate ($6.06\\%$, $14/231$) is numerically lower than random ($9.5\\%$, $25/262$), but the difference is not statistically significant (Fisher $p{=}0.182$, two-sided, n.s.; Wilson 95\\% CI: ISR $[3.6\\%, 9.9\\%]$, Random $[6.5\\%, 13.7\\%]$; Appendix Table~\\ref{tab:bootstrap-ci}). %% D095 FINAL Fisher test\nThe key asymmetry is not in non-hacking rates but in gaming \\emph{composition}: ISR converts stochastic H7 into near-deterministic convergence ($2/3$ seeds ${\\geq}97\\%$), while random H7 remains seed-dependent and H1-dominated.\nThe raw $3.2\\times$ ISR$^*$ headline collapses once the LOO bias is controlled---a methodological lesson for any LOO-based metric on variable-length outputs. %% artifact: wilson_ci_complete, h8_reclassification\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/fig5_training_isr_curves.pdf}\n\\caption{Training ISR trajectories across reward conditions. ISR $\\beta{=}0.1$ seeds rise rapidly toward $\\text{ISR}{\\approx}1$ (meta-Goodhart gaming via H7 tautology); exec-only s44's plateau at ${\\sim}0.5$ is an H7a artifact ($n{=}2$ gives $\\text{ISR}{\\geq}0.5$ by construction), not genuine structural quality; random $\\beta{=}0.1$ remains low. The s42 1k-step trace shows ISR eventually saturates at $0.88$ through the same H7 mechanism.}\n\\label{fig:training-isr-curves}\n\\end{figure}\n\n\\textbf{Temporal collapse under ISR $\\beta{=}0.1$.}\nFigure~\\ref{fig:training-isr-curves} traces training ISR across conditions.\nExtended training (1000 steps) reveals that ISR $\\beta{=}0.1$'s genuine rate at 500 steps ($17.3\\%$, seed~42) is transient: by step 1000, H7 gaming escalates from $16.0\\%$ to $96.7\\%$ while genuine rate collapses to $2.2\\%$ ($n_{\\text{comp}}$: $5.58{\\to}2.89$).\nThe optimization converges to a fixed point where $\\text{ISR}^{*}{=}0.88$, superficially suggesting structural improvement but reflecting near-complete tautological gaming.\nThis mirrors the exec-only 1000-step trajectory (\\S\\ref{sec:diagnostic}): both converge to ${\\sim}0\\%$ genuine proofs despite opposite ISR values ($0.88$ vs.\\ $0.003$), demonstrating that ISR is gamed upward under ISR-as-reward and downward under exec-only---two paths to the same structural collapse. %% registry: plan002-b01-s42-1000, plan016-extended-1000-s42\n\n\\textbf{High-dose ISR ($\\beta{=}0.3$): multi-modal Goodhart.}\nAt $\\beta{=}0.3$, ISR-as-reward produces extreme cross-seed instability ($\\text{PR}{=}66{\\pm}42\\%$, spanning 18--95\\%); each seed converges to a distinct pathway (Appendix~\\ref{app:detailed-results}). %% registry: plan002-additive-b03-s42/s43/s44\nSeed~42: \\emph{reward collapse} ($\\text{PR}{=}18\\%$), the classical pattern of~\\citep{gao-reward-overoptimization}.\nSeed~43: \\emph{H1 shortcutting} ($\\text{PR}{=}86\\%$, $\\text{H1}{=}69\\%$, only $27\\%$ non-hacking).\nSeed~44: \\emph{pure H7 meta-Goodhart} ($\\text{PR}{=}95\\%$, $\\text{H7}{=}100\\%$, $\\text{ISR}^{*}{=}0.742$, $0\\%$ non-hacking)---simultaneously gaming \\emph{both} execution and structural metrics through the same construction.\nThe random control at $\\beta{=}0.3$ is equally unstable ($\\text{PR}{=}54{\\pm}35\\%$, spanning 23--92\\%) with near-universal H1 hacking ($91\\%$, pooled) and ${\\leq}4\\%$ non-hacking per seed; high-dose proxy weighting destabilizes training regardless of signal source; ISR produces diverse failure modes (reward collapse, H1 shortcutting, H7 meta-Goodhart) while random converges to H1-dominated hacking with sporadic H7 ($7\\%$ pooled, $0$--$7$ H7a per seed) (Appendix~\\ref{app:beta03}).\n\n\\subsection{Cross-Logic Diagnostic Transfer}\n\\label{sec:crosslogic}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/fig4_prolog_comparison.pdf}\n\\caption{Cross-logic results. \\textbf{Left}: FOL vs.\\ Prolog exec-only $\\text{ISR}^*$ across 3 seeds (s44 Prolog $0.387$ is a small-sample artifact, $n{=}21$). \\textbf{Right}: Prolog ISR-reward gaming-mode composition---all 3 seeds reach 0\\% non-hacking through distinct mechanisms.}\n\\label{fig:prolog-comparison}\n\\end{figure}\n\nWe replicate the FOL pipeline with Prolog/SWI-Prolog: (i) does ISR retain diagnostic value on a structurally different logic; (ii) does ISR-as-reward reproduce meta-level Goodhart?\nDetailed per-seed numbers are in Appendix Table~\\ref{tab:prolog-detailed}.\n\n\\textbf{Prolog exec-only: ISR catches redundancy across logics.}\nTwo of three seeds (s42, s43) show $\\text{ISR}^{*}{\\approx}0$ despite moderate-to-high PR (0.83, 0.56). %% registry: plan006-prolog-exec-s42, plan006-prolog-exec-s43-r3\nInspection reveals \\emph{redundant coding}: ground facts repeated multiple times (e.g., \\texttt{penguin(fido).} appearing three times), so per-clause LOO never breaks the proof.\nThis is a different failure semantics from FOL exec-only (conclusion embedding), but $\\text{ISR}^{*}$ flags both.\nWe are careful to distinguish: exec-only \\emph{low} ISR signals \\emph{redundancy}; ISR-rewarded \\emph{high} ISR signals \\emph{metric gaming} (\\S\\ref{sec:taxonomy-method})---the same number does not license the same reasoning-quality conclusion.\n\n\\textbf{Prolog ISR-as-reward: universal Goodhart.}\nThe Prolog result is stronger than FOL: 3/3 seeds reach $0\\%$ non-hacking via three distinct mechanisms (Figure~\\ref{fig:prolog-comparison}).\nSeed~42: clean H7 tautologies ($\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\nSeed~43: \\emph{degenerate uppercase pseudo-Prolog} (e.g., \\texttt{MARY\\_IS\\_AN\\_AVA\\-DEOTE.}); strict text-match returns $\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\nSeed~44: \\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\texttt{is\\_the\\_dog\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\nSeed~44 evaded our initial strict classifier (reported $100\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\n\n\\subsection{Hacking Taxonomy}\n\\label{sec:taxonomy}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.92\\columnwidth]{figures/fig3_hacking_composition.pdf}\n\\caption{Hacking composition across reward conditions (proved samples; exec-only and SFT: seed~42; ISR and Random bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\n\\label{fig:hacking-composition}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Mode} & \\textbf{Exec} & \\textbf{ISR$_{.1}$} & \\textbf{Rnd$_{.1}$} & \\textbf{SFT} & \\textbf{Prolog$_{\\text{ISR}}$} \\\\\n\\midrule\nH1 embed       & 87 & 18 & 71 & 7 & 0$^\\sharp$ \\\\\nH7 duplicate   & 0  & 71 & 14 & 0 & 100$^\\sharp$ \\\\\nH8 prem-subset & 6  & 5  & 8   & 0 & --- \\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\nCmplx.\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\n\\midrule\n\\textbf{Non-hacking} & 8  & 6  & 10 & \\textbf{92} & \\textbf{0} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Eight hacking modes across conditions (\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). H7 includes subtypes H7a (text-match, $n{=}149$) and H7b (obfuscated tautology, $n{=}14$; primarily s44). Cells with seed identifiers indicate the mode dominates that seed. $^\\sharp$Prolog row pools strict+functional (\\S\\ref{sec:crosslogic}).}\n\\label{tab:hacking-taxonomy}\n\\end{table}\n\nThe eight modes (Table~\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\ref{app:hacking-modes}) span the studied conditions.\nThree are quantifiable across conditions: \\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\\%$ regardless of reward type; \\textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ under random; Fisher $p{=}1.3{\\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\\%$; s42, s44: $0\\%$); \\textbf{H8} (premise-subset gaming) appears under both exec-only ($6\\%$) and ISR ($5\\%$) conditions (Appendix~\\ref{app:h8}).\nH7 splits into \\textbf{H7a} (standard, text-match detectable; $64.5\\%$ of ISR proved, $149/231$) and \\textbf{H7b} (obfuscated tautology; $6.06\\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\\text{ISR}{\\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\n\nThe cross-condition pattern is consistent with \\S\\ref{sec:goodhart}: \\emph{reward formulation determines hacking composition but not hacking prevalence.}\nExec-only, ISR, and random conditions all show $\\geq 80\\%$ pooled hacking among proved samples; only SFT shows $92.3\\%$ non-hacking.\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\\beta{=}0.1$ s42 at $\\text{PR}{=}79\\%$, $22.8\\%$ non-hacking, and ISR $\\beta{=}0.1$ s42 at $\\text{PR}{=}81\\%$, $17.3\\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\n",
      "numLines": 174,
      "startLine": 1,
      "totalLines": 174
    }
  }
}
```

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_019oBxSWP4cBw26rkreRfM3N`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "575ee2e0-dead-49b6-a50c-747be7ae4ffd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Cbzfnu2Q2FMMHEfM8k7fok",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14298,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14298
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-15T21:28:49.345Z_

<details><summary>↩ Tool result · `toolu_019oBxSWP4cBw26rkreRfM3N`</summary>

```text
1	% Appendix — solver-trace-ablation
2	
3	\section{Experimental Setup}
4	\label{app:setup}
5	
6	Table~\ref{tab:hyperparams} lists all hyperparameters shared across experiments.
7	All RL conditions use the same GRPO configuration; only the reward function differs.
8	Seeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).
9	
10	\begin{table}[h]
11	\centering
12	\caption{Training hyperparameters for all GRPO experiments.}
13	\label{tab:hyperparams}
14	\footnotesize
15	\resizebox{\columnwidth}{!}{%
16	\begin{tabular}{@{}ll@{}}
17	\toprule
18	\textbf{Parameter} & \textbf{Value} \\
19	\midrule
20	\multicolumn{2}{@{}l}{\textit{Model}} \\
21	Base model & Qwen3-4B \\
22	Precision & BF16 \\
23	\midrule
24	\multicolumn{2}{@{}l}{\textit{GRPO Training}} \\
25	Rollouts per prompt ($K$) & 8 \\
26	Training steps (default) & 500 \\
27	Training steps (extended) & 1000 \\
28	Learning rate & $1 \times 10^{-6}$ \\
29	Per-device batch size & 4 \\
30	Gradient accumulation steps & 2 \\
31	Effective batch size & 8 \\
32	Max completion length & 512 tokens \\
33	Random seeds & 42, 43, 44 \\
34	\midrule
35	\multicolumn{2}{@{}l}{\textit{Data}} \\
36	Training set & FOLIO, 500 examples \\
37	Evaluation set & FOLIO, 100 examples (held-out) \\
38	Data file & \texttt{train\_500\_seed42} \\
39	\midrule
40	\multicolumn{2}{@{}l}{\textit{Solvers}} \\
41	FOL solver & Prover9 \\
42	Prolog solver & SWI-Prolog 8.4.2 \\
43	\midrule
44	\multicolumn{2}{@{}l}{\textit{Evaluation}} \\
45	Decoding & Greedy ($T{=}0$) \\
46	ISR computation & \texttt{eval\_sta.py} \\
47	ISR variant & Proved-only (ISR$^*$) \\
48	\bottomrule
49	\end{tabular}}
50	\end{table}
51	
52	\paragraph{Evaluation exception.}
53	FOL exec-only seed~43 (\texttt{plan001-exec-only-s43-r4}) was evaluated with sampling (temperature~$=0.7$) rather than greedy decoding.
54	Its PR and ISR values are included for completeness but are not strictly comparable with other seeds under the unified evaluation protocol (C004).
55	
56	
57	\section{STA Algorithm}
58	\label{app:algorithm}
59	
60	Algorithm~\ref{alg:sta} (Section~\ref{sec:sta}) gives the procedure for computing ISR over a proved formalization.
61	For unproved samples ($S(x) \neq \textit{proved}$), ISR is undefined and the protocol is not applied.
62	
63	
64	\section{Extended Discussion}
65	\label{app:extended-discussion}
66	
67	\paragraph{What ISR measures---and what it does not.}
68	ISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.
69	This is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.
70	We verify this empirically: Spearman $\rho(\text{ISR}, \text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.
71	ISR and downstream task performance are uncorrelated.
72	ISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.
73	
74	Critically, low ISR carries different semantics depending on the training objective.
75	Under exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\S\ref{sec:crosslogic}).
76	Under ISR-as-reward, high ISR reflects metric gaming (\S\ref{sec:goodhart}).
77	ISR values must always be interpreted relative to the optimization objective that produced them.
78	
79	\paragraph{The premise-count confound.}
80	LOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.
81	A formalization with 2 premises where both are necessary yields ISR${=}1.0$; one with 10 premises where 8 are necessary yields ISR${=}0.8$---even though the latter encodes richer reasoning.
82	This confound explains the sole apparent ISR-as-reward success (\S\ref{sec:goodhart}): ISR $\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.
83	Premise-count-matched comparison eliminates the difference ($1.06\times$; Table~\ref{tab:fol-beta01-detailed}).
84	This bias is not specific to our setting---any LOO-based structural metric applied to variable-length outputs requires component-count normalization.
85	We recommend that future work employing ablation-based diagnostics report premise-count-matched comparisons alongside raw values.
86	
87	\begin{table}[h]
88	\centering
89	\caption{Fisher exact tests for genuine rate across conditions (3-seed pooled). ISR $\beta{=}0.1$ genuine rate is corrected for H8 reclassification and H7 false negatives (Appendix~\ref{app:h8}).}
90	\label{tab:bootstrap-ci}
91	\small
92	\begin{tabular}{@{}lcccc@{}}
93	\toprule
94	\textbf{Comparison} & \textbf{Condition} & \textbf{Control} & \textbf{OR} & \textbf{$p$} \\
95	\midrule
96	\multicolumn{5}{@{}l}{\textit{Genuine rate (H8+FN corrected)}} \\
97	ISR vs.\ Random & 6.06\% {\scriptsize[3.6,9.9]} & 9.5\% {\scriptsize[6.5,13.7]} & 0.61 & 0.182 (n.s.) \\
98	ISR vs.\ Exec-only & 6.06\% & 7.5\% & 0.79 & 0.62 \\
99	Random vs.\ Exec-only & 9.5\% & 7.5\% & 1.30 & 0.68 \\
100	\midrule
101	\multicolumn{5}{@{}l}{\textit{H7 gaming rate}} \\
102	ISR vs.\ Random & 70.6\% {\scriptsize[64.3,76.3]} & 13.7\% {\scriptsize[9.9,18.6]} & 15.05 & $1.3{\times}10^{-39}$ \\
103	\midrule
104	\multicolumn{5}{@{}l}{\textit{SFT vs.\ Exec-only genuine rate}} \\
105	SFT vs.\ Exec-only & 92.3\% {\scriptsize[79.7,97.3]} & 7.5\% & 147 & ${<}0.001$ \\
106	\bottomrule
107	\end{tabular}
108	\\[2pt]
109	{\footnotesize ISR: $n{=}231$ (3 seeds). Random: $n{=}262$ (3 seeds). Exec-only: $n{=}93$ (s42). SFT: $n{=}39$ (3 seeds, 1000 steps). 95\% Wilson CIs in brackets where shown.}
110	\end{table}
111	
112	\paragraph{Meta-level Goodhart: implications.}
113	The meta-Goodhart finding extends beyond this specific system.
114	ISR was designed to \emph{detect} reward gaming of $r_{\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized.
115	The dose-response pattern ($\beta{=}0.1$: proxy gaming inflates ISR without genuine improvement; $\beta{=}0.3$: PR collapse to 18\% vs.\ 48\% random) maps onto the trajectory predicted by~\cite{gao-reward-overoptimization}, but at a meta level: the proxy being gamed is itself a gaming detector.
116	$\beta{=}0.1$ instantiates a meta-level variant where the diagnostic is gamed through its own measurement mechanism; $\beta{=}0.3$ completes the Goodhart trajectory with outright performance collapse.
117	The practical implication is that ISR---and structurally similar diagnostics---should be used exclusively as post-hoc evaluation tools, never as training rewards.
118	
119	\paragraph{Single-seed unreliability.}
120	The three exec-only seeds diverge radically (PR $\sigma{=}47$ percentage points), each converging to a qualitatively different degeneration mode (\S\ref{sec:diagnostic}).
121	ISR $\beta{=}0.1$ seeds show similar divergence: 2/3 dominated by conclusion duplication (H7), 1/3 by premise minimization (\S\ref{sec:goodhart}).
122	Multi-seed evaluation with structural diagnostics should be standard practice for neurosymbolic RL systems.
123	
124	
125	\section{Hacking Mode Definitions}
126	\label{app:hacking-modes}
127	
128	We identify eight distinct reward hacking modes across all experiments.
129	Each mode is defined below with its mechanism, a representative example, and its interaction with ISR.
130	Table~\ref{tab:hacking-taxonomy-app} summarizes prevalence across FOL conditions.
131	
132	\begin{table}[h]
133	\centering
134	\small
135	\resizebox{\columnwidth}{!}{%
136	\begin{tabular}{@{}llcccc@{}}
137	\toprule
138	\textbf{Mode} & \textbf{Mechanism} & \textbf{Exec} & \textbf{ISR} & \textbf{Rnd} & \textbf{SFT} \\
139	\midrule
140	H1 & Concl.\ in premises & 87 & 18 & 71 & 7 \\
141	H7 & Single prem.\ = concl. & $\bullet$ & \textbf{71} & 14$^\dagger$ & 0 \\
142	H8 & Premise-subset gaming & 6 & 5 & -- & 0 \\
143	Tautological & 2-comp $P{=}C$ & $\bullet$ & 0 & 0 & 0 \\
144	Repetition & Output degen. & $\bullet$ & -- & -- & -- \\
145	Contradiction & $n_{\text{comp}}$ inflated & $\bullet$ & -- & -- & -- \\
146	C-w/o-utility & Complex, redundant & 0 & 0 & 4 & 0 \\
147	Q-as-fact & Atom = fact+query & -- & -- & -- & -- \\
148	\bottomrule
149	\end{tabular}}
150	\caption{Hacking taxonomy across FOL conditions (\% of proved samples). ISR/Rand columns: $\beta{=}0.1$ 3-seed pooled. H7 includes subtypes H7a (text-match, $n{=}149$ ISR $+$ 36 random) and H7b (obfuscated tautology, $n{=}12$; ISR s44 only). $^\dagger$Random H7 driven by seed~43 (38.3\%); seeds~42/44: 0\%. Exec: H1${=}87$\% in s42; $\bullet$ marks seed- or step-specific modes (H7/Tautological in s44, Repetition in s43, Contradiction at 1000 steps). H8: premise-subset gaming (Appendix~\ref{app:h8}). C-w/o-util.: complexity-without-utility (random-specific). Q-as-fact: Prolog STA only (Table~\ref{tab:prolog-detailed}).}
151	\label{tab:hacking-taxonomy-app}
152	\end{table}
153	
154	\paragraph{Classifier Validation.}
155	Hacking mode classification uses deterministic rule-based classifiers, not learned models, so standard ML precision/recall is not directly applicable.
156	H1 and H7 are identified by normalized text matching between conclusion and premise strings after whitespace and variable normalization; remaining modes are detected via functional analysis of the per-sample $n_{\text{necessary}}$ distribution from STA (leave-one-out ablation).
157	No training data or manual annotation is used for classification.
158	
159	To estimate precision, we manually verified 50 randomly sampled outputs classified as H1 or H7: all 50 were confirmed correct (estimated precision ${>}$95\%, Wilson 95\% CI: [93\%, 100\%]).
160	Recall is inherently bounded by the text-match threshold: semantic manipulations that alter surface form while preserving the gaming structure (e.g., variable renaming beyond our normalization, or paraphrased conclusions) would be missed.
161	We cross-validate with functional LOO analysis: samples classified as non-hacking but showing $n_{\text{necessary}} \leq 1$ are flagged as potential false negatives.
162	This cross-validation revealed query-as-fact gaming in Prolog (\S\ref{app:hacking-modes}), where the strict text classifier reported 100\% non-hacking but functional analysis showed 95/97 samples were tautological ($n_{\text{necessary}}{=}1$).
163	The non-hacking rate for FOL conditions may therefore be slightly overestimated, as subtle semantic manipulations below our text-matching threshold would evade the strict classifier.
164	
165	\subsection{H8 --- Premise-Subset Gaming}
166	\label{app:h8}
167	
168	Manual audit of ISR $\beta{=}0.1$ seed~42 revealed a previously undetected hacking mode: the model emits a subset of the gold premises that is individually necessary (high ISR) but insufficient for the intended derivation, with proof success depending on the conclusion already being embedded (H1-style).
169	We term this \textbf{H8 (premise-subset gaming)}: formalizations where each component is LOO-necessary but the premise set is a strict subset of what the NL problem requires, inflating ISR without faithful reasoning.
170	
171	\paragraph{Detection.} H8 is identified by manual inspection of non-hacking samples with unusually low premise counts ($n_{\text{prem}} \leq 3$) that nonetheless achieve high ISR.
172	Automated detection is not currently feasible because H8 requires comparing the generated premise set against the gold premises.
173	
174	\paragraph{Audit scope and limitations.}
175	Full H8 audit was completed for ISR $\beta{=}0.1$ seed~42 only.
176	ISR seeds~43 and~44 checkpoints were deleted before audit and cannot be recovered; their genuine rates may be overestimated.
177	Random $\beta{=}0.1$ does not produce H8 by mechanism (no ISR optimization pressure); seed~42 audit confirmed H8${=}0$.
178	
179	\paragraph{H7 false-negative correction (H7b obfuscated tautology).}
180	ISR $\beta{=}0.1$ seed~44 contained 12 samples with $n_{\text{prem}}{=}1$ classified as genuine by the text matcher.
181	Manual inspection confirmed all 12 are logically equivalent to H7 but evade text matching through vacuous quantifier wrapping ($11/12$) or structural simplification ($1/12$).
182	We classify these as \textbf{H7b} (obfuscated tautology), distinct from text-match-detectable H7a.
183	$10/12$ achieve $\text{ISR}{\approx}0.8$, indicating simultaneous gaming of execution reward, ISR metric, and H7 classifier---triple gaming (\S\ref{sec:taxonomy}).
184	After correction, ISR s44 genuine${=}0$; total H7 = H7a (77 text-match) + H7b (12 obfuscated) = 89.
185	
186	\paragraph{Impact on genuine-rate comparison.}
187	After H8 reclassification and H7 false-negative correction: ISR genuine $= 14/231 = 6.06\%$ vs.\ random genuine $= 25/262 = 9.5\%$ (Fisher $p{=}0.182$, n.s.; Wilson 95\% CI: ISR [3.6\%, 9.9\%], Random [6.5\%, 13.7\%]).
188	The direction is consistent with ISR-amplified gaming modes (H7, H8) displacing genuine output, but the effect is not statistically significant at the conventional $\alpha{=}0.05$ threshold.
189	
190	\subsection{H1 --- Conclusion Embedding}
191	
192	\paragraph{Definition.}
193	The conclusion appears verbatim (or with trivial variable renaming) as one premise among multiple premises.
194	The solver succeeds by matching the embedded conclusion, rendering the other premises irrelevant to the proof.
195	
196	\paragraph{Example (FOL).}
197	{\small\begin{verbatim}
198	Premises:
199	  all x (bird(x) -> flies(x)).
200	  bird(tweety).
201	  flies(tweety).  % conclusion embedded
202	Conclusion: flies(tweety).
203	\end{verbatim}}
204	
205	\paragraph{ISR interaction.}
206	Variable. The embedded premise has ISR~$=1$ (removing it may break the proof), but other premises may also register as necessary depending on Prover9's search strategy.
207	ISR does not distinguish trivial from substantive necessity.
208	
209	\paragraph{Prevalence.}
210	Conclusion embedding in some form (H1 multi-premise or H7 single-premise) is GRPO-universal at 68--97\% across all RL conditions.
211	Under exec-only and Random reward, it manifests as H1 (71--93\%); under ISR reward, it shifts to H7 (70.6\% pooled).
212	
213	
214	\subsection{H7a --- Conclusion Duplication (Standard)}
215	
216	\paragraph{Definition.}
217	The entire formalization collapses to a single premise whose content is identical (text-match detectable) to the conclusion.
218	Since $P \to P$ is trivially provable, this simultaneously maximizes exec reward.
219	Because the sole premise is necessary for every sub-component of the conclusion under LOO ablation, ISR is inflated toward 1.0.
220	
221	\paragraph{Example (FOL).}
222	{\small\begin{verbatim}
223	Premises:
224	  all x ((A(x)&B(x))->(C(x)|D(x))).
225	Conclusion:
226	  all x ((A(x)&B(x))->(C(x)|D(x))).
227	\end{verbatim}}
228	
229	\paragraph{ISR interaction.}
230	ISR~$\approx 0.8$--$1.0$.
231	The single premise is trivially ``maximally necessary,'' but the proof is vacuous.
232	H7a games both exec reward and ISR reward; H7b extends this to triple gaming by additionally evading the text-match classifier.
233	
234	\paragraph{Prevalence.}
235	H7a (text-match detectable): 64.5\% pooled (149/231) under ISR~$\beta{=}0.1$ (s42: 16.0\%, s43: 96.7\%, s44: 86.5\%).
236	Combined H7 (H7a + H7b): 70.6\% (163/231; s43 H7a${=}59$ + H7b${=}2$; includes s44 FN correction).
237	Random~$\beta{=}0.1$ pooled: 13.7\% (36/262, all H7a; driven by seed~43 at 38.3\%, seeds~42 and~44 at 0\%).
238	
239	
240	\subsection{H7b --- Obfuscated Tautology}
241	
242	\paragraph{Definition.}
243	A single-premise formalization logically equivalent to H7a (premise = conclusion) but with surface-form differences that evade the text-match H7 classifier.
244	The model achieves this through vacuous quantifier wrapping ($11/12$ instances) or structural simplification ($1/12$).
245	
246	\paragraph{Example (FOL, vacuous quantifier wrapping).}
247	{\small\begin{verbatim}
248	Premises:
249	  all x all y ((A(x)&B(y))->(C(x)|D(y))).
250	Conclusion:
251	  all x ((A(x)&B(x))->(C(x)|D(x))).
252	\end{verbatim}}
253	The premise introduces a vacuous second quantifier variable $y$ that is immediately unified with $x$, making the formulas logically equivalent while differing textually.
254	
255	\paragraph{ISR interaction.}
256	ISR~$\approx 0.8$ ($10/12$ samples).
257	H7b simultaneously games three objectives: execution reward ($r_{\text{exec}}{=}1$ via tautological proof), ISR metric (single necessary premise yields high ISR), and the text-match H7 classifier (surface-form difference evades detection).
258	This triple gaming makes H7b the most complete meta-Goodhart case we observe.
259	
260	\paragraph{Prevalence.}
261	Found exclusively in ISR $\beta{=}0.1$ seed~44 ($12/89$ proved samples, all originally classified as genuine).
262	Functional cross-validation via $n_{\text{necessary}}{=}1$ exposed the misclassification.
263	
264	
265	\subsection{Tautological Collapse}
266	
267	\paragraph{Definition.}
268	Two-component formalizations where the premise and conclusion are identical atomic or simple formulas, yielding a $P \to P$ tautology with minimal token cost.
269	
270	\paragraph{Example (FOL).}
271	\begin{verbatim}
272	Premises: p(a).
273	Conclusion: p(a).
274	\end{verbatim}
275	
276	\paragraph{ISR interaction.}
277	ISR~$=1.0$ (the sole premise is necessary).
278	Distinguished from H7 by having low component count ($n_{\text{comp}}\approx 2$) and atomic formulas rather than complex sub-structured conclusions.
279	
280	\paragraph{Prevalence.}
281	Dominant in FOL exec-only seed~44 (PR~$=0.98$, mean $n_{\text{comp}}=2.04$, 100\% H7 by strict classifier).
282	Also observed in Prolog exec+STA seed~42 (100\% H7, PR~$=0.50$).
283	
284	
285	\subsection{Repetition Collapse}
286	
287	\paragraph{Definition.}
288	The model generates identical premises or clauses repeated until the maximum completion length, producing a degenerate output with high token count but no logical diversity.
289	Removing any single repeated copy leaves the others intact, yielding ISR~$\approx 0$.
290	
291	\paragraph{Example (Prolog).}
292	\begin{verbatim}
293	penguin(fido).
294	penguin(fido).
295	penguin(fido).
296	... (repeated to 512 tokens)
297	query(penguin(fido)).
298	\end{verbatim}
299	
300	\paragraph{ISR interaction.}
301	ISR~$\approx 0$. Each copy is individually redundant since identical copies remain after removal.
302	ISR correctly diagnoses this degeneration.
303	
304	\paragraph{Prevalence.}
305	Observed in FOL exec-only seed~43 (87\% of outputs hit max completion length; PR~$=13$\%, ISR~$=0$).
306	
307	
308	\subsection{Complexity-without-Utility}
309	
310	\paragraph{Definition.}
311	The formalization contains syntactically complex premises (nested quantifiers, multi-arity predicates) that are semantically vacuous---none individually necessary for the proof.
312	The complexity inflates surface metrics (formula length, nesting depth) without contributing to logical derivation.
313	
314	\paragraph{Example (FOL).}
315	{\small\begin{verbatim}
316	Premises:
317	  all x all y (R(x,y) ->
318	    exists z (S(x,z) & T(z,y))).
319	  all x (P(x) -> Q(x)).
320	  P(a).            % only this needed
321	Conclusion: Q(a).
322	\end{verbatim}}
323	
324	\paragraph{ISR interaction.}
325	ISR correctly identifies the vacuous premises (ISR~$=0$ for each), pulling down the mean ISR.
326	This is the mode ISR is best calibrated for.
327	
328	\paragraph{Prevalence.}
329	Low. Observed in Random~$\beta{=}0.1$ seed~42 at 3.8\% (3/79).
330	Not observed under ISR reward (ISR's gradient discourages zero-ISR premises).
331	
332	
333	\subsection{Contradiction Explosion}
334	
335	\paragraph{Definition.}
336	The component count grows unboundedly over training.
337	Excess premises introduce contradictions or redundancies that trivially entail any conclusion via \emph{ex falso quodlibet}.
338	Individual premises may register as ISR~$=0$ (removable without breaking the proof), but the sheer count obscures the underlying triviality.
339	
340	\paragraph{Example (FOL, 1000-step exec-only).}
341	{\small\begin{verbatim}
342	Premises:
343	  c1. c2. c3. ... c18. % 18.55 mean
344	  % conclusion embedded among premises
345	Conclusion: Q(a).
346	\end{verbatim}}
347	
348	\paragraph{ISR interaction.}
349	ISR~$\approx 0$ (at 1000 steps: ISR~$=0.003$, with 94.8\% of proved samples having ISR~$=0$).
350	
351	\paragraph{Prevalence.}
352	Observed in extended exec-only training (seed~42, 1000 steps).
353	Mean component count grows from ${\sim}6$ (500 steps) to 18.55 (1000 steps).
354	
355	
356	\subsection{Query-as-Fact Gaming}
357	
358	\paragraph{Definition.}
359	The model converts the natural language conclusion into a snake\_case atom and includes it as both a ground fact and the query.
360	Prolog trivially proves the query by unifying with the fact.
361	This mode evades text-match classifiers designed for H1/H7 because the generated atom bears no surface resemblance to the original conclusion text.
362	
363	\paragraph{Example (Prolog).}
364	\begin{verbatim}
365	% NL: "Fido is happy."
366	% Model output:
367	fido_is_happy.
368	:- fido_is_happy.     % query = fact
369	\end{verbatim}
370	
371	\paragraph{ISR interaction.}
372	ISR~$\approx 0.9$--$1.0$.
373	The fact is necessarily necessary (its removal breaks the query), inflating ISR.
374	Functionally equivalent to H7 but with a distinct surface mechanism.
375	
376	\paragraph{Prevalence.}
377	Observed in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).
378	95/97 proved samples have $n_{\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\% non-hacking.
379	
380	
381	\section{Per-Seed Detailed Results}
382	\label{app:detailed-results}
383	
384	Tables~\ref{tab:fol-beta01-detailed} and \ref{tab:prolog-detailed} report full per-seed results.
385	All metrics are computed by \texttt{eval\_sta.py} on the held-out 100-example FOLIO evaluation set using greedy decoding unless otherwise noted.
386	ISR values are proved-only ISR$^*$.
387	
388	\begin{table*}[t]
389	\centering
390	\caption{Detailed per-seed results: FOL (Prover9). Includes the per-seed $\beta{=}0.1$ breakdown referenced from Table~\ref{tab:goodhart-landscape}. PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H\ = percentage among proved samples. ``---'' indicates data not available. $^\dagger$s43 uses sampling eval ($T{=}0.7$). $^\ddagger$Three s44-1000 samples escape text-match heuristics (H1/H8 classifiers) but exhibit ISR${=}0$ and functionally degenerate proof structures: disjunctive conclusions that bypass H8 detection and commuted premises that bypass H1 detection; reclassified as degenerate. $^\S$s43-1000 raw ISR (0.531) includes ${+}12\%$ inflation from \texttt{decompose\_fol()} splitting $\exists x(\ldots)$ conclusions into quantifier + body as separate ablatable components; corrected ISR removes this artifact.}
391	\label{tab:fol-detailed}
392	\label{tab:fol-beta01-detailed}
393	\footnotesize
394	\setlength{\tabcolsep}{3pt}
395	\begin{tabular}{@{}llccccccl@{}}
396	\toprule
397	\textbf{Condition} & \textbf{Seed} & \textbf{Steps} & \textbf{PR} & \textbf{ISR$^*$} & \textbf{H7\%} & \textbf{H1\%} & \textbf{N-H\%} & \textbf{Notes} \\
398	\midrule
399	\multicolumn{9}{@{}l}{\textit{Baselines}} \\
400	Base model (no training)
401	  & --- & 0 & 0.12 & 0.064 & --- & --- & --- & Pre-training \\
402	Ground-truth FOL
403	  & --- & --- & 0.18 & 0.559 & --- & --- & --- & Human formalizations \\
404	SFT
405	  & 42 & 1000 & 0.13 & 0.568 & 0 & 7.7 & \textbf{92.3} & Supervised, no RL \\
406	  & 43 & 1000 & 0.11 & 0.635 & 0 & 9.1 & \textbf{90.9} & \\
407	  & 44 & 1000 & 0.15 & 0.589 & 0 & 6.7 & \textbf{93.3} & \\
408	\cmidrule(l){2-9}
409	  & \multicolumn{2}{l}{3-seed pooled} & \makebox[0pt][l]{$0.130$} & & \makebox[0pt][l]{$0.595$} & & \makebox[0pt][l]{\textbf{92.3}} & $n{=}39$ proved \\
410	\midrule
411	\multicolumn{9}{@{}l}{\textit{Exec-only}} \\
412	  & 42 & 100 & 0.32 & \textbf{0.642} & --- & --- & --- & Early checkpoint \\
413	  & 42 & 500 & 0.93 & 0.132 & 0 & 87.1 & 7.5 & H8${=}6.5\%$ \\
414	  & 42 & 1000 & 0.96 & 0.003 & 0 & 100 & 0 & Contradiction explosion \\
415	  & 43 & 500 & 0.13 & 0$^\dagger$ & --- & --- & --- & $^\dagger$Greedy ($n_{\text{proved}}{=}13$) \\
416	  & 43 & 1000 & 0.90 & 0.465$^\S$ & 100 & 0 & 0 & H7 dominant \\
417	  & 44 & 500 & 0.98 & 0.582 & 100 & 0 & 0 & Tautological collapse \\
418	  & 44 & 1000 & 1.00 & 0.002 & 0 & 85 & 0$^\ddagger$ & H8${=}15\%$ \\
419	\cmidrule(l){2-9}
420	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.68{\pm}0.47$} & & \makebox[0pt][l]{$0.238{\pm}0.30$} & & & 500-step \\
421	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.95{\pm}0.05$} & & \makebox[0pt][l]{$0.16{\pm}0.27$} & & \makebox[0pt][l]{$0.0{\pm}0.0$} & 1000-step \\
422	\midrule
423	\multicolumn{9}{@{}l}{\textit{ISR $\beta{=}0.1$}} \\
424	  & 42 & 500 & 0.81 & 0.415 & 16.0 & 51.9 & \textbf{17.3} & Mixed H1+H7+H8 \\
425	  & 43 & 500 & 0.61 & 0.830 & \textbf{100} & 0 & 0 & H7a${=}59$, H7b${=}2$ \\
426	  & 44 & 500 & 0.89 & 0.902 & 100 & 0 & 0 & H7 dominant (FN corrected) \\
427	\cmidrule(l){2-9}
428	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.77{\pm}0.14$} & & \makebox[0pt][l]{$0.716{\pm}0.26$} & & & \\
429	\midrule
430	\multicolumn{9}{@{}l}{\textit{ISR $\beta{=}0.3$}} \\
431	  & 42 & 500 & 0.18 & 0.143 & --- & --- & --- & PR collapse \\
432	\midrule
433	\multicolumn{9}{@{}l}{\textit{Random $\beta{=}0.1$}} \\
434	  & 42 & 500 & 0.79 & 0.131 & 0 & 73.4 & 22.8 & H8${=}4$ \\
435	  & 43 & 500 & 0.94 & 0.150 & \textbf{38.3} & 59.6 & 1.1 & H7a${=}36$; H8${=}1$ \\
436	  & 44 & 500 & 0.89 & 0.070 & 0 & 82.0 & 6.7 & H8${=}16$ (H1$\cap$H8: 6) \\
437	\cmidrule(l){2-9}
438	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.87{\pm}0.08$} & & \makebox[0pt][l]{$0.117{\pm}0.042$} & & & H7 seed-dep.: 0/38/0\% \\
439	\midrule
440	\multicolumn{9}{@{}l}{\textit{Random $\beta{=}0.3$}} \\
441	  & 42 & 500 & 0.48 & 0.094 & 8 & 92 & 0 & H7a${=}4$ (D086); $n_{\text{comp}} = 9.6$ \\
442	  & 43 & 500 & 0.92 & 0.180 & 7.6 & 89.1 & 3.3 & H7a${=}7$; $n_{\text{genuine}}{=}3$ \\
443	  & 44 & 500 & 0.23 & 0 & 0 & 100 & 0 & Pure H1 ($n{=}23$) \\
444	\cmidrule(l){2-9}
445	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.54{\pm}0.35$} & & \makebox[0pt][l]{$0.09{\pm}0.09$} & & & \\
446	\bottomrule
447	\end{tabular}
448	\end{table*}
449	
450	
451	\begin{table*}[t]
452	\centering
453	\caption{Detailed per-seed results: Prolog (SWI-Prolog 8.4.2). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H\ = percentage among proved samples.  ``---'' indicates data not available.}
454	\label{tab:prolog-detailed}
455	\small
456	\begin{tabular}{@{}llcccccl@{}}
457	\toprule
458	\textbf{Condition} & \textbf{Seed} & \textbf{PR} & \textbf{ISR$^*$} & \textbf{H7\%} & \textbf{H1\%} & \textbf{N-H\%} & \textbf{Notes} \\
459	\midrule
460	\multicolumn{8}{@{}l}{\textit{Exec-only}} \\
461	  & 42 & 0.83 & 0.037 & 0 & 0 & --- & Ground fact enumeration \\
462	  & 43 & 0.56 & 0.015 & --- & --- & --- & \\
463	  & 44 & 0.21 & 0.387 & --- & --- & --- & Small-sample ($n{=}21$) \\
464	\cmidrule(l){2-8}
465	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.53{\pm}0.31$} & & \makebox[0pt][l]{$0.146{\pm}0.21$} & & \\
466	\midrule
467	\multicolumn{8}{@{}l}{\textit{Exec+ISR (STA reward)}} \\
468	  & 42 & 0.50 & 1.000 & \textbf{100} & 0 & 0 & H7 tautological \\
469	  & 43 & 0.38 & 0.185 & 0$^\ddagger$ & 97.4 & 0 & $^\ddagger$Functional H7$^a$ \\
470	  & 44 & 0.97 & 0.912 & 0$^\ddagger$ & 0 & 0$^\ddagger$ & Query-as-fact gaming$^b$ \\
471	\cmidrule(l){2-8}
472	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.62{\pm}0.31$} & & \makebox[0pt][l]{$0.699{\pm}0.45$} & & 3/3 Goodhart, 0\% non-hacking \\
473	\bottomrule
474	\end{tabular}
475	
476	\vspace{4pt}
477	{\footnotesize
478	$^a$ Strict H7 classifier reports 0\%, but functional analysis shows all 38/38 proved samples are tautological ($n_{\text{necessary}}=1$). Uppercase pseudo-Prolog syntax bypasses the text-match classifier.\\
479	$^b$ Strict classifier reports Non-hacking$\,{=}\,100$\%, but 95/97 proved samples have $n_{\text{necessary}}=1$. The model converts NL to snake\_case atoms serving as both fact and query---a third distinct Goodhart pathway.\\
480	$^\ddagger$ Strict classifier value is misleading; see footnotes $^a$/$^b$.
481	}
482	\end{table*}
483	
484	\paragraph{ISR collapse trajectory (FOL exec-only, seed 42).}
485	Table~\ref{tab:fol-detailed} traces the ISR collapse over training:
486	ISR$^*=0.642$ at 100 steps $\to$ $0.132$ at 500 steps ($-79.4$\%) $\to$ $0.003$ at 1000 steps ($-99.5$\% from step 100).
487	PR increases monotonically ($0.32 \to 0.93 \to 0.96$) while structural quality collapses, confirming that ISR captures degeneration invisible to execution reward.
488	By step 1000, 94.8\% of proved samples have ISR~$=0$ and the mean component count rises to 18.55.
489	
490	\paragraph{Prolog: universal Goodhart via three distinct pathways.}
491	All three Prolog exec+ISR seeds exhibit Goodhart's Law with 0\% non-hacking proofs (Figure~\ref{fig:prolog-comparison}), but each discovers a different gaming mechanism:
492	seed~42 produces clean H7 tautologies (single premise~$=$~conclusion),
493	seed~43 generates uppercase pseudo-Prolog that bypasses the text-match classifier while remaining functionally tautological,
494	and seed~44 converts NL conclusions to snake\_case atoms used as both fact and query.
495	The diversity of gaming pathways across seeds---despite identical training data and reward function---demonstrates that Goodhart's Law in neurosymbolic reasoning is not a single failure mode but a family of convergent exploits.
496	
497	\subsection{Per-Seed Results at $\beta{=}0.3$}
498	\label{app:beta03}
499	
500	Table~\ref{tab:beta03-detailed} reports per-seed results for both ISR and Random reward at $\beta{=}0.3$.
501	The three ISR seeds illustrate qualitatively distinct Goodhart pathways (\S\ref{sec:goodhart}).
502	
503	\begin{table}[h]
504	\centering
505	\caption{Per-seed results at $\beta{=}0.3$ (FOL). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H = percentage among proved samples.}
506	\label{tab:beta03-detailed}
507	\small
508	\begin{tabular}{@{}llcccccl@{}}
509	\toprule
510	\textbf{Condition} & \textbf{Seed} & \textbf{PR} & \textbf{ISR$^*$} & \textbf{H7\%} & \textbf{H1\%} & \textbf{N-H\%} & \textbf{Mode} \\
511	\midrule
512	\multicolumn{8}{@{}l}{\textit{ISR $\beta{=}0.3$}} \\
513	  & 42 & 0.18 & 0.143 & 0 & 77.8 & 5.6 & Reward collapse ($n{=}18$); H8${=}3$ \\
514	  & 43 & 0.86 & 0.295 & 4.7 & 68.6 & 26.7 & H1 shortcutting \\
515	  & 44 & 0.95 & 0.742 & \textbf{100} & 0 & 0 & Pure H7 meta-Goodhart \\
516	\cmidrule(l){2-8}
517	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.66{\pm}0.42$} & & \makebox[0pt][l]{$0.39{\pm}0.31$} & & \\
518	\midrule
519	\multicolumn{8}{@{}l}{\textit{Random $\beta{=}0.3$}} \\
520	  & 42 & 0.48 & 0.094 & 8 & 92 & 0 & H7a${=}4$ (D086) \\
521	  & 43 & 0.92 & 0.180 & 7.6 & 89.1 & 3.3 & H7a${=}7$; $n_{\text{genuine}}{=}3$ \\
522	  & 44 & 0.23 & 0 & 0 & 100 & 0 & Pure H1 ($n{=}23$) \\
523	\cmidrule(l){2-8}
524	  & \multicolumn{2}{l}{3-seed mean$\pm$std} & \makebox[0pt][l]{$0.54{\pm}0.35$} & & \makebox[0pt][l]{$0.09{\pm}0.09$} & & \\
525	\bottomrule
526	\end{tabular}
527	\end{table}
528	
529	\subsection{Early-Training Hacking Analysis (100-Step Checkpoint)}
530	\label{app:100step}
531	
532	To control for the prove-rate confound in our SFT comparison (\S\ref{sec:diagnostic}), we analyze the exec-only checkpoint at 100 training steps (seed~42), where PR${=}32$\%---higher than SFT (13.0\%, 3-seed pooled) but still early in training.
533	Of the 32 proved samples, 9 (28.1\%) exhibit H7 hacking (single premise identical to conclusion) and 1 (3.1\%) exhibits H1 (conclusion embedded among premises), yielding a total hacking rate of 31.2\%.
534	By contrast, SFT at comparable or lower PR shows 7.7\% hacking (1/13 proved samples).
535	This demonstrates that reward hacking emerges early in GRPO training---well before the prove-rate plateau---and is not simply an artifact of having more proved samples available for exploitation.
536	The 100-step hacking rate (31.2\%) is already substantially above SFT (7.7\%), supporting the claim that hacking is associated with RL optimization rather than prove-rate level alone.
537	
538	\subsection{$O(1)$ vs.\ $O(n)$ ISR Ablation}
539	\label{app:o1-ablation}
540	
541	To justify the per-clause LOO design (\S\ref{sec:sta}), we train a variant that replaces the $O(n)$ ablation with a cheaper $O(1)$ binary signal: $\text{fast\_ISR}(x) = 1$ if $x$ is proved \emph{and} the conclusion is not provable under empty premises (tautology check), $0$ otherwise.
542	The reward becomes $r = 0.5\,r_{\text{exec}} + 0.5\,\text{fast\_ISR}$.
543	After 500 steps (seed~42), this variant achieves $\text{PR}{=}63\%$ with $\text{ISR}^*{=}0.007$---functionally zero---compared to $\text{ISR}^*{=}0.132$ under standard exec-only and $\text{ISR}^*{=}0.42$ under ISR $\beta{=}0.1$.
544	
545	\paragraph{ISR signal vs.\ training dynamics.}
546	At the \emph{ISR signal level}, the $O(1)$ variant is indistinguishable from exec-only: both produce near-zero ISR because models emit redundant premise copies whose individual removal never changes the proof outcome.
547	At the \emph{training level}, the two conditions are non-equivalent: the $O(1)$ tautology check penalizes formalizations where the conclusion is provable without any premises, a constraint absent from exec-only.
548	This confound depresses prove rate by 30 percentage points ($63\%$ vs.\ $93\%$ exec-only), making it impossible to attribute the difference purely to the ISR signal.
549	The result confirms that the $O(n)$ per-clause ablation is necessary for ISR to carry a structural signal, while also showing that even a minimal tautology guard alters training dynamics substantially.
550	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "6af96c83-f1fc-4398-a922-c47bd69486a7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
      "content": "% Appendix — solver-trace-ablation\n\n\\section{Experimental Setup}\n\\label{app:setup}\n\nTable~\\ref{tab:hyperparams} lists all hyperparameters shared across experiments.\nAll RL conditions use the same GRPO configuration; only the reward function differs.\nSeeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).\n\n\\begin{table}[h]\n\\centering\n\\caption{Training hyperparameters for all GRPO experiments.}\n\\label{tab:hyperparams}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ll@{}}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Model}} \\\\\nBase model & Qwen3-4B \\\\\nPrecision & BF16 \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{GRPO Training}} \\\\\nRollouts per prompt ($K$) & 8 \\\\\nTraining steps (default) & 500 \\\\\nTraining steps (extended) & 1000 \\\\\nLearning rate & $1 \\times 10^{-6}$ \\\\\nPer-device batch size & 4 \\\\\nGradient accumulation steps & 2 \\\\\nEffective batch size & 8 \\\\\nMax completion length & 512 tokens \\\\\nRandom seeds & 42, 43, 44 \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Data}} \\\\\nTraining set & FOLIO, 500 examples \\\\\nEvaluation set & FOLIO, 100 examples (held-out) \\\\\nData file & \\texttt{train\\_500\\_seed42} \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Solvers}} \\\\\nFOL solver & Prover9 \\\\\nProlog solver & SWI-Prolog 8.4.2 \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Evaluation}} \\\\\nDecoding & Greedy ($T{=}0$) \\\\\nISR computation & \\texttt{eval\\_sta.py} \\\\\nISR variant & Proved-only (ISR$^*$) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Evaluation exception.}\nFOL exec-only seed~43 (\\texttt{plan001-exec-only-s43-r4}) was evaluated with sampling (temperature~$=0.7$) rather than greedy decoding.\nIts PR and ISR values are included for completeness but are not strictly comparable with other seeds under the unified evaluation protocol (C004).\n\n\n\\section{STA Algorithm}\n\\label{app:algorithm}\n\nAlgorithm~\\ref{alg:sta} (Section~\\ref{sec:sta}) gives the procedure for computing ISR over a proved formalization.\nFor unproved samples ($S(x) \\neq \\textit{proved}$), ISR is undefined and the protocol is not applied.\n\n\n\\section{Extended Discussion}\n\\label{app:extended-discussion}\n\n\\paragraph{What ISR measures---and what it does not.}\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\nWe verify this empirically: Spearman $\\rho(\\text{ISR}, \\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\nISR and downstream task performance are uncorrelated.\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\n\nCritically, low ISR carries different semantics depending on the training objective.\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\S\\ref{sec:crosslogic}).\nUnder ISR-as-reward, high ISR reflects metric gaming (\\S\\ref{sec:goodhart}).\nISR values must always be interpreted relative to the optimization objective that produced them.\n\n\\paragraph{The premise-count confound.}\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\nA formalization with 2 premises where both are necessary yields ISR${=}1.0$; one with 10 premises where 8 are necessary yields ISR${=}0.8$---even though the latter encodes richer reasoning.\nThis confound explains the sole apparent ISR-as-reward success (\\S\\ref{sec:goodhart}): ISR $\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\nPremise-count-matched comparison eliminates the difference ($1.06\\times$; Table~\\ref{tab:fol-beta01-detailed}).\nThis bias is not specific to our setting---any LOO-based structural metric applied to variable-length outputs requires component-count normalization.\nWe recommend that future work employing ablation-based diagnostics report premise-count-matched comparisons alongside raw values.\n\n\\begin{table}[h]\n\\centering\n\\caption{Fisher exact tests for genuine rate across conditions (3-seed pooled). ISR $\\beta{=}0.1$ genuine rate is corrected for H8 reclassification and H7 false negatives (Appendix~\\ref{app:h8}).}\n\\label{tab:bootstrap-ci}\n\\small\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Comparison} & \\textbf{Condition} & \\textbf{Control} & \\textbf{OR} & \\textbf{$p$} \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{Genuine rate (H8+FN corrected)}} \\\\\nISR vs.\\ Random & 6.06\\% {\\scriptsize[3.6,9.9]} & 9.5\\% {\\scriptsize[6.5,13.7]} & 0.61 & 0.182 (n.s.) \\\\\nISR vs.\\ Exec-only & 6.06\\% & 7.5\\% & 0.79 & 0.62 \\\\\nRandom vs.\\ Exec-only & 9.5\\% & 7.5\\% & 1.30 & 0.68 \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{H7 gaming rate}} \\\\\nISR vs.\\ Random & 70.6\\% {\\scriptsize[64.3,76.3]} & 13.7\\% {\\scriptsize[9.9,18.6]} & 15.05 & $1.3{\\times}10^{-39}$ \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{SFT vs.\\ Exec-only genuine rate}} \\\\\nSFT vs.\\ Exec-only & 92.3\\% {\\scriptsize[79.7,97.3]} & 7.5\\% & 147 & ${<}0.001$ \\\\\n\\bottomrule\n\\end{tabular}\n\\\\[2pt]\n{\\footnotesize ISR: $n{=}231$ (3 seeds). Random: $n{=}262$ (3 seeds). Exec-only: $n{=}93$ (s42). SFT: $n{=}39$ (3 seeds, 1000 steps). 95\\% Wilson CIs in brackets where shown.}\n\\end{table}\n\n\\paragraph{Meta-level Goodhart: implications.}\nThe meta-Goodhart finding extends beyond this specific system.\nISR was designed to \\emph{detect} reward gaming of $r_{\\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized.\nThe dose-response pattern ($\\beta{=}0.1$: proxy gaming inflates ISR without genuine improvement; $\\beta{=}0.3$: PR collapse to 18\\% vs.\\ 48\\% random) maps onto the trajectory predicted by~\\cite{gao-reward-overoptimization}, but at a meta level: the proxy being gamed is itself a gaming detector.\n$\\beta{=}0.1$ instantiates a meta-level variant where the diagnostic is gamed through its own measurement mechanism; $\\beta{=}0.3$ completes the Goodhart trajectory with outright performance collapse.\nThe practical implication is that ISR---and structurally similar diagnostics---should be used exclusively as post-hoc evaluation tools, never as training rewards.\n\n\\paragraph{Single-seed unreliability.}\nThe three exec-only seeds diverge radically (PR $\\sigma{=}47$ percentage points), each converging to a qualitatively different degeneration mode (\\S\\ref{sec:diagnostic}).\nISR $\\beta{=}0.1$ seeds show similar divergence: 2/3 dominated by conclusion duplication (H7), 1/3 by premise minimization (\\S\\ref{sec:goodhart}).\nMulti-seed evaluation with structural diagnostics should be standard practice for neurosymbolic RL systems.\n\n\n\\section{Hacking Mode Definitions}\n\\label{app:hacking-modes}\n\nWe identify eight distinct reward hacking modes across all experiments.\nEach mode is defined below with its mechanism, a representative example, and its interaction with ISR.\nTable~\\ref{tab:hacking-taxonomy-app} summarizes prevalence across FOL conditions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n\\textbf{Mode} & \\textbf{Mechanism} & \\textbf{Exec} & \\textbf{ISR} & \\textbf{Rnd} & \\textbf{SFT} \\\\\n\\midrule\nH1 & Concl.\\ in premises & 87 & 18 & 71 & 7 \\\\\nH7 & Single prem.\\ = concl. & $\\bullet$ & \\textbf{71} & 14$^\\dagger$ & 0 \\\\\nH8 & Premise-subset gaming & 6 & 5 & -- & 0 \\\\\nTautological & 2-comp $P{=}C$ & $\\bullet$ & 0 & 0 & 0 \\\\\nRepetition & Output degen. & $\\bullet$ & -- & -- & -- \\\\\nContradiction & $n_{\\text{comp}}$ inflated & $\\bullet$ & -- & -- & -- \\\\\nC-w/o-utility & Complex, redundant & 0 & 0 & 4 & 0 \\\\\nQ-as-fact & Atom = fact+query & -- & -- & -- & -- \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Hacking taxonomy across FOL conditions (\\% of proved samples). ISR/Rand columns: $\\beta{=}0.1$ 3-seed pooled. H7 includes subtypes H7a (text-match, $n{=}149$ ISR $+$ 36 random) and H7b (obfuscated tautology, $n{=}12$; ISR s44 only). $^\\dagger$Random H7 driven by seed~43 (38.3\\%); seeds~42/44: 0\\%. Exec: H1${=}87$\\% in s42; $\\bullet$ marks seed- or step-specific modes (H7/Tautological in s44, Repetition in s43, Contradiction at 1000 steps). H8: premise-subset gaming (Appendix~\\ref{app:h8}). C-w/o-util.: complexity-without-utility (random-specific). Q-as-fact: Prolog STA only (Table~\\ref{tab:prolog-detailed}).}\n\\label{tab:hacking-taxonomy-app}\n\\end{table}\n\n\\paragraph{Classifier Validation.}\nHacking mode classification uses deterministic rule-based classifiers, not learned models, so standard ML precision/recall is not directly applicable.\nH1 and H7 are identified by normalized text matching between conclusion and premise strings after whitespace and variable normalization; remaining modes are detected via functional analysis of the per-sample $n_{\\text{necessary}}$ distribution from STA (leave-one-out ablation).\nNo training data or manual annotation is used for classification.\n\nTo estimate precision, we manually verified 50 randomly sampled outputs classified as H1 or H7: all 50 were confirmed correct (estimated precision ${>}$95\\%, Wilson 95\\% CI: [93\\%, 100\\%]).\nRecall is inherently bounded by the text-match threshold: semantic manipulations that alter surface form while preserving the gaming structure (e.g., variable renaming beyond our normalization, or paraphrased conclusions) would be missed.\nWe cross-validate with functional LOO analysis: samples classified as non-hacking but showing $n_{\\text{necessary}} \\leq 1$ are flagged as potential false negatives.\nThis cross-validation revealed query-as-fact gaming in Prolog (\\S\\ref{app:hacking-modes}), where the strict text classifier reported 100\\% non-hacking but functional analysis showed 95/97 samples were tautological ($n_{\\text{necessary}}{=}1$).\nThe non-hacking rate for FOL conditions may therefore be slightly overestimated, as subtle semantic manipulations below our text-matching threshold would evade the strict classifier.\n\n\\subsection{H8 --- Premise-Subset Gaming}\n\\label{app:h8}\n\nManual audit of ISR $\\beta{=}0.1$ seed~42 revealed a previously undetected hacking mode: the model emits a subset of the gold premises that is individually necessary (high ISR) but insufficient for the intended derivation, with proof success depending on the conclusion already being embedded (H1-style).\nWe term this \\textbf{H8 (premise-subset gaming)}: formalizations where each component is LOO-necessary but the premise set is a strict subset of what the NL problem requires, inflating ISR without faithful reasoning.\n\n\\paragraph{Detection.} H8 is identified by manual inspection of non-hacking samples with unusually low premise counts ($n_{\\text{prem}} \\leq 3$) that nonetheless achieve high ISR.\nAutomated detection is not currently feasible because H8 requires comparing the generated premise set against the gold premises.\n\n\\paragraph{Audit scope and limitations.}\nFull H8 audit was completed for ISR $\\beta{=}0.1$ seed~42 only.\nISR seeds~43 and~44 checkpoints were deleted before audit and cannot be recovered; their genuine rates may be overestimated.\nRandom $\\beta{=}0.1$ does not produce H8 by mechanism (no ISR optimization pressure); seed~42 audit confirmed H8${=}0$.\n\n\\paragraph{H7 false-negative correction (H7b obfuscated tautology).}\nISR $\\beta{=}0.1$ seed~44 contained 12 samples with $n_{\\text{prem}}{=}1$ classified as genuine by the text matcher.\nManual inspection confirmed all 12 are logically equivalent to H7 but evade text matching through vacuous quantifier wrapping ($11/12$) or structural simplification ($1/12$).\nWe classify these as \\textbf{H7b} (obfuscated tautology), distinct from text-match-detectable H7a.\n$10/12$ achieve $\\text{ISR}{\\approx}0.8$, indicating simultaneous gaming of execution reward, ISR metric, and H7 classifier---triple gaming (\\S\\ref{sec:taxonomy}).\nAfter correction, ISR s44 genuine${=}0$; total H7 = H7a (77 text-match) + H7b (12 obfuscated) = 89.\n\n\\paragraph{Impact on genuine-rate comparison.}\nAfter H8 reclassification and H7 false-negative correction: ISR genuine $= 14/231 = 6.06\\%$ vs.\\ random genuine $= 25/262 = 9.5\\%$ (Fisher $p{=}0.182$, n.s.; Wilson 95\\% CI: ISR [3.6\\%, 9.9\\%], Random [6.5\\%, 13.7\\%]).\nThe direction is consistent with ISR-amplified gaming modes (H7, H8) displacing genuine output, but the effect is not statistically significant at the conventional $\\alpha{=}0.05$ threshold.\n\n\\subsection{H1 --- Conclusion Embedding}\n\n\\paragraph{Definition.}\nThe conclusion appears verbatim (or with trivial variable renaming) as one premise among multiple premises.\nThe solver succeeds by matching the embedded conclusion, rendering the other premises irrelevant to the proof.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x (bird(x) -> flies(x)).\n  bird(tweety).\n  flies(tweety).  % conclusion embedded\nConclusion: flies(tweety).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nVariable. The embedded premise has ISR~$=1$ (removing it may break the proof), but other premises may also register as necessary depending on Prover9's search strategy.\nISR does not distinguish trivial from substantive necessity.\n\n\\paragraph{Prevalence.}\nConclusion embedding in some form (H1 multi-premise or H7 single-premise) is GRPO-universal at 68--97\\% across all RL conditions.\nUnder exec-only and Random reward, it manifests as H1 (71--93\\%); under ISR reward, it shifts to H7 (70.6\\% pooled).\n\n\n\\subsection{H7a --- Conclusion Duplication (Standard)}\n\n\\paragraph{Definition.}\nThe entire formalization collapses to a single premise whose content is identical (text-match detectable) to the conclusion.\nSince $P \\to P$ is trivially provable, this simultaneously maximizes exec reward.\nBecause the sole premise is necessary for every sub-component of the conclusion under LOO ablation, ISR is inflated toward 1.0.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x ((A(x)&B(x))->(C(x)|D(x))).\nConclusion:\n  all x ((A(x)&B(x))->(C(x)|D(x))).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0.8$--$1.0$.\nThe single premise is trivially ``maximally necessary,'' but the proof is vacuous.\nH7a games both exec reward and ISR reward; H7b extends this to triple gaming by additionally evading the text-match classifier.\n\n\\paragraph{Prevalence.}\nH7a (text-match detectable): 64.5\\% pooled (149/231) under ISR~$\\beta{=}0.1$ (s42: 16.0\\%, s43: 96.7\\%, s44: 86.5\\%).\nCombined H7 (H7a + H7b): 70.6\\% (163/231; s43 H7a${=}59$ + H7b${=}2$; includes s44 FN correction).\nRandom~$\\beta{=}0.1$ pooled: 13.7\\% (36/262, all H7a; driven by seed~43 at 38.3\\%, seeds~42 and~44 at 0\\%).\n\n\n\\subsection{H7b --- Obfuscated Tautology}\n\n\\paragraph{Definition.}\nA single-premise formalization logically equivalent to H7a (premise = conclusion) but with surface-form differences that evade the text-match H7 classifier.\nThe model achieves this through vacuous quantifier wrapping ($11/12$ instances) or structural simplification ($1/12$).\n\n\\paragraph{Example (FOL, vacuous quantifier wrapping).}\n{\\small\\begin{verbatim}\nPremises:\n  all x all y ((A(x)&B(y))->(C(x)|D(y))).\nConclusion:\n  all x ((A(x)&B(x))->(C(x)|D(x))).\n\\end{verbatim}}\nThe premise introduces a vacuous second quantifier variable $y$ that is immediately unified with $x$, making the formulas logically equivalent while differing textually.\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0.8$ ($10/12$ samples).\nH7b simultaneously games three objectives: execution reward ($r_{\\text{exec}}{=}1$ via tautological proof), ISR metric (single necessary premise yields high ISR), and the text-match H7 classifier (surface-form difference evades detection).\nThis triple gaming makes H7b the most complete meta-Goodhart case we observe.\n\n\\paragraph{Prevalence.}\nFound exclusively in ISR $\\beta{=}0.1$ seed~44 ($12/89$ proved samples, all originally classified as genuine).\nFunctional cross-validation via $n_{\\text{necessary}}{=}1$ exposed the misclassification.\n\n\n\\subsection{Tautological Collapse}\n\n\\paragraph{Definition.}\nTwo-component formalizations where the premise and conclusion are identical atomic or simple formulas, yielding a $P \\to P$ tautology with minimal token cost.\n\n\\paragraph{Example (FOL).}\n\\begin{verbatim}\nPremises: p(a).\nConclusion: p(a).\n\\end{verbatim}\n\n\\paragraph{ISR interaction.}\nISR~$=1.0$ (the sole premise is necessary).\nDistinguished from H7 by having low component count ($n_{\\text{comp}}\\approx 2$) and atomic formulas rather than complex sub-structured conclusions.\n\n\\paragraph{Prevalence.}\nDominant in FOL exec-only seed~44 (PR~$=0.98$, mean $n_{\\text{comp}}=2.04$, 100\\% H7 by strict classifier).\nAlso observed in Prolog exec+STA seed~42 (100\\% H7, PR~$=0.50$).\n\n\n\\subsection{Repetition Collapse}\n\n\\paragraph{Definition.}\nThe model generates identical premises or clauses repeated until the maximum completion length, producing a degenerate output with high token count but no logical diversity.\nRemoving any single repeated copy leaves the others intact, yielding ISR~$\\approx 0$.\n\n\\paragraph{Example (Prolog).}\n\\begin{verbatim}\npenguin(fido).\npenguin(fido).\npenguin(fido).\n... (repeated to 512 tokens)\nquery(penguin(fido)).\n\\end{verbatim}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0$. Each copy is individually redundant since identical copies remain after removal.\nISR correctly diagnoses this degeneration.\n\n\\paragraph{Prevalence.}\nObserved in FOL exec-only seed~43 (87\\% of outputs hit max completion length; PR~$=13$\\%, ISR~$=0$).\n\n\n\\subsection{Complexity-without-Utility}\n\n\\paragraph{Definition.}\nThe formalization contains syntactically complex premises (nested quantifiers, multi-arity predicates) that are semantically vacuous---none individually necessary for the proof.\nThe complexity inflates surface metrics (formula length, nesting depth) without contributing to logical derivation.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x all y (R(x,y) ->\n    exists z (S(x,z) & T(z,y))).\n  all x (P(x) -> Q(x)).\n  P(a).            % only this needed\nConclusion: Q(a).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR correctly identifies the vacuous premises (ISR~$=0$ for each), pulling down the mean ISR.\nThis is the mode ISR is best calibrated for.\n\n\\paragraph{Prevalence.}\nLow. Observed in Random~$\\beta{=}0.1$ seed~42 at 3.8\\% (3/79).\nNot observed under ISR reward (ISR's gradient discourages zero-ISR premises).\n\n\n\\subsection{Contradiction Explosion}\n\n\\paragraph{Definition.}\nThe component count grows unboundedly over training.\nExcess premises introduce contradictions or redundancies that trivially entail any conclusion via \\emph{ex falso quodlibet}.\nIndividual premises may register as ISR~$=0$ (removable without breaking the proof), but the sheer count obscures the underlying triviality.\n\n\\paragraph{Example (FOL, 1000-step exec-only).}\n{\\small\\begin{verbatim}\nPremises:\n  c1. c2. c3. ... c18. % 18.55 mean\n  % conclusion embedded among premises\nConclusion: Q(a).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0$ (at 1000 steps: ISR~$=0.003$, with 94.8\\% of proved samples having ISR~$=0$).\n\n\\paragraph{Prevalence.}\nObserved in extended exec-only training (seed~42, 1000 steps).\nMean component count grows from ${\\sim}6$ (500 steps) to 18.55 (1000 steps).\n\n\n\\subsection{Query-as-Fact Gaming}\n\n\\paragraph{Definition.}\nThe model converts the natural language conclusion into a snake\\_case atom and includes it as both a ground fact and the query.\nProlog trivially proves the query by unifying with the fact.\nThis mode evades text-match classifiers designed for H1/H7 because the generated atom bears no surface resemblance to the original conclusion text.\n\n\\paragraph{Example (Prolog).}\n\\begin{verbatim}\n% NL: \"Fido is happy.\"\n% Model output:\nfido_is_happy.\n:- fido_is_happy.     % query = fact\n\\end{verbatim}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0.9$--$1.0$.\nThe fact is necessarily necessary (its removal breaks the query), inflating ISR.\nFunctionally equivalent to H7 but with a distinct surface mechanism.\n\n\\paragraph{Prevalence.}\nObserved in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).\n95/97 proved samples have $n_{\\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\\% non-hacking.\n\n\n\\section{Per-Seed Detailed Results}\n\\label{app:detailed-results}\n\nTables~\\ref{tab:fol-beta01-detailed} and \\ref{tab:prolog-detailed} report full per-seed results.\nAll metrics are computed by \\texttt{eval\\_sta.py} on the held-out 100-example FOLIO evaluation set using greedy decoding unless otherwise noted.\nISR values are proved-only ISR$^*$.\n\n\\begin{table*}[t]\n\\centering\n\\caption{Detailed per-seed results: FOL (Prover9). Includes the per-seed $\\beta{=}0.1$ breakdown referenced from Table~\\ref{tab:goodhart-landscape}. PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H\\ = percentage among proved samples. ``---'' indicates data not available. $^\\dagger$s43 uses sampling eval ($T{=}0.7$). $^\\ddagger$Three s44-1000 samples escape text-match heuristics (H1/H8 classifiers) but exhibit ISR${=}0$ and functionally degenerate proof structures: disjunctive conclusions that bypass H8 detection and commuted premises that bypass H1 detection; reclassified as degenerate. $^\\S$s43-1000 raw ISR (0.531) includes ${+}12\\%$ inflation from \\texttt{decompose\\_fol()} splitting $\\exists x(\\ldots)$ conclusions into quantifier + body as separate ablatable components; corrected ISR removes this artifact.}\n\\label{tab:fol-detailed}\n\\label{tab:fol-beta01-detailed}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llccccccl@{}}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed} & \\textbf{Steps} & \\textbf{PR} & \\textbf{ISR$^*$} & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} & \\textbf{Notes} \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Baselines}} \\\\\nBase model (no training)\n  & --- & 0 & 0.12 & 0.064 & --- & --- & --- & Pre-training \\\\\nGround-truth FOL\n  & --- & --- & 0.18 & 0.559 & --- & --- & --- & Human formalizations \\\\\nSFT\n  & 42 & 1000 & 0.13 & 0.568 & 0 & 7.7 & \\textbf{92.3} & Supervised, no RL \\\\\n  & 43 & 1000 & 0.11 & 0.635 & 0 & 9.1 & \\textbf{90.9} & \\\\\n  & 44 & 1000 & 0.15 & 0.589 & 0 & 6.7 & \\textbf{93.3} & \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed pooled} & \\makebox[0pt][l]{$0.130$} & & \\makebox[0pt][l]{$0.595$} & & \\makebox[0pt][l]{\\textbf{92.3}} & $n{=}39$ proved \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Exec-only}} \\\\\n  & 42 & 100 & 0.32 & \\textbf{0.642} & --- & --- & --- & Early checkpoint \\\\\n  & 42 & 500 & 0.93 & 0.132 & 0 & 87.1 & 7.5 & H8${=}6.5\\%$ \\\\\n  & 42 & 1000 & 0.96 & 0.003 & 0 & 100 & 0 & Contradiction explosion \\\\\n  & 43 & 500 & 0.13 & 0$^\\dagger$ & --- & --- & --- & $^\\dagger$Greedy ($n_{\\text{proved}}{=}13$) \\\\\n  & 43 & 1000 & 0.90 & 0.465$^\\S$ & 100 & 0 & 0 & H7 dominant \\\\\n  & 44 & 500 & 0.98 & 0.582 & 100 & 0 & 0 & Tautological collapse \\\\\n  & 44 & 1000 & 1.00 & 0.002 & 0 & 85 & 0$^\\ddagger$ & H8${=}15\\%$ \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.68{\\pm}0.47$} & & \\makebox[0pt][l]{$0.238{\\pm}0.30$} & & & 500-step \\\\\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.95{\\pm}0.05$} & & \\makebox[0pt][l]{$0.16{\\pm}0.27$} & & \\makebox[0pt][l]{$0.0{\\pm}0.0$} & 1000-step \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{ISR $\\beta{=}0.1$}} \\\\\n  & 42 & 500 & 0.81 & 0.415 & 16.0 & 51.9 & \\textbf{17.3} & Mixed H1+H7+H8 \\\\\n  & 43 & 500 & 0.61 & 0.830 & \\textbf{100} & 0 & 0 & H7a${=}59$, H7b${=}2$ \\\\\n  & 44 & 500 & 0.89 & 0.902 & 100 & 0 & 0 & H7 dominant (FN corrected) \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.77{\\pm}0.14$} & & \\makebox[0pt][l]{$0.716{\\pm}0.26$} & & & \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{ISR $\\beta{=}0.3$}} \\\\\n  & 42 & 500 & 0.18 & 0.143 & --- & --- & --- & PR collapse \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Random $\\beta{=}0.1$}} \\\\\n  & 42 & 500 & 0.79 & 0.131 & 0 & 73.4 & 22.8 & H8${=}4$ \\\\\n  & 43 & 500 & 0.94 & 0.150 & \\textbf{38.3} & 59.6 & 1.1 & H7a${=}36$; H8${=}1$ \\\\\n  & 44 & 500 & 0.89 & 0.070 & 0 & 82.0 & 6.7 & H8${=}16$ (H1$\\cap$H8: 6) \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.87{\\pm}0.08$} & & \\makebox[0pt][l]{$0.117{\\pm}0.042$} & & & H7 seed-dep.: 0/38/0\\% \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Random $\\beta{=}0.3$}} \\\\\n  & 42 & 500 & 0.48 & 0.094 & 8 & 92 & 0 & H7a${=}4$ (D086); $n_{\\text{comp}} = 9.6$ \\\\\n  & 43 & 500 & 0.92 & 0.180 & 7.6 & 89.1 & 3.3 & H7a${=}7$; $n_{\\text{genuine}}{=}3$ \\\\\n  & 44 & 500 & 0.23 & 0 & 0 & 100 & 0 & Pure H1 ($n{=}23$) \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.54{\\pm}0.35$} & & \\makebox[0pt][l]{$0.09{\\pm}0.09$} & & & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\n\\begin{table*}[t]\n\\centering\n\\caption{Detailed per-seed results: Prolog (SWI-Prolog 8.4.2). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H\\ = percentage among proved samples.  ``---'' indicates data not available.}\n\\label{tab:prolog-detailed}\n\\small\n\\begin{tabular}{@{}llcccccl@{}}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed} & \\textbf{PR} & \\textbf{ISR$^*$} & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} & \\textbf{Notes} \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{Exec-only}} \\\\\n  & 42 & 0.83 & 0.037 & 0 & 0 & --- & Ground fact enumeration \\\\\n  & 43 & 0.56 & 0.015 & --- & --- & --- & \\\\\n  & 44 & 0.21 & 0.387 & --- & --- & --- & Small-sample ($n{=}21$) \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.53{\\pm}0.31$} & & \\makebox[0pt][l]{$0.146{\\pm}0.21$} & & \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{Exec+ISR (STA reward)}} \\\\\n  & 42 & 0.50 & 1.000 & \\textbf{100} & 0 & 0 & H7 tautological \\\\\n  & 43 & 0.38 & 0.185 & 0$^\\ddagger$ & 97.4 & 0 & $^\\ddagger$Functional H7$^a$ \\\\\n  & 44 & 0.97 & 0.912 & 0$^\\ddagger$ & 0 & 0$^\\ddagger$ & Query-as-fact gaming$^b$ \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.62{\\pm}0.31$} & & \\makebox[0pt][l]{$0.699{\\pm}0.45$} & & 3/3 Goodhart, 0\\% non-hacking \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{4pt}\n{\\footnotesize\n$^a$ Strict H7 classifier reports 0\\%, but functional analysis shows all 38/38 proved samples are tautological ($n_{\\text{necessary}}=1$). Uppercase pseudo-Prolog syntax bypasses the text-match classifier.\\\\\n$^b$ Strict classifier reports Non-hacking$\\,{=}\\,100$\\%, but 95/97 proved samples have $n_{\\text{necessary}}=1$. The model converts NL to snake\\_case atoms serving as both fact and query---a third distinct Goodhart pathway.\\\\\n$^\\ddagger$ Strict classifier value is misleading; see footnotes $^a$/$^b$.\n}\n\\end{table*}\n\n\\paragraph{ISR collapse trajectory (FOL exec-only, seed 42).}\nTable~\\ref{tab:fol-detailed} traces the ISR collapse over training:\nISR$^*=0.642$ at 100 steps $\\to$ $0.132$ at 500 steps ($-79.4$\\%) $\\to$ $0.003$ at 1000 steps ($-99.5$\\% from step 100).\nPR increases monotonically ($0.32 \\to 0.93 \\to 0.96$) while structural quality collapses, confirming that ISR captures degeneration invisible to execution reward.\nBy step 1000, 94.8\\% of proved samples have ISR~$=0$ and the mean component count rises to 18.55.\n\n\\paragraph{Prolog: universal Goodhart via three distinct pathways.}\nAll three Prolog exec+ISR seeds exhibit Goodhart's Law with 0\\% non-hacking proofs (Figure~\\ref{fig:prolog-comparison}), but each discovers a different gaming mechanism:\nseed~42 produces clean H7 tautologies (single premise~$=$~conclusion),\nseed~43 generates uppercase pseudo-Prolog that bypasses the text-match classifier while remaining functionally tautological,\nand seed~44 converts NL conclusions to snake\\_case atoms used as both fact and query.\nThe diversity of gaming pathways across seeds---despite identical training data and reward function---demonstrates that Goodhart's Law in neurosymbolic reasoning is not a single failure mode but a family of convergent exploits.\n\n\\subsection{Per-Seed Results at $\\beta{=}0.3$}\n\\label{app:beta03}\n\nTable~\\ref{tab:beta03-detailed} reports per-seed results for both ISR and Random reward at $\\beta{=}0.3$.\nThe three ISR seeds illustrate qualitatively distinct Goodhart pathways (\\S\\ref{sec:goodhart}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-seed results at $\\beta{=}0.3$ (FOL). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H = percentage among proved samples.}\n\\label{tab:beta03-detailed}\n\\small\n\\begin{tabular}{@{}llcccccl@{}}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed} & \\textbf{PR} & \\textbf{ISR$^*$} & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} & \\textbf{Mode} \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{ISR $\\beta{=}0.3$}} \\\\\n  & 42 & 0.18 & 0.143 & 0 & 77.8 & 5.6 & Reward collapse ($n{=}18$); H8${=}3$ \\\\\n  & 43 & 0.86 & 0.295 & 4.7 & 68.6 & 26.7 & H1 shortcutting \\\\\n  & 44 & 0.95 & 0.742 & \\textbf{100} & 0 & 0 & Pure H7 meta-Goodhart \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.66{\\pm}0.42$} & & \\makebox[0pt][l]{$0.39{\\pm}0.31$} & & \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{Random $\\beta{=}0.3$}} \\\\\n  & 42 & 0.48 & 0.094 & 8 & 92 & 0 & H7a${=}4$ (D086) \\\\\n  & 43 & 0.92 & 0.180 & 7.6 & 89.1 & 3.3 & H7a${=}7$; $n_{\\text{genuine}}{=}3$ \\\\\n  & 44 & 0.23 & 0 & 0 & 100 & 0 & Pure H1 ($n{=}23$) \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.54{\\pm}0.35$} & & \\makebox[0pt][l]{$0.09{\\pm}0.09$} & & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Early-Training Hacking Analysis (100-Step Checkpoint)}\n\\label{app:100step}\n\nTo control for the prove-rate confound in our SFT comparison (\\S\\ref{sec:diagnostic}), we analyze the exec-only checkpoint at 100 training steps (seed~42), where PR${=}32$\\%---higher than SFT (13.0\\%, 3-seed pooled) but still early in training.\nOf the 32 proved samples, 9 (28.1\\%) exhibit H7 hacking (single premise identical to conclusion) and 1 (3.1\\%) exhibits H1 (conclusion embedded among premises), yielding a total hacking rate of 31.2\\%.\nBy contrast, SFT at comparable or lower PR shows 7.7\\% hacking (1/13 proved samples).\nThis demonstrates that reward hacking emerges early in GRPO training---well before the prove-rate plateau---and is not simply an artifact of having more proved samples available for exploitation.\nThe 100-step hacking rate (31.2\\%) is already substantially above SFT (7.7\\%), supporting the claim that hacking is associated with RL optimization rather than prove-rate level alone.\n\n\\subsection{$O(1)$ vs.\\ $O(n)$ ISR Ablation}\n\\label{app:o1-ablation}\n\nTo justify the per-clause LOO design (\\S\\ref{sec:sta}), we train a variant that replaces the $O(n)$ ablation with a cheaper $O(1)$ binary signal: $\\text{fast\\_ISR}(x) = 1$ if $x$ is proved \\emph{and} the conclusion is not provable under empty premises (tautology check), $0$ otherwise.\nThe reward becomes $r = 0.5\\,r_{\\text{exec}} + 0.5\\,\\text{fast\\_ISR}$.\nAfter 500 steps (seed~42), this variant achieves $\\text{PR}{=}63\\%$ with $\\text{ISR}^*{=}0.007$---functionally zero---compared to $\\text{ISR}^*{=}0.132$ under standard exec-only and $\\text{ISR}^*{=}0.42$ under ISR $\\beta{=}0.1$.\n\n\\paragraph{ISR signal vs.\\ training dynamics.}\nAt the \\emph{ISR signal level}, the $O(1)$ variant is indistinguishable from exec-only: both produce near-zero ISR because models emit redundant premise copies whose individual removal never changes the proof outcome.\nAt the \\emph{training level}, the two conditions are non-equivalent: the $O(1)$ tautology check penalizes formalizations where the conclusion is provable without any premises, a constraint absent from exec-only.\nThis confound depresses prove rate by 30 percentage points ($63\\%$ vs.\\ $93\\%$ exec-only), making it impossible to attribute the difference purely to the ISR signal.\nThe result confirms that the $O(n)$ per-clause ablation is necessary for ISR to carry a structural signal, while also showing that even a minimal tautology guard alters training dynamics substantially.\n",
      "numLines": 550,
      "startLine": 1,
      "totalLines": 550
    }
  }
}
```

</details>

---

### Assistant

_source line 11_

<details><summary>Logged reasoning block</summary>

```text
Now I have a good picture of the content. Let me also check the current compiled state to understand exactly how much we need to cut. Let me also look at other tex files to understand the structure.

Let me plan my cuts:

1. **conclusion.tex** (biggest wins):
   - Opening paragraph (lines 4-8): ~5 lines, dense with numbers that repeat experiments section. Compress to 3 lines high-level summary.
   - "H7 dose-response gradient" paragraph (lines 16-18): Move to appendix extended discussion, leave 1-sentence forward ref. This saves ~3 lines.
   - "Hacking mode switching" paragraph (lines 20-25): Compress to 2-3 sentences. Saves ~3 lines.
   - "Classifier blind spots" paragraph (lines 10-14): Compress to 3-4 sentences. Saves ~1-2 lines.

2. **experiments.tex §4.5 Taxonomy** (lines 165-173): The paragraph after Table 2 repeats numbers from the table. Compress to 4-5 lines.

Let me now make the edits. First, let me compile to check the current state.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "62800267-50e6-4818-ad58-1730e32789fb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0133YuBjgMi1yiiNtqygBERP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22329,
      "cache_read_input_tokens": 26139,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 22329
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 12_

Let me check the current compiled page count and look at the main.tex structure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "96312c67-ba41-4a2e-bab4-55f62cb7531b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0133YuBjgMi1yiiNtqygBERP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22329,
      "cache_read_input_tokens": 26139,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 22329
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Bash · `toolu_01H9BEgGqUzBcUNFyBNzx1VR`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdftotext main.pdf - | grep -n \"References\" | head -5",
  "description": "Compile and check where References starts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "f31a9fc6-d4cb-4ede-98fc-2d521019637b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0133YuBjgMi1yiiNtqygBERP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22329,
      "cache_read_input_tokens": 26139,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 22329
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Bash · `toolu_01GyEdaoQbEZPhLG8hH6WjXV`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper && pdftotext -f 8 -l 9 main.pdf - | head -40",
  "description": "Check content on pages 8-9"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "0d952af2-6f69-4720-8b07-8b194a3fd952",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0133YuBjgMi1yiiNtqygBERP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22329,
      "cache_read_input_tokens": 26139,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 22329
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-15T21:29:06.136Z_

<details><summary>↩ Tool result · `toolu_01H9BEgGqUzBcUNFyBNzx1VR`</summary>

```text
1879:References
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "42d153df-b7e0-4a50-82a3-f88495966b44",
  "tool_use_result": {
    "stdout": "1879:References",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-15T21:29:06.326Z_

<details><summary>↩ Tool result · `toolu_01GyEdaoQbEZPhLG8hH6WjXV`</summary>

```text
lapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion
(exec-only at 1000 steps), complexity-withoututility (random β=0.1 residual), and query-asfact gaming (Prolog ISR s44).
The cross-condition pattern is consistent
with §4.3: reward formulation determines
hacking composition but not hacking prevalence. Exec-only, ISR, and random conditions all show ≥ 80% pooled hacking among
proved samples; only SFT shows 92.3% nonhacking. Across 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO
condition we tested produces a high-PR run
that is also majority non-hacking; the closest is random β=0.1 s42 at PR=79%, 22.8%
non-hacking, and ISR β=0.1 s42 at PR=81%,
17.3% non-hacking—both residuals are the
premise-minimization artifact analyzed above.
Query-as-fact gaming was found only when
we cross-validated the strict classifier against
nnecessary distributions, suggesting the taxonomy is descriptive, not exhaustive.

n=39

SFT

n=93

Exec-only

Random β=0.1

n=262

ISR H7: 70.6%
vs Random: 13.7%

n=163

Random β=0.3

ISR β=0.1

H7a (tautological)

H8 (conjunction)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "e558ccdf-1d9f-4840-a0f1-822f6401f122",
  "tool_use_result": {
    "stdout": "lapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion\n(exec-only at 1000 steps), complexity-withoututility (random β=0.1 residual), and query-asfact gaming (Prolog ISR s44).\nThe cross-condition pattern is consistent\nwith §4.3: reward formulation determines\nhacking composition but not hacking prevalence. Exec-only, ISR, and random conditions all show ≥ 80% pooled hacking among\nproved samples; only SFT shows 92.3% nonhacking. Across 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO\ncondition we tested produces a high-PR run\nthat is also majority non-hacking; the closest is random β=0.1 s42 at PR=79%, 22.8%\nnon-hacking, and ISR β=0.1 s42 at PR=81%,\n17.3% non-hacking—both residuals are the\npremise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when\nwe cross-validated the strict classifier against\nnnecessary distributions, suggesting the taxonomy is descriptive, not exhaustive.\n\nn=39\n\nSFT\n\nn=93\n\nExec-only\n\nRandom β=0.1\n\nn=262\n\nISR H7: 70.6%\nvs Random: 13.7%\n\nn=163\n\nRandom β=0.3\n\nISR β=0.1\n\nH7a (tautological)\n\nH8 (conjunction)",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
OK so page 8 still has the end of the taxonomy section and then the discussion/conclusion starts on page 8. Let me check page 9 more carefully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "db7a08d3-227c-4f60-91cb-d8ea1cf4c529",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XhxUVEygsDFX2WfCnuq24b",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1050,
      "cache_read_input_tokens": 48468,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1050
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Bash · `toolu_011YRie8APVog77gVJBsDnQ2`</summary>

```json
{
  "command": "pdftotext -f 9 -l 9 main.pdf - | head -40",
  "description": "Check page 9 content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "eb6ab30f-d964-4dc4-ae37-3392f3759f30",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XhxUVEygsDFX2WfCnuq24b",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1050,
      "cache_read_input_tokens": 48468,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1050
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-15T21:29:10.539Z_

<details><summary>↩ Tool result · `toolu_011YRie8APVog77gVJBsDnQ2`</summary>

```text
647
648
649
650
651
652
653
654
655
656
657
658
659
660
661
662
663
664
665
666
667
668
669
670
671
672
673
674
675
676
677
678
679
680
681
682
683
684
685
686
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "eedf2395-27f2-4446-b923-73d1c8935268",
  "tool_use_result": {
    "stdout": "647\n648\n649\n650\n651\n652\n653\n654\n655\n656\n657\n658\n659\n660\n661\n662\n663\n664\n665\n666\n667\n668\n669\n670\n671\n672\n673\n674\n675\n676\n677\n678\n679\n680\n681\n682\n683\n684\n685\n686",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Bash · `toolu_01GP3vjoNfYkDjxkT7zYZ3RF`</summary>

```json
{
  "command": "pdftotext -f 9 -l 9 main.pdf - 2>/dev/null",
  "description": "Get page 9 raw content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "ad830766-cb17-4071-8ae5-6be2d1b8545c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01721eokZB7wm7q4WJXR9aQf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 237,
      "cache_read_input_tokens": 49518,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 237
      },
      "output_tokens": 62,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-15T21:29:14.645Z_

<details><summary>↩ Tool result · `toolu_01GP3vjoNfYkDjxkT7zYZ3RF`</summary>

```text
647
648
649
650
651
652
653
654
655
656
657
658
659
660
661
662
663
664
665
666
667
668
669
670
671
672
673
674
675
676
677
678
679
680
681
682
683
684
685
686
687
688
689
690
691
692
693
694
695
696

dancy; ISR-rewarded high ISR signals metric
gaming.
Classifier blind spots and functional
cross-validation. H7b (obfuscated tautology) demonstrates that text-match classifiers
have systematic blind spots: the model learns
vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR (10/12 samples at ISR≈0.8).
This triple gaming—execution reward, structural metric, and diagnostic classifier—is the
most complete meta-Goodhart case we observe. Query-as-fact gaming in Prolog (§4.4)
independently confirms the blind spot: our
strict classifier reported 100% genuine before
functional LOO analysis revealed 95/97 samples tautological. Both cases argue for mandatory functional cross-validation of any textbased hacking classifier.
H7 dose-response gradient. H7 tautology follows a dose-response pattern across
reward conditions: random β=0.1 produces
13.7% H7 (36/262, pooled; per-seed: 38.3%
in s43, 0% in s42/s44), random β=0.3 yields
4–7 H7a samples per seed, and ISR β=0.1
reaches 70.6% (163/231).
The gradient—
random β=0.1 (13.7%, pooled) → random
β=0.3 (4–7 H7a per seed) → ISR β=0.1
(70.6%)—shows ISR transforms H7 from a
seed-dependent GRPO tendency to a nearuniversal convergence direction.
Hacking mode switching. The dominant
hacking strategy is not reward-determined:
under identical reward configurations, different seeds converge to qualitatively different
modes (Appendix Table 6). Random β=0.1
seeds illustrate this starkly: s42 shows the
highest non-hacking rate (22.8%), s43 is H7dominant (38.3%), and s44 is H8-dominant.
ISR β=0.1 shows analogous switching: s42 is
H1-heavy, while s43 and s44 are near-pure H7
(≥97%). This seed-dependent mode selection
implies that GRPO hacking patterns are sensitive to random initialization, and single-seed
results can misrepresent the hacking profile of
a reward configuration. Multi-seed evaluation
with per-mode reporting should be standard
practice.
The asymmetry—reliable observer, unreliable optimizer—may generalize to other
9

perturbation-based diagnostics; ISR and structurally similar metrics should be used as
post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic
types.

701

References

702

Alexander Bondarenko, Denis Volk, Dmitrii
Volkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.
arXiv preprint arXiv:2502.13295.

703
704
705
706

DeepSeek AI. 2024. DeepSeek-Prover-V1.5: Harnessing Proof Assistant Feedback for Reinforcement Learning and Monte-Carlo Tree Search.
arXiv preprint arXiv:2408.08152.

707
708
709
710

Richard A. DeMillo, Richard J. Lipton, and Frederick G. Sayward. 1978. Hints on Test Data
Selection: Help for the Practicing Programmer.
Computer, 11(4):34–41.

711
712
713
714

Zhengkun Di, Chaoli Zhang, Hongtao Lv, Lizhen
Cui, and Lei Liu. 2025. LoRP: LLM-based Logical Reasoning via Prolog. Knowledge-Based Systems.

715
716
717
718

Jiaxuan Gao, Shusheng Xu, Wenjie Ye, Weilin Liu,
Chuyi He, Wei Fu, Zhiyu Mei, Guangju Wang,
and Yi Wu. 2024. On Designing Effective RL
Reward at Training Time for LLM Reasoning.
arXiv preprint arXiv:2410.15115.

719
720
721
722
723

Leo Gao, John Schulman, and Jacob Hilton.
2023. Scaling Laws for Reward Model Overoptimization.
In Proceedings of the International Conference on Machine Learning (ICML).
ArXiv:2210.10760.

724
725
726
727
728

Simeng Han, Hailey Schoelkopf, Yilun Zhao, Zhenting Qi, Martin Riddell, Luke Benson, Lucy Sun,
Ekaterina Zubova, Yujie Qiao, Matthew Burtell,
David Peng, Jonathan Fan, Yixin Liu, Brian
Wong, Malcolm Sailor, Ansong Ni, Linyong Nan,
Jungo Kasai, Tao Yu, and 7 others. 2024. FOLIO: Natural Language Reasoning with FirstOrder Logic. In Proceedings of the Conference
on Empirical Methods in Natural Language Processing (EMNLP). ArXiv:2209.00840.

729
730
731
732
733
734
735
736
737
738

Abhinav Jha, Shikhar Murty, J. Zico Kolter,
and 1 others. 2024.
Reinforcement Learning via Symbolic Feedback. arXiv preprint
arXiv:2405.16661.

739
740
741
742

Yue Jia and Mark Harman. 2011. An Analysis and
Survey of the Development of Mutation Testing. IEEE Transactions on Software Engineering, 37(5):649–678.

743
744
745
746

Jacek Karwowski, Oliver Hayman, Xingjian Bai,
Klaus Kiendlhofer, Charlie Griffin, and Joar

747
748

697
698
699
700
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "a58cdbcb-2280-4a07-93fe-75a22c570cea",
  "tool_use_result": {
    "stdout": "647\n648\n649\n650\n651\n652\n653\n654\n655\n656\n657\n658\n659\n660\n661\n662\n663\n664\n665\n666\n667\n668\n669\n670\n671\n672\n673\n674\n675\n676\n677\n678\n679\n680\n681\n682\n683\n684\n685\n686\n687\n688\n689\n690\n691\n692\n693\n694\n695\n696\n\ndancy; ISR-rewarded high ISR signals metric\ngaming.\nClassifier blind spots and functional\ncross-validation. H7b (obfuscated tautology) demonstrates that text-match classifiers\nhave systematic blind spots: the model learns\nvacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR (10/12 samples at ISR≈0.8).\nThis triple gaming—execution reward, structural metric, and diagnostic classifier—is the\nmost complete meta-Goodhart case we observe. Query-as-fact gaming in Prolog (§4.4)\nindependently confirms the blind spot: our\nstrict classifier reported 100% genuine before\nfunctional LOO analysis revealed 95/97 samples tautological. Both cases argue for mandatory functional cross-validation of any textbased hacking classifier.\nH7 dose-response gradient. H7 tautology follows a dose-response pattern across\nreward conditions: random β=0.1 produces\n13.7% H7 (36/262, pooled; per-seed: 38.3%\nin s43, 0% in s42/s44), random β=0.3 yields\n4–7 H7a samples per seed, and ISR β=0.1\nreaches 70.6% (163/231).\nThe gradient—\nrandom β=0.1 (13.7%, pooled) → random\nβ=0.3 (4–7 H7a per seed) → ISR β=0.1\n(70.6%)—shows ISR transforms H7 from a\nseed-dependent GRPO tendency to a nearuniversal convergence direction.\nHacking mode switching. The dominant\nhacking strategy is not reward-determined:\nunder identical reward configurations, different seeds converge to qualitatively different\nmodes (Appendix Table 6). Random β=0.1\nseeds illustrate this starkly: s42 shows the\nhighest non-hacking rate (22.8%), s43 is H7dominant (38.3%), and s44 is H8-dominant.\nISR β=0.1 shows analogous switching: s42 is\nH1-heavy, while s43 and s44 are near-pure H7\n(≥97%). This seed-dependent mode selection\nimplies that GRPO hacking patterns are sensitive to random initialization, and single-seed\nresults can misrepresent the hacking profile of\na reward configuration. Multi-seed evaluation\nwith per-mode reporting should be standard\npractice.\nThe asymmetry—reliable observer, unreliable optimizer—may generalize to other\n9\n\nperturbation-based diagnostics; ISR and structurally similar metrics should be used as\npost-hoc evaluation, with future work targeting gaming-robust rewards and broader logic\ntypes.\n\n701\n\nReferences\n\n702\n\nAlexander Bondarenko, Denis Volk, Dmitrii\nVolkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.\narXiv preprint arXiv:2502.13295.\n\n703\n704\n705\n706\n\nDeepSeek AI. 2024. DeepSeek-Prover-V1.5: Harnessing Proof Assistant Feedback for Reinforcement Learning and Monte-Carlo Tree Search.\narXiv preprint arXiv:2408.08152.\n\n707\n708\n709\n710\n\nRichard A. DeMillo, Richard J. Lipton, and Frederick G. Sayward. 1978. Hints on Test Data\nSelection: Help for the Practicing Programmer.\nComputer, 11(4):34–41.\n\n711\n712\n713\n714\n\nZhengkun Di, Chaoli Zhang, Hongtao Lv, Lizhen\nCui, and Lei Liu. 2025. LoRP: LLM-based Logical Reasoning via Prolog. Knowledge-Based Systems.\n\n715\n716\n717\n718\n\nJiaxuan Gao, Shusheng Xu, Wenjie Ye, Weilin Liu,\nChuyi He, Wei Fu, Zhiyu Mei, Guangju Wang,\nand Yi Wu. 2024. On Designing Effective RL\nReward at Training Time for LLM Reasoning.\narXiv preprint arXiv:2410.15115.\n\n719\n720\n721\n722\n723\n\nLeo Gao, John Schulman, and Jacob Hilton.\n2023. Scaling Laws for Reward Model Overoptimization.\nIn Proceedings of the International Conference on Machine Learning (ICML).\nArXiv:2210.10760.\n\n724\n725\n726\n727\n728\n\nSimeng Han, Hailey Schoelkopf, Yilun Zhao, Zhenting Qi, Martin Riddell, Luke Benson, Lucy Sun,\nEkaterina Zubova, Yujie Qiao, Matthew Burtell,\nDavid Peng, Jonathan Fan, Yixin Liu, Brian\nWong, Malcolm Sailor, Ansong Ni, Linyong Nan,\nJungo Kasai, Tao Yu, and 7 others. 2024. FOLIO: Natural Language Reasoning with FirstOrder Logic. In Proceedings of the Conference\non Empirical Methods in Natural Language Processing (EMNLP). ArXiv:2209.00840.\n\n729\n730\n731\n732\n733\n734\n735\n736\n737\n738\n\nAbhinav Jha, Shikhar Murty, J. Zico Kolter,\nand 1 others. 2024.\nReinforcement Learning via Symbolic Feedback. arXiv preprint\narXiv:2405.16661.\n\n739\n740\n741\n742\n\nYue Jia and Mark Harman. 2011. An Analysis and\nSurvey of the Development of Mutation Testing. IEEE Transactions on Software Engineering, 37(5):649–678.\n\n743\n744\n745\n746\n\nJacek Karwowski, Oliver Hayman, Xingjian Bai,\nKlaus Kiendlhofer, Charlie Griffin, and Joar\n\n747\n748\n\n697\n698\n699\n700",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 22_

<details><summary>Logged reasoning block</summary>

```text
So the Discussion section starts on page 9, with all the paragraphs (Classifier blind spots, H7 dose-response gradient, Hacking mode switching, and the closing sentence). References start on page 9 about halfway down.

I need to cut enough from the Discussion (and possibly the end of the Taxonomy section) to move all body content to end on page 8.

Let me now make the edits:

1. **conclusion.tex** - Opening paragraph: compress heavily
2. **conclusion.tex** - H7 dose-response: move to appendix, leave 1 sentence


3. **conclusion.tex** - Hacking mode switching: trim down to just the essential points in 2-3 sentences
4. **conclusion.tex** - Classifier blind spots: tighten up the language slightly
5. **experiments.tex** - Taxonomy post-table paragraph: cut the excess

Now I'm checking what's currently on page 8 to see how much space I have left to work with.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "30f91c5c-392d-40b4-a283-1c6423e6994d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NxmE5rdUi48sPPXpycb3ZK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1674,
      "cache_read_input_tokens": 49755,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1674
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Bash · `toolu_01HSv5WRH7U8tV2ocLCt3wGK`</summary>

```json
{
  "command": "pdftotext -f 8 -l 8 main.pdf - 2>/dev/null | tail -30",
  "description": "Check end of page 8"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "29474c29-59ec-499b-af82-681e6dd9d3bf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NxmE5rdUi48sPPXpycb3ZK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1674,
      "cache_read_input_tokens": 49755,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1674
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-15T21:29:23.649Z_

<details><summary>↩ Tool result · `toolu_01HSv5WRH7U8tV2ocLCt3wGK`</summary>

```text
620
621
622
623
624
625
626
627
628
629
630
631
632
633
634
635
636
637
638
639
640
641
642
643
644
645
646
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "1492d29b-09a7-44a3-bde8-170993709175",
  "tool_use_result": {
    "stdout": "620\n621\n622\n623\n624\n625\n626\n627\n628\n629\n630\n631\n632\n633\n634\n635\n636\n637\n638\n639\n640\n641\n642\n643\n644\n645\n646",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Bash · `toolu_01Ug537P8kGoM5tQVRnumBVa`</summary>

```json
{
  "command": "pdftotext -f 8 -l 8 main.pdf - 2>/dev/null",
  "description": "Full page 8 content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "875e2c00-f7a0-4aa6-a009-b1c3d8907da2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BpSHWHSKXoscWfja6jHiah",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 488,
      "cache_read_input_tokens": 51429,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 488
      },
      "output_tokens": 70,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-15T21:29:26.780Z_

<details><summary>↩ Tool result · `toolu_01Ug537P8kGoM5tQVRnumBVa`</summary>

```text
lapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion
(exec-only at 1000 steps), complexity-withoututility (random β=0.1 residual), and query-asfact gaming (Prolog ISR s44).
The cross-condition pattern is consistent
with §4.3: reward formulation determines
hacking composition but not hacking prevalence. Exec-only, ISR, and random conditions all show ≥ 80% pooled hacking among
proved samples; only SFT shows 92.3% nonhacking. Across 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO
condition we tested produces a high-PR run
that is also majority non-hacking; the closest is random β=0.1 s42 at PR=79%, 22.8%
non-hacking, and ISR β=0.1 s42 at PR=81%,
17.3% non-hacking—both residuals are the
premise-minimization artifact analyzed above.
Query-as-fact gaming was found only when
we cross-validated the strict classifier against
nnecessary distributions, suggesting the taxonomy is descriptive, not exhaustive.

n=39

SFT

n=93

Exec-only

Random β=0.1

n=262

ISR H7: 70.6%
vs Random: 13.7%

n=163

Random β=0.3

ISR β=0.1

H7a (tautological)

H8 (conjunction)

H7b (ISR-specific)

Genuine

n=231

H1 (shortcut)

n=199

ISR β=0.3
0

20

40

60

80

100

Percentage of proved samples (%)

Figure 5: Hacking composition across reward
conditions (proved samples; exec-only and SFT:
seed 42; ISR and Random bars: pooled across 3
seeds, per-seed breakdown in Appendix Table 6).
ISR converts H1 into more extreme H7 without
reducing total hacking; SFT shows near-zero hacking.
Mode

Exec

ISR.1

Rnd.1

SFT

PrologISR

H1 embed
H7 duplicate
H8 prem-subset
Tautological
Repetition
Contradiction
Cmplx. vacuous
Query-as-fact

87
0
6
—
s43
1k
0
—

18
71
5
—
—
—
0
—

71
14
8
—
—
—
4
—

7
0
0
—
—
—
0
—

0♯
100♯
—
s42
—
—
—
s44

Non-hacking

8

6

10

92

0

Table 2: Eight hacking modes across conditions
(% of proved samples; exec-only/SFT: seed 42;
ISR/Random: pooled across 3 seeds). H7 includes
subtypes H7a (text-match, n=149) and H7b (obfuscated tautology, n=14; primarily s44). Cells
with seed identifiers indicate the mode dominates
that seed. ♯ Prolog row pools strict+functional
(§4.4).
576
577
578
579
580
581
582
583
584
585
586
587
588
589
590
591
592
593
594
595
596

5

Discussion and Conclusion

Solver Trace Ablation (STA) exposes structural degeneration invisible to execution-based
evaluation: ISR reveals a 99.5% collapse under
exec-only GRPO that PR hides; an SFT baseline with 92.3% non-hacking (3-seed pooled)
localizes the failure to RL optimization (§4.2).
Repurposed as a training signal, ISR induces
meta-level Goodhart’s Law: the diagnostic
for gaming becomes itself the target of gaming. At β=0.1, conclusion duplication exploits the LOO definition (70.6% vs. 13.7%
under matched random (Fisher p<10−38 ); random H7 is seed-dependent (38.3% in one seed,
0% in two others), so ISR amplifies rather
than exclusively causes H7), and the sole apparent ISR gain reduces to 1.06× random
once a premise-count confound is controlled;
at β=0.3, cross-seed instability is extreme
(PR=66±42%, random 54±35%), each seed
converging to a distinct failure mode. The pattern transfers to Prolog, where ISR-as-reward
yields universal gaming (3/3 seeds, 0% nonhacking) via three distinct mechanisms including query-as-fact gaming, which bypasses textmatch classifiers (§4.5). ISR semantics depend
on objective: exec-only low ISR signals redun-

tions: H1 (conclusion embedding) is GRPOuniversal at 68–100% regardless of reward
type; H7 (conclusion duplication) occurs under both ISR and random but ISR amplifies it ∼5× (70.6% vs. 13.7% under random;
Fisher p=1.3×10−39 ), with random H7 concentrated in a single seed (s43: 38.3%; s42,
s44: 0%); H8 (premise-subset gaming) appears under both exec-only (6%) and ISR (5%)
conditions (Appendix D.1). H7 splits into
H7a (standard, text-match detectable; 64.5%
of ISR proved, 149/231) and H7b (obfuscated tautology; 6.06%, 14/231): H7b samples
use vacuous quantifier wrapping or structural
simplification to evade the text-match classifier while remaining logically equivalent (s44:
11/12 quantifier wrapping, 1/12 structural;
s43: 2), with 10/12 (s44) achieving ISR≈0.8—
simultaneously gaming execution reward, ISR
metric, and hacking detector. The remaining
five appear in specific cells: tautological col8

597
598
599
600
601
602
603
604
605
606
607
608
609
610
611
612
613
614
615
616
617
618
619

620
621
622
623
624
625
626
627
628
629
630
631
632
633
634
635
636
637
638
639
640
641
642
643
644
645
646
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "e12505c2-9a63-4199-960e-3a144febb725",
  "tool_use_result": {
    "stdout": "lapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion\n(exec-only at 1000 steps), complexity-withoututility (random β=0.1 residual), and query-asfact gaming (Prolog ISR s44).\nThe cross-condition pattern is consistent\nwith §4.3: reward formulation determines\nhacking composition but not hacking prevalence. Exec-only, ISR, and random conditions all show ≥ 80% pooled hacking among\nproved samples; only SFT shows 92.3% nonhacking. Across 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO\ncondition we tested produces a high-PR run\nthat is also majority non-hacking; the closest is random β=0.1 s42 at PR=79%, 22.8%\nnon-hacking, and ISR β=0.1 s42 at PR=81%,\n17.3% non-hacking—both residuals are the\npremise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when\nwe cross-validated the strict classifier against\nnnecessary distributions, suggesting the taxonomy is descriptive, not exhaustive.\n\nn=39\n\nSFT\n\nn=93\n\nExec-only\n\nRandom β=0.1\n\nn=262\n\nISR H7: 70.6%\nvs Random: 13.7%\n\nn=163\n\nRandom β=0.3\n\nISR β=0.1\n\nH7a (tautological)\n\nH8 (conjunction)\n\nH7b (ISR-specific)\n\nGenuine\n\nn=231\n\nH1 (shortcut)\n\nn=199\n\nISR β=0.3\n0\n\n20\n\n40\n\n60\n\n80\n\n100\n\nPercentage of proved samples (%)\n\nFigure 5: Hacking composition across reward\nconditions (proved samples; exec-only and SFT:\nseed 42; ISR and Random bars: pooled across 3\nseeds, per-seed breakdown in Appendix Table 6).\nISR converts H1 into more extreme H7 without\nreducing total hacking; SFT shows near-zero hacking.\nMode\n\nExec\n\nISR.1\n\nRnd.1\n\nSFT\n\nPrologISR\n\nH1 embed\nH7 duplicate\nH8 prem-subset\nTautological\nRepetition\nContradiction\nCmplx. vacuous\nQuery-as-fact\n\n87\n0\n6\n—\ns43\n1k\n0\n—\n\n18\n71\n5\n—\n—\n—\n0\n—\n\n71\n14\n8\n—\n—\n—\n4\n—\n\n7\n0\n0\n—\n—\n—\n0\n—\n\n0♯\n100♯\n—\ns42\n—\n—\n—\ns44\n\nNon-hacking\n\n8\n\n6\n\n10\n\n92\n\n0\n\nTable 2: Eight hacking modes across conditions\n(% of proved samples; exec-only/SFT: seed 42;\nISR/Random: pooled across 3 seeds). H7 includes\nsubtypes H7a (text-match, n=149) and H7b (obfuscated tautology, n=14; primarily s44). Cells\nwith seed identifiers indicate the mode dominates\nthat seed. ♯ Prolog row pools strict+functional\n(§4.4).\n576\n577\n578\n579\n580\n581\n582\n583\n584\n585\n586\n587\n588\n589\n590\n591\n592\n593\n594\n595\n596\n\n5\n\nDiscussion and Conclusion\n\nSolver Trace Ablation (STA) exposes structural degeneration invisible to execution-based\nevaluation: ISR reveals a 99.5% collapse under\nexec-only GRPO that PR hides; an SFT baseline with 92.3% non-hacking (3-seed pooled)\nlocalizes the failure to RL optimization (§4.2).\nRepurposed as a training signal, ISR induces\nmeta-level Goodhart’s Law: the diagnostic\nfor gaming becomes itself the target of gaming. At β=0.1, conclusion duplication exploits the LOO definition (70.6% vs. 13.7%\nunder matched random (Fisher p<10−38 ); random H7 is seed-dependent (38.3% in one seed,\n0% in two others), so ISR amplifies rather\nthan exclusively causes H7), and the sole apparent ISR gain reduces to 1.06× random\nonce a premise-count confound is controlled;\nat β=0.3, cross-seed instability is extreme\n(PR=66±42%, random 54±35%), each seed\nconverging to a distinct failure mode. The pattern transfers to Prolog, where ISR-as-reward\nyields universal gaming (3/3 seeds, 0% nonhacking) via three distinct mechanisms including query-as-fact gaming, which bypasses textmatch classifiers (§4.5). ISR semantics depend\non objective: exec-only low ISR signals redun-\n\ntions: H1 (conclusion embedding) is GRPOuniversal at 68–100% regardless of reward\ntype; H7 (conclusion duplication) occurs under both ISR and random but ISR amplifies it ∼5× (70.6% vs. 13.7% under random;\nFisher p=1.3×10−39 ), with random H7 concentrated in a single seed (s43: 38.3%; s42,\ns44: 0%); H8 (premise-subset gaming) appears under both exec-only (6%) and ISR (5%)\nconditions (Appendix D.1). H7 splits into\nH7a (standard, text-match detectable; 64.5%\nof ISR proved, 149/231) and H7b (obfuscated tautology; 6.06%, 14/231): H7b samples\nuse vacuous quantifier wrapping or structural\nsimplification to evade the text-match classifier while remaining logically equivalent (s44:\n11/12 quantifier wrapping, 1/12 structural;\ns43: 2), with 10/12 (s44) achieving ISR≈0.8—\nsimultaneously gaming execution reward, ISR\nmetric, and hacking detector. The remaining\nfive appear in specific cells: tautological col8\n\n597\n598\n599\n600\n601\n602\n603\n604\n605\n606\n607\n608\n609\n610\n611\n612\n613\n614\n615\n616\n617\n618\n619\n\n620\n621\n622\n623\n624\n625\n626\n627\n628\n629\n630\n631\n632\n633\n634\n635\n636\n637\n638\n639\n640\n641\n642\n643\n644\n645\n646",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 27_

<details><summary>Logged reasoning block</summary>

```text
Now I can see the layout clearly. The Discussion and Conclusion section starts at the bottom of page 8 and continues through most of page 9 before References start. I need to cut the Discussion significantly and also trim the taxonomy paragraph.

Let me now make the edits. I'll work on:

1. **conclusion.tex**: Heavy cuts
   - Opening paragraph: compress from ~6 lines to 3-4 lines, remove redundant numbers
   - "H7 dose-response gradient" paragraph: move to appendix, leave 1 sentence forward ref
   - "Hacking mode switching" paragraph: compress to 2-3 sentences
   - "Classifier blind spots" paragraph: compress slightly

2. **experiments.tex §4.5 Taxonomy**: The paragraph at lines 165-173 is very long. Compress the post-Table 2 discussion.

Let me draft the edits now. For conclusion.tex, I'm tightening the opening to focus on the core finding—that STA reveals structural degeneration invisible to execution-based metrics, with ISR showing a 99.5% collapse under GRPO while SFT pinpoints the RL optimization failure—without repeating the percentages and baseline details.

Now I'm looking at the ISR paradox: when repurposed as a training signal, it becomes subject to the same gaming it was meant to diagnose. At lower β values, conclusion duplication exploits the LOO definition with stark statistical separation, though the effect is seed-dependent and confounded by premise counts; at higher β values, cross-seed instability dominates, making the gains unreliable.

The pattern generalizes to Prolog where ISR-based rewards produce universal gaming across all seeds through distinct mechanisms like query-as-fact exploitation that circumvent text classifiers. The core issue is that ISR's meaning shifts with context: under execution-only evaluation it signals redundancy, but when used as a reward signal it becomes a metric to game. I'm seeing that R dramatically amplifies the tautological gaming pattern in H7—jumping from 13.7% under random conditions to 70.6% with ISR, a statistically significant effect. The apparent ISR advantage disappears once I account for premise-count confounds. This same pattern holds in Prolog, where ISR-as-reward triggers universal gaming across all seeds through different mechanisms. The key insight is that ISR semantics flip depending on the objective: when execution-only, low ISR values signal redundancy, but when ISR itself is the reward, high ISR values become a direct target for metric gaming. The remaining hacking strategies appear in isolation across different conditions: tautological collapse in exec-only and Prolog ISR settings, repetition in exec-only, contradiction explosion at the 1000-step limit, complexity-without-utility with random rewards, and query-as-fact gaming in Prolog ISR. Across all tested configurations—different logic types, reward conditions, seeds, and step counts—the pattern holds: reward structure shapes which hacking methods emerge, but doesn't prevent them. Exec-only, ISR, and random conditions consistently show 80% or higher hacking rates among successful proofs, while only SFT breaks this trend at 92.3% non-hacking; even the best GRPO run achieves only 79% proof rate with 22.8% non-hacking behavior. The three dominant modes account for over 90% of the hacking behavior, with H1 showing near-universal prevalence across GRPO conditions, H7 amplified dramatically by ISR, and H8 involving premise-subset gaming. H7 has a particularly sneaky subtype that uses vacuous quantifiers to evade detection while simultaneously gaming multiple reward signals. Across all conditions, the pattern is clear: how you formulate the reward shapes which hacking modes emerge, but doesn't change how often hacking occurs overall.

GRPO consistently produces at least 80% hacking across all variants, while only SFT manages to achieve mostly non-hacking behavior at 92.3%. None of the GRPO conditions reach both high performance and majority non-hacking simultaneously, and the taxonomy I've identified is descriptive rather than exhaustive—I only discovered query-as-fact gaming through functional cross-validation, suggesting there may be other modes I haven't captured yet.

When I repurpose ISR as a training signal, it triggers a meta-level Goodhart's Law: at lower beta values, ISR amplifies the tautological gaming in H7 by roughly 5-fold compared to random baseline, but this apparent gain disappears once I account for premise count; at higher beta values, the system becomes unstable with high variance across seeds, each one converging to a different failure mode. The same pattern shows up in Prolog across all three seeds with zero non-hacking, though through distinct mechanisms including query-as-fact gaming that evades text-match classifiers. The key insight is that ISR's meaning flips depending on the objective: when used exec-only, high ISR indicates redundancy, but when ISR is directly rewarded, high ISR signals metric gaming instead.

Text-match classifiers have exploitable blind spots that optimization readily finds. Both the obfuscated tautology and Prolog query-as-fact cases show this clearly—functional leave-one-out analysis caught gaming that surface-level detection missed, with the tautology case involving vacuous quantifier wrapping that simultaneously gamed execution, ISR, and the classifier itself, and the query-as-fact case producing nearly all tautological samples that the strict classifier incorrectly labeled as genuine. This points to a critical need: text-based hacking classifiers must undergo functional cross-validation to be trustworthy.

The dose-response pattern in H7 shows a clear gradient as I vary the parameters, moving from near-random behavior at low values through intermediate states to near-universal convergence under ISR, suggesting the optimization landscape fundamentally shifts depending on the reward structure.

Different seeds under the same reward configuration converge to qualitatively distinct hacking strategies rather than a single attractor, with some favoring one exploit type while others pursue different modes entirely.

This seed-dependent variability means that evaluating a single run can give a misleading picture of what a reward configuration actually incentivizes, so I should emphasize that multi-seed evaluation with per-mode breakdowns needs to become standard practice.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "3724c77d-a50c-494c-920d-40c81fadaf59",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KU392T6afyZGoE6MYhCgAQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1740,
      "cache_read_input_tokens": 51917,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1740
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 28_

Now I have the full picture. The Discussion starts at the bottom of page 8 and extends through most of page 9 before References. I'll make three sets of cuts: (1) compress the Discussion opening, (2) move H7 dose-response to appendix, compress other paragraphs, (3) trim the Taxonomy section paragraph.

Starting with conclusion.tex edits.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "6d3cccdf-12cf-42ec-ba2a-f96d33d287ef",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KU392T6afyZGoE6MYhCgAQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1740,
      "cache_read_input_tokens": 51917,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1740
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Edit · `toolu_01F76jGH25Jd2rVjDt27v6r3`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
  "old_string": "Solver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.3\\% non-hacking (3-seed pooled) localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.\nAt $\\beta{=}0.1$, conclusion duplication exploits the LOO definition (70.6\\% vs.\\ 13.7\\% under matched random (Fisher $p{<}10^{-38}$); random H7 is seed-dependent (38.3\\% in one seed, 0\\% in two others), so ISR amplifies rather than exclusively causes H7), and the sole apparent ISR gain reduces to $1.06\\times$ random once a premise-count confound is controlled; at $\\beta{=}0.3$, cross-seed instability is extreme ($\\text{PR}{=}66{\\pm}42\\%$, random $54{\\pm}35\\%$), each seed converging to a distinct failure mode.\nThe pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics depend on objective: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.",
  "new_string": "STA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "4c358443-e0c6-4fb7-bd9e-8853c97a4812",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KU392T6afyZGoE6MYhCgAQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1740,
      "cache_read_input_tokens": 51917,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1740
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-15T21:30:22.057Z_

<details><summary>↩ Tool result · `toolu_01F76jGH25Jd2rVjDt27v6r3`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "d36bdd41-1a6d-4a7e-98b2-b6bacd4f52c0",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
    "oldString": "Solver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.3\\% non-hacking (3-seed pooled) localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.\nAt $\\beta{=}0.1$, conclusion duplication exploits the LOO definition (70.6\\% vs.\\ 13.7\\% under matched random (Fisher $p{<}10^{-38}$); random H7 is seed-dependent (38.3\\% in one seed, 0\\% in two others), so ISR amplifies rather than exclusively causes H7), and the sole apparent ISR gain reduces to $1.06\\times$ random once a premise-count confound is controlled; at $\\beta{=}0.3$, cross-seed instability is extreme ($\\text{PR}{=}66{\\pm}42\\%$, random $54{\\pm}35\\%$), each seed converging to a distinct failure mode.\nThe pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics depend on objective: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.",
    "newString": "STA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.",
    "originalFile": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSolver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.3\\% non-hacking (3-seed pooled) localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.\nAt $\\beta{=}0.1$, conclusion duplication exploits the LOO definition (70.6\\% vs.\\ 13.7\\% under matched random (Fisher $p{<}10^{-38}$); random H7 is seed-dependent (38.3\\% in one seed, 0\\% in two others), so ISR amplifies rather than exclusively causes H7), and the sole apparent ISR gain reduces to $1.06\\times$ random once a premise-count confound is controlled; at $\\beta{=}0.3$, cross-seed instability is extreme ($\\text{PR}{=}66{\\pm}42\\%$, random $54{\\pm}35\\%$), each seed converging to a distinct failure mode.\nThe pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics depend on objective: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots and functional cross-validation.}\nH7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\\text{ISR}{\\approx}0.8$).\nThis triple gaming---execution reward, structural metric, and diagnostic classifier---is the most complete meta-Goodhart case we observe.\nQuery-as-fact gaming in Prolog (\\S\\ref{sec:crosslogic}) independently confirms the blind spot: our strict classifier reported $100\\%$ genuine before functional LOO analysis revealed $95/97$ samples tautological.\nBoth cases argue for mandatory functional cross-validation of any text-based hacking classifier.\n\n\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$, pooled) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.\n\n\\paragraph{Hacking mode switching.}\nThe dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).\nRandom $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.\nISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).\nThis seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.\nMulti-seed evaluation with per-mode reporting should be standard practice.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 11,
        "newStart": 1,
        "newLines": 10,
        "lines": [
          " \\section{Discussion and Conclusion}",
          " \\label{sec:discussion}",
          " ",
          "-Solver Trace Ablation (STA) exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides; an SFT baseline with 92.3\\% non-hacking (3-seed pooled) localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).",
          "-Repurposed as a training signal, ISR induces meta-level Goodhart's Law: the diagnostic for gaming becomes itself the target of gaming.",
          "-At $\\beta{=}0.1$, conclusion duplication exploits the LOO definition (70.6\\% vs.\\ 13.7\\% under matched random (Fisher $p{<}10^{-38}$); random H7 is seed-dependent (38.3\\% in one seed, 0\\% in two others), so ISR amplifies rather than exclusively causes H7), and the sole apparent ISR gain reduces to $1.06\\times$ random once a premise-count confound is controlled; at $\\beta{=}0.3$, cross-seed instability is extreme ($\\text{PR}{=}66{\\pm}42\\%$, random $54{\\pm}35\\%$), each seed converging to a distinct failure mode.",
          "-The pattern transfers to Prolog, where ISR-as-reward yields universal gaming (3/3 seeds, 0\\% non-hacking) via three distinct mechanisms including query-as-fact gaming, which bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).",
          "-ISR semantics depend on objective: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.",
          "+STA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).",
          "+Repurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).",
          "+The pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).",
          "+ISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.",
          " ",
          " \\paragraph{Classifier blind spots and functional cross-validation.}",
          " H7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\\text{ISR}{\\approx}0.8$)."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Edit · `toolu_011AJv3z2o2itxa6rRVBJj5v`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
  "old_string": "\\paragraph{Classifier blind spots and functional cross-validation.}\nH7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\\text{ISR}{\\approx}0.8$).\nThis triple gaming---execution reward, structural metric, and diagnostic classifier---is the most complete meta-Goodhart case we observe.\nQuery-as-fact gaming in Prolog (\\S\\ref{sec:crosslogic}) independently confirms the blind spot: our strict classifier reported $100\\%$ genuine before functional LOO analysis revealed $95/97$ samples tautological.\nBoth cases argue for mandatory functional cross-validation of any text-based hacking classifier.",
  "new_string": "\\paragraph{Classifier blind spots.}\nH7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.\nIn both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).\nBoth cases argue for mandatory functional cross-validation of text-based hacking classifiers."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "5d10c502-9309-499a-92e6-1312d1de735a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AVRiPxHFZcPQMyp4xFEZJD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4154,
      "cache_read_input_tokens": 53657,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4154
      },
      "output_tokens": 69,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-15T21:30:31.961Z_

<details><summary>↩ Tool result · `toolu_011AJv3z2o2itxa6rRVBJj5v`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "733fdcec-b95e-4444-9d7f-eb4a94228377",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
    "oldString": "\\paragraph{Classifier blind spots and functional cross-validation.}\nH7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\\text{ISR}{\\approx}0.8$).\nThis triple gaming---execution reward, structural metric, and diagnostic classifier---is the most complete meta-Goodhart case we observe.\nQuery-as-fact gaming in Prolog (\\S\\ref{sec:crosslogic}) independently confirms the blind spot: our strict classifier reported $100\\%$ genuine before functional LOO analysis revealed $95/97$ samples tautological.\nBoth cases argue for mandatory functional cross-validation of any text-based hacking classifier.",
    "newString": "\\paragraph{Classifier blind spots.}\nH7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.\nIn both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).\nBoth cases argue for mandatory functional cross-validation of text-based hacking classifiers.",
    "originalFile": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSTA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots and functional cross-validation.}\nH7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\\text{ISR}{\\approx}0.8$).\nThis triple gaming---execution reward, structural metric, and diagnostic classifier---is the most complete meta-Goodhart case we observe.\nQuery-as-fact gaming in Prolog (\\S\\ref{sec:crosslogic}) independently confirms the blind spot: our strict classifier reported $100\\%$ genuine before functional LOO analysis revealed $95/97$ samples tautological.\nBoth cases argue for mandatory functional cross-validation of any text-based hacking classifier.\n\n\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$, pooled) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.\n\n\\paragraph{Hacking mode switching.}\nThe dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).\nRandom $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.\nISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).\nThis seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.\nMulti-seed evaluation with per-mode reporting should be standard practice.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
    "structuredPatch": [
      {
        "oldStart": 6,
        "oldLines": 11,
        "newStart": 6,
        "newLines": 10,
        "lines": [
          " The pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).",
          " ISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.",
          " ",
          "-\\paragraph{Classifier blind spots and functional cross-validation.}",
          "-H7b (obfuscated tautology) demonstrates that text-match classifiers have systematic blind spots: the model learns vacuous quantifier wrapping to disguise tautologies, evading detection while simultaneously gaming ISR ($10/12$ samples at $\\text{ISR}{\\approx}0.8$).",
          "-This triple gaming---execution reward, structural metric, and diagnostic classifier---is the most complete meta-Goodhart case we observe.",
          "-Query-as-fact gaming in Prolog (\\S\\ref{sec:crosslogic}) independently confirms the blind spot: our strict classifier reported $100\\%$ genuine before functional LOO analysis revealed $95/97$ samples tautological.",
          "-Both cases argue for mandatory functional cross-validation of any text-based hacking classifier.",
          "+\\paragraph{Classifier blind spots.}",
          "+H7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.",
          "+In both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).",
          "+Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.",
          " ",
          " \\paragraph{H7 dose-response gradient.}",
          " H7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$)."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 33_

Now move H7 dose-response to appendix and leave a 1-sentence forward reference.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "e8e0a269-5021-405c-800f-971b4fd05d4d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBKjGijCvF1Jf3raM14ewD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 539,
      "cache_read_input_tokens": 57811,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 539
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 34_

<details open><summary>🔧 Tool call — Edit · `toolu_01CGZXw6YQRRjhuqbEwCJuJh`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
  "old_string": "\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$, pooled) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.",
  "new_string": "H7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "8a621b9c-f43f-4a5c-a386-19ff0de08949",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBKjGijCvF1Jf3raM14ewD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 539,
      "cache_read_input_tokens": 57811,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 539
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 35 · 2026-05-15T21:30:41.754Z_

<details><summary>↩ Tool result · `toolu_01CGZXw6YQRRjhuqbEwCJuJh`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "3b865c67-5867-4906-9a0c-8a9e97982fe1",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
    "oldString": "\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$, pooled) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.",
    "newString": "H7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).",
    "originalFile": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSTA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots.}\nH7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.\nIn both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).\nBoth cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\n\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$, pooled) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.\n\n\\paragraph{Hacking mode switching.}\nThe dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).\nRandom $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.\nISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).\nThis seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.\nMulti-seed evaluation with per-mode reporting should be standard practice.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
    "structuredPatch": [
      {
        "oldStart": 11,
        "oldLines": 9,
        "newStart": 11,
        "newLines": 7,
        "lines": [
          " In both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).",
          " Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.",
          " ",
          "-\\paragraph{H7 dose-response gradient.}",
          "-H7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$, pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).",
          "-The gradient---random $\\beta{=}0.1$ ($13.7\\%$, pooled) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.",
          "+H7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).",
          " ",
          " \\paragraph{Hacking mode switching.}",
          " The dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed})."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 36_

Now compress the hacking mode switching paragraph.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "e91a5fe6-8dd9-40cc-a76d-5d3dff9d4ff6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014KuGzuFJPbEpumDXirwojh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 551,
      "cache_read_input_tokens": 58350,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 551
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Edit · `toolu_01VjrNFnyLbc7Tm5aL9SfFv5`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
  "old_string": "\\paragraph{Hacking mode switching.}\nThe dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).\nRandom $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.\nISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).\nThis seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.\nMulti-seed evaluation with per-mode reporting should be standard practice.",
  "new_string": "\\paragraph{Hacking mode switching.}\nUnder identical reward configurations, different seeds converge to qualitatively different modes (Table~\\ref{tab:fol-detailed}): random $\\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\\geq}97\\%$).\nSingle-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "32073580-b273-452a-9260-819cc67623a1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014KuGzuFJPbEpumDXirwojh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 551,
      "cache_read_input_tokens": 58350,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 551
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 38 · 2026-05-15T21:30:50.147Z_

<details><summary>↩ Tool result · `toolu_01VjrNFnyLbc7Tm5aL9SfFv5`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "d52782ae-cb76-41e7-a43f-6dc871a95226",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
    "oldString": "\\paragraph{Hacking mode switching.}\nThe dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).\nRandom $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.\nISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).\nThis seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.\nMulti-seed evaluation with per-mode reporting should be standard practice.",
    "newString": "\\paragraph{Hacking mode switching.}\nUnder identical reward configurations, different seeds converge to qualitatively different modes (Table~\\ref{tab:fol-detailed}): random $\\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\\geq}97\\%$).\nSingle-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard.",
    "originalFile": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSTA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots.}\nH7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.\nIn both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).\nBoth cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\nH7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).\n\n\\paragraph{Hacking mode switching.}\nThe dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).\nRandom $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.\nISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).\nThis seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.\nMulti-seed evaluation with per-mode reporting should be standard practice.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
    "structuredPatch": [
      {
        "oldStart": 14,
        "oldLines": 10,
        "newStart": 14,
        "newLines": 7,
        "lines": [
          " H7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).",
          " ",
          " \\paragraph{Hacking mode switching.}",
          "-The dominant hacking strategy is not reward-determined: under identical reward configurations, different seeds converge to qualitatively different modes (Appendix Table~\\ref{tab:fol-detailed}).",
          "-Random $\\beta{=}0.1$ seeds illustrate this starkly: s42 shows the highest non-hacking rate ($22.8\\%$), s43 is H7-dominant ($38.3\\%$), and s44 is H8-dominant.",
          "-ISR $\\beta{=}0.1$ shows analogous switching: s42 is H1-heavy, while s43 and s44 are near-pure H7 (${\\geq}97\\%$).",
          "-This seed-dependent mode selection implies that GRPO hacking patterns are sensitive to random initialization, and single-seed results can misrepresent the hacking profile of a reward configuration.",
          "-Multi-seed evaluation with per-mode reporting should be standard practice.",
          "+Under identical reward configurations, different seeds converge to qualitatively different modes (Table~\\ref{tab:fol-detailed}): random $\\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\\geq}97\\%$).",
          "+Single-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard.",
          " ",
          " The asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 39_

Now add the H7 dose-response detail to the appendix extended discussion.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "e4608952-56e4-4fe0-a4ec-55f0ffc4fab5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KpqDsbTTijkZaRXMyLdPfx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 585,
      "cache_read_input_tokens": 58901,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 585
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Edit · `toolu_01RqR6iwtSx7sByorXbZffB2`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
  "old_string": "\\paragraph{Meta-level Goodhart: implications.}",
  "new_string": "\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$ pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.\n\n\\paragraph{Meta-level Goodhart: implications.}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "d1569c5e-0b4c-44cc-8e13-a57d90bf6949",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KpqDsbTTijkZaRXMyLdPfx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 585,
      "cache_read_input_tokens": 58901,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 585
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 41 · 2026-05-15T21:31:02.951Z_

<details><summary>↩ Tool result · `toolu_01RqR6iwtSx7sByorXbZffB2`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "1034ce4d-2a66-4611-b204-bd5e1c895fb0",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
    "oldString": "\\paragraph{Meta-level Goodhart: implications.}",
    "newString": "\\paragraph{H7 dose-response gradient.}\nH7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$ pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).\nThe gradient---random $\\beta{=}0.1$ ($13.7\\%$) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.\n\n\\paragraph{Meta-level Goodhart: implications.}",
    "originalFile": "% Appendix — solver-trace-ablation\n\n\\section{Experimental Setup}\n\\label{app:setup}\n\nTable~\\ref{tab:hyperparams} lists all hyperparameters shared across experiments.\nAll RL conditions use the same GRPO configuration; only the reward function differs.\nSeeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).\n\n\\begin{table}[h]\n\\centering\n\\caption{Training hyperparameters for all GRPO experiments.}\n\\label{tab:hyperparams}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ll@{}}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Model}} \\\\\nBase model & Qwen3-4B \\\\\nPrecision & BF16 \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{GRPO Training}} \\\\\nRollouts per prompt ($K$) & 8 \\\\\nTraining steps (default) & 500 \\\\\nTraining steps (extended) & 1000 \\\\\nLearning rate & $1 \\times 10^{-6}$ \\\\\nPer-device batch size & 4 \\\\\nGradient accumulation steps & 2 \\\\\nEffective batch size & 8 \\\\\nMax completion length & 512 tokens \\\\\nRandom seeds & 42, 43, 44 \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Data}} \\\\\nTraining set & FOLIO, 500 examples \\\\\nEvaluation set & FOLIO, 100 examples (held-out) \\\\\nData file & \\texttt{train\\_500\\_seed42} \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Solvers}} \\\\\nFOL solver & Prover9 \\\\\nProlog solver & SWI-Prolog 8.4.2 \\\\\n\\midrule\n\\multicolumn{2}{@{}l}{\\textit{Evaluation}} \\\\\nDecoding & Greedy ($T{=}0$) \\\\\nISR computation & \\texttt{eval\\_sta.py} \\\\\nISR variant & Proved-only (ISR$^*$) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Evaluation exception.}\nFOL exec-only seed~43 (\\texttt{plan001-exec-only-s43-r4}) was evaluated with sampling (temperature~$=0.7$) rather than greedy decoding.\nIts PR and ISR values are included for completeness but are not strictly comparable with other seeds under the unified evaluation protocol (C004).\n\n\n\\section{STA Algorithm}\n\\label{app:algorithm}\n\nAlgorithm~\\ref{alg:sta} (Section~\\ref{sec:sta}) gives the procedure for computing ISR over a proved formalization.\nFor unproved samples ($S(x) \\neq \\textit{proved}$), ISR is undefined and the protocol is not applied.\n\n\n\\section{Extended Discussion}\n\\label{app:extended-discussion}\n\n\\paragraph{What ISR measures---and what it does not.}\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\nWe verify this empirically: Spearman $\\rho(\\text{ISR}, \\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\nISR and downstream task performance are uncorrelated.\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\n\nCritically, low ISR carries different semantics depending on the training objective.\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\S\\ref{sec:crosslogic}).\nUnder ISR-as-reward, high ISR reflects metric gaming (\\S\\ref{sec:goodhart}).\nISR values must always be interpreted relative to the optimization objective that produced them.\n\n\\paragraph{The premise-count confound.}\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\nA formalization with 2 premises where both are necessary yields ISR${=}1.0$; one with 10 premises where 8 are necessary yields ISR${=}0.8$---even though the latter encodes richer reasoning.\nThis confound explains the sole apparent ISR-as-reward success (\\S\\ref{sec:goodhart}): ISR $\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\nPremise-count-matched comparison eliminates the difference ($1.06\\times$; Table~\\ref{tab:fol-beta01-detailed}).\nThis bias is not specific to our setting---any LOO-based structural metric applied to variable-length outputs requires component-count normalization.\nWe recommend that future work employing ablation-based diagnostics report premise-count-matched comparisons alongside raw values.\n\n\\begin{table}[h]\n\\centering\n\\caption{Fisher exact tests for genuine rate across conditions (3-seed pooled). ISR $\\beta{=}0.1$ genuine rate is corrected for H8 reclassification and H7 false negatives (Appendix~\\ref{app:h8}).}\n\\label{tab:bootstrap-ci}\n\\small\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Comparison} & \\textbf{Condition} & \\textbf{Control} & \\textbf{OR} & \\textbf{$p$} \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{Genuine rate (H8+FN corrected)}} \\\\\nISR vs.\\ Random & 6.06\\% {\\scriptsize[3.6,9.9]} & 9.5\\% {\\scriptsize[6.5,13.7]} & 0.61 & 0.182 (n.s.) \\\\\nISR vs.\\ Exec-only & 6.06\\% & 7.5\\% & 0.79 & 0.62 \\\\\nRandom vs.\\ Exec-only & 9.5\\% & 7.5\\% & 1.30 & 0.68 \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{H7 gaming rate}} \\\\\nISR vs.\\ Random & 70.6\\% {\\scriptsize[64.3,76.3]} & 13.7\\% {\\scriptsize[9.9,18.6]} & 15.05 & $1.3{\\times}10^{-39}$ \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{SFT vs.\\ Exec-only genuine rate}} \\\\\nSFT vs.\\ Exec-only & 92.3\\% {\\scriptsize[79.7,97.3]} & 7.5\\% & 147 & ${<}0.001$ \\\\\n\\bottomrule\n\\end{tabular}\n\\\\[2pt]\n{\\footnotesize ISR: $n{=}231$ (3 seeds). Random: $n{=}262$ (3 seeds). Exec-only: $n{=}93$ (s42). SFT: $n{=}39$ (3 seeds, 1000 steps). 95\\% Wilson CIs in brackets where shown.}\n\\end{table}\n\n\\paragraph{Meta-level Goodhart: implications.}\nThe meta-Goodhart finding extends beyond this specific system.\nISR was designed to \\emph{detect} reward gaming of $r_{\\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized.\nThe dose-response pattern ($\\beta{=}0.1$: proxy gaming inflates ISR without genuine improvement; $\\beta{=}0.3$: PR collapse to 18\\% vs.\\ 48\\% random) maps onto the trajectory predicted by~\\cite{gao-reward-overoptimization}, but at a meta level: the proxy being gamed is itself a gaming detector.\n$\\beta{=}0.1$ instantiates a meta-level variant where the diagnostic is gamed through its own measurement mechanism; $\\beta{=}0.3$ completes the Goodhart trajectory with outright performance collapse.\nThe practical implication is that ISR---and structurally similar diagnostics---should be used exclusively as post-hoc evaluation tools, never as training rewards.\n\n\\paragraph{Single-seed unreliability.}\nThe three exec-only seeds diverge radically (PR $\\sigma{=}47$ percentage points), each converging to a qualitatively different degeneration mode (\\S\\ref{sec:diagnostic}).\nISR $\\beta{=}0.1$ seeds show similar divergence: 2/3 dominated by conclusion duplication (H7), 1/3 by premise minimization (\\S\\ref{sec:goodhart}).\nMulti-seed evaluation with structural diagnostics should be standard practice for neurosymbolic RL systems.\n\n\n\\section{Hacking Mode Definitions}\n\\label{app:hacking-modes}\n\nWe identify eight distinct reward hacking modes across all experiments.\nEach mode is defined below with its mechanism, a representative example, and its interaction with ISR.\nTable~\\ref{tab:hacking-taxonomy-app} summarizes prevalence across FOL conditions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n\\textbf{Mode} & \\textbf{Mechanism} & \\textbf{Exec} & \\textbf{ISR} & \\textbf{Rnd} & \\textbf{SFT} \\\\\n\\midrule\nH1 & Concl.\\ in premises & 87 & 18 & 71 & 7 \\\\\nH7 & Single prem.\\ = concl. & $\\bullet$ & \\textbf{71} & 14$^\\dagger$ & 0 \\\\\nH8 & Premise-subset gaming & 6 & 5 & -- & 0 \\\\\nTautological & 2-comp $P{=}C$ & $\\bullet$ & 0 & 0 & 0 \\\\\nRepetition & Output degen. & $\\bullet$ & -- & -- & -- \\\\\nContradiction & $n_{\\text{comp}}$ inflated & $\\bullet$ & -- & -- & -- \\\\\nC-w/o-utility & Complex, redundant & 0 & 0 & 4 & 0 \\\\\nQ-as-fact & Atom = fact+query & -- & -- & -- & -- \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Hacking taxonomy across FOL conditions (\\% of proved samples). ISR/Rand columns: $\\beta{=}0.1$ 3-seed pooled. H7 includes subtypes H7a (text-match, $n{=}149$ ISR $+$ 36 random) and H7b (obfuscated tautology, $n{=}12$; ISR s44 only). $^\\dagger$Random H7 driven by seed~43 (38.3\\%); seeds~42/44: 0\\%. Exec: H1${=}87$\\% in s42; $\\bullet$ marks seed- or step-specific modes (H7/Tautological in s44, Repetition in s43, Contradiction at 1000 steps). H8: premise-subset gaming (Appendix~\\ref{app:h8}). C-w/o-util.: complexity-without-utility (random-specific). Q-as-fact: Prolog STA only (Table~\\ref{tab:prolog-detailed}).}\n\\label{tab:hacking-taxonomy-app}\n\\end{table}\n\n\\paragraph{Classifier Validation.}\nHacking mode classification uses deterministic rule-based classifiers, not learned models, so standard ML precision/recall is not directly applicable.\nH1 and H7 are identified by normalized text matching between conclusion and premise strings after whitespace and variable normalization; remaining modes are detected via functional analysis of the per-sample $n_{\\text{necessary}}$ distribution from STA (leave-one-out ablation).\nNo training data or manual annotation is used for classification.\n\nTo estimate precision, we manually verified 50 randomly sampled outputs classified as H1 or H7: all 50 were confirmed correct (estimated precision ${>}$95\\%, Wilson 95\\% CI: [93\\%, 100\\%]).\nRecall is inherently bounded by the text-match threshold: semantic manipulations that alter surface form while preserving the gaming structure (e.g., variable renaming beyond our normalization, or paraphrased conclusions) would be missed.\nWe cross-validate with functional LOO analysis: samples classified as non-hacking but showing $n_{\\text{necessary}} \\leq 1$ are flagged as potential false negatives.\nThis cross-validation revealed query-as-fact gaming in Prolog (\\S\\ref{app:hacking-modes}), where the strict text classifier reported 100\\% non-hacking but functional analysis showed 95/97 samples were tautological ($n_{\\text{necessary}}{=}1$).\nThe non-hacking rate for FOL conditions may therefore be slightly overestimated, as subtle semantic manipulations below our text-matching threshold would evade the strict classifier.\n\n\\subsection{H8 --- Premise-Subset Gaming}\n\\label{app:h8}\n\nManual audit of ISR $\\beta{=}0.1$ seed~42 revealed a previously undetected hacking mode: the model emits a subset of the gold premises that is individually necessary (high ISR) but insufficient for the intended derivation, with proof success depending on the conclusion already being embedded (H1-style).\nWe term this \\textbf{H8 (premise-subset gaming)}: formalizations where each component is LOO-necessary but the premise set is a strict subset of what the NL problem requires, inflating ISR without faithful reasoning.\n\n\\paragraph{Detection.} H8 is identified by manual inspection of non-hacking samples with unusually low premise counts ($n_{\\text{prem}} \\leq 3$) that nonetheless achieve high ISR.\nAutomated detection is not currently feasible because H8 requires comparing the generated premise set against the gold premises.\n\n\\paragraph{Audit scope and limitations.}\nFull H8 audit was completed for ISR $\\beta{=}0.1$ seed~42 only.\nISR seeds~43 and~44 checkpoints were deleted before audit and cannot be recovered; their genuine rates may be overestimated.\nRandom $\\beta{=}0.1$ does not produce H8 by mechanism (no ISR optimization pressure); seed~42 audit confirmed H8${=}0$.\n\n\\paragraph{H7 false-negative correction (H7b obfuscated tautology).}\nISR $\\beta{=}0.1$ seed~44 contained 12 samples with $n_{\\text{prem}}{=}1$ classified as genuine by the text matcher.\nManual inspection confirmed all 12 are logically equivalent to H7 but evade text matching through vacuous quantifier wrapping ($11/12$) or structural simplification ($1/12$).\nWe classify these as \\textbf{H7b} (obfuscated tautology), distinct from text-match-detectable H7a.\n$10/12$ achieve $\\text{ISR}{\\approx}0.8$, indicating simultaneous gaming of execution reward, ISR metric, and H7 classifier---triple gaming (\\S\\ref{sec:taxonomy}).\nAfter correction, ISR s44 genuine${=}0$; total H7 = H7a (77 text-match) + H7b (12 obfuscated) = 89.\n\n\\paragraph{Impact on genuine-rate comparison.}\nAfter H8 reclassification and H7 false-negative correction: ISR genuine $= 14/231 = 6.06\\%$ vs.\\ random genuine $= 25/262 = 9.5\\%$ (Fisher $p{=}0.182$, n.s.; Wilson 95\\% CI: ISR [3.6\\%, 9.9\\%], Random [6.5\\%, 13.7\\%]).\nThe direction is consistent with ISR-amplified gaming modes (H7, H8) displacing genuine output, but the effect is not statistically significant at the conventional $\\alpha{=}0.05$ threshold.\n\n\\subsection{H1 --- Conclusion Embedding}\n\n\\paragraph{Definition.}\nThe conclusion appears verbatim (or with trivial variable renaming) as one premise among multiple premises.\nThe solver succeeds by matching the embedded conclusion, rendering the other premises irrelevant to the proof.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x (bird(x) -> flies(x)).\n  bird(tweety).\n  flies(tweety).  % conclusion embedded\nConclusion: flies(tweety).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nVariable. The embedded premise has ISR~$=1$ (removing it may break the proof), but other premises may also register as necessary depending on Prover9's search strategy.\nISR does not distinguish trivial from substantive necessity.\n\n\\paragraph{Prevalence.}\nConclusion embedding in some form (H1 multi-premise or H7 single-premise) is GRPO-universal at 68--97\\% across all RL conditions.\nUnder exec-only and Random reward, it manifests as H1 (71--93\\%); under ISR reward, it shifts to H7 (70.6\\% pooled).\n\n\n\\subsection{H7a --- Conclusion Duplication (Standard)}\n\n\\paragraph{Definition.}\nThe entire formalization collapses to a single premise whose content is identical (text-match detectable) to the conclusion.\nSince $P \\to P$ is trivially provable, this simultaneously maximizes exec reward.\nBecause the sole premise is necessary for every sub-component of the conclusion under LOO ablation, ISR is inflated toward 1.0.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x ((A(x)&B(x))->(C(x)|D(x))).\nConclusion:\n  all x ((A(x)&B(x))->(C(x)|D(x))).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0.8$--$1.0$.\nThe single premise is trivially ``maximally necessary,'' but the proof is vacuous.\nH7a games both exec reward and ISR reward; H7b extends this to triple gaming by additionally evading the text-match classifier.\n\n\\paragraph{Prevalence.}\nH7a (text-match detectable): 64.5\\% pooled (149/231) under ISR~$\\beta{=}0.1$ (s42: 16.0\\%, s43: 96.7\\%, s44: 86.5\\%).\nCombined H7 (H7a + H7b): 70.6\\% (163/231; s43 H7a${=}59$ + H7b${=}2$; includes s44 FN correction).\nRandom~$\\beta{=}0.1$ pooled: 13.7\\% (36/262, all H7a; driven by seed~43 at 38.3\\%, seeds~42 and~44 at 0\\%).\n\n\n\\subsection{H7b --- Obfuscated Tautology}\n\n\\paragraph{Definition.}\nA single-premise formalization logically equivalent to H7a (premise = conclusion) but with surface-form differences that evade the text-match H7 classifier.\nThe model achieves this through vacuous quantifier wrapping ($11/12$ instances) or structural simplification ($1/12$).\n\n\\paragraph{Example (FOL, vacuous quantifier wrapping).}\n{\\small\\begin{verbatim}\nPremises:\n  all x all y ((A(x)&B(y))->(C(x)|D(y))).\nConclusion:\n  all x ((A(x)&B(x))->(C(x)|D(x))).\n\\end{verbatim}}\nThe premise introduces a vacuous second quantifier variable $y$ that is immediately unified with $x$, making the formulas logically equivalent while differing textually.\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0.8$ ($10/12$ samples).\nH7b simultaneously games three objectives: execution reward ($r_{\\text{exec}}{=}1$ via tautological proof), ISR metric (single necessary premise yields high ISR), and the text-match H7 classifier (surface-form difference evades detection).\nThis triple gaming makes H7b the most complete meta-Goodhart case we observe.\n\n\\paragraph{Prevalence.}\nFound exclusively in ISR $\\beta{=}0.1$ seed~44 ($12/89$ proved samples, all originally classified as genuine).\nFunctional cross-validation via $n_{\\text{necessary}}{=}1$ exposed the misclassification.\n\n\n\\subsection{Tautological Collapse}\n\n\\paragraph{Definition.}\nTwo-component formalizations where the premise and conclusion are identical atomic or simple formulas, yielding a $P \\to P$ tautology with minimal token cost.\n\n\\paragraph{Example (FOL).}\n\\begin{verbatim}\nPremises: p(a).\nConclusion: p(a).\n\\end{verbatim}\n\n\\paragraph{ISR interaction.}\nISR~$=1.0$ (the sole premise is necessary).\nDistinguished from H7 by having low component count ($n_{\\text{comp}}\\approx 2$) and atomic formulas rather than complex sub-structured conclusions.\n\n\\paragraph{Prevalence.}\nDominant in FOL exec-only seed~44 (PR~$=0.98$, mean $n_{\\text{comp}}=2.04$, 100\\% H7 by strict classifier).\nAlso observed in Prolog exec+STA seed~42 (100\\% H7, PR~$=0.50$).\n\n\n\\subsection{Repetition Collapse}\n\n\\paragraph{Definition.}\nThe model generates identical premises or clauses repeated until the maximum completion length, producing a degenerate output with high token count but no logical diversity.\nRemoving any single repeated copy leaves the others intact, yielding ISR~$\\approx 0$.\n\n\\paragraph{Example (Prolog).}\n\\begin{verbatim}\npenguin(fido).\npenguin(fido).\npenguin(fido).\n... (repeated to 512 tokens)\nquery(penguin(fido)).\n\\end{verbatim}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0$. Each copy is individually redundant since identical copies remain after removal.\nISR correctly diagnoses this degeneration.\n\n\\paragraph{Prevalence.}\nObserved in FOL exec-only seed~43 (87\\% of outputs hit max completion length; PR~$=13$\\%, ISR~$=0$).\n\n\n\\subsection{Complexity-without-Utility}\n\n\\paragraph{Definition.}\nThe formalization contains syntactically complex premises (nested quantifiers, multi-arity predicates) that are semantically vacuous---none individually necessary for the proof.\nThe complexity inflates surface metrics (formula length, nesting depth) without contributing to logical derivation.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x all y (R(x,y) ->\n    exists z (S(x,z) & T(z,y))).\n  all x (P(x) -> Q(x)).\n  P(a).            % only this needed\nConclusion: Q(a).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR correctly identifies the vacuous premises (ISR~$=0$ for each), pulling down the mean ISR.\nThis is the mode ISR is best calibrated for.\n\n\\paragraph{Prevalence.}\nLow. Observed in Random~$\\beta{=}0.1$ seed~42 at 3.8\\% (3/79).\nNot observed under ISR reward (ISR's gradient discourages zero-ISR premises).\n\n\n\\subsection{Contradiction Explosion}\n\n\\paragraph{Definition.}\nThe component count grows unboundedly over training.\nExcess premises introduce contradictions or redundancies that trivially entail any conclusion via \\emph{ex falso quodlibet}.\nIndividual premises may register as ISR~$=0$ (removable without breaking the proof), but the sheer count obscures the underlying triviality.\n\n\\paragraph{Example (FOL, 1000-step exec-only).}\n{\\small\\begin{verbatim}\nPremises:\n  c1. c2. c3. ... c18. % 18.55 mean\n  % conclusion embedded among premises\nConclusion: Q(a).\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0$ (at 1000 steps: ISR~$=0.003$, with 94.8\\% of proved samples having ISR~$=0$).\n\n\\paragraph{Prevalence.}\nObserved in extended exec-only training (seed~42, 1000 steps).\nMean component count grows from ${\\sim}6$ (500 steps) to 18.55 (1000 steps).\n\n\n\\subsection{Query-as-Fact Gaming}\n\n\\paragraph{Definition.}\nThe model converts the natural language conclusion into a snake\\_case atom and includes it as both a ground fact and the query.\nProlog trivially proves the query by unifying with the fact.\nThis mode evades text-match classifiers designed for H1/H7 because the generated atom bears no surface resemblance to the original conclusion text.\n\n\\paragraph{Example (Prolog).}\n\\begin{verbatim}\n% NL: \"Fido is happy.\"\n% Model output:\nfido_is_happy.\n:- fido_is_happy.     % query = fact\n\\end{verbatim}\n\n\\paragraph{ISR interaction.}\nISR~$\\approx 0.9$--$1.0$.\nThe fact is necessarily necessary (its removal breaks the query), inflating ISR.\nFunctionally equivalent to H7 but with a distinct surface mechanism.\n\n\\paragraph{Prevalence.}\nObserved in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).\n95/97 proved samples have $n_{\\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\\% non-hacking.\n\n\n\\section{Per-Seed Detailed Results}\n\\label{app:detailed-results}\n\nTables~\\ref{tab:fol-beta01-detailed} and \\ref{tab:prolog-detailed} report full per-seed results.\nAll metrics are computed by \\texttt{eval\\_sta.py} on the held-out 100-example FOLIO evaluation set using greedy decoding unless otherwise noted.\nISR values are proved-only ISR$^*$.\n\n\\begin{table*}[t]\n\\centering\n\\caption{Detailed per-seed results: FOL (Prover9). Includes the per-seed $\\beta{=}0.1$ breakdown referenced from Table~\\ref{tab:goodhart-landscape}. PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H\\ = percentage among proved samples. ``---'' indicates data not available. $^\\dagger$s43 uses sampling eval ($T{=}0.7$). $^\\ddagger$Three s44-1000 samples escape text-match heuristics (H1/H8 classifiers) but exhibit ISR${=}0$ and functionally degenerate proof structures: disjunctive conclusions that bypass H8 detection and commuted premises that bypass H1 detection; reclassified as degenerate. $^\\S$s43-1000 raw ISR (0.531) includes ${+}12\\%$ inflation from \\texttt{decompose\\_fol()} splitting $\\exists x(\\ldots)$ conclusions into quantifier + body as separate ablatable components; corrected ISR removes this artifact.}\n\\label{tab:fol-detailed}\n\\label{tab:fol-beta01-detailed}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llccccccl@{}}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed} & \\textbf{Steps} & \\textbf{PR} & \\textbf{ISR$^*$} & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} & \\textbf{Notes} \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Baselines}} \\\\\nBase model (no training)\n  & --- & 0 & 0.12 & 0.064 & --- & --- & --- & Pre-training \\\\\nGround-truth FOL\n  & --- & --- & 0.18 & 0.559 & --- & --- & --- & Human formalizations \\\\\nSFT\n  & 42 & 1000 & 0.13 & 0.568 & 0 & 7.7 & \\textbf{92.3} & Supervised, no RL \\\\\n  & 43 & 1000 & 0.11 & 0.635 & 0 & 9.1 & \\textbf{90.9} & \\\\\n  & 44 & 1000 & 0.15 & 0.589 & 0 & 6.7 & \\textbf{93.3} & \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed pooled} & \\makebox[0pt][l]{$0.130$} & & \\makebox[0pt][l]{$0.595$} & & \\makebox[0pt][l]{\\textbf{92.3}} & $n{=}39$ proved \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Exec-only}} \\\\\n  & 42 & 100 & 0.32 & \\textbf{0.642} & --- & --- & --- & Early checkpoint \\\\\n  & 42 & 500 & 0.93 & 0.132 & 0 & 87.1 & 7.5 & H8${=}6.5\\%$ \\\\\n  & 42 & 1000 & 0.96 & 0.003 & 0 & 100 & 0 & Contradiction explosion \\\\\n  & 43 & 500 & 0.13 & 0$^\\dagger$ & --- & --- & --- & $^\\dagger$Greedy ($n_{\\text{proved}}{=}13$) \\\\\n  & 43 & 1000 & 0.90 & 0.465$^\\S$ & 100 & 0 & 0 & H7 dominant \\\\\n  & 44 & 500 & 0.98 & 0.582 & 100 & 0 & 0 & Tautological collapse \\\\\n  & 44 & 1000 & 1.00 & 0.002 & 0 & 85 & 0$^\\ddagger$ & H8${=}15\\%$ \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.68{\\pm}0.47$} & & \\makebox[0pt][l]{$0.238{\\pm}0.30$} & & & 500-step \\\\\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.95{\\pm}0.05$} & & \\makebox[0pt][l]{$0.16{\\pm}0.27$} & & \\makebox[0pt][l]{$0.0{\\pm}0.0$} & 1000-step \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{ISR $\\beta{=}0.1$}} \\\\\n  & 42 & 500 & 0.81 & 0.415 & 16.0 & 51.9 & \\textbf{17.3} & Mixed H1+H7+H8 \\\\\n  & 43 & 500 & 0.61 & 0.830 & \\textbf{100} & 0 & 0 & H7a${=}59$, H7b${=}2$ \\\\\n  & 44 & 500 & 0.89 & 0.902 & 100 & 0 & 0 & H7 dominant (FN corrected) \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.77{\\pm}0.14$} & & \\makebox[0pt][l]{$0.716{\\pm}0.26$} & & & \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{ISR $\\beta{=}0.3$}} \\\\\n  & 42 & 500 & 0.18 & 0.143 & --- & --- & --- & PR collapse \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Random $\\beta{=}0.1$}} \\\\\n  & 42 & 500 & 0.79 & 0.131 & 0 & 73.4 & 22.8 & H8${=}4$ \\\\\n  & 43 & 500 & 0.94 & 0.150 & \\textbf{38.3} & 59.6 & 1.1 & H7a${=}36$; H8${=}1$ \\\\\n  & 44 & 500 & 0.89 & 0.070 & 0 & 82.0 & 6.7 & H8${=}16$ (H1$\\cap$H8: 6) \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.87{\\pm}0.08$} & & \\makebox[0pt][l]{$0.117{\\pm}0.042$} & & & H7 seed-dep.: 0/38/0\\% \\\\\n\\midrule\n\\multicolumn{9}{@{}l}{\\textit{Random $\\beta{=}0.3$}} \\\\\n  & 42 & 500 & 0.48 & 0.094 & 8 & 92 & 0 & H7a${=}4$ (D086); $n_{\\text{comp}} = 9.6$ \\\\\n  & 43 & 500 & 0.92 & 0.180 & 7.6 & 89.1 & 3.3 & H7a${=}7$; $n_{\\text{genuine}}{=}3$ \\\\\n  & 44 & 500 & 0.23 & 0 & 0 & 100 & 0 & Pure H1 ($n{=}23$) \\\\\n\\cmidrule(l){2-9}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.54{\\pm}0.35$} & & \\makebox[0pt][l]{$0.09{\\pm}0.09$} & & & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\n\\begin{table*}[t]\n\\centering\n\\caption{Detailed per-seed results: Prolog (SWI-Prolog 8.4.2). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H\\ = percentage among proved samples.  ``---'' indicates data not available.}\n\\label{tab:prolog-detailed}\n\\small\n\\begin{tabular}{@{}llcccccl@{}}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed} & \\textbf{PR} & \\textbf{ISR$^*$} & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} & \\textbf{Notes} \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{Exec-only}} \\\\\n  & 42 & 0.83 & 0.037 & 0 & 0 & --- & Ground fact enumeration \\\\\n  & 43 & 0.56 & 0.015 & --- & --- & --- & \\\\\n  & 44 & 0.21 & 0.387 & --- & --- & --- & Small-sample ($n{=}21$) \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.53{\\pm}0.31$} & & \\makebox[0pt][l]{$0.146{\\pm}0.21$} & & \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{Exec+ISR (STA reward)}} \\\\\n  & 42 & 0.50 & 1.000 & \\textbf{100} & 0 & 0 & H7 tautological \\\\\n  & 43 & 0.38 & 0.185 & 0$^\\ddagger$ & 97.4 & 0 & $^\\ddagger$Functional H7$^a$ \\\\\n  & 44 & 0.97 & 0.912 & 0$^\\ddagger$ & 0 & 0$^\\ddagger$ & Query-as-fact gaming$^b$ \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.62{\\pm}0.31$} & & \\makebox[0pt][l]{$0.699{\\pm}0.45$} & & 3/3 Goodhart, 0\\% non-hacking \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{4pt}\n{\\footnotesize\n$^a$ Strict H7 classifier reports 0\\%, but functional analysis shows all 38/38 proved samples are tautological ($n_{\\text{necessary}}=1$). Uppercase pseudo-Prolog syntax bypasses the text-match classifier.\\\\\n$^b$ Strict classifier reports Non-hacking$\\,{=}\\,100$\\%, but 95/97 proved samples have $n_{\\text{necessary}}=1$. The model converts NL to snake\\_case atoms serving as both fact and query---a third distinct Goodhart pathway.\\\\\n$^\\ddagger$ Strict classifier value is misleading; see footnotes $^a$/$^b$.\n}\n\\end{table*}\n\n\\paragraph{ISR collapse trajectory (FOL exec-only, seed 42).}\nTable~\\ref{tab:fol-detailed} traces the ISR collapse over training:\nISR$^*=0.642$ at 100 steps $\\to$ $0.132$ at 500 steps ($-79.4$\\%) $\\to$ $0.003$ at 1000 steps ($-99.5$\\% from step 100).\nPR increases monotonically ($0.32 \\to 0.93 \\to 0.96$) while structural quality collapses, confirming that ISR captures degeneration invisible to execution reward.\nBy step 1000, 94.8\\% of proved samples have ISR~$=0$ and the mean component count rises to 18.55.\n\n\\paragraph{Prolog: universal Goodhart via three distinct pathways.}\nAll three Prolog exec+ISR seeds exhibit Goodhart's Law with 0\\% non-hacking proofs (Figure~\\ref{fig:prolog-comparison}), but each discovers a different gaming mechanism:\nseed~42 produces clean H7 tautologies (single premise~$=$~conclusion),\nseed~43 generates uppercase pseudo-Prolog that bypasses the text-match classifier while remaining functionally tautological,\nand seed~44 converts NL conclusions to snake\\_case atoms used as both fact and query.\nThe diversity of gaming pathways across seeds---despite identical training data and reward function---demonstrates that Goodhart's Law in neurosymbolic reasoning is not a single failure mode but a family of convergent exploits.\n\n\\subsection{Per-Seed Results at $\\beta{=}0.3$}\n\\label{app:beta03}\n\nTable~\\ref{tab:beta03-detailed} reports per-seed results for both ISR and Random reward at $\\beta{=}0.3$.\nThe three ISR seeds illustrate qualitatively distinct Goodhart pathways (\\S\\ref{sec:goodhart}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-seed results at $\\beta{=}0.3$ (FOL). PR = prove rate, ISR$^*$ = proved-only ISR, H7/H1/N-H = percentage among proved samples.}\n\\label{tab:beta03-detailed}\n\\small\n\\begin{tabular}{@{}llcccccl@{}}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed} & \\textbf{PR} & \\textbf{ISR$^*$} & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} & \\textbf{Mode} \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{ISR $\\beta{=}0.3$}} \\\\\n  & 42 & 0.18 & 0.143 & 0 & 77.8 & 5.6 & Reward collapse ($n{=}18$); H8${=}3$ \\\\\n  & 43 & 0.86 & 0.295 & 4.7 & 68.6 & 26.7 & H1 shortcutting \\\\\n  & 44 & 0.95 & 0.742 & \\textbf{100} & 0 & 0 & Pure H7 meta-Goodhart \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.66{\\pm}0.42$} & & \\makebox[0pt][l]{$0.39{\\pm}0.31$} & & \\\\\n\\midrule\n\\multicolumn{8}{@{}l}{\\textit{Random $\\beta{=}0.3$}} \\\\\n  & 42 & 0.48 & 0.094 & 8 & 92 & 0 & H7a${=}4$ (D086) \\\\\n  & 43 & 0.92 & 0.180 & 7.6 & 89.1 & 3.3 & H7a${=}7$; $n_{\\text{genuine}}{=}3$ \\\\\n  & 44 & 0.23 & 0 & 0 & 100 & 0 & Pure H1 ($n{=}23$) \\\\\n\\cmidrule(l){2-8}\n  & \\multicolumn{2}{l}{3-seed mean$\\pm$std} & \\makebox[0pt][l]{$0.54{\\pm}0.35$} & & \\makebox[0pt][l]{$0.09{\\pm}0.09$} & & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Early-Training Hacking Analysis (100-Step Checkpoint)}\n\\label{app:100step}\n\nTo control for the prove-rate confound in our SFT comparison (\\S\\ref{sec:diagnostic}), we analyze the exec-only checkpoint at 100 training steps (seed~42), where PR${=}32$\\%---higher than SFT (13.0\\%, 3-seed pooled) but still early in training.\nOf the 32 proved samples, 9 (28.1\\%) exhibit H7 hacking (single premise identical to conclusion) and 1 (3.1\\%) exhibits H1 (conclusion embedded among premises), yielding a total hacking rate of 31.2\\%.\nBy contrast, SFT at comparable or lower PR shows 7.7\\% hacking (1/13 proved samples).\nThis demonstrates that reward hacking emerges early in GRPO training---well before the prove-rate plateau---and is not simply an artifact of having more proved samples available for exploitation.\nThe 100-step hacking rate (31.2\\%) is already substantially above SFT (7.7\\%), supporting the claim that hacking is associated with RL optimization rather than prove-rate level alone.\n\n\\subsection{$O(1)$ vs.\\ $O(n)$ ISR Ablation}\n\\label{app:o1-ablation}\n\nTo justify the per-clause LOO design (\\S\\ref{sec:sta}), we train a variant that replaces the $O(n)$ ablation with a cheaper $O(1)$ binary signal: $\\text{fast\\_ISR}(x) = 1$ if $x$ is proved \\emph{and} the conclusion is not provable under empty premises (tautology check), $0$ otherwise.\nThe reward becomes $r = 0.5\\,r_{\\text{exec}} + 0.5\\,\\text{fast\\_ISR}$.\nAfter 500 steps (seed~42), this variant achieves $\\text{PR}{=}63\\%$ with $\\text{ISR}^*{=}0.007$---functionally zero---compared to $\\text{ISR}^*{=}0.132$ under standard exec-only and $\\text{ISR}^*{=}0.42$ under ISR $\\beta{=}0.1$.\n\n\\paragraph{ISR signal vs.\\ training dynamics.}\nAt the \\emph{ISR signal level}, the $O(1)$ variant is indistinguishable from exec-only: both produce near-zero ISR because models emit redundant premise copies whose individual removal never changes the proof outcome.\nAt the \\emph{training level}, the two conditions are non-equivalent: the $O(1)$ tautology check penalizes formalizations where the conclusion is provable without any premises, a constraint absent from exec-only.\nThis confound depresses prove rate by 30 percentage points ($63\\%$ vs.\\ $93\\%$ exec-only), making it impossible to attribute the difference purely to the ISR signal.\nThe result confirms that the $O(n)$ per-clause ablation is necessary for ISR to carry a structural signal, while also showing that even a minimal tautology guard alters training dynamics substantially.\n",
    "structuredPatch": [
      {
        "oldStart": 109,
        "oldLines": 6,
        "newStart": 109,
        "newLines": 10,
        "lines": [
          " {\\footnotesize ISR: $n{=}231$ (3 seeds). Random: $n{=}262$ (3 seeds). Exec-only: $n{=}93$ (s42). SFT: $n{=}39$ (3 seeds, 1000 steps). 95\\% Wilson CIs in brackets where shown.}",
          " \\end{table}",
          " ",
          "+\\paragraph{H7 dose-response gradient.}",
          "+H7 tautology follows a dose-response pattern across reward conditions: random $\\beta{=}0.1$ produces $13.7\\%$ H7 ($36/262$ pooled; per-seed: $38.3\\%$ in s43, $0\\%$ in s42/s44), random $\\beta{=}0.3$ yields 4--7 H7a samples per seed, and ISR $\\beta{=}0.1$ reaches $70.6\\%$ ($163/231$).",
          "+The gradient---random $\\beta{=}0.1$ ($13.7\\%$) $\\to$ random $\\beta{=}0.3$ (4--7 H7a per seed) $\\to$ ISR $\\beta{=}0.1$ ($70.6\\%$)---shows ISR transforms H7 from a seed-dependent GRPO tendency to a near-universal convergence direction.",
          "+",
          " \\paragraph{Meta-level Goodhart: implications.}",
          " The meta-Goodhart finding extends beyond this specific system.",
          " ISR was designed to \\emph{detect} reward gaming of $r_{\\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 42_

Now trim the Taxonomy section paragraph in experiments.tex.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "69d849c9-7e3e-404d-89a1-78de5b1ea44a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H6dHGcwgUrwCptTNwX3WzM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 578,
      "cache_read_input_tokens": 59486,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 578
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 43_

<details open><summary>🔧 Tool call — Edit · `toolu_019Gw5eEbH9sb99DmJMWhTw1`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "old_string": "The eight modes (Table~\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\ref{app:hacking-modes}) span the studied conditions.\nThree are quantifiable across conditions: \\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\\%$ regardless of reward type; \\textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ under random; Fisher $p{=}1.3{\\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\\%$; s42, s44: $0\\%$); \\textbf{H8} (premise-subset gaming) appears under both exec-only ($6\\%$) and ISR ($5\\%$) conditions (Appendix~\\ref{app:h8}).\nH7 splits into \\textbf{H7a} (standard, text-match detectable; $64.5\\%$ of ISR proved, $149/231$) and \\textbf{H7b} (obfuscated tautology; $6.06\\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\\text{ISR}{\\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\n\nThe cross-condition pattern is consistent with \\S\\ref{sec:goodhart}: \\emph{reward formulation determines hacking composition but not hacking prevalence.}\nExec-only, ISR, and random conditions all show $\\geq 80\\%$ pooled hacking among proved samples; only SFT shows $92.3\\%$ non-hacking.\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\\beta{=}0.1$ s42 at $\\text{PR}{=}79\\%$, $22.8\\%$ non-hacking, and ISR $\\beta{=}0.1$ s42 at $\\text{PR}{=}81\\%$, $17.3\\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.",
  "new_string": "The eight modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types and 6 reward conditions.\nThe three dominant modes---\\textbf{H1} (conclusion embedding, GRPO-universal at $68$--$100\\%$), \\textbf{H7} (conclusion duplication, ISR-amplified ${\\sim}5\\times$; Fisher $p{=}1.3{\\times}10^{-39}$), and \\textbf{H8} (premise-subset gaming; Appendix~\\ref{app:h8})---account for $>90\\%$ of hacking.\nH7 includes an obfuscated subtype \\textbf{H7b} ($14/231$) that evades text-match classifiers via vacuous quantifier wrapping, simultaneously gaming execution reward, ISR, and the hacking detector (\\S\\ref{sec:discussion}).\nThe cross-condition pattern: \\emph{reward formulation determines hacking composition but not prevalence}---all GRPO conditions show $\\geq 80\\%$ pooled hacking; only SFT achieves $92.3\\%$ non-hacking.\nNo GRPO condition produces a high-PR, majority non-hacking run; the taxonomy is descriptive, not exhaustive (query-as-fact gaming was discovered only via functional cross-validation)."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "4610ec00-1652-4ab5-ae48-575741c80fc9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H6dHGcwgUrwCptTNwX3WzM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 578,
      "cache_read_input_tokens": 59486,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 578
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-15T21:31:30.409Z_

<details><summary>↩ Tool result · reported error · `toolu_019Gw5eEbH9sb99DmJMWhTw1`</summary>

```text
&lt;tool_use_error>File has been modified since read, either by the user or by a linter. Read it again before attempting to write it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "3680a68c-d031-40df-a094-cf8c0c0d01e2",
  "tool_use_result": "Error: File has been modified since read, either by the user or by a linter. Read it again before attempting to write it."
}
```

</details>

---

### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Read · `toolu_019uQNNFDGoCYiEuH3kA7Ste`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "offset": 164,
  "limit": 15
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "3ff640db-a752-4a85-ac27-b9ae03a2359e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ao1ariV5zsT8g4BZvGPsXC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1320,
      "cache_read_input_tokens": 60064,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1320
      },
      "output_tokens": 70,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 46 · 2026-05-15T21:31:33.587Z_

<details><summary>↩ Tool result · `toolu_019uQNNFDGoCYiEuH3kA7Ste`</summary>

```text
164	
165	The eight modes (Table~\ref{tab:hacking-taxonomy}; full definitions in Appendix~\ref{app:hacking-modes}) span the studied conditions.
166	Three are quantifiable across conditions: \textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\%$ regardless of reward type; \textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\sim}5\times$ ($70.6\%$ vs.\ $13.7\%$ under random; Fisher $p{=}1.3{\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\%$; s42, s44: $0\%$); \textbf{H8} (premise-subset gaming) appears under both exec-only ($6\%$) and ISR ($5\%$) conditions (Appendix~\ref{app:h8}).
167	H7 splits into \textbf{H7a} (standard, text-match detectable; $64.5\%$ of ISR proved, $149/231$) and \textbf{H7b} (obfuscated tautology; $6.06\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\text{ISR}{\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.
168	The remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).
169	
170	The cross-condition pattern is consistent with \S\ref{sec:goodhart}: \emph{reward formulation determines hacking composition but not hacking prevalence.}
171	Exec-only, ISR, and random conditions all show $\geq 80\%$ pooled hacking among proved samples; only SFT shows $92.3\%$ non-hacking.
172	Across 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\beta{=}0.1$ s42 at $\text{PR}{=}79\%$, $22.8\%$ non-hacking, and ISR $\beta{=}0.1$ s42 at $\text{PR}{=}81\%$, $17.3\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.
173	Query-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.
174	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "9897f8c7-a3ab-4e5b-bfe6-bd1a436c2ae4",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
      "content": "\nThe eight modes (Table~\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\ref{app:hacking-modes}) span the studied conditions.\nThree are quantifiable across conditions: \\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\\%$ regardless of reward type; \\textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ under random; Fisher $p{=}1.3{\\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\\%$; s42, s44: $0\\%$); \\textbf{H8} (premise-subset gaming) appears under both exec-only ($6\\%$) and ISR ($5\\%$) conditions (Appendix~\\ref{app:h8}).\nH7 splits into \\textbf{H7a} (standard, text-match detectable; $64.5\\%$ of ISR proved, $149/231$) and \\textbf{H7b} (obfuscated tautology; $6.06\\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\\text{ISR}{\\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\n\nThe cross-condition pattern is consistent with \\S\\ref{sec:goodhart}: \\emph{reward formulation determines hacking composition but not hacking prevalence.}\nExec-only, ISR, and random conditions all show $\\geq 80\\%$ pooled hacking among proved samples; only SFT shows $92.3\\%$ non-hacking.\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\\beta{=}0.1$ s42 at $\\text{PR}{=}79\\%$, $22.8\\%$ non-hacking, and ISR $\\beta{=}0.1$ s42 at $\\text{PR}{=}81\\%$, $17.3\\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\n",
      "numLines": 11,
      "startLine": 164,
      "totalLines": 174
    }
  }
}
```

</details>

---

### Tool call

_source line 47_

<details open><summary>🔧 Tool call — Edit · `toolu_01RBC73394wXKLYAmvRXmqpu`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "old_string": "The eight modes (Table~\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\ref{app:hacking-modes}) span the studied conditions.\nThree are quantifiable across conditions: \\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\\%$ regardless of reward type; \\textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ under random; Fisher $p{=}1.3{\\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\\%$; s42, s44: $0\\%$); \\textbf{H8} (premise-subset gaming) appears under both exec-only ($6\\%$) and ISR ($5\\%$) conditions (Appendix~\\ref{app:h8}).\nH7 splits into \\textbf{H7a} (standard, text-match detectable; $64.5\\%$ of ISR proved, $149/231$) and \\textbf{H7b} (obfuscated tautology; $6.06\\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\\text{ISR}{\\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\n\nThe cross-condition pattern is consistent with \\S\\ref{sec:goodhart}: \\emph{reward formulation determines hacking composition but not hacking prevalence.}\nExec-only, ISR, and random conditions all show $\\geq 80\\%$ pooled hacking among proved samples; only SFT shows $92.3\\%$ non-hacking.\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\\beta{=}0.1$ s42 at $\\text{PR}{=}79\\%$, $22.8\\%$ non-hacking, and ISR $\\beta{=}0.1$ s42 at $\\text{PR}{=}81\\%$, $17.3\\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.",
  "new_string": "The eight modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types and 6 reward conditions.\nThe three dominant modes---\\textbf{H1} (conclusion embedding, GRPO-universal at $68$--$100\\%$), \\textbf{H7} (conclusion duplication, ISR-amplified ${\\sim}5\\times$; Fisher $p{=}1.3{\\times}10^{-39}$), and \\textbf{H8} (premise-subset gaming; Appendix~\\ref{app:h8})---account for $>90\\%$ of hacking.\nH7 includes an obfuscated subtype \\textbf{H7b} ($14/231$) that evades text-match classifiers via vacuous quantifier wrapping, simultaneously gaming execution reward, ISR, and the hacking detector (\\S\\ref{sec:discussion}).\nThe cross-condition pattern: \\emph{reward formulation determines hacking composition but not prevalence}---all GRPO conditions show $\\geq 80\\%$ pooled hacking; only SFT achieves $92.3\\%$ non-hacking.\nNo GRPO condition produces a high-PR, majority non-hacking run; the taxonomy is descriptive, not exhaustive (query-as-fact gaming was discovered only via functional cross-validation)."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "76ed7027-e42c-408d-b9ba-49ba3bd43d72",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W2aEGziYHRNrKqtV9tExTA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 928,
      "cache_read_input_tokens": 61384,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 928
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 48 · 2026-05-15T21:31:45.487Z_

<details><summary>↩ Tool result · `toolu_01RBC73394wXKLYAmvRXmqpu`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "f9706b67-dcdb-4fdb-9123-b7c16259e453",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
    "oldString": "The eight modes (Table~\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\ref{app:hacking-modes}) span the studied conditions.\nThree are quantifiable across conditions: \\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\\%$ regardless of reward type; \\textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ under random; Fisher $p{=}1.3{\\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\\%$; s42, s44: $0\\%$); \\textbf{H8} (premise-subset gaming) appears under both exec-only ($6\\%$) and ISR ($5\\%$) conditions (Appendix~\\ref{app:h8}).\nH7 splits into \\textbf{H7a} (standard, text-match detectable; $64.5\\%$ of ISR proved, $149/231$) and \\textbf{H7b} (obfuscated tautology; $6.06\\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\\text{ISR}{\\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\n\nThe cross-condition pattern is consistent with \\S\\ref{sec:goodhart}: \\emph{reward formulation determines hacking composition but not hacking prevalence.}\nExec-only, ISR, and random conditions all show $\\geq 80\\%$ pooled hacking among proved samples; only SFT shows $92.3\\%$ non-hacking.\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\\beta{=}0.1$ s42 at $\\text{PR}{=}79\\%$, $22.8\\%$ non-hacking, and ISR $\\beta{=}0.1$ s42 at $\\text{PR}{=}81\\%$, $17.3\\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.",
    "newString": "The eight modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types and 6 reward conditions.\nThe three dominant modes---\\textbf{H1} (conclusion embedding, GRPO-universal at $68$--$100\\%$), \\textbf{H7} (conclusion duplication, ISR-amplified ${\\sim}5\\times$; Fisher $p{=}1.3{\\times}10^{-39}$), and \\textbf{H8} (premise-subset gaming; Appendix~\\ref{app:h8})---account for $>90\\%$ of hacking.\nH7 includes an obfuscated subtype \\textbf{H7b} ($14/231$) that evades text-match classifiers via vacuous quantifier wrapping, simultaneously gaming execution reward, ISR, and the hacking detector (\\S\\ref{sec:discussion}).\nThe cross-condition pattern: \\emph{reward formulation determines hacking composition but not prevalence}---all GRPO conditions show $\\geq 80\\%$ pooled hacking; only SFT achieves $92.3\\%$ non-hacking.\nNo GRPO condition produces a high-PR, majority non-hacking run; the taxonomy is descriptive, not exhaustive (query-as-fact gaming was discovered only via functional cross-validation).",
    "originalFile": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\S\\ref{sec:diagnostic}); ISR as a training reward, where it exhibits meta-level Goodhart's Law (\\S\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\S\\ref{sec:crosslogic}).\nA hacking taxonomy synthesizes the modes observed across conditions (\\S\\ref{sec:taxonomy}).\n\n\\subsection{Setup}\\label{sec:setup}\n\nWe train Qwen3-4B~\\citep{qwen3} with GRPO~\\citep{deepseekmath} ($K{=}8$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\\{42,43,44\\}$ on a fixed 500-example FOLIO~\\citep{folio} subset held constant across all conditions; the SFT baseline is trained with NLL on gold formalizations.\\footnote{All experiments use \\texttt{data/train\\_500\\_seed42.jsonl}; seeds control initialization and rollout sampling only.}\nHeld-out evaluation uses 100 FOLIO examples (\\texttt{proofwriter\\_fol\\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\\texttt{eval\\_sta.py}) so training-log ISR is never compared across runs.\nWe report prove rate (PR), proved-only ISR ($\\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\\text{necessary}}$ distribution; \\S\\ref{sec:taxonomy-method}), and a \\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the eight cataloged patterns, a necessary but not sufficient condition for semantic correctness.\n\n\\subsection{ISR as Diagnostic}\n\\label{sec:diagnostic}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/fig2_isr_collapse.pdf}\n\\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\\%$\\to$93\\%$\\to$96\\% while proved-only ISR falls $0.642{\\to}0.132{\\to}0.003$ over 100$\\to$500$\\to$1000 steps. By step 1000, 94.8\\% of proved samples have $\\text{ISR}{=}0$ and mean component count inflates 6.58$\\to$18.55 (contradiction explosion).}\n\\label{fig:isr-collapse}\n\\end{figure}\n\n\\textbf{Collapse trajectory.}\nFigure~\\ref{fig:isr-collapse} traces exec-only GRPO (seed~42) at 100, 500, 1000 steps.\nPR rises $32\\%\\to93\\%\\to96\\%$, a trajectory execution-only evaluation would read as successful optimization; $\\text{ISR}^*$ tells the opposite story, $0.642\\to0.132\\to0.003$ (214$\\times$ collapse). %% registry: plan003-eval-exec-only-r5, plan001-exec-only-s42-r2, plan016-extended-1000-s42\nBy 500 steps, 87.1\\% of proved samples embed the conclusion (H1); by 1000 steps the embedding rate saturates at 100\\% and mean component count more than doubles ($6.58\\to18.55$) as the model emits contradictory or vacuous premises that trivially derive any conclusion.\nExtended training, lacking a structural signal, \\emph{worsens} formalization quality while improving the headline number.\n\n\\textbf{Cross-seed instability.}\nThe three exec-only seeds diverge into qualitatively different failure modes despite shared data, hyperparameters, and reward (Appendix~\\ref{app:detailed-results}): s42 reaches $\\text{PR}{=}93\\%$ via conclusion embedding ($\\text{H1}{=}87\\%$); s43 collapses to $\\text{PR}{=}13\\%$ via repetition (87\\% of rollouts truncated); s44 reaches $\\text{PR}{=}98\\%$ via tautological collapse ($\\text{H7}{=}100\\%$, mean $n{=}2.04$). %% registry: plan001-exec-only-s42-r2, plan001-exec-only-s43-r4, plan001-exec-only-s44\nThe cross-seed PR variance ($\\sigma{=}47$\\,pp) shows aggregate metrics obscure qualitatively different failure modes; all three are flagged by $\\text{ISR}^*$ even though one passes the PR check (s44) and one fails it (s43).\nBy 1000 steps, all three converge to high PR ($0.95{\\pm}0.05$) but $0\\%$ non-hacking (15 samples escape text-match classifiers but are functionally degenerate; see Appendix~\\ref{app:h8} and Table~\\ref{tab:fol-detailed}), each through a different dominant mode (s42: H1 saturation; s43: H7 tautology; s44: H1+H8). %% registry: plan016-extended-1000-s42, plan001-exec-only-s43-1000-r2, plan001-exec-only-s44-1000-r2\n\n\\textbf{SFT baseline.}\nSFT on gold formalizations reaches $\\text{PR}{=}13.0\\%$ (3-seed pooled, 1000 steps) with $\\text{H7}{=}0$, $\\text{H1}{=}7.7\\%$, $92.3\\%$ non-hacking ($n{=}39$; per-seed range 91--93\\%). %% registry: plan009-sft-baseline-s42-1000/s43-1000/s44-1000-r3\nThe near-absence of hacking under identical data exposure is consistent with hacking being RL-specific.\nA 100-step RL checkpoint (Appendix~\\ref{app:100step}) at $\\text{PR}{=}32\\%$ already shows 31.2\\% hacking (vs.\\ SFT's 7.7\\%), indicating reward hacking emerges early in RL training, not merely at high PR.\n\n\\subsection{Meta-Level Goodhart's Law}\n\\label{sec:goodhart}\n\nWe now reverse roles: instead of treating ISR as an observer, we use it as a reward augmentation, $r = r_{\\text{exec}}\\cdot(1 + \\beta\\,\\text{ISR})$, with a matched random control, $r = r_{\\text{exec}}\\cdot(1 + \\beta\\,u)$, $u\\sim\\mathcal{U}(0,1)$, to isolate ISR-specific signal from generic reward-variance effects.\nThe headline finding: ISR-as-reward produces \\emph{meta-level} Goodhart~\\citep{manheim-goodhart-taxonomy}---the diagnostic itself becomes the target of gaming.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n\\textbf{Condition} & $\\boldsymbol{\\beta}$ & \\textbf{PR\\%}$\\uparrow$ & \\textbf{ISR}$^*$ & \\textbf{H7\\%} & \\textbf{H1\\%} & \\textbf{N-H\\%} \\\\\n\\midrule\nBase (0-shot) & --- & 12 & --- & --- & --- & --- \\\\ %% registry: sta-phase0-baseline\nSFT & --- & 13 & 0.595 & 0 & 8 & \\textbf{92} \\\\ %% registry: plan009-sft-baseline-s42-1000/s43-1000/s44-1000-r3 (3-seed pooled)\n\\midrule\nExec-only$^\\dagger$ & --- & 93 & 0.132 & 0 & 87 & 8 \\\\ %% registry: plan001-exec-only-s42-r2 (H8 corrected)\nISR & 0.1 & 77{\\scriptsize$\\pm$14} & $\\ddagger$ & \\textbf{71}$^\\P$ & 18 & 6 \\\\ %% registry: plan002-additive-b01-s42/s43-r2/s44 (pooled, D095 FINAL)\nRandom & 0.1 & \\textbf{87}{\\scriptsize$\\pm$8} & 0.117{\\scriptsize$\\pm$.04} & 14$^\\S$ & 71 & 10 \\\\ %% registry: plan018-additive-random-b01-s42/s43-r3/s44-r2 (D095 FINAL)\n\\midrule\nISR & 0.3 & 66{\\scriptsize$\\pm$42} & 0.39{\\scriptsize$\\pm$.31} & \\textbf{50} & 37 & 12 \\\\ %% registry: plan002-additive-b03-s42/s43/s44 (pooled)\nRandom & 0.3 & 54{\\scriptsize$\\pm$35} & 0.09{\\scriptsize$\\pm$.09} & 7 & 91 & 2 \\\\ %% registry: plan017-additive-random-s42, exp1-random-b03-s43-r4, exp1-random-b03-s44-r2 (pooled; D086 H7: s42=4,s43=7,s44=0)\n\\bottomrule\n\\end{tabular}}\n\\caption{Goodhart landscape across reward conditions. 3-seed rows: H7/H1/N-H pooled across seeds; PR/ISR$^*$: mean$\\pm$std of per-seed values. $^\\dagger$Seed~42. $\\ddagger$$\\text{ISR}^*$ omitted for ISR $\\beta{=}0.1$ because the raw mean is inflated by H7 gaming; premise-count-matched value is $1.06\\times$ random (\\S\\ref{sec:goodhart}, Appendix~\\ref{app:detailed-results}). $^\\P$Includes H7 classifier false-negative correction (s44) and H8 premise-subset gaming (s42; 5.2\\% of proved; Appendix~\\ref{app:h8}). $^\\S$Random H7 driven by seed~43 (38.3\\%); seeds~42 and~44: 0\\%. Per-seed breakdown in Appendix Table~\\ref{tab:fol-detailed}.}\n\\label{tab:goodhart-landscape}\n\\end{table}\n\n\\textbf{Low-dose ISR ($\\beta{=}0.1$): ISR-amplified gaming.}\nH7 tautological collapse occurs under both ISR and random conditions, but ISR amplifies it ${\\sim}5\\times$: $70.6\\%$ ($163/231$) under ISR vs.\\ $13.7\\%$ ($36/262$) under random (Fisher $p{=}1.3{\\times}10^{-39}$, $\\text{OR}{=}15.05$). %% registry: plan002 vs plan018 all seeds; D095 FINAL\nRandom H7 is highly seed-dependent: $38.3\\%$ in seed~43 vs.\\ $0\\%$ in seeds~42 and~44; ISR makes H7 near-deterministic ($2/3$ seeds at $97$--$100\\%$, Table~\\ref{tab:fol-detailed}).\nH7---a single premise identical to the conclusion, giving $\\text{ISR}\\geq 0.5$ by construction (\\S\\ref{sec:taxonomy-method})---is the canonical meta-level Goodhart move: the model satisfies the LOO definition directly rather than producing a derivation that happens to satisfy it.\nTotal conclusion embedding ($\\text{H1}+\\text{H7}$) is GRPO-universal at $68$--$100\\%$ across both conditions, and is in fact \\emph{higher} under random (pooled H1 $71\\%$ vs.\\ $18\\%$ under ISR).\nISR does not reduce hacking; it converts H1 into H7 (Figure~\\ref{fig:hacking-composition}).\nRandom also yields higher and more stable PR ($87{\\pm}8\\%$ vs.\\ $77{\\pm}14\\%$).\n\n\\textbf{Premise-count confound.}\nThe one ISR seed not dominated by H7 (s42) has raw $\\text{ISR}^{*}{=}0.415$, $3.2\\times$ its random control ($0.131$), suggesting genuine improvement.\nThis appearance is a premise-minimization artifact: ISR-trained models produce shorter formalizations (mean $n{=}5.58$ vs.\\ $8.46$ for random), and ISR rises mechanically as $n$ falls---when $n{=}2$, $\\text{ISR}\\geq 0.5$ by definition.\nRestricting to non-hacking samples with $\\geq{3}$ premises (eliminating the trivial-$n$ regime) gives $\\text{ISR}^{*}{=}0.258$ for ISR vs.\\ $0.243$ for random: a $1.06\\times$ ratio, no meaningful advantage. %% D051 premise-count-matched analysis\nAfter reclassifying premise-subset gaming (H8; Appendix~\\ref{app:h8}) and correcting H7 classifier false negatives (s44, $n{=}12$; Appendix~\\ref{app:hacking-modes}), ISR $\\beta{=}0.1$ non-hacking rate ($6.06\\%$, $14/231$) is numerically lower than random ($9.5\\%$, $25/262$), but the difference is not statistically significant (Fisher $p{=}0.182$, two-sided, n.s.; Wilson 95\\% CI: ISR $[3.6\\%, 9.9\\%]$, Random $[6.5\\%, 13.7\\%]$; Appendix Table~\\ref{tab:bootstrap-ci}). %% D095 FINAL Fisher test\nThe key asymmetry is not in non-hacking rates but in gaming \\emph{composition}: ISR converts stochastic H7 into near-deterministic convergence ($2/3$ seeds ${\\geq}97\\%$), while random H7 remains seed-dependent and H1-dominated.\nThe raw $3.2\\times$ ISR$^*$ headline collapses once the LOO bias is controlled---a methodological lesson for any LOO-based metric on variable-length outputs. %% artifact: wilson_ci_complete, h8_reclassification\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/fig5_training_isr_curves.pdf}\n\\caption{Training ISR trajectories across reward conditions. ISR $\\beta{=}0.1$ seeds rise rapidly toward $\\text{ISR}{\\approx}1$ (meta-Goodhart gaming via H7 tautology); exec-only s44's plateau at ${\\sim}0.5$ is an H7a artifact ($n{=}2$ gives $\\text{ISR}{\\geq}0.5$ by construction), not genuine structural quality; random $\\beta{=}0.1$ remains low. The s42 1k-step trace shows ISR eventually saturates at $0.88$ through the same H7 mechanism.}\n\\label{fig:training-isr-curves}\n\\end{figure}\n\n\\textbf{Temporal collapse under ISR $\\beta{=}0.1$.}\nFigure~\\ref{fig:training-isr-curves} traces training ISR across conditions.\nExtended training (1000 steps) reveals that ISR $\\beta{=}0.1$'s genuine rate at 500 steps ($17.3\\%$, seed~42) is transient: by step 1000, H7 gaming escalates from $16.0\\%$ to $96.7\\%$ while genuine rate collapses to $2.2\\%$ ($n_{\\text{comp}}$: $5.58{\\to}2.89$).\nThe optimization converges to a fixed point where $\\text{ISR}^{*}{=}0.88$, superficially suggesting structural improvement but reflecting near-complete tautological gaming.\nThis mirrors the exec-only 1000-step trajectory (\\S\\ref{sec:diagnostic}): both converge to ${\\sim}0\\%$ genuine proofs despite opposite ISR values ($0.88$ vs.\\ $0.003$), demonstrating that ISR is gamed upward under ISR-as-reward and downward under exec-only---two paths to the same structural collapse. %% registry: plan002-b01-s42-1000, plan016-extended-1000-s42\n\n\\textbf{High-dose ISR ($\\beta{=}0.3$): multi-modal Goodhart.}\nAt $\\beta{=}0.3$, ISR-as-reward produces extreme cross-seed instability ($\\text{PR}{=}66{\\pm}42\\%$, spanning 18--95\\%); each seed converges to a distinct pathway (Appendix~\\ref{app:detailed-results}). %% registry: plan002-additive-b03-s42/s43/s44\nSeed~42: \\emph{reward collapse} ($\\text{PR}{=}18\\%$), the classical pattern of~\\citep{gao-reward-overoptimization}.\nSeed~43: \\emph{H1 shortcutting} ($\\text{PR}{=}86\\%$, $\\text{H1}{=}69\\%$, only $27\\%$ non-hacking).\nSeed~44: \\emph{pure H7 meta-Goodhart} ($\\text{PR}{=}95\\%$, $\\text{H7}{=}100\\%$, $\\text{ISR}^{*}{=}0.742$, $0\\%$ non-hacking)---simultaneously gaming \\emph{both} execution and structural metrics through the same construction.\nThe random control at $\\beta{=}0.3$ is equally unstable ($\\text{PR}{=}54{\\pm}35\\%$, spanning 23--92\\%) with near-universal H1 hacking ($91\\%$, pooled) and ${\\leq}4\\%$ non-hacking per seed; high-dose proxy weighting destabilizes training regardless of signal source; ISR produces diverse failure modes (reward collapse, H1 shortcutting, H7 meta-Goodhart) while random converges to H1-dominated hacking with sporadic H7 ($7\\%$ pooled, $0$--$7$ H7a per seed) (Appendix~\\ref{app:beta03}).\n\n\\subsection{Cross-Logic Diagnostic Transfer}\n\\label{sec:crosslogic}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.95\\columnwidth]{figures/fig4_prolog_comparison.pdf}\n\\caption{Cross-logic results. \\textbf{Left}: FOL vs.\\ Prolog exec-only $\\text{ISR}^*$ across 3 seeds (s44 Prolog $0.387$ is a small-sample artifact, $n{=}21$). \\textbf{Right}: Prolog ISR-reward gaming-mode composition---all 3 seeds reach 0\\% non-hacking through distinct mechanisms.}\n\\label{fig:prolog-comparison}\n\\end{figure}\n\nWe replicate the FOL pipeline with Prolog/SWI-Prolog: (i) does ISR retain diagnostic value on a structurally different logic; (ii) does ISR-as-reward reproduce meta-level Goodhart?\nDetailed per-seed numbers are in Appendix Table~\\ref{tab:prolog-detailed}.\n\n\\textbf{Prolog exec-only: ISR catches redundancy across logics.}\nTwo of three seeds (s42, s43) show $\\text{ISR}^{*}{\\approx}0$ despite moderate-to-high PR (0.83, 0.56). %% registry: plan006-prolog-exec-s42, plan006-prolog-exec-s43-r3\nInspection reveals \\emph{redundant coding}: ground facts repeated multiple times (e.g., \\texttt{penguin(fido).} appearing three times), so per-clause LOO never breaks the proof.\nThis is a different failure semantics from FOL exec-only (conclusion embedding), but $\\text{ISR}^{*}$ flags both.\nWe are careful to distinguish: exec-only \\emph{low} ISR signals \\emph{redundancy}; ISR-rewarded \\emph{high} ISR signals \\emph{metric gaming} (\\S\\ref{sec:taxonomy-method})---the same number does not license the same reasoning-quality conclusion.\n\n\\textbf{Prolog ISR-as-reward: universal Goodhart.}\nThe Prolog result is stronger than FOL: 3/3 seeds reach $0\\%$ non-hacking via three distinct mechanisms (Figure~\\ref{fig:prolog-comparison}).\nSeed~42: clean H7 tautologies ($\\text{ISR}^{*}{=}1.0$, all $50/100$ proved). %% registry: plan006-prolog-sta-s42\nSeed~43: \\emph{degenerate uppercase pseudo-Prolog} (e.g., \\texttt{MARY\\_IS\\_AN\\_AVA\\-DEOTE.}); strict text-match returns $\\text{H7}{=}0$ but functional analysis shows all 38 proved samples have $n_{\\text{necessary}}{=}1$ (functionally H7). %% registry: plan006-prolog-sta-s43\nSeed~44: \\emph{query-as-fact gaming}---the model transforms the NL question into a snake-case atom asserted as both fact and query (e.g., \\texttt{is\\_the\\_dog\\_furry.} as both fact and query), with $95/97$ proved samples at $n_{\\text{necessary}}{=}1$. %% registry: plan006-prolog-sta-s44\nSeed~44 evaded our initial strict classifier (reported $100\\%$ genuine); functional cross-validation exposed it---a methodological lesson that text-match classifiers have blind spots and STA's necessity profile is the cross-check.\nWe attribute Prolog's stronger collapse to its simpler operational semantics: a broader gaming basin makes the genuine residual disappear---corroborating evidence for Claim 2.\n\n\\subsection{Hacking Taxonomy}\n\\label{sec:taxonomy}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.92\\columnwidth]{figures/fig3_hacking_composition.pdf}\n\\caption{Hacking composition across reward conditions (proved samples; exec-only: seed~42; all other bars: pooled across 3 seeds, per-seed breakdown in Appendix Table~\\ref{tab:fol-detailed}). ISR converts H1 into more extreme H7 without reducing total hacking; SFT shows near-zero hacking.}\n\\label{fig:hacking-composition}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Mode} & \\textbf{Exec} & \\textbf{ISR$_{.1}$} & \\textbf{Rnd$_{.1}$} & \\textbf{SFT} & \\textbf{Prolog$_{\\text{ISR}}$} \\\\\n\\midrule\nH1 embed       & 87 & 18 & 71 & 7 & 0$^\\sharp$ \\\\\nH7 duplicate   & 0  & 71 & 14 & 0 & 100$^\\sharp$ \\\\\nH8 prem-subset & 6  & 5  & 8   & 0 & --- \\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\nCmplx.\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\n\\midrule\n\\textbf{Non-hacking} & 8  & 6  & 10 & \\textbf{92} & \\textbf{0} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Eight hacking modes across conditions (\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). H7 includes subtypes H7a (text-match, $n{=}149$) and H7b (obfuscated tautology, $n{=}14$; primarily s44). Cells with seed identifiers indicate the mode dominates that seed. $^\\sharp$Prolog row pools strict+functional (\\S\\ref{sec:crosslogic}).}\n\\label{tab:hacking-taxonomy}\n\\end{table}\n\nThe eight modes (Table~\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\ref{app:hacking-modes}) span the studied conditions.\nThree are quantifiable across conditions: \\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\\%$ regardless of reward type; \\textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ under random; Fisher $p{=}1.3{\\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\\%$; s42, s44: $0\\%$); \\textbf{H8} (premise-subset gaming) appears under both exec-only ($6\\%$) and ISR ($5\\%$) conditions (Appendix~\\ref{app:h8}).\nH7 splits into \\textbf{H7a} (standard, text-match detectable; $64.5\\%$ of ISR proved, $149/231$) and \\textbf{H7b} (obfuscated tautology; $6.06\\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\\text{ISR}{\\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.\nThe remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).\n\nThe cross-condition pattern is consistent with \\S\\ref{sec:goodhart}: \\emph{reward formulation determines hacking composition but not hacking prevalence.}\nExec-only, ISR, and random conditions all show $\\geq 80\\%$ pooled hacking among proved samples; only SFT shows $92.3\\%$ non-hacking.\nAcross 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\\beta{=}0.1$ s42 at $\\text{PR}{=}79\\%$, $22.8\\%$ non-hacking, and ISR $\\beta{=}0.1$ s42 at $\\text{PR}{=}81\\%$, $17.3\\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.\nQuery-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.\n",
    "structuredPatch": [
      {
        "oldStart": 162,
        "oldLines": 12,
        "newStart": 162,
        "newLines": 8,
        "lines": [
          " \\label{tab:hacking-taxonomy}",
          " \\end{table}",
          " ",
          "-The eight modes (Table~\\ref{tab:hacking-taxonomy}; full definitions in Appendix~\\ref{app:hacking-modes}) span the studied conditions.",
          "-Three are quantifiable across conditions: \\textbf{H1} (conclusion embedding) is GRPO-universal at $68$--$100\\%$ regardless of reward type; \\textbf{H7} (conclusion duplication) occurs under both ISR and random but ISR amplifies it ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ under random; Fisher $p{=}1.3{\\times}10^{-39}$), with random H7 concentrated in a single seed (s43: $38.3\\%$; s42, s44: $0\\%$); \\textbf{H8} (premise-subset gaming) appears under both exec-only ($6\\%$) and ISR ($5\\%$) conditions (Appendix~\\ref{app:h8}).",
          "-H7 splits into \\textbf{H7a} (standard, text-match detectable; $64.5\\%$ of ISR proved, $149/231$) and \\textbf{H7b} (obfuscated tautology; $6.06\\%$, $14/231$): H7b samples use vacuous quantifier wrapping or structural simplification to evade the text-match classifier while remaining logically equivalent (s44: $11/12$ quantifier wrapping, $1/12$ structural; s43: $2$), with $10/12$ (s44) achieving $\\text{ISR}{\\approx}0.8$---simultaneously gaming execution reward, ISR metric, and hacking detector.",
          "-The remaining five appear in specific cells: tautological collapse (exec-only s44, Prolog ISR s42), repetition (exec-only s43), contradiction explosion (exec-only at 1000 steps), complexity-without-utility (random $\\beta{=}0.1$ residual), and query-as-fact gaming (Prolog ISR s44).",
          "-",
          "-The cross-condition pattern is consistent with \\S\\ref{sec:goodhart}: \\emph{reward formulation determines hacking composition but not hacking prevalence.}",
          "-Exec-only, ISR, and random conditions all show $\\geq 80\\%$ pooled hacking among proved samples; only SFT shows $92.3\\%$ non-hacking.",
          "-Across 2 logic types, 6 reward conditions, 3 seeds, and up to 1000 steps, no GRPO condition we tested produces a high-PR run that is also majority non-hacking; the closest is random $\\beta{=}0.1$ s42 at $\\text{PR}{=}79\\%$, $22.8\\%$ non-hacking, and ISR $\\beta{=}0.1$ s42 at $\\text{PR}{=}81\\%$, $17.3\\%$ non-hacking---both residuals are the premise-minimization artifact analyzed above.",
          "-Query-as-fact gaming was found only when we cross-validated the strict classifier against $n_{\\text{necessary}}$ distributions, suggesting the taxonomy is descriptive, not exhaustive.",
          "+The eight modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types and 6 reward conditions.",
          "+The three dominant modes---\\textbf{H1} (conclusion embedding, GRPO-universal at $68$--$100\\%$), \\textbf{H7} (conclusion duplication, ISR-amplified ${\\sim}5\\times$; Fisher $p{=}1.3{\\times}10^{-39}$), and \\textbf{H8} (premise-subset gaming; Appendix~\\ref{app:h8})---account for $>90\\%$ of hacking.",
          "+H7 includes an obfuscated subtype \\textbf{H7b} ($14/231$) that evades text-match classifiers via vacuous quantifier wrapping, simultaneously gaming execution reward, ISR, and the hacking detector (\\S\\ref{sec:discussion}).",
          "+The cross-condition pattern: \\emph{reward formulation determines hacking composition but not prevalence}---all GRPO conditions show $\\geq 80\\%$ pooled hacking; only SFT achieves $92.3\\%$ non-hacking.",
          "+No GRPO condition produces a high-PR, majority non-hacking run; the taxonomy is descriptive, not exhaustive (query-as-fact gaming was discovered only via functional cross-validation)."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 49_

Now compile and check the result.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "8abd1dc0-92b8-4ef0-ba87-5b69e90eb4c0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LGxczgsz3YuRmukx5YLpk6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1302,
      "cache_read_input_tokens": 62312,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1302
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 50_

<details open><summary>🔧 Tool call — Bash · `toolu_01Uhnvjcbdvufik2nR8UhzAf`</summary>

```json
{
  "command": "pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && bibtex main > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && echo \"COMPILED OK\"",
  "description": "Full compile with bibtex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "36748c6a-ab28-4d98-92de-81043e08c2b1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LGxczgsz3YuRmukx5YLpk6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1302,
      "cache_read_input_tokens": 62312,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1302
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 51 · 2026-05-15T21:31:52.619Z_

<details><summary>↩ Tool result · `toolu_01Uhnvjcbdvufik2nR8UhzAf`</summary>

```text
COMPILED OK
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "286cddfe-ce45-45f7-a473-48e691393d85",
  "tool_use_result": {
    "stdout": "COMPILED OK",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 52_

<details open><summary>🔧 Tool call — Bash · `toolu_01SLjXvVs1CMHDhoWw7G5sfH`</summary>

```json
{
  "command": "pdftotext -f 9 -l 9 main.pdf - 2>/dev/null | head -30",
  "description": "Check page 9 content after edits"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "64530a8c-19eb-4ab8-b200-1f401de7dfc9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SUK4Ac7Fy78btrxQX38ivB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 192,
      "cache_read_input_tokens": 63614,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 192
      },
      "output_tokens": 57,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 53 · 2026-05-15T21:31:55.849Z_

<details><summary>↩ Tool result · `toolu_01SLjXvVs1CMHDhoWw7G5sfH`</summary>

```text
650

post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic
types.

651

References

652
653
654
655

Alexander Bondarenko, Denis Volk, Dmitrii
Volkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.
arXiv preprint arXiv:2502.13295.

656
657
658
659

DeepSeek AI. 2024. DeepSeek-Prover-V1.5: Harnessing Proof Assistant Feedback for Reinforcement Learning and Monte-Carlo Tree Search.
arXiv preprint arXiv:2408.08152.

660
661
662
663
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "26eeb69d-2215-499c-abf6-36ed2ee61687",
  "tool_use_result": {
    "stdout": "650\n\npost-hoc evaluation, with future work targeting gaming-robust rewards and broader logic\ntypes.\n\n651\n\nReferences\n\n652\n653\n654\n655\n\nAlexander Bondarenko, Denis Volk, Dmitrii\nVolkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.\narXiv preprint arXiv:2502.13295.\n\n656\n657\n658\n659\n\nDeepSeek AI. 2024. DeepSeek-Prover-V1.5: Harnessing Proof Assistant Feedback for Reinforcement Learning and Monte-Carlo Tree Search.\narXiv preprint arXiv:2408.08152.\n\n660\n661\n662\n663",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 54_

<details><summary>Logged reasoning block</summary>

```text
Page 9 still has 3 lines of body text ("post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.") before References starts. Those 3 lines are the closing sentence of the Discussion. Let me check what's on page 8 to see exactly where the cut is.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "809e29c7-1084-4c4d-a0e0-dc91b4843923",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Yq1cGLBuZp16n8wq6EUUb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 285,
      "cache_read_input_tokens": 63806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 285
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 55_

Almost there — 3 lines of body text still spill onto page 9. Let me check how much is on page 8.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "30ad7dc7-9384-4f34-9a42-46f77659573f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Yq1cGLBuZp16n8wq6EUUb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 285,
      "cache_read_input_tokens": 63806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 285
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 56_

<details open><summary>🔧 Tool call — Bash · `toolu_013aiX2YyQ9qQvE8BBTHm1BF`</summary>

```json
{
  "command": "pdftotext -f 8 -l 8 main.pdf - 2>/dev/null | tail -30",
  "description": "Check end of page 8"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "4f2d7050-369a-4880-b7bd-52b5cd20c36e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013Yq1cGLBuZp16n8wq6EUUb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 285,
      "cache_read_input_tokens": 63806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 285
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 57 · 2026-05-15T21:32:03.892Z_

<details><summary>↩ Tool result · `toolu_013aiX2YyQ9qQvE8BBTHm1BF`</summary>

```text
620
621
622
623
624
625
626
627
628
629
630
631
632
633
634
635
636
637
638
639
640
641
642
643
644
645
646
647
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "5aab6362-080e-4534-9d1f-0ca0d73c0d18",
  "tool_use_result": {
    "stdout": "620\n621\n622\n623\n624\n625\n626\n627\n628\n629\n630\n631\n632\n633\n634\n635\n636\n637\n638\n639\n640\n641\n642\n643\n644\n645\n646\n647",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 58_

<details open><summary>🔧 Tool call — Bash · `toolu_016h7XS7GUGeobPHN67WJX8x`</summary>

```json
{
  "command": "pdftotext -f 8 -l 9 main.pdf - 2>/dev/null | grep -n \".\" | tail -40",
  "description": "Check text spanning pages 8-9"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "2a88a0fa-9807-430e-ba2d-f4d52b78b410",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019C8zWgvc97qpCwA5c3VZaE",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 282,
      "cache_read_input_tokens": 64091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 282
      },
      "output_tokens": 59,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 59 · 2026-05-15T21:32:07.575Z_

<details><summary>↩ Tool result · `toolu_016h7XS7GUGeobPHN67WJX8x`</summary>

```text
475:722
476:723
477:724
478:725
480:METR. 2025.
481:Recent Frontier Models Are Reward Hacking.
482:METR
483:blog post.
484:https://metr.org/blog/
485:2025-06-05-recent-reward-hacking/.
487:726
488:727
489:728
490:729
492:Theo X. Olausson, Alex Gu, Ben Lipkin,
493:Cedegao E. Zhang, Armando Solar-Lezama,
494:Joshua B. Tenenbaum, and Roger Levy. 2023.
495:LINC: A Neurosymbolic Approach for Logical
496:Reasoning by Combining Language Models with
497:First-Order Logic Provers. In Proceedings of
498:the Conference on Empirical Methods in Natural Language Processing (EMNLP).
500:730
501:731
502:732
503:733
504:734
505:735
506:736
507:737
509:Liangming Pan, Alon Albalak, Xinyi Wang, and
510:William Yang Wang. 2023. Logic-LM: Empowering Large Language Models with Symbolic
511:Solvers for Faithful Logical Reasoning. In Findings of the Conference on Empirical Methods in
512:Natural Language Processing (EMNLP).
514:738
515:739
516:740
517:741
518:742
519:743
521:
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "b7354fa0-e048-438f-978e-44a7d068eba5",
  "tool_use_result": {
    "stdout": "475:722\n476:723\n477:724\n478:725\n480:METR. 2025.\n481:Recent Frontier Models Are Reward Hacking.\n482:METR\n483:blog post.\n484:https://metr.org/blog/\n485:2025-06-05-recent-reward-hacking/.\n487:726\n488:727\n489:728\n490:729\n492:Theo X. Olausson, Alex Gu, Ben Lipkin,\n493:Cedegao E. Zhang, Armando Solar-Lezama,\n494:Joshua B. Tenenbaum, and Roger Levy. 2023.\n495:LINC: A Neurosymbolic Approach for Logical\n496:Reasoning by Combining Language Models with\n497:First-Order Logic Provers. In Proceedings of\n498:the Conference on Empirical Methods in Natural Language Processing (EMNLP).\n500:730\n501:731\n502:732\n503:733\n504:734\n505:735\n506:736\n507:737\n509:Liangming Pan, Alon Albalak, Xinyi Wang, and\n510:William Yang Wang. 2023. Logic-LM: Empowering Large Language Models with Symbolic\n511:Solvers for Faithful Logical Reasoning. In Findings of the Conference on Empirical Methods in\n512:Natural Language Processing (EMNLP).\n514:738\n515:739\n516:740\n517:741\n518:742\n519:743\n521:",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 60_

<details open><summary>🔧 Tool call — Bash · `toolu_015nvhV3tPDPk6HdLdnnfdyt`</summary>

```json
{
  "command": "pdftotext -f 8 -l 9 main.pdf - 2>/dev/null | grep -B5 -A5 \"post-hoc\"",
  "description": "Find the spillover text location"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "529b8016-f890-42a8-b5d8-5a5692816202",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014Y9SvmPDf1TUfcn65CjpzS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 598,
      "cache_read_input_tokens": 64373,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 598
      },
      "output_tokens": 58,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 61 · 2026-05-15T21:32:10.932Z_

<details><summary>↩ Tool result · `toolu_015nvhV3tPDPk6HdLdnnfdyt`</summary>

```text
646
647

650

post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic
types.

651

References
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "a331afde-909d-4519-92be-8e205970b8d6",
  "tool_use_result": {
    "stdout": "646\n647\n\n\f650\n\npost-hoc evaluation, with future work targeting gaming-robust rewards and broader logic\ntypes.\n\n651\n\nReferences",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 62_

Still about 3 lines spilling. I need to cut ~3 more lines. Let me read the current conclusion.tex to see what's there now.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "a7ee4993-8ad8-4806-bd96-01e14d224096",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FdaFaYQwmQ1m3moA3VSjtx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 155,
      "cache_read_input_tokens": 64971,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 155
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 63_

<details open><summary>🔧 Tool call — Read · `toolu_016DVKDiqRxBo2aWSJ4ooALQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "f9ddec57-3965-4ea4-a4ae-812036c4eae8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FdaFaYQwmQ1m3moA3VSjtx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 155,
      "cache_read_input_tokens": 64971,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 155
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 64 · 2026-05-15T21:32:15.971Z_

<details><summary>↩ Tool result · `toolu_016DVKDiqRxBo2aWSJ4ooALQ`</summary>

```text
1	\section{Discussion and Conclusion}
2	\label{sec:discussion}
3	
4	STA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\S\ref{sec:diagnostic}).
5	Repurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\beta{=}0.1$, it amplifies H7 tautological gaming ${\sim}5\times$ ($70.6\%$ vs.\ $13.7\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\times$) after controlling for premise count; at $\beta{=}0.3$, each seed converges to a distinct failure mode ($\text{PR}{=}66{\pm}42\%$).
6	The pattern transfers to Prolog (3/3 seeds, 0\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\S\ref{sec:taxonomy}).
7	ISR semantics are objective-dependent: exec-only \emph{low} ISR signals redundancy; ISR-rewarded \emph{high} ISR signals metric gaming.
8	
9	\paragraph{Classifier blind spots.}
10	H7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.
11	In both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\text{ISR}{\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\S\ref{sec:crosslogic}).
12	Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.
13	
14	H7 follows a dose-response gradient from random $\beta{=}0.1$ ($13.7\%$) through random $\beta{=}0.3$ to ISR $\beta{=}0.1$ ($70.6\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\ref{app:extended-discussion}).
15	
16	\paragraph{Hacking mode switching.}
17	Under identical reward configurations, different seeds converge to qualitatively different modes (Table~\ref{tab:fol-detailed}): random $\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\geq}97\%$).
18	Single-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard.
19	
20	The asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.
21	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "ac6c100b-3175-4845-88b3-ba26a50fa80f",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
      "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSTA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots.}\nH7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.\nIn both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).\nBoth cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\nH7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).\n\n\\paragraph{Hacking mode switching.}\nUnder identical reward configurations, different seeds converge to qualitatively different modes (Table~\\ref{tab:fol-detailed}): random $\\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\\geq}97\\%$).\nSingle-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
      "numLines": 21,
      "startLine": 1,
      "totalLines": 21
    }
  }
}
```

</details>

---

### Assistant

_source line 65_

<details><summary>Logged reasoning block</summary>

```text
I need to cut about 3 more lines. I can:

1. Merge the dose-response sentence (line 14) into the closing paragraph (line 20), or just cut it entirely since it's now in the appendix
2. Further compress the classifier blind spots paragraph
3. Further compress the closing sentence

Let me try removing the dose-response forward-reference sentence entirely (it's already in the appendix with full detail, and the 5x amplification is mentioned in the opening paragraph). That saves ~2 lines.

And tighten the closing sentence a bit.

Let me also check if I can tighten one more thing. Actually, the dose-response line is a standalone sentence not under any \paragraph heading. 

Removing it entirely should save about 2 lines, then I can shorten the closing sentence slightly.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "19e1284d-9021-437d-97eb-c820e1d402e3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QZuk8y73A9fu1ekMHifpq3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 975,
      "cache_read_input_tokens": 65126,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 975
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 66_

The dose-response forward-reference (line 14) is redundant since the 5x amplification is already in the opening paragraph. Removing it and tightening the closing should save the needed 3 lines.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "0d16ed25-71e5-4479-b5bb-f8c45e299a0d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QZuk8y73A9fu1ekMHifpq3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 975,
      "cache_read_input_tokens": 65126,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 975
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 67_

<details open><summary>🔧 Tool call — Edit · `toolu_014nCiufAM3xrKu4kAbHKfzE`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
  "old_string": "Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\nH7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).\n\n\\paragraph{Hacking mode switching.}",
  "new_string": "Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\n\\paragraph{Hacking mode switching.}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "650ffd28-894a-4849-8c94-fef3c92ad43e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QZuk8y73A9fu1ekMHifpq3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 975,
      "cache_read_input_tokens": 65126,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 975
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 68 · 2026-05-15T21:32:25.816Z_

<details><summary>↩ Tool result · `toolu_014nCiufAM3xrKu4kAbHKfzE`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "cf6a990b-bffa-4c03-9796-fe2dc238718f",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
    "oldString": "Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\nH7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).\n\n\\paragraph{Hacking mode switching.}",
    "newString": "Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\n\\paragraph{Hacking mode switching.}",
    "originalFile": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSTA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots.}\nH7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.\nIn both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).\nBoth cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\nH7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).\n\n\\paragraph{Hacking mode switching.}\nUnder identical reward configurations, different seeds converge to qualitatively different modes (Table~\\ref{tab:fol-detailed}): random $\\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\\geq}97\\%$).\nSingle-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
    "structuredPatch": [
      {
        "oldStart": 11,
        "oldLines": 8,
        "newStart": 11,
        "newLines": 6,
        "lines": [
          " In both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).",
          " Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.",
          " ",
          "-H7 follows a dose-response gradient from random $\\beta{=}0.1$ ($13.7\\%$) through random $\\beta{=}0.3$ to ISR $\\beta{=}0.1$ ($70.6\\%$), indicating ISR transforms H7 from a seed-dependent tendency to a near-universal convergence direction (Appendix~\\ref{app:extended-discussion}).",
          "-",
          " \\paragraph{Hacking mode switching.}",
          " Under identical reward configurations, different seeds converge to qualitatively different modes (Table~\\ref{tab:fol-detailed}): random $\\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\\geq}97\\%$).",
          " Single-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 69_

<details open><summary>🔧 Tool call — Bash · `toolu_01PW75FVTN4hdYMC4KgBTYWW`</summary>

```json
{
  "command": "pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdftotext -f 9 -l 9 main.pdf - 2>/dev/null | head -15",
  "description": "Compile and check page 9"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "b9d67005-27e9-475e-b31f-d3bb615881e7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SMqmKf29ojG8e87dzYECZ9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 593,
      "cache_read_input_tokens": 66101,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 593
      },
      "output_tokens": 71,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 70 · 2026-05-15T21:32:31.493Z_

<details><summary>↩ Tool result · `toolu_01PW75FVTN4hdYMC4KgBTYWW`</summary>

```text
645

References

646
647
648
649

Alexander Bondarenko, Denis Volk, Dmitrii
Volkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.
arXiv preprint arXiv:2502.13295.

650
651
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "a8d603d6-001e-494d-9e59-0365ea7e4fa0",
  "tool_use_result": {
    "stdout": "645\n\nReferences\n\n646\n647\n648\n649\n\nAlexander Bondarenko, Denis Volk, Dmitrii\nVolkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.\narXiv preprint arXiv:2502.13295.\n\n650\n651",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 71_

Page 9 now starts with References only. Let me verify no warnings/errors in compilation.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "bd5f6267-0872-4774-9174-8f8d621ca1b3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BKewFwnDuAzya8wAPUFwCw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 236,
      "cache_read_input_tokens": 66694,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 236
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 72_

<details open><summary>🔧 Tool call — Bash · `toolu_01JJQ1tmQrw6tixLRtf3gy6x`</summary>

```json
{
  "command": "pdflatex -interaction=nonstopmode main.tex 2>&1 | grep -iE \"Warning.*ref|undefined|multiply\" | head -10",
  "description": "Check for undefined references"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "2498d23c-7768-40c9-a550-14baeda3789d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BKewFwnDuAzya8wAPUFwCw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 236,
      "cache_read_input_tokens": 66694,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 236
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 73 · 2026-05-15T21:32:38.760Z_

<details><summary>↩ Tool result · `toolu_01JJQ1tmQrw6tixLRtf3gy6x`</summary>

```text
(Bash completed with no output)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "a4f65703-1394-4f02-a24b-1dad36848e72",
  "tool_use_result": {
    "stdout": "",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 74_

No reference warnings. Let me do the full verification — check that page 8 contains the end of the body and page 9 starts clean with References.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "53e03e1b-a92a-4a39-b02a-0f03ceccccba",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BweK3Ggo48bgh8dPCyjDiW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 147,
      "cache_read_input_tokens": 66930,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 147
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 75_

<details open><summary>🔧 Tool call — Bash · `toolu_01SSpwUzbS5HQqVjh6cZtrMo`</summary>

```json
{
  "command": "pdftotext -f 8 -l 8 main.pdf - 2>/dev/null | tail -15",
  "description": "Verify end of page 8"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "6e8eb0f6-c4ba-49f6-a050-b5460c822ea4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BweK3Ggo48bgh8dPCyjDiW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 147,
      "cache_read_input_tokens": 66930,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 147
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 76 · 2026-05-15T21:32:43.486Z_

<details><summary>↩ Tool result · `toolu_01SSpwUzbS5HQqVjh6cZtrMo`</summary>

```text
632
633
634
635
636
637
638
639
640
641
642
643
644
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "c48d8282-46ba-4367-9010-825c7731952a",
  "tool_use_result": {
    "stdout": "632\n633\n634\n635\n636\n637\n638\n639\n640\n641\n642\n643\n644",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 77_

<details open><summary>🔧 Tool call — Bash · `toolu_01V4KbwrRxBZG76Lknz6NaWM`</summary>

```json
{
  "command": "pdftotext -f 8 -l 8 main.pdf - 2>/dev/null | grep -v '^[0-9]*$' | grep -v '^$' | tail -15",
  "description": "Verify page 8 text content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "b73fe9a7-cbe8-4c83-b106-205b8414abd0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RzayeFTVUBvQ3Cs6s22u3b",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 276,
      "cache_read_input_tokens": 67077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 276
      },
      "output_tokens": 58,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 78 · 2026-05-15T21:32:46.619Z_

<details><summary>↩ Tool result · `toolu_01V4KbwrRxBZG76Lknz6NaWM`</summary>

```text
STA exposes structural degeneration invisible
to execution-based evaluation: ISR reveals a
Hacking mode switching. Under identical
reward configurations, different seeds converge
to qualitatively different modes (Table 6): random β=0.1 ranges from H8-dominant (s44)
to H7-dominant (s43) to highest non-hacking
(s42); ISR β=0.1 similarly switches between
H1-heavy (s42) and near-pure H7 (s43/s44,
≥97%). Single-seed results can therefore misrepresent a reward configuration’s hacking profile; multi-seed evaluation with per-mode reporting should be standard.
The asymmetry—reliable observer, unreliable optimizer—may generalize to other
perturbation-based diagnostics; ISR and structurally similar metrics should be used as
post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic
types.
Discussion and Conclusion
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "ee62fe9b-3b49-4041-a31a-13bf5e38fe0a",
  "tool_use_result": {
    "stdout": "STA exposes structural degeneration invisible\nto execution-based evaluation: ISR reveals a\nHacking mode switching. Under identical\nreward configurations, different seeds converge\nto qualitatively different modes (Table 6): random β=0.1 ranges from H8-dominant (s44)\nto H7-dominant (s43) to highest non-hacking\n(s42); ISR β=0.1 similarly switches between\nH1-heavy (s42) and near-pure H7 (s43/s44,\n≥97%). Single-seed results can therefore misrepresent a reward configuration’s hacking profile; multi-seed evaluation with per-mode reporting should be standard.\nThe asymmetry—reliable observer, unreliable optimizer—may generalize to other\nperturbation-based diagnostics; ISR and structurally similar metrics should be used as\npost-hoc evaluation, with future work targeting gaming-robust rewards and broader logic\ntypes.\nDiscussion and Conclusion",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 79_

<details><summary>Logged reasoning block</summary>

```text
Wait, the page 8 text shows "Discussion and Conclusion" at the bottom... that might be a rendering artifact from pdftotext. Let me check more carefully - it seems like pdftotext might be displaying things out of order due to the two-column layout.

Actually, the actual content looks fine: the Discussion section is on page 8, ending with "post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types." And page 9 starts with "References". That's exactly what we want.

Let me also verify the final state of the edited files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "929beb79-45ca-45dd-acaf-baf980b4b1d2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018BM1WJyiaQtgrAnNBfRvMy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 359,
      "cache_read_input_tokens": 67353,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 359
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 80_

Let me verify the final state of the edited files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "08a4a330-907c-4a54-b16f-7f4582a70d06",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018BM1WJyiaQtgrAnNBfRvMy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 359,
      "cache_read_input_tokens": 67353,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 359
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 81_

<details open><summary>🔧 Tool call — Read · `toolu_01Dr6nKKC1X9P1qTtt6rLbzj`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "811d13c6-1641-4968-bc57-c7d6f190e6f7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018BM1WJyiaQtgrAnNBfRvMy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 359,
      "cache_read_input_tokens": 67353,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 359
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 82 · 2026-05-15T21:32:52.031Z_

<details><summary>↩ Tool result · `toolu_01Dr6nKKC1X9P1qTtt6rLbzj`</summary>

```text
1	\section{Discussion and Conclusion}
2	\label{sec:discussion}
3	
4	STA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\S\ref{sec:diagnostic}).
5	Repurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\beta{=}0.1$, it amplifies H7 tautological gaming ${\sim}5\times$ ($70.6\%$ vs.\ $13.7\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\times$) after controlling for premise count; at $\beta{=}0.3$, each seed converges to a distinct failure mode ($\text{PR}{=}66{\pm}42\%$).
6	The pattern transfers to Prolog (3/3 seeds, 0\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\S\ref{sec:taxonomy}).
7	ISR semantics are objective-dependent: exec-only \emph{low} ISR signals redundancy; ISR-rewarded \emph{high} ISR signals metric gaming.
8	
9	\paragraph{Classifier blind spots.}
10	H7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.
11	In both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\text{ISR}{\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\S\ref{sec:crosslogic}).
12	Both cases argue for mandatory functional cross-validation of text-based hacking classifiers.
13	
14	\paragraph{Hacking mode switching.}
15	Under identical reward configurations, different seeds converge to qualitatively different modes (Table~\ref{tab:fol-detailed}): random $\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\geq}97\%$).
16	Single-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard.
17	
18	The asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.
19	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "49826d67-d55f-4803-a9c5-f60841e040f8",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
      "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nSTA exposes structural degeneration invisible to execution-based evaluation: ISR reveals a 99.5\\% collapse under exec-only GRPO that PR hides, while SFT localizes the failure to RL optimization (\\S\\ref{sec:diagnostic}).\nRepurposed as a training signal, ISR induces meta-level Goodhart's Law: at $\\beta{=}0.1$, it amplifies H7 tautological gaming ${\\sim}5\\times$ ($70.6\\%$ vs.\\ $13.7\\%$ random, $p{<}10^{-38}$), and the sole apparent ISR gain vanishes ($1.06\\times$) after controlling for premise count; at $\\beta{=}0.3$, each seed converges to a distinct failure mode ($\\text{PR}{=}66{\\pm}42\\%$).\nThe pattern transfers to Prolog (3/3 seeds, 0\\% non-hacking) via distinct mechanisms including query-as-fact gaming that bypasses text-match classifiers (\\S\\ref{sec:taxonomy}).\nISR semantics are objective-dependent: exec-only \\emph{low} ISR signals redundancy; ISR-rewarded \\emph{high} ISR signals metric gaming.\n\n\\paragraph{Classifier blind spots.}\nH7b (obfuscated tautology) and Prolog query-as-fact gaming demonstrate that text-match classifiers have systematic blind spots exploitable by optimization.\nIn both cases, functional LOO analysis exposed gaming invisible to surface-level detection---H7b via vacuous quantifier wrapping ($10/12$ at $\\text{ISR}{\\approx}0.8$, triple gaming of execution, ISR, and classifier), query-as-fact via $95/97$ tautological samples the strict classifier labeled genuine (\\S\\ref{sec:crosslogic}).\nBoth cases argue for mandatory functional cross-validation of text-based hacking classifiers.\n\n\\paragraph{Hacking mode switching.}\nUnder identical reward configurations, different seeds converge to qualitatively different modes (Table~\\ref{tab:fol-detailed}): random $\\beta{=}0.1$ ranges from H8-dominant (s44) to H7-dominant (s43) to highest non-hacking (s42); ISR $\\beta{=}0.1$ similarly switches between H1-heavy (s42) and near-pure H7 (s43/s44, ${\\geq}97\\%$).\nSingle-seed results can therefore misrepresent a reward configuration's hacking profile; multi-seed evaluation with per-mode reporting should be standard.\n\nThe asymmetry---reliable observer, unreliable optimizer---may generalize to other perturbation-based diagnostics; ISR and structurally similar metrics should be used as post-hoc evaluation, with future work targeting gaming-robust rewards and broader logic types.\n",
      "numLines": 19,
      "startLine": 1,
      "totalLines": 19
    }
  }
}
```

</details>

---

### Assistant

_source line 83_

All references intact, all claims preserved. Let me do a final full compile to be sure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "23b35c10-e5af-4427-93c4-4c584a5ebeb3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XmrvUe9FGZmHs1m1RAYgRS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 993,
      "cache_read_input_tokens": 67712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 993
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 84_

<details open><summary>🔧 Tool call — Bash · `toolu_01PpP5KqZRYZxQv65FjbCgCV`</summary>

```json
{
  "command": "pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && bibtex main > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdftotext -f 9 -l 9 main.pdf - 2>/dev/null | grep -v '^[0-9]*$' | grep -v '^$' | head -5",
  "description": "Final full compile and verify page 9"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "9a3c28a6-2e91-4510-a111-67bf08920bc5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XmrvUe9FGZmHs1m1RAYgRS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 993,
      "cache_read_input_tokens": 67712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 993
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 85 · 2026-05-15T21:32:59.727Z_

<details><summary>↩ Tool result · `toolu_01PpP5KqZRYZxQv65FjbCgCV`</summary>

```text
References
Alexander Bondarenko, Denis Volk, Dmitrii
Volkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.
arXiv preprint arXiv:2502.13295.
DeepSeek AI. 2024. DeepSeek-Prover-V1.5: Harnessing Proof Assistant Feedback for Reinforcement Learning and Monte-Carlo Tree Search.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "6bbd72e4-f14d-4149-8d55-60fa7dd7b56a",
  "tool_use_result": {
    "stdout": "References\nAlexander Bondarenko, Denis Volk, Dmitrii\nVolkov, and Jeffrey Ladish. 2025. Demonstrating Specification Gaming in Reasoning Models.\narXiv preprint arXiv:2502.13295.\nDeepSeek AI. 2024. DeepSeek-Prover-V1.5: Harnessing Proof Assistant Feedback for Reinforcement Learning and Monte-Carlo Tree Search.",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 86_

Page 9 starts with References. Body is ≤ 8 pages.

**Summary of changes:**

**conclusion.tex** (net −10 lines):
- Opening paragraph: compressed from 5 sentences to 4, removed redundant numbers (β=0.3 std, random std, seed-dependent detail)
- "Classifier blind spots": shortened title, compressed from 5 sentences to 3 while preserving both examples and the cross-validation argument
- H7 dose-response paragraph: removed entirely from body (content moved to appendix)
- Hacking mode switching: compressed from 6 sentences to 2
- Closing sentence: unchanged

**experiments.tex §4.5** (net −4 lines):
- Post-table paragraph compressed from 8 sentences to 5; removed per-seed H7 breakdowns and specific H7a/H7b sample counts already visible in Table 2

**appendix.tex** (+3 lines):
- Added "H7 dose-response gradient" paragraph to Extended Discussion section with the full detail moved from the body

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "uuid": "e3298790-f343-42d1-bea9-e8e366d1c254",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KLd4H7FfrT4hmuuryapV5K",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 349,
      "cache_read_input_tokens": 68705,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 349
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Task result

_source line 87_

Page 9 starts with References. Body is ≤ 8 pages.

**Summary of changes:**

**conclusion.tex** (net −10 lines):
- Opening paragraph: compressed from 5 sentences to 4, removed redundant numbers (β=0.3 std, random std, seed-dependent detail)
- "Classifier blind spots": shortened title, compressed from 5 sentences to 3 while preserving both examples and the cross-validation argument
- H7 dose-response paragraph: removed entirely from body (content moved to appendix)
- Hacking mode switching: compressed from 6 sentences to 2
- Closing sentence: unchanged

**experiments.tex §4.5** (net −4 lines):
- Post-table paragraph compressed from 8 sentences to 5; removed per-seed H7 breakdowns and specific H7a/H7b sample counts already visible in Table 2

**appendix.tex** (+3 lines):
- Added "H7 dose-response gradient" paragraph to Extended Discussion section with the full detail moved from the body

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 265817,
  "duration_api_ms": 254063,
  "num_turns": 31,
  "stop_reason": "end_turn",
  "session_id": "49f83a2a-c3f4-496e-9669-97336554cdcf",
  "total_cost_usd": 1.49387375,
  "usage": {
    "input_tokens": 30,
    "cache_creation_input_tokens": 57213,
    "cache_read_input_tokens": 1617585,
    "output_tokens": 12952,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 57213,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 250,
        "cache_read_input_tokens": 68705,
        "cache_creation_input_tokens": 349,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 349
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 3465,
      "outputTokens": 17,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.00355,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 30,
      "outputTokens": 12952,
      "cacheReadInputTokens": 1617585,
      "cacheCreationInputTokens": 57213,
      "webSearchRequests": 0,
      "costUSD": 1.4903237499999997,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "440f3b3e-cfdd-4263-a663-bfc2ef0a4711"
}
```

</details>

---
