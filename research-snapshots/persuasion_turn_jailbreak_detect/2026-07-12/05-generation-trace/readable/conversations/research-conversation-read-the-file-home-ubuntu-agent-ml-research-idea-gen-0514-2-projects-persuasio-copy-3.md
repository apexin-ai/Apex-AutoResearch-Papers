# Research conversation: Read the file /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/exper

**DisPeD: A Controlled Study of Encoder Adaptation for Multi-Turn Jailbreak Detection (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 5
- **Recorded user turns:** 1
- **Tool calls:** 1
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-a2de1cb09b0ebea5c.jsonl`
- **Structured JSON:** [`1bcae9a17109f97b1430.json`](../../sessions/1b/1bcae9a17109f97b1430.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

5 recorded events

### User

_source line 1 · 2026-05-23T11:38:02.478Z_

Read the file /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/experiments.tex and find:
1. All mentions of ToxicChat, especially F1 scores and the "hierarchy reversal" claim
2. The "dual-pillar" or "two-axis" framing language
3. Any mentions of mixed-LLM results and AA=0.504 or "chance level"
4. The "4-20×" or "3-23×" variance claim
5. Lines containing "d < 0.1" or "|d| ≤ 0.14"

Report the exact line numbers and text for each finding. Be thorough — check every line.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "618938e8-d7d7-4898-8c14-94b0b5bade52",
  "agentId": "a2de1cb09b0ebea5c",
  "type": "user",
  "uuid": "8009444c-4052-491a-a2b9-acaf890e9f36",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/.claude/sessions/reviewer_d38db4c2",
  "sessionId": "1484cbee-ce0d-45bb-bfc6-f65fdcd0b20b",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "hidden-leaping-stallman"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-23T11:38:02.551Z_

```json
{
  "parentUuid": "8009444c-4052-491a-a2b9-acaf890e9f36",
  "isSidechain": true,
  "agentId": "a2de1cb09b0ebea5c",
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterWorktree",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskStop",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__check_figures_and_layout",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reviewer_post_to_director",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__tail_training_logs"
    ],
    "addedLines": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterWorktree",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskStop",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__check_figures_and_layout",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reviewer_post_to_director",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__tail_training_logs"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "fafaeb72-ead8-4dc7-9594-35bc80a50992",
  "timestamp": "2026-05-23T11:38:02.551Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/.claude/sessions/reviewer_d38db4c2",
  "sessionId": "1484cbee-ce0d-45bb-bfc6-f65fdcd0b20b",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "hidden-leaping-stallman"
}
```

---

### Tool call

_source line 3 · 2026-05-23T11:38:05.180Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Hrxvb8bonzyDUgGW7Rb1b8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fafaeb72-ead8-4dc7-9594-35bc80a50992",
  "isSidechain": true,
  "agentId": "a2de1cb09b0ebea5c",
  "requestId": "req_011CbKS9XFcgYrAjdWRSAYrt",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4ca74b7b-294e-460f-a656-77547f3a98ea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/.claude/sessions/reviewer_d38db4c2",
  "sessionId": "1484cbee-ce0d-45bb-bfc6-f65fdcd0b20b",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "hidden-leaping-stallman",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VGVNyZmsZYNMExvRJu3vHc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 24698,
      "cache_read_input_tokens": 0,
      "output_tokens": 94,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 24698
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 94,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 24698,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 24698,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-23T11:38:05.197Z_

<details><summary>↩ Tool result · `toolu_01Hrxvb8bonzyDUgGW7Rb1b8`</summary>

```text
1	% experiments.tex
2	
3	\section{Experiments}
4	
5	\paragraph{Terminology.}
6	\emph{Cross-attack OOD}: evaluation on attack families unseen during training; benign distribution remains IID throughout (OOD reflects attack-side shift only). $K$: prefix length (number of conversation turns retained). \emph{DAPT}: all Stage-1 adaptations; we extend \citet{gururangan2020dontstop} to supervised variants. \emph{Evidence hierarchy} (on synthetic data): vanilla $<$ MLM $<$ classification (Section~\ref{sec:decomposition}).
7	
8	\subsection{Setup}
9	
10	\paragraph{Data.}
11	All synthetic data is generated by Qwen3-8B~\citep{qwen3_2025}.
12	The IID dataset contains 250 Crescendo~\citep{russinovich2024crescendo} jailbreak and 250 topic-anchored benign conversations, split into training (350), validation (74), and test (76) sets with balanced class ratios (e.g., test = 38 jailbreak + 38 benign).
13	Stage~1 (DAPT) uses training + validation conversations; Stage~2 (BiGRU) trains on training, early-stops on validation, and evaluates on test.
14	OOD evaluation pairs attack-specific jailbreak conversations with the 38 IID-test benign conversations: 80 FITD~\citep{fitd2024} (non-discriminative; Section~\ref{sec:decomposition}) + 38 benign = 118 total, 80 Deceptive Delight (DD)~\citep{deceptivedelight2024} + 38 benign = 118 total, and 80 ActorAttack~\citep{ren2024actorattack} + 38 benign = 118 total.
15	No overlap exists in attack templates across families; benign is IID (same generation pipeline).
16	A paraphrased version of the IID test set (BERTScore 0.92, lexical overlap 0.20) serves as the adversarial robustness benchmark (Section~\ref{sec:perturbation}).
17	For human data validation, we use ToxicChat~\citep{lin2023toxicchat} (204 jailbreak + 204 benign from real LMSYS user interactions), entirely independent of Qwen3-8B generation.
18	
19	\paragraph{Models.}
20	Seven DeBERTa-v3 variants share the same Stage-2 pipeline and differ only in Stage-1 training (Section~\ref{sec:method}).
21	Our vanilla DeBERTa+BiGRU configuration is architecturally equivalent to DeepContext~\citep{deepcontext2026} and differs only in encoder choice (DeBERTa-v3-base vs.\ BERT); it serves as our primary baseline.
22	For cross-encoder validation, we replicate vanilla, MLM, and 9-class variants on RoBERTa-base~\citep{liu2019roberta} (Section~\ref{sec:cross_encoder}).
23	We also compare TF-IDF LR, LLM-as-judge (Appendix~\ref{sec:llm_judge}), and Llama Guard~3~8B~\citep{metallamaguard3_2024} (zero-shot; evaluates last-response safety given conversation context), which detects only 1.8\% of multi-turn jailbreaks (5/278 pooled recall; Table~\ref{tab:evidence_hierarchy}).
24	
25	\paragraph{Metrics.}
26	F1 for binary jailbreak detection at prefix $K$=2 and full conversations (full per-$K$ results in Appendix~\ref{sec:full_prefix}).
27	OOD results report 3-seed mean$\pm$std (seeds 42, 123, 456) for all variants.
28	For key pairwise comparisons, we report BCa bootstrap 95\% confidence intervals (10,000 resamples over individual predictions pooled across 3 seeds; this assumes cross-seed independence and is exploratory) and paired permutation tests (10,000 permutations). Seed-level F1 values (Table~\ref{tab:seed_level}, Appendix~\ref{app:seed_level}) confirm all pairwise conclusions hold at every seed.
29	All standard deviations are computed over 3 random seeds using the population formula ($n$ divisor); Bessel-corrected estimates ($n{-}1$ divisor) are $\approx$22\% larger but do not alter any significance conclusions.
30	
31	\paragraph{Training.}
32	Stage-1: learning rate $2 \times 10^{-5}$, batch 16, 4 epochs, MLM masking 15\%.
33	Stage-2: two-layer MLP, 20 epochs.
34	
35	%----------------------------------------------------------------------
36	\subsection{Cross-Attack Generalization}
37	
38	\begin{table}[t]
39	\centering
40	\small
41	\caption{Cross-attack generalization (F1) at $K$=2 and full conversation length. IID: Crescendo; OOD: Deceptive Delight (DD). 3-seed mean$\pm$std where noted; full per-$K$ in Appendix~\ref{sec:full_prefix}.}
42	\label{tab:main_results}
43	\begin{tabular}{@{}lcc|cc@{}}
44	\toprule
45	& \multicolumn{2}{c|}{\textit{IID (Cresc.)}} & \multicolumn{2}{c}{\textit{OOD (DD)}} \\
46	\textbf{Method} & $K$=2 & Full & $K$=2 & Full \\
47	\midrule
48	9-class & \textbf{1.000$\pm$.000} & \textbf{1.000$\pm$.000} & .981$\pm$.013 & \textbf{.997$\pm$.005} \\
49	MLM-only$^{\ddagger}$ & .974 & 1.000 & \textbf{.993$\pm$.009} & .914$\pm$.115 \\
50	Vanilla & .978$\pm$.016 & 1.000$\pm$.000 & .479$\pm$.038 & .312$\pm$.026 \\
51	TF-IDF LR$^{\S}$ & 1.000 & 1.000 & 1.000 & .961 \\
52	\bottomrule
53	\end{tabular}
54	\vspace{-2pt}
55	{\footnotesize $^{\ddagger}$MLM-only IID reports single seed (42); OOD reports 3-seed. $^{\S}$TF-IDF is deterministic (no std).}
56	\end{table}
57	
58	Vanilla encoders collapse under cross-attack transfer; domain-adapted variants recover near-perfect detection (Table~\ref{tab:main_results}, Figure~\ref{fig:cross_attack_bar}).
59	DD exhibits high lexical separability (TF-IDF F1\,=\,0.961); ActorAttack, where TF-IDF collapses to 0.261, serves as the primary stress test for beyond-lexical generalization.
60	On OOD DD, vanilla DeBERTa collapses to F1 = 0.312$\pm$0.026 and worsens with more turns (0.628 at $K$=1 to 0.312 at Full), consistent with attack turns occupying ``benign'' embedding regions~\citep{bullwinkel2025repeng}.
61	MLM achieves mean F1 $\geq$ 0.97 at all prefixes $K \leq 5$ without any classification labels; domain exposure alone is sufficient.
62	At full conversation length, MLM drops to 0.914$\pm$0.115 (seed 456 recall = 0.64), while the 9-class model maintains 0.997$\pm$0.005.
63	TF-IDF LR reaches F1 = 0.961 on full DD; DD is fully solvable by lexical features.
64	On strategy-diverse ActorAttack, TF-IDF collapses to F1 = 0.261 (precision = 1.0, recall = 0.15), while 9-class maintains 0.972$\pm$0.026: a 71\,pp gap. Lexical methods cannot capture multi-persona role-playing attack structure. This establishes a ``difficulty threshold'' for lexical methods parallel to that of vanilla encoders: both succeed on DD and fail on ActorAttack (Section~\ref{sec:limitations}).
65	Bootstrap CIs confirm non-overlapping intervals (9-class DD Full [0.943, 1.000] vs.\ vanilla [0.202, 0.341]; all permutation $p < 0.0001$). FITD is non-discriminative (all variants F1\,$\geq$\,0.990; Section~\ref{sec:limitations}).
66	
67	\begin{figure}[t]
68	\centering
69	\includegraphics[width=\columnwidth]{figures/paper/fig2_cross_attack_bar.pdf}
70	\caption{Cross-attack overview (F1 at full conversation length). DisPeD (9-class) maintains near-perfect detection across IID and both OOD families; vanilla collapses on OOD DD. FITD is non-discriminative for all methods.}
71	\label{fig:cross_attack_bar}
72	\end{figure}
73	
74	Prefix-length analysis (Appendix Table~\ref{tab:full_prefix}) shows vanilla F1 drops from 0.628 at $K$=1 to 0.312 at full length. MLM achieves strong early detection ($K$=2: 0.993) but is unstable at full length (0.914$\pm$0.115); the 9-class model maintains 0.972--0.997 across all prefixes. Classification supervision thus stabilizes against distributional drift.
75	
76	%----------------------------------------------------------------------
77	\subsection{Decomposing the Detection Mechanism}
78	\label{sec:decomposition}
79	
80	\begin{table}[t]
81	\centering
82	\small
83	\caption{Evidence hierarchy on OOD DD and ActorAttack (AA) at full conversation length (3-seed mean$\pm$std where available). OOD F1 reflects attack-side generalization only; benign samples are IID from training distribution (benign-side shift evaluated in Section~\ref{sec:benign_shift}). Bold indicates best per column. All variants share the same Stage-2 pipeline. Full per-prefix results in Appendix Tables~\ref{tab:full_prefix} and~\ref{tab:actorattack_full}.}
84	\label{tab:evidence_hierarchy}
85	\resizebox{\columnwidth}{!}{%
86	\begin{tabular}{@{}lccc@{}}
87	\toprule
88	\textbf{Variant} & DD-Full & AA-Full & DD-$K$=2 \\
89	\midrule
90	9-class (full model) & .997$\pm$.005 & .972$\pm$.026 & .981$\pm$.013 \\
91	Binary (2-class) & \textbf{1.000$\pm$.000} & \textbf{.990$\pm$.008} & .994$\pm$.009 \\
92	Scrambled labels & .997$\pm$.005 & .951$\pm$.043 & .981$\pm$.026 \\
93	MLM-only$^{\ddagger}$ (no labels) & .914$\pm$.115 & .893$\pm$.080 & .993$\pm$.009 \\
94	Mean pooling$^{*}$ & .991$\pm$.013 & .962$\pm$.015 & \textbf{1.000} \\
95	\midrule
96	Topic classif.\ (5-class) & .541$\pm$.207 & .625$\pm$.141 & .593$\pm$.166 \\
97	Wikipedia MLM & .904$\pm$.115 & .686$\pm$.297 & .911$\pm$.073 \\
98	Vanilla DeBERTa & .312$\pm$.026 & .258$\pm$.000 & .479$\pm$.038 \\
99	TF-IDF LR$^{\dagger}$ & .961 & .261 & \textbf{1.000} \\
100	Llama Guard~3$^{\P}$ & .025 & .000 & -- \\
101	\bottomrule
102	\end{tabular}}
103	\vspace{-2pt}
104	{\footnotesize $^{*}$9-class encoder with mean pooling replacing BiGRU. $^{\dagger}$Deterministic (no std). $^{\ddagger}$MLM-only IID (Table~\ref{tab:main_results}) is single-seed (42); all OOD values are 3-seed. $^{\P}$Zero-shot; no domain training.}
105	\end{table}
106	
107	A clear \emph{evidence hierarchy} emerges across seven variants (Table~\ref{tab:evidence_hierarchy}), ordered by OOD detection at full conversation length on DD:
108	
109	\noindent\hspace{0.5em}{\small vanilla (0.312$\pm$0.026) $<$ topic (0.541$\pm$0.207) $\ll$ wiki-MLM (0.904$\pm$0.115) $\approx$ jb-MLM (0.914$\pm$0.115) $<$ scrambled (0.997$\pm$0.005) $=$ 9-class (0.997$\pm$0.005) $\approx$ binary (1.000$\pm$0.000)}
110	\vspace{1pt}
111	
112	\paragraph{Domain exposure is the primary mechanism.}
113	MLM bridges $\sim$60\,pp from vanilla (0.312$\pm$0.026 $\to$ 0.914$\pm$0.115) without labels; this supports the DAPT interpretation~\citep{gururangan2020dontstop}. TF-IDF collapse on ActorAttack (0.261 vs.\ 9-class 0.972) confirms that domain-adapted representations capture features beyond lexical overlap.
114	All three classification-supervised variants converge to equivalent detection (F1 = 0.997--1.000); McNemar's ($p > 0.13$) and paired permutation tests ($p \geq 0.40$) provide descriptive evidence suggesting equivalence. Extended to $n$\,=\,10 seeds, TOST (margin = 5\,pp) confirms equivalence on DD ($p < 10^{-8}$, $d$\,=\,$-$0.14; Table~\ref{tab:tost_sensitivity}) and FITD ($p < 10^{-8}$, $d \approx 0$). An observed difficulty gradient emerges: template attacks show full equivalence ($d < 0.1$), while strategy-diverse ActorAttack retains moderate label sensitivity ($d$\,=\,0.44, $p$\,=\,0.183). Label quality and granularity are descriptively non-factors for detection.
115	Classification supervision is associated with 3--23$\times$ lower cross-seed variance over MLM on synthetic OOD (std 0.005 vs.\ 0.115 on DD; observed range across 3 seeds; formal variance ratio tests are not applicable at $n$=3; cross-seed ensemble yields marginal additional gains, Appendix~\ref{app:ensemble}). This stability benefit does not transfer to human-authored data, where classification-supervised variants exhibit the highest variance and pure MLM the lowest (Section~\ref{sec:human_data}).
116	Appendix~\ref{app:tsne} provides t-SNE visualizations confirming that domain-adapted variants produce tighter, more separable embedding clusters than the vanilla baseline.
117	
118	\paragraph{Domain specificity is marginal at full length but meaningful for early detection.}
119	Wikipedia MLM (0.904$\pm$0.115) nearly matches jailbreak-domain MLM at full length (1\,pp gap), though jailbreak-domain text provides an 8\,pp advantage at early prefixes ($K$=2: 0.993 vs.\ 0.911).
120	Perturbation analysis (Section~\ref{sec:perturbation}) reveals a sharper domain specificity effect: Wikipedia MLM degrades by $\sim$12\,pp under adversarial paraphrasing while jailbreak-domain MLM degrades by only 2.6\,pp.
121	
122	\paragraph{Misaligned supervision destabilizes generalization.}
123	Topic classification yields DD-Full F1 = 0.541$\pm$0.207; seed 123 falls \emph{below} vanilla (0.252 vs.\ 0.312). Despite using the same jailbreak-domain training data, topic classification performs worse than Wikipedia MLM (0.904$\pm$0.115), which uses out-of-domain text with no labels. A misaligned objective forces the encoder to allocate capacity to irrelevant features and actively destabilizes representations that MLM would preserve.
124	
125	\paragraph{Evidence hierarchy on strategy-diverse attacks.}
126	ActorAttack~\citep{ren2024actorattack} uses multi-persona steering across longer conversation structures and provides a more challenging OOD benchmark than DD.
127	The evidence hierarchy at full conversation length is:
128	
129	\noindent\hspace{0.5em}{\small TF-IDF (0.261) $\approx$ vanilla (0.258$\pm$0.000) $<$ topic (0.625$\pm$0.141) $<$ wiki-MLM (0.686$\pm$0.297) $<$ jb-MLM (0.893$\pm$0.080) $<$ scrambled (0.951$\pm$0.043) $\approx$ 9-class (0.972$\pm$0.026) $\approx$ binary (0.990$\pm$0.008)}
130	\vspace{1pt}
131	
132	TF-IDF collapses from 0.961 (DD) to 0.261 (ActorAttack, precision = 1.0, recall = 0.15). This gap shows that domain-adapted representations capture features beyond bag-of-words.
133	All classification-supervised variants converge to equivalent performance (0.951--0.990, max gap 3.9\,pp); this extends the DD finding. DAPT provides $\sim$71\,pp over both vanilla (0.258) and TF-IDF (0.261). Full per-prefix results and per-prefix error analysis in Appendix~\ref{sec:actorattack_full} and~\ref{app:aa_error}.
134	
135	\paragraph{Temporal modeling.}
136	Mean pooling matches BiGRU on both DD and ActorAttack (F1 gap $\leq$ 1\,pp, overlapping CIs; Appendix~\ref{app:temporal}).
137	Turn-order shuffling produces negligible change ($|\Delta| < 1$\,pp) across both DeBERTa-v3-base 9-class (DD $\Delta$\,=\,0.000, AA $\Delta$\,=\,$-$0.009, IID $\Delta$\,=\,0.000) and RoBERTa-large 9-class (DD $\Delta$\,=\,+0.001, AA $\Delta$\,=\,$-$0.007, IID $\Delta$\,=\,0.000); detection relies on per-turn representations rather than sequential patterns.
138	
139	%----------------------------------------------------------------------
140	\subsection{Cross-Encoder Validation}
141	\label{sec:cross_encoder}
142	
143	\begin{table}[t]
144	\centering
145	\small
146	\caption{Cross-encoder comparison on OOD Full (3-seed mean$\pm$std). DD = Deceptive Delight, AA = ActorAttack. Bold indicates best per encoder group.}
147	\label{tab:cross_encoder}
148	\resizebox{\columnwidth}{!}{%
149	\begin{tabular}{@{}lcc@{}}
150	\toprule
151	\textbf{Variant} & DD & AA \\
152	\midrule
153	\multicolumn{3}{l}{\textit{DeBERTa-v3-base (184M)}} \\[2pt]
154	Vanilla & .312$\pm$.026 & .258$\pm$.000 \\
155	MLM & .914$\pm$.115 & .893$\pm$.080 \\
156	9-class & \textbf{.997$\pm$.005} & \textbf{.972$\pm$.026} \\
157	\midrule
158	\multicolumn{3}{l}{\textit{RoBERTa-base (125M)}} \\[2pt]
159	Vanilla & .981$\pm$.026 & .466$\pm$.163 \\
160	MLM & .987$\pm$.018 & .730$\pm$.201 \\
161	9-class & \textbf{.994$\pm$.005} & \textbf{.939$\pm$.046} \\
162	\midrule
163	\multicolumn{3}{l}{\textit{RoBERTa-large (355M)}} \\[2pt]
164	Vanilla & .927$\pm$.036 & \textbf{1.000$\pm$.000} \\
165	MLM & .884$\pm$.065 & .874$\pm$.014 \\
166	9-class & \textbf{.987$\pm$.004} & .946$\pm$.057 \\
167	\bottomrule
168	\end{tabular}}
169	\end{table}
170	
171	To test whether the evidence hierarchy depends on encoder choice, we replicate vanilla, MLM, and 9-class on RoBERTa-base~\citep{liu2019roberta} (Table~\ref{tab:cross_encoder}).
172	On DD, RoBERTa-base vanilla already achieves 0.981$\pm$0.026 (vs.\ DeBERTa 0.312$\pm$0.026), so DAPT adds only 1.3\,pp. ActorAttack exposes this as DD's simplicity: RoBERTa-base vanilla collapses to 0.466$\pm$0.163, a 51.5\,pp drop, while domain-adapted variants recover (9-class: 0.939$\pm$0.046).
173	
174	RoBERTa-large (355M) reveals a capacity-DAPT interaction: its effect on ActorAttack reverses (vanilla 1.000 vs.\ 9-class 0.946), while smaller encoders require DAPT to bridge 47--71\,pp. All continued pretraining reduces ActorAttack performance for the largest encoder via representation drift (Table~\ref{tab:roberta_large_lr}), though classification DAPT partially compensates on DD (+6\,pp).
175	
176	Three encoder scales thus reveal a scale-dependent pattern for the \emph{difficulty threshold}: DeBERTa-v3-base requires adaptation for all attacks, RoBERTa-base only for complex ones, and RoBERTa-large for none (Section~\ref{sec:discussion}).
177	Classification supervision provides a consistent stability benefit across both base encoders (cross-seed variance: 0.005--0.046 vs.\ 0.026--0.201).
178	A BERT-base-uncased proxy (110M, matching DeepContext's encoder family) without adaptation achieves DD\,=\,0.318$\pm$0.031 and AA\,=\,0.275$\pm$0.027, comparable to vanilla DeBERTa-v3 (Appendix~\ref{app:bert_proxy}); cross-attack generalization is driven by DAPT rather than encoder architecture.
179	
180	%----------------------------------------------------------------------
181	\subsection{Mixed-LLM Training}
182	
183	All preceding experiments use single-source (Qwen3-8B) data. To test whether the evidence hierarchy transfers when training data mixes LLM sources, we train on 250 Qwen + 250 Llama-3.1-8B conversations (Table~\ref{tab:mixed_llm}).
184	Classification-based DAPT is the only variant that substantially outperforms vanilla: 9-class achieves DD OOD F1\,=\,0.818$\pm$0.096 (+53\,pp over vanilla 0.291$\pm$0.065), while MLM drops to vanilla level (0.289$\pm$0.101). On strategy-diverse ActorAttack, the advantage narrows (9-class 0.504$\pm$0.107 vs.\ vanilla 0.389$\pm$0.073, +11.5\,pp) with high seed variance; limited per-source volume (250 per LLM) likely constrains generalization to complex attacks. DD and FITD thus primarily validate the baseline rather than the method; ActorAttack, where lexical methods collapse (TF-IDF F1\,=\,0.261) and vanilla encoders fail (F1\,$\leq$\,0.389 across conditions), provides the discriminative evaluation axis.
185	Mixed-LLM training confirms that classification supervision generalizes across LLM sources where unsupervised pretraining does not; full results in Appendix~\ref{app:mixed_llm}.
186	
187	%----------------------------------------------------------------------
188	\subsection{Human Data Validation}
189	\label{sec:human_data}
190	
191	Since both training and OOD evaluation data are Qwen3-8B-generated, we validate on ToxicChat~\citep{lin2023toxicchat} (204 human-written jailbreak attempts + 204 benign conversations from real LMSYS interactions).
192	
193	\begin{table}[t]
194	\centering
195	\small
196	\caption{Human data validation on ToxicChat~\citep{lin2023toxicchat} (macro F1, 3-seed mean$\pm$std). Bold indicates best. Single-turn data from real LMSYS user interactions, independent of Qwen3-8B.}
197	\label{tab:human_data}
198	\begin{tabular}{@{}lc@{}}
199	\toprule
200	\textbf{Variant} & Macro F1 \\
201	\midrule
202	JB-MLM & \textbf{.837$\pm$.013} \\
203	Wiki-MLM & .791$\pm$.093 \\
204	Binary & .705$\pm$.072 \\
205	Scrambled & .616$\pm$.056 \\
206	9-class & .596$\pm$.087 \\
207	Topic & .496$\pm$.042 \\
208	\midrule
209	Vanilla & .413$\pm$.021 \\
210	\bottomrule
211	\end{tabular}
212	\end{table}
213	
214	All DAPT variants exceed vanilla by 18--42\,pp (Table~\ref{tab:human_data}): the adapted-vs.-vanilla gap is not a Qwen3-8B generation artifact, and domain exposure on synthetic jailbreak text transfers to human-written attacks.
215	
216	The ordering reverses: JB-MLM leads (0.837$\pm$0.013) while 9-class ranks lower (0.596$\pm$0.087; $p < 0.001$, non-overlapping CIs). ToxicChat is single-turn, so the classification head provides no advantage; validating the multi-turn hierarchy requires multi-turn human data.
217	
218	%----------------------------------------------------------------------
219	\subsection{Perturbation Analysis}
220	\label{sec:perturbation}
221	
222	Under adversarial paraphrasing (BERTScore 0.92), classification-supervised variants achieve zero degradation on IID and OOD DD (Table~\ref{tab:ood_perturbation}) while non-adapted models degrade by $\sim$12\,pp ($p < 0.001$); on ActorAttack, DAPT variants degrade ($\Delta$\,=\,$-$20.4\,pp) but maintain 52\,pp over vanilla (Appendix~\ref{sec:perturbation_full}).
223	
224	%----------------------------------------------------------------------
225	\subsection{Strategy Trajectory Analysis}
226	\label{sec:strategy}
227	
228	The 9-class taxonomy provides interpretable characterization of known attacks ($\kappa$=0.78, $n$=50; Appendix~\ref{sec:strategy_full}) but degrades to near-random on OOD ($\kappa$=0.126; Appendix~\ref{app:strategy_pred}). Its value is twofold: as ablation infrastructure (scrambled labels produce equivalent detection) and as an interpretability tool for known attacks; detection operates through domain-adapted \texttt{[CLS]} embeddings, not strategy accuracy.
229	
230	%----------------------------------------------------------------------
231	\subsection{Benign Distribution Shift}
232	\label{sec:benign_shift}
233	
234	All preceding OOD results use IID benign data. On WildChat benign conversations, 9-class FPR rises to 68.1\%; cross-LLM error decomposition confirms false positives on unfamiliar benign text drive the collapse (Appendix~\ref{app:wildchat_fpr},~\ref{app:cross_llm}).
235	Few-shot benign-only adaptation resolves this without target-domain attack data: 10 WildChat conversations reduce FPR to 0\%, and 25 OASST2 conversations reduce FPR to 1.0\% (Appendix~\ref{app:wildchat_fpr},~\ref{app:oasst2}); dual-OOD F1 drops 12--14\,pp without adaptation but recovers within 0.3\,pp (Appendix~\ref{app:dual_ood}).
236	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4ca74b7b-294e-460f-a656-77547f3a98ea",
  "isSidechain": true,
  "promptId": "618938e8-d7d7-4898-8c14-94b0b5bade52",
  "agentId": "a2de1cb09b0ebea5c",
  "type": "user",
  "uuid": "c8602639-0e8f-4f3f-8a71-c839d2dc5012",
  "sourceToolAssistantUUID": "4ca74b7b-294e-460f-a656-77547f3a98ea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/.claude/sessions/reviewer_d38db4c2",
  "sessionId": "1484cbee-ce0d-45bb-bfc6-f65fdcd0b20b",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "hidden-leaping-stallman"
}
```

</details>

---

### Assistant

_source line 5 · 2026-05-23T11:38:44.617Z_

The file is 236 lines. Here are all findings organized by category:

---

**1. ToxicChat mentions, F1 scores, and "hierarchy reversal" claim**

- **Line 17**: `For human data validation, we use ToxicChat~\citep{lin2023toxicchat} (204 jailbreak + 204 benign from real LMSYS user interactions), entirely independent of Qwen3-8B generation.`
- **Line 191**: `Since both training and OOD evaluation data are Qwen3-8B-generated, we validate on ToxicChat~\citep{lin2023toxicchat} (204 human-written jailbreak attempts + 204 benign conversations from real LMSYS interactions).`
- **Line 196**: `\caption{Human data validation on ToxicChat~\citep{lin2023toxicchat} (macro F1, 3-seed mean$\pm$std). Bold indicates best. Single-turn data from real LMSYS user interactions, independent of Qwen3-8B.}`
- **Lines 202-210** (Table body): JB-MLM .837±.013, Wiki-MLM .791±.093, Binary .705±.072, Scrambled .616±.056, 9-class .596±.087, Topic .496±.042, Vanilla .413±.021
- **Line 214**: `All DAPT variants exceed vanilla by 18--42\,pp (Table~\ref{tab:human_data}): the adapted-vs.-vanilla gap is not a Qwen3-8B generation artifact, and domain exposure on synthetic jailbreak text transfers to human-written attacks.`
- **Line 216** (hierarchy reversal claim): `The ordering reverses: JB-MLM leads (0.837$\pm$0.013) while 9-class ranks lower (0.596$\pm$0.087; $p < 0.001$, non-overlapping CIs). ToxicChat is single-turn, so the classification head provides no advantage; validating the multi-turn hierarchy requires multi-turn human data.`

---

**2. "Dual-pillar" or "two-axis" framing language**

**No occurrences found.** Neither "dual-pillar" nor "two-axis" nor "dual pillar" nor "two axis" appear anywhere in the file.

---

**3. Mixed-LLM results and AA=0.504 / "chance level"**

- **Line 184**: `Classification-based DAPT is the only variant that substantially outperforms vanilla: 9-class achieves DD OOD F1\,=\,0.818$\pm$0.096 (+53\,pp over vanilla 0.291$\pm$0.065), while MLM drops to vanilla level (0.289$\pm$0.101). On strategy-diverse ActorAttack, the advantage narrows (9-class 0.504$\pm$0.107 vs.\ vanilla 0.389$\pm$0.073, +11.5\,pp) with high seed variance; limited per-source volume (250 per LLM) likely constrains generalization to complex attacks. DD and FITD thus primarily validate the baseline rather than the method; ActorAttack, where lexical methods collapse (TF-IDF F1\,=\,0.261) and vanilla encoders fail (F1\,$\leq$\,0.389 across conditions), provides the discriminative evaluation axis.`

The value **AA=0.504±0.107** appears on line 184. **"Chance level" does not appear** anywhere in the file.

---

**4. "4-20x" or "3-23x" variance claim**

- **Line 115**: `Classification supervision is associated with 3--23$\times$ lower cross-seed variance over MLM on synthetic OOD (std 0.005 vs.\ 0.115 on DD; observed range across 3 seeds; formal variance ratio tests are not applicable at $n$=3; cross-seed ensemble yields marginal additional gains, Appendix~\ref{app:ensemble}). This stability benefit does not transfer to human-authored data, where classification-supervised variants exhibit the highest variance and pure MLM the lowest (Section~\ref{sec:human_data}).`

The claim is **"3--23x"** (line 115). **"4-20x" does not appear** in the file.

---

**5. Lines containing "d < 0.1" or "|d| <= 0.14"**

- **Line 114**: `...Extended to $n$\,=\,10 seeds, TOST (margin = 5\,pp) confirms equivalence on DD ($p < 10^{-8}$, $d$\,=\,$-$0.14; Table~\ref{tab:tost_sensitivity}) and FITD ($p < 10^{-8}$, $d \approx 0$). An observed difficulty gradient emerges: template attacks show full equivalence ($d < 0.1$), while strategy-diverse ActorAttack retains moderate label sensitivity ($d$\,=\,0.44, $p$\,=\,0.183).`

Both `$d$\,=\,$-$0.14` (i.e., d = -0.14, which corresponds to |d| = 0.14) and `$d < 0.1$` appear on **line 114**. The exact text for the two relevant fragments:
- `$d$\,=\,$-$0.14` — the effect size for DD equivalence
- `$d < 0.1$` — template attacks showing full equivalence

---

**Summary of absent terms:**
- "dual-pillar" / "two-axis" — not found
- "chance level" — not found
- "4-20x" — not found (only "3--23x" on line 115)

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c8602639-0e8f-4f3f-8a71-c839d2dc5012",
  "isSidechain": true,
  "agentId": "a2de1cb09b0ebea5c",
  "requestId": "req_011CbKS9ircrHjLedPtzF2nG",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "68b3e9c0-3a64-47df-b683-976de409b4dc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/.claude/sessions/reviewer_d38db4c2",
  "sessionId": "1484cbee-ce0d-45bb-bfc6-f65fdcd0b20b",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "hidden-leaping-stallman",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HXcZEJm1jqJPa8fehqow5D",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8712,
      "cache_read_input_tokens": 24698,
      "output_tokens": 1430,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 8712
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1430,
          "cache_read_input_tokens": 24698,
          "cache_creation_input_tokens": 8712,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 8712,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---
