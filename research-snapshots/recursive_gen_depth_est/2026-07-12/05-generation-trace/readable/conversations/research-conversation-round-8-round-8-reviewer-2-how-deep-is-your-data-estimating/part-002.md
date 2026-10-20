# Research conversation: [Round 8 审稿请求]: ## Round 8 ���稿任务 �� Reviewer 2（新颖性 + 写作完整性 + 引用覆盖） ### 论文信息 - **标题**: How Deep Is Your Data? Estimating — Part 2 of 2

**How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints (July export snapshot)** · Conversation logs

[← Part 1](part-001.md) · [Transcript overview](../research-conversation-round-8-round-8-reviewer-2-how-deep-is-your-data-estimating.md) · [Structured JSON](../../../sessions/9d/9d17720d6a0c1b842133.json)

## Round 5

### Tool result

_source line 112 · 2026-05-17T08:47:06.607Z_

<details><summary>↩ Tool result · `toolu_01JuZM8zN2RgH3927Yho8Mn6`</summary>

```text
1	\section{Additional Results}
2	\label{app:additional}
3	
4	\subsection{Top-$k$ Feature Trajectories}
5	\label{app:topk_trajectories}
6	
7	Figure~\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\tau{=}0.9$) sampling.
8	Top-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \S\ref{sec:atlas:strategy}.
9	Concretely, the d0$\to$d1 drop in \textsc{p90\_ppl} under top-$k$ is 78\% (vs.\ 87\% for nucleus), and the d2$\to$d3 reduction is 31\% (vs.\ 39\% for nucleus).
10	Despite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.
11	
12	\subsection{Permutation Importance}
13	\label{app:permutation}
14	
15	To verify that the Gini-based importance rankings in \S\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.
16	The top-2 features are stable across measures: \textsc{p90\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \textsc{var\_surprisal} in 8/9 (vs.\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \textsc{p75\_ppl} displaces \textsc{var\_surprisal} to rank 3).
17	Kendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).
18	Pairwise Spearman correlations are: SHAP--Gini $\rho{=}0.93$, SHAP--permutation $\rho{=}0.84$, Gini--permutation $\rho{=}0.76$.
19	Per-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.
20	
21	\subsection{Per-Class Recall}
22	\label{app:per_class}
23	
24	Table~\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).
25	Depth~0 recall exceeds 98\% uniformly.
26	Among generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.
27	
28	\begin{table}[h]
29	\centering
30	\small
31	\caption{Per-class recall (\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}
32	\label{tab:per_class_recall}
33	\begin{tabular}{@{}lcccc@{}}
34	\toprule
35	Cell & d0 & d1 & d2 & d3 \\
36	\midrule
37	Pythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\
38	Pythia, $\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\
39	Pythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\
40	OLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\
41	OLMo, $\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\
42	OLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\
43	GPT-2~XL, nuc.     & 99.2 & 85.9 & \textbf{73.3} & 77.5 \\
44	GPT-2~XL, $\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\
45	GPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\
46	\bottomrule
47	\end{tabular}
48	\end{table}
49	
50	\subsection{DCOL Iteration Details}
51	\label{app:dcol_iterations}
52	
53	Table~\ref{tab:dcol_iterations} summarizes all six DCOL iterations.
54	DeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.
55	
56	\begin{table}[h]
57	\centering
58	\small
59	\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\%.}
60	\label{tab:dcol_iterations}
61	\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}
62	\toprule
63	Ver. & Backbone & Config & Outcome \\
64	\midrule
65	v1 & DeBERTa & FT, m\_lr $10^{-3}$ & Embed.\ collapse (31.5\%) \\
66	v2 & DeBERTa & FT, m\_lr $10^{-4}$ & OOM \\
67	v3 & DeBERTa & FT, m\_lr $10^{-4}$ & Forgetting + OOM \\
68	v4 & DeBERTa & LoRA, m\_lr $10^{-3}$ & Embed.\ collapse \\
69	v5 & DeBERTa & LoRA, m\_lr $10^{-4}$ & NaN gradients \\
70	v6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\% ($-$13.7pp) \\
71	\bottomrule
72	\end{tabular}
73	\end{table}
74	
75	\subsection{Zero-Shot LLM Prompt Template}
76	\label{app:zeroshot_prompt}
77	
78	Both DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.
79	The system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).
80	The user message presents the passage (truncated to ${\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.
81	No in-context examples are provided.
82	
83	\begin{quote}
84	\small
85	\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\ldots]''
86	
87	\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \{text\}. Respond with ONLY a JSON object: \{\texttt{"depth"}: $\langle$int 0--3$\rangle$, \texttt{"confidence"}: $\langle$float 0--1$\rangle$, \texttt{"reasoning"}: $\langle$str$\rangle$\}''
88	\end{quote}
89	
90	\subsection{Temperature Robustness}
91	\label{app:multi_tau}
92	
93	The cross-strategy results in \S\ref{sec:gen:crossstrategy} use a single temperature ($\tau{=}0.9$).
94	To test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\tau \in \{0.5, 0.7, 0.9, 1.1\}$ on Pythia-1.4B.
95	
96	\paragraph{Within-$\tau$ robustness.}
97	For $\tau \in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\% to 77.3\% (Table~\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.
98	The same top-5 features (\texttt{var\_surprisal}, \texttt{p90\_ppl}, \texttt{mean\_ppl}, \texttt{mean\_surprisal}, \texttt{p75\_ppl}) dominate across all $\tau$ values with only minor rank-order variation.
99	
100	\paragraph{Collapse at $\tau{=}1.1$: memorization as prerequisite.}
101	At $\tau{=}1.1$, 4-class accuracy drops to 57.2\% and d1v2 AUC falls to 0.528.
102	Training loss reveals the mechanism: at low temperature ($\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \to 0.42 \to 0.16$), indicating rapid memorization of the model's own output.
103	At $\tau{=}1.1$, loss remains nearly flat ($2.27 \to 1.91 \to 1.85$); high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.
104	This establishes \emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.
105	
106	\paragraph{Cross-$\tau$ non-transferability.}
107	Leave-one-$\tau$-out transfer yields mean accuracy of 46.7\% with mean d1v2 AUC of 0.319 (Table~\ref{tab:multi_tau_cross}), worse than cross-strategy transfer (59.1\%; \S\ref{sec:gen:crossstrategy}).
108	Holdout $\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.
109	This extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific, reinforcing the need for strategy-conditioned classifiers.
110	
111	\paragraph{Ecological validity.}
112	On WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\geq$98.5\% d0 accuracy despite $+$621\% domain shift in mean perplexity, partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.
113	On noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.
114	
115	\begin{table}[h]
116	\centering
117	\small
118	\caption{Within-$\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\ depth $j$.}
119	\label{tab:multi_tau_within}
120	\begin{tabular}{@{}lcccc@{}}
121	\toprule
122	$\tau$ & 4-class acc (\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\
123	\midrule
124	0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\
125	0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\
126	0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\
127	1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\
128	\bottomrule
129	\end{tabular}
130	\end{table}
131	
132	\begin{table}[h]
133	\centering
134	\small
135	\caption{Cross-$\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}
136	\label{tab:multi_tau_cross}
137	\begin{tabular}{@{}lcc@{}}
138	\toprule
139	Holdout & Acc (\%) & d1v2 AUC \\
140	\midrule
141	$\tau{=}0.5$ & 52.2 & 0.176 \\
142	$\tau{=}0.7$ & 41.0 & 0.299 \\
143	$\tau{=}0.9$ & 46.4 & 0.277 \\
144	$\tau{=}1.1$ & 47.1 & 0.525 \\
145	\midrule
146	Mean & 46.7 & 0.319 \\
147	\bottomrule
148	\end{tabular}
149	\end{table}
150	
151	\subsection{Feature Overlap Analysis}
152	\label{app:feature_overlap}
153	
154	We probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.
155	PLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics; \textsc{var\_surprisal} and \textsc{p90\_ppl} yield negative $R^2$ under linear probing, indicating these features are not linearly accessible in the pretrained representation space.
156	This confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\S\ref{app:e2e}) stems from complementary, not redundant, representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.
157	
158	\subsection{End-to-End Learning}
159	\label{app:e2e}
160	
161	DeBERTa-v3-base \cite{he2021_deberta_v3} and RoBERTa-base \cite{liu2019_roberta} finetuned end-to-end achieve 58.3\% ($\pm$4.7\%) and 59.5\% ($\pm$3.2\%) respectively, lagging the RF baseline (78.2\%) by 19.9pp and 18.7pp.
162	The 1.2pp inter-backbone gap rules out architecture bias; Table~\ref{tab:e2e_detail} shows both backbones share the same failure mode (high d0 F1, $>$0.94, but collapsed d1/d2 performance, F1 $\leq$ 0.42), while RF achieves 0.596 d2 recall, a $>$2$\times$ advantage at the hardest depth class.
163	
164	\begin{table}[h]
165	\centering
166	\small
167	\caption{Per-class performance for end-to-end PLM classifiers vs.\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}
168	\label{tab:e2e_detail}
169	\begin{tabular}{@{}lccccc@{}}
170	\toprule
171	Method & Acc (\%) & d0 & d1 & d2 & d3 \\
172	\midrule
173	DeBERTa-v3 & 58.3\,$\pm$\,4.7 & .947 & .378 & .247 & .656 \\
174	RoBERTa-base & 59.5\,$\pm$\,3.2 & .958 & .416 & .261 & .647 \\
175	\midrule
176	RF (19 feat.) & 78.2 & --- & --- & .596$^\dagger$ & --- \\
177	\bottomrule
178	\multicolumn{6}{@{}l}{\footnotesize $^\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}
179	\end{tabular}
180	\end{table}
181	
182	\paragraph{Feature space divergence.}
183	SHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\% of RF's total contribution.
184	Three independent importance measures (SHAP, Gini, and permutation) show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \S\ref{app:permutation}), with \texttt{p90\_ppl} appearing in the SHAP top-2 in 9/9 cells and \texttt{var\_surprisal} in 8/9.
185	Linear probing of PLM [CLS] representations yields negative $R^2$ for both \texttt{var\_surprisal} and \texttt{p90\_ppl} (\S\ref{app:feature_overlap}), indicating that pretrained representations lack the linear structure needed to recover perplexity tail statistics, a systematic representational gap rather than a backbone-specific artifact.
186	
187	DCOL \cite{cloc2025} reached 64.5\% (\S\ref{app:dcol_iterations}); all end-to-end approaches (58--65\%) underperform feature-based methods, suggesting depth estimation benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.
188	This comparison is bounded by backbone scale ($\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.
189	
190	\subsection{Domain Bias Analysis}
191	\label{app:domain_bias}
192	
193	To assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.
194	
195	\paragraph{Methodological note.}
196	An initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\%, seed-group prediction 20.8\%).
197	We discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.
198	The results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.
199	
200	\paragraph{Sub-A: Standard CV.}
201	Five-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\% to 82\% across the 9 atlas cells (up to 2.5$\times$ above the 33.3\% chance level), confirming that depth signal is the dominant classification factor.
202	
203	\paragraph{Sub-B: LOGO evaluation.}
204	We assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.
205	LOGO mean accuracy is 72.1\% (range 59.5--81.6\%), matching standard CV (72.0\%) within noise (before fix: 64.0\%, reflecting the depth--group confound).
206	Per-cell fold standard deviations range from 0.4pp to 1.4pp, indicating that cross-group generalization is as reliable as within-group classification.
207	
208	\paragraph{Sub-C: Negative control.}
209	We train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\%).
210	Depth prediction accuracy averages 72.0\%; seed-group prediction averages 10.2\%, indistinguishable from chance (before fix: 20.8\%, inflated by the depth--group confound).
211	The depth-to-seed-group accuracy ratio is 7.1$\times$, confirming that the feature representation encodes depth but not seed-article identity.
212	
213	Taken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.
214	
215	\subsection{Wild-Data Calibration}
216	\label{app:calibration}
217	
218	Table~\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).
219	
220	\begin{table}[h]
221	\centering
222	\small
223	\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\% Wilson CIs computed for C4 ($n{=}5{,}000$).}
224	\label{tab:calibration}
225	\begin{tabular}{@{}llrccc@{}}
226	\toprule
227	Model & Source & $n$ & d0 (\%) & FPR (\%) & 95\% Wilson CI \\
228	\midrule
229	Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\
230	 & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\
231	\addlinespace
232	GPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\
233	 & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\
234	\addlinespace
235	OLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\
236	 & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\
237	\bottomrule
238	\end{tabular}
239	\end{table}
240	
241	On WikiText-103, all three classifiers achieve $\geq$98.5\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.
242	On C4, FPR varies sharply: OLMo (4.7\%) vs.\ Pythia (20.2\%) and GPT-2~XL (22.4\%).
243	C4 misclassifications concentrate in template and SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0 passages), rather than in random noise.
244	The model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.
245	Among C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\%), d2 (3.7\%), d3 (9.6\%); for OLMo, d1 (2.9\%), d2 (0.5\%), d3 (1.3\%). The non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.
246	
247	\subsection{Downstream Curation PoC}
248	\label{app:curation_poc}
249	
250	To validate that depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.
251	We fine-tune Pythia-410M with LoRA ($r{=}16$, $\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.
252	Conditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\approx$25\%, moderate $\approx$50\%, soft threshold).
253	Table~\ref{tab:curation_poc} reports per-condition perplexity; Table~\ref{tab:curation_comparisons} reports pairwise contrasts.
254	
255	\begin{table}[h]
256	\centering
257	\small
258	\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\,: $p<0.05$ (paired $t$-test vs.\ unfiltered).}
259	\label{tab:curation_poc}
260	\resizebox{\columnwidth}{!}{%
261	\begin{tabular}{@{}lcccccc@{}}
262	\toprule
263	Condition & Mean PPL & Std & $n$ & $\Delta$ vs Unfilt. & $p$ & $d_z$ \\
264	\midrule
265	unfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\
266	rf\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\
267	rf\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\
268	rf\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\
269	oracle\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\
270	oracle\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\
271	random\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\
272	random\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\
273	random\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\
274	\bottomrule
275	\end{tabular}}
276	\end{table}
277	
278	\begin{table}[h]
279	\centering
280	\small
281	\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\,: $p<0.05$; $^{**}$\,: $p<0.01$.}
282	\label{tab:curation_comparisons}
283	\begin{tabular}{@{}lccc@{}}
284	\toprule
285	Comparison & $\Delta$ PPL & $t$ & $p$ \\
286	\midrule
287	rf\_strict vs random\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\
288	rf\_moderate vs random\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\
289	rf\_soft vs random\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\
290	rf\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\
291	\bottomrule
292	\end{tabular}
293	\end{table}
294	
295	\subsection{Reference Model Ablation}
296	\label{app:ref_ablation}
297	
298	\begin{table}[h]
299	\centering
300	\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}
301	\label{tab:ref_ablation}
302	\begin{tabular}{lcc}
303	\toprule
304	Reference Model & Architecture & Accuracy (\%) \\
305	\midrule
306	Pythia-1.4B (self) & GPT-NeoX & 78.6 $\pm$ 0.6 \\
307	OLMo-1B (cross) & OLMo & 74.5 $\pm$ 0.7 \\
308	\bottomrule
309	\end{tabular}
310	\end{table}
311	
312	\subsection{Cross-Scale Full Results}
313	\label{app:cross_scale_full}
314	
315	This section provides the full cross-scale analysis summarized in \S\ref{sec:gen:crossscale}.
316	We extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \in \{0, 1, \ldots, 5\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).
317	Feature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.
318	
319	\paragraph{Scale comparison.}
320	Table~\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).
321	
322	\begin{table}[h]
323	\centering
324	\small
325	\caption{Cross-scale comparison: 4-class RF accuracy (\%, depths 0--3, nucleus), $\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\% bootstrap. Chance = 25\%.}
326	\label{tab:cross_scale}
327	\begin{tabular}{@{}lccc@{}}
328	\toprule
329	Model & 4-class acc & $\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\
330	\midrule
331	GPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\
332	OLMo-1B & 78.8 & 4 & 0.997 \\
333	Pythia-1.4B & 78.2 & 4 & 0.998 \\
334	\midrule
335	Llama-3.1-8B & 70.2\,[68.3, 72.4] & 4 & 0.949 \\
336	Qwen2.5-7B & 60.1\,[58.0, 62.1] & ${>}5$ & 0.969 \\
337	\bottomrule
338	\end{tabular}
339	\end{table}
340	
341	\paragraph{(1) Depth signal persists at 7--8B scale.}
342	Both 7--8B models substantially exceed the 25\% chance baseline: Llama-3.1-8B achieves 70.2\% (95\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\% ($[58.0, 62.1]$), confirming that recursive depth remains estimable from perplexity-based features even when the generator is 5--7$\times$ larger than the reference model.
343	Depth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).
344	
345	\paragraph{(2) EDD at 7--8B scale.}
346	At threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\ref{tab:cross_scale_auc}), yielding $\mathrm{EDD}_{T{=}0.70} > 5$, exceeding the $\mathrm{EDD}{=}4$ observed at 1--1.5B.
347	Llama-3.1-8B matches the smaller models at $\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.
348	Both larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\ 0.852 at 1--1.5B).
349	
350	\begin{table}[h]
351	\centering
352	\small
353	\caption{Consecutive binary AUC for 7--8B models (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a non-monotonic (U-shaped) pattern with all pairs above $T$.}
354	\label{tab:cross_scale_auc}
355	\begin{tabular}{@{}lccccc@{}}
356	\toprule
357	Model & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\
358	\midrule
359	Llama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\
360	Qwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\
361	\bottomrule
362	\end{tabular}
363	\end{table}
364	
365	\paragraph{(3) Divergent AUC trajectories and instruction-tuning effect.}
366	Among instruction-tuned models, Llama-3.1-8B exhibits monotonic AUC decay consistent with the 1--1.5B pattern, while Qwen2.5-7B shows a U-shaped recovery beyond d2v3 (Table~\ref{tab:cross_scale_auc}).
367	A base-model control (Llama-3.1-8B without instruction tuning) clarifies the causal direction: the base model achieves 59.9\% four-class accuracy (95\% CI [57.8, 62.15], $\mathrm{EDD}_{0.70}{=}2$) with non-monotonic AUC decay (Table~\ref{tab:llama3_base_auc}), while the instruction-tuned variant reaches 70.2\% with strictly monotonic decay.
368	The base-model control experiment suggests instruction-tuning regularizes rather than confounds the depth signal.
369	
370	\begin{table}[h]
371	\centering
372	\small
373	\caption{Pairwise AUC: Llama-3.1-8B Base vs.\ Instruct.}
374	\label{tab:llama3_base_auc}
375	\begin{tabular}{lccccc}
376	\toprule
377	Variant & $d_{0\text{v}1}$ & $d_{1\text{v}2}$ & $d_{2\text{v}3}$ & $d_{3\text{v}4}$ & $d_{4\text{v}5}$ \\
378	\midrule
379	Base & 0.918 & 0.794 & 0.682 & 0.730 & 0.595 \\
380	Instruct & 0.965 & 0.874 & 0.771 & 0.716 & 0.618 \\
381	\bottomrule
382	\end{tabular}
383	\end{table}
384	
385	The base model exhibits non-monotonic decay with a U-shaped recovery at $d_{3\text{v}4}$, while the instruction-tuned variant shows strictly monotonic decay. Both variants exceed chance (AUC $> 0.5$) at all boundaries, confirming depth signal exists regardless of instruction-tuning, though instruction-tuning strengthens and regularizes it.
386	
387	\paragraph{Caveats.}
388	For Qwen2.5-7B, the CI lower bound (58.0\%) does not exclude sub-60\% accuracy; Llama-3.1-8B's lower bound (68.3\%) is more comfortably above chance but still below the 75--83\% range at 1--1.5B.
389	The divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.
390	
391	\paragraph{Confounds.}
392	\label{app:cross_scale_confounds}
393	Four confounds limit these results: (1)~4-bit NF4 QLoRA quantization (absent at 1--1.5B) may distort the perplexity distribution independently of depth; (2)~smaller sample size (500 vs.\ 5{,}000 per depth) widens confidence intervals; (3)~evaluation is limited to nucleus sampling, leaving other strategies untested at this scale; (4)~vocabulary mismatch between 7--8B generators and the 1.4B reference model.
394	The base-model control partially addresses a former confound (instruction-tuning): since the base variant shows weaker signal with non-monotonic decay while the instruction-tuned variant shows stronger monotonic signal, instruction-tuning regularizes rather than confounds depth estimation.
395	The remaining confounds are not mutually independent (quantization and vocabulary mismatch both affect the perplexity distribution), making it infeasible to attribute the observed accuracy gap (60--70\% vs.\ 78--85\% at 1--1.5B) to any single factor.
396	
397	\subsection{Cross-Boundary Generalization}
398	\label{app:cross_boundary}
399	
400	The preceding experiments assume a single model family generates all recursive depths.
401	In practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.
402	We probe whether the depth signal persists under two relaxations of the single-model assumption.
403	
404	\paragraph{Cross-model recursive chains.}
405	We construct a heterogeneous chain: human text (d0) $\to$ Pythia-1.4B generates d1 $\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.
406	Each recursive step uses a \emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.
407	A 4-class Random Forest achieves 84.75\% accuracy (95\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).
408	Pairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.
409	These results suggest that distributional artifacts of recursive generation persist across model boundaries, providing preliminary evidence consistent with a process-level depth signal rather than individual generator artifacts.
410	
411	\paragraph{Confound discussion.}
412	The heterogeneous chain confounds architecture identity with depth (d1=Pythia, d2=OLMo, d3=GPT-2~XL).
413	However, if the classifier exploited architecture fingerprints rather than depth signal, near-perfect accuracy would be expected since architecture perfectly determines depth label.
414	The observed 84.75\% with monotonically decreasing per-depth F1 (d0=0.98, d1=0.88, d2=0.76, d3=0.76) is more consistent with a depth-signal interpretation, as architecture fingerprinting would not produce this graded pattern.
415	We address this confound directly with a reverse-chain control below.
416	
417	\paragraph{Reverse-chain control.}
418	To empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\to$ OLMo $\to$ Pythia) reversing the model-depth assignment.
419	The reverse chain achieves 85.75\% (95\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\%, [81.0, 88.25]).
420	If the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.
421	
422	\paragraph{Cross-domain transfer.}
423	All prior experiments use WikiText-103 as the seed corpus.
424	To test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).
425	Five-fold cross-validation yields 74.1\% $\pm$ 2.0\% accuracy, compared to ${\sim}$78\% on the WikiText seed.
426	Per-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66, with d2 remaining the most challenging class.
427	The 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.
428	These results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.
429	
430	\subsection{Cross-Seed Replication}
431	\label{app:seed_replication}
432	
433	Table~\ref{tab:seed_replication} reports within-seed and cross-seed classification accuracy for Pythia-1.4B (nucleus, depths 0--3) under two independent LoRA training seeds.
434	
435	\begin{table}[h]
436	\centering
437	\small
438	\caption{Cross-seed transfer (Pythia-1.4B nucleus). Baseline seed=42 is the primary benchmark LoRA; seed=43 is an independent replication. $\Delta$: difference from respective comparison point.}
439	\label{tab:seed_replication}
440	\begin{tabular}{@{}lcc@{}}
441	\toprule
442	Condition & Acc (\%) & $\Delta$ (pp) \\
443	\midrule
444	Within-seed (seed=42) & 78.20 & --- \\
445	Within-seed (seed=43) & 77.15 & $-$1.05$^\dagger$ \\
446	\midrule
447	Cross-seed (train 42$\to$test 43) & 77.85 & \\
448	Cross-seed (train 43$\to$test 42) & 75.68 & \\
449	Cross-seed avg & 76.76 & $-$1.30$^\ddagger$ \\
450	\bottomrule
451	\multicolumn{3}{@{}l}{\footnotesize $^\dagger$vs.\ baseline (78.20\%). $^\ddagger$vs.\ within-seed avg (78.07\%).}
452	\end{tabular}
453	\end{table}
454	
455	The seed=43 LoRA achieves 77.15\% (95\% CI [76.4, 78.15]), within 1.05\,pp of the seed=42 baseline.
456	Cross-seed transfer averages 76.76\%, a 1.30\,pp deficit relative to within-seed performance.
457	Top-5 feature importance is identical across seeds (\texttt{var\_surprisal}, \texttt{p90\_ppl}, \texttt{mean\_ppl}, \texttt{var\_ppl}, \texttt{p75\_ppl}), confirming that depth signal arises from the recursive process itself rather than idiosyncratic LoRA weight configurations.
458	
459	\subsection{Generation Length Ablation}
460	\label{app:length_ablation}
461	
462	Table~\ref{tab:length_ablation} reports classification accuracy as a function of passage length (Pythia-1.4B nucleus, depths 0--3).
463	
464	\begin{table}[h]
465	\centering
466	\small
467	\caption{Generation length ablation (Pythia-1.4B nucleus, 5-fold CV). Accuracy increases monotonically with passage length; the 9.47\,pp spread confirms that longer passages provide stronger statistical signal.}
468	\label{tab:length_ablation}
469	\begin{tabular}{@{}lc@{}}
470	\toprule
471	Passage length (tokens) & Acc (\%) \\
472	\midrule
473	128 & 68.35 \\
474	256 & 73.80 \\
475	512 & 77.82 \\
476	\bottomrule
477	\end{tabular}
478	\end{table}
479	
480	Depth signal is detectable from 128 tokens (2.7$\times$ chance) and saturates near 500 tokens.
481	The monotonic increase reflects the statistical nature of the features: longer passages yield more stable estimates of perplexity percentiles and surprisal variance, reducing within-class overlap at adjacent depth boundaries.
482	
483	\subsection{Mixed-Depth Corpus}
484	\label{app:mixed_depth}
485	
486	Per-passage classification is largely independent of corpus composition: evaluating on a corpus containing mixed proportions of d0--d3 passages (rather than balanced classes) yields macro-recall $\Delta{=}{-}1.62$\,pp relative to the balanced benchmark (within the 2\,pp tolerance).
487	Individual class deltas range from $-$0.45\,pp to $-$2.43\,pp (d1 shows the largest shift), confirming that the RF classifier operates on per-sample features without sensitivity to the class distribution of the evaluation corpus.
488	Macro-recall $\Delta$ = $-$1.62\,pp (within the 2\,pp threshold); individual class variations (max 2.43\,pp on d1) arise from held-out sample composition rather than classifier sensitivity to corpus distribution, as the Random Forest produces identical per-sample predictions regardless of batch context.
489	
490	\subsection{Extended Discussion}
491	\label{app:extended_discussion}
492	
493	\paragraph{Depth-graduated curation.}
494	Current data curation operates on a binary human-vs-machine distinction \cite{dsir2023,qurating2024}.
495	Recursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.
496	The 70--85\% in-distribution accuracy and $\mathrm{EDD}_{0.75}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\S\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a pilot study (Appendix~\ref{app:curation_poc}) yields an inconclusive RF-vs-unfiltered comparison ($p>0.4$), though RF-filtered subsets significantly outperform size-matched random subsampling ($p<0.001$--$0.02$); large-scale validation remains open.
497	Importance weighting \cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.
498	
499	\paragraph{Toward a provenance toolkit.}
500	Depth estimation complements existing provenance methods along orthogonal axes.
501	Watermarking \cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.
502	Source attribution \cite{uchendu2020_attribution} identifies the generating model but not the generation history.
503	Depth estimation characterizes \emph{iterative reuse} regardless of generator cooperation or identity.
504	A layered provenance system combining these three signals (watermark presence, source model, and recursive generation depth) could support more nuanced data auditing than any single method.
505	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8dbb574a-c47e-43b9-bc0b-4e772ab6a353",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "f39ae071-6676-4f42-8121-898ebea2b675",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
      "content": "\\section{Additional Results}\n\\label{app:additional}\n\n\\subsection{Top-$k$ Feature Trajectories}\n\\label{app:topk_trajectories}\n\nFigure~\\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\\tau{=}0.9$) sampling.\nTop-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \\S\\ref{sec:atlas:strategy}.\nConcretely, the d0$\\to$d1 drop in \\textsc{p90\\_ppl} under top-$k$ is 78\\% (vs.\\ 87\\% for nucleus), and the d2$\\to$d3 reduction is 31\\% (vs.\\ 39\\% for nucleus).\nDespite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.\n\n\\subsection{Permutation Importance}\n\\label{app:permutation}\n\nTo verify that the Gini-based importance rankings in \\S\\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.\nThe top-2 features are stable across measures: \\textsc{p90\\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \\textsc{var\\_surprisal} in 8/9 (vs.\\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \\textsc{p75\\_ppl} displaces \\textsc{var\\_surprisal} to rank 3).\nKendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).\nPairwise Spearman correlations are: SHAP--Gini $\\rho{=}0.93$, SHAP--permutation $\\rho{=}0.84$, Gini--permutation $\\rho{=}0.76$.\nPer-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.\n\n\\subsection{Per-Class Recall}\n\\label{app:per_class}\n\nTable~\\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).\nDepth~0 recall exceeds 98\\% uniformly.\nAmong generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class recall (\\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}\n\\label{tab:per_class_recall}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & d0 & d1 & d2 & d3 \\\\\n\\midrule\nPythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\\\\nPythia, $\\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\\\\nPythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\\\\nOLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\\\\nOLMo, $\\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\\\\nOLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\\\\nGPT-2~XL, nuc.     & 99.2 & 85.9 & \\textbf{73.3} & 77.5 \\\\\nGPT-2~XL, $\\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\\\\nGPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{DCOL Iteration Details}\n\\label{app:dcol_iterations}\n\nTable~\\ref{tab:dcol_iterations} summarizes all six DCOL iterations.\nDeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\\%.}\n\\label{tab:dcol_iterations}\n\\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}\n\\toprule\nVer. & Backbone & Config & Outcome \\\\\n\\midrule\nv1 & DeBERTa & FT, m\\_lr $10^{-3}$ & Embed.\\ collapse (31.5\\%) \\\\\nv2 & DeBERTa & FT, m\\_lr $10^{-4}$ & OOM \\\\\nv3 & DeBERTa & FT, m\\_lr $10^{-4}$ & Forgetting + OOM \\\\\nv4 & DeBERTa & LoRA, m\\_lr $10^{-3}$ & Embed.\\ collapse \\\\\nv5 & DeBERTa & LoRA, m\\_lr $10^{-4}$ & NaN gradients \\\\\nv6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\\% ($-$13.7pp) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Zero-Shot LLM Prompt Template}\n\\label{app:zeroshot_prompt}\n\nBoth DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.\nThe system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).\nThe user message presents the passage (truncated to ${\\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.\nNo in-context examples are provided.\n\n\\begin{quote}\n\\small\n\\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\\ldots]''\n\n\\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \\{text\\}. Respond with ONLY a JSON object: \\{\\texttt{\"depth\"}: $\\langle$int 0--3$\\rangle$, \\texttt{\"confidence\"}: $\\langle$float 0--1$\\rangle$, \\texttt{\"reasoning\"}: $\\langle$str$\\rangle$\\}''\n\\end{quote}\n\n\\subsection{Temperature Robustness}\n\\label{app:multi_tau}\n\nThe cross-strategy results in \\S\\ref{sec:gen:crossstrategy} use a single temperature ($\\tau{=}0.9$).\nTo test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\\tau \\in \\{0.5, 0.7, 0.9, 1.1\\}$ on Pythia-1.4B.\n\n\\paragraph{Within-$\\tau$ robustness.}\nFor $\\tau \\in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\\% to 77.3\\% (Table~\\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.\nThe same top-5 features (\\texttt{var\\_surprisal}, \\texttt{p90\\_ppl}, \\texttt{mean\\_ppl}, \\texttt{mean\\_surprisal}, \\texttt{p75\\_ppl}) dominate across all $\\tau$ values with only minor rank-order variation.\n\n\\paragraph{Collapse at $\\tau{=}1.1$: memorization as prerequisite.}\nAt $\\tau{=}1.1$, 4-class accuracy drops to 57.2\\% and d1v2 AUC falls to 0.528.\nTraining loss reveals the mechanism: at low temperature ($\\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \\to 0.42 \\to 0.16$), indicating rapid memorization of the model's own output.\nAt $\\tau{=}1.1$, loss remains nearly flat ($2.27 \\to 1.91 \\to 1.85$); high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.\nThis establishes \\emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.\n\n\\paragraph{Cross-$\\tau$ non-transferability.}\nLeave-one-$\\tau$-out transfer yields mean accuracy of 46.7\\% with mean d1v2 AUC of 0.319 (Table~\\ref{tab:multi_tau_cross}), worse than cross-strategy transfer (59.1\\%; \\S\\ref{sec:gen:crossstrategy}).\nHoldout $\\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.\nThis extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific, reinforcing the need for strategy-conditioned classifiers.\n\n\\paragraph{Ecological validity.}\nOn WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity, partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.\nOn noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Within-$\\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\\ depth $j$.}\n\\label{tab:multi_tau_within}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n$\\tau$ & 4-class acc (\\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\\\\n\\midrule\n0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\\\\n0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\\\\n0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\\\\n1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-$\\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}\n\\label{tab:multi_tau_cross}\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nHoldout & Acc (\\%) & d1v2 AUC \\\\\n\\midrule\n$\\tau{=}0.5$ & 52.2 & 0.176 \\\\\n$\\tau{=}0.7$ & 41.0 & 0.299 \\\\\n$\\tau{=}0.9$ & 46.4 & 0.277 \\\\\n$\\tau{=}1.1$ & 47.1 & 0.525 \\\\\n\\midrule\nMean & 46.7 & 0.319 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Feature Overlap Analysis}\n\\label{app:feature_overlap}\n\nWe probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.\nPLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics; \\textsc{var\\_surprisal} and \\textsc{p90\\_ppl} yield negative $R^2$ under linear probing, indicating these features are not linearly accessible in the pretrained representation space.\nThis confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\\S\\ref{app:e2e}) stems from complementary, not redundant, representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.\n\n\\subsection{End-to-End Learning}\n\\label{app:e2e}\n\nDeBERTa-v3-base \\cite{he2021_deberta_v3} and RoBERTa-base \\cite{liu2019_roberta} finetuned end-to-end achieve 58.3\\% ($\\pm$4.7\\%) and 59.5\\% ($\\pm$3.2\\%) respectively, lagging the RF baseline (78.2\\%) by 19.9pp and 18.7pp.\nThe 1.2pp inter-backbone gap rules out architecture bias; Table~\\ref{tab:e2e_detail} shows both backbones share the same failure mode (high d0 F1, $>$0.94, but collapsed d1/d2 performance, F1 $\\leq$ 0.42), while RF achieves 0.596 d2 recall, a $>$2$\\times$ advantage at the hardest depth class.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class performance for end-to-end PLM classifiers vs.\\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}\n\\label{tab:e2e_detail}\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nMethod & Acc (\\%) & d0 & d1 & d2 & d3 \\\\\n\\midrule\nDeBERTa-v3 & 58.3\\,$\\pm$\\,4.7 & .947 & .378 & .247 & .656 \\\\\nRoBERTa-base & 59.5\\,$\\pm$\\,3.2 & .958 & .416 & .261 & .647 \\\\\n\\midrule\nRF (19 feat.) & 78.2 & --- & --- & .596$^\\dagger$ & --- \\\\\n\\bottomrule\n\\multicolumn{6}{@{}l}{\\footnotesize $^\\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Feature space divergence.}\nSHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\\% of RF's total contribution.\nThree independent importance measures (SHAP, Gini, and permutation) show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \\S\\ref{app:permutation}), with \\texttt{p90\\_ppl} appearing in the SHAP top-2 in 9/9 cells and \\texttt{var\\_surprisal} in 8/9.\nLinear probing of PLM [CLS] representations yields negative $R^2$ for both \\texttt{var\\_surprisal} and \\texttt{p90\\_ppl} (\\S\\ref{app:feature_overlap}), indicating that pretrained representations lack the linear structure needed to recover perplexity tail statistics, a systematic representational gap rather than a backbone-specific artifact.\n\nDCOL \\cite{cloc2025} reached 64.5\\% (\\S\\ref{app:dcol_iterations}); all end-to-end approaches (58--65\\%) underperform feature-based methods, suggesting depth estimation benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.\nThis comparison is bounded by backbone scale ($\\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.\n\n\\subsection{Domain Bias Analysis}\n\\label{app:domain_bias}\n\nTo assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.\n\n\\paragraph{Methodological note.}\nAn initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\\%, seed-group prediction 20.8\\%).\nWe discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.\nThe results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.\n\n\\paragraph{Sub-A: Standard CV.}\nFive-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\\% to 82\\% across the 9 atlas cells (up to 2.5$\\times$ above the 33.3\\% chance level), confirming that depth signal is the dominant classification factor.\n\n\\paragraph{Sub-B: LOGO evaluation.}\nWe assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.\nLOGO mean accuracy is 72.1\\% (range 59.5--81.6\\%), matching standard CV (72.0\\%) within noise (before fix: 64.0\\%, reflecting the depth--group confound).\nPer-cell fold standard deviations range from 0.4pp to 1.4pp, indicating that cross-group generalization is as reliable as within-group classification.\n\n\\paragraph{Sub-C: Negative control.}\nWe train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\\%).\nDepth prediction accuracy averages 72.0\\%; seed-group prediction averages 10.2\\%, indistinguishable from chance (before fix: 20.8\\%, inflated by the depth--group confound).\nThe depth-to-seed-group accuracy ratio is 7.1$\\times$, confirming that the feature representation encodes depth but not seed-article identity.\n\nTaken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.\n\n\\subsection{Wild-Data Calibration}\n\\label{app:calibration}\n\nTable~\\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\\% Wilson CIs computed for C4 ($n{=}5{,}000$).}\n\\label{tab:calibration}\n\\begin{tabular}{@{}llrccc@{}}\n\\toprule\nModel & Source & $n$ & d0 (\\%) & FPR (\\%) & 95\\% Wilson CI \\\\\n\\midrule\nPythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\\\\n & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\\\\n\\addlinespace\nGPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\\\\n & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\\\\n\\addlinespace\nOLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\\\\n & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOn WikiText-103, all three classifiers achieve $\\geq$98.5\\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.\nOn C4, FPR varies sharply: OLMo (4.7\\%) vs.\\ Pythia (20.2\\%) and GPT-2~XL (22.4\\%).\nC4 misclassifications concentrate in template and SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0 passages), rather than in random noise.\nThe model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.\nAmong C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\\%), d2 (3.7\\%), d3 (9.6\\%); for OLMo, d1 (2.9\\%), d2 (0.5\\%), d3 (1.3\\%). The non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.\n\n\\subsection{Downstream Curation PoC}\n\\label{app:curation_poc}\n\nTo validate that depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.\nWe fine-tune Pythia-410M with LoRA ($r{=}16$, $\\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.\nConditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\\approx$25\\%, moderate $\\approx$50\\%, soft threshold).\nTable~\\ref{tab:curation_poc} reports per-condition perplexity; Table~\\ref{tab:curation_comparisons} reports pairwise contrasts.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\\,: $p<0.05$ (paired $t$-test vs.\\ unfiltered).}\n\\label{tab:curation_poc}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\nCondition & Mean PPL & Std & $n$ & $\\Delta$ vs Unfilt. & $p$ & $d_z$ \\\\\n\\midrule\nunfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\\\\nrf\\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\\\\nrf\\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\\\\nrf\\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\\\\noracle\\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\\\\noracle\\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\\\\nrandom\\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\\\\nrandom\\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\\\\nrandom\\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\\,: $p<0.05$; $^{**}$\\,: $p<0.01$.}\n\\label{tab:curation_comparisons}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nComparison & $\\Delta$ PPL & $t$ & $p$ \\\\\n\\midrule\nrf\\_strict vs random\\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\\\\nrf\\_moderate vs random\\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\\\\nrf\\_soft vs random\\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\\\\nrf\\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Reference Model Ablation}\n\\label{app:ref_ablation}\n\n\\begin{table}[h]\n\\centering\n\\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}\n\\label{tab:ref_ablation}\n\\begin{tabular}{lcc}\n\\toprule\nReference Model & Architecture & Accuracy (\\%) \\\\\n\\midrule\nPythia-1.4B (self) & GPT-NeoX & 78.6 $\\pm$ 0.6 \\\\\nOLMo-1B (cross) & OLMo & 74.5 $\\pm$ 0.7 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Cross-Scale Full Results}\n\\label{app:cross_scale_full}\n\nThis section provides the full cross-scale analysis summarized in \\S\\ref{sec:gen:crossscale}.\nWe extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \\in \\{0, 1, \\ldots, 5\\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).\nFeature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.\n\n\\paragraph{Scale comparison.}\nTable~\\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-scale comparison: 4-class RF accuracy (\\%, depths 0--3, nucleus), $\\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\\% bootstrap. Chance = 25\\%.}\n\\label{tab:cross_scale}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nModel & 4-class acc & $\\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\\\\n\\midrule\nGPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\\\\nOLMo-1B & 78.8 & 4 & 0.997 \\\\\nPythia-1.4B & 78.2 & 4 & 0.998 \\\\\n\\midrule\nLlama-3.1-8B & 70.2\\,[68.3, 72.4] & 4 & 0.949 \\\\\nQwen2.5-7B & 60.1\\,[58.0, 62.1] & ${>}5$ & 0.969 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{(1) Depth signal persists at 7--8B scale.}\nBoth 7--8B models substantially exceed the 25\\% chance baseline: Llama-3.1-8B achieves 70.2\\% (95\\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\\% ($[58.0, 62.1]$), confirming that recursive depth remains estimable from perplexity-based features even when the generator is 5--7$\\times$ larger than the reference model.\nDepth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).\n\n\\paragraph{(2) EDD at 7--8B scale.}\nAt threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\\ref{tab:cross_scale_auc}), yielding $\\mathrm{EDD}_{T{=}0.70} > 5$, exceeding the $\\mathrm{EDD}{=}4$ observed at 1--1.5B.\nLlama-3.1-8B matches the smaller models at $\\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.\nBoth larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\\ 0.852 at 1--1.5B).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Consecutive binary AUC for 7--8B models (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a non-monotonic (U-shaped) pattern with all pairs above $T$.}\n\\label{tab:cross_scale_auc}\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nModel & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\\\\n\\midrule\nLlama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\\\\nQwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{(3) Divergent AUC trajectories and instruction-tuning effect.}\nAmong instruction-tuned models, Llama-3.1-8B exhibits monotonic AUC decay consistent with the 1--1.5B pattern, while Qwen2.5-7B shows a U-shaped recovery beyond d2v3 (Table~\\ref{tab:cross_scale_auc}).\nA base-model control (Llama-3.1-8B without instruction tuning) clarifies the causal direction: the base model achieves 59.9\\% four-class accuracy (95\\% CI [57.8, 62.15], $\\mathrm{EDD}_{0.70}{=}2$) with non-monotonic AUC decay (Table~\\ref{tab:llama3_base_auc}), while the instruction-tuned variant reaches 70.2\\% with strictly monotonic decay.\nThe base-model control experiment suggests instruction-tuning regularizes rather than confounds the depth signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pairwise AUC: Llama-3.1-8B Base vs.\\ Instruct.}\n\\label{tab:llama3_base_auc}\n\\begin{tabular}{lccccc}\n\\toprule\nVariant & $d_{0\\text{v}1}$ & $d_{1\\text{v}2}$ & $d_{2\\text{v}3}$ & $d_{3\\text{v}4}$ & $d_{4\\text{v}5}$ \\\\\n\\midrule\nBase & 0.918 & 0.794 & 0.682 & 0.730 & 0.595 \\\\\nInstruct & 0.965 & 0.874 & 0.771 & 0.716 & 0.618 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe base model exhibits non-monotonic decay with a U-shaped recovery at $d_{3\\text{v}4}$, while the instruction-tuned variant shows strictly monotonic decay. Both variants exceed chance (AUC $> 0.5$) at all boundaries, confirming depth signal exists regardless of instruction-tuning, though instruction-tuning strengthens and regularizes it.\n\n\\paragraph{Caveats.}\nFor Qwen2.5-7B, the CI lower bound (58.0\\%) does not exclude sub-60\\% accuracy; Llama-3.1-8B's lower bound (68.3\\%) is more comfortably above chance but still below the 75--83\\% range at 1--1.5B.\nThe divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.\n\n\\paragraph{Confounds.}\n\\label{app:cross_scale_confounds}\nFour confounds limit these results: (1)~4-bit NF4 QLoRA quantization (absent at 1--1.5B) may distort the perplexity distribution independently of depth; (2)~smaller sample size (500 vs.\\ 5{,}000 per depth) widens confidence intervals; (3)~evaluation is limited to nucleus sampling, leaving other strategies untested at this scale; (4)~vocabulary mismatch between 7--8B generators and the 1.4B reference model.\nThe base-model control partially addresses a former confound (instruction-tuning): since the base variant shows weaker signal with non-monotonic decay while the instruction-tuned variant shows stronger monotonic signal, instruction-tuning regularizes rather than confounds depth estimation.\nThe remaining confounds are not mutually independent (quantization and vocabulary mismatch both affect the perplexity distribution), making it infeasible to attribute the observed accuracy gap (60--70\\% vs.\\ 78--85\\% at 1--1.5B) to any single factor.\n\n\\subsection{Cross-Boundary Generalization}\n\\label{app:cross_boundary}\n\nThe preceding experiments assume a single model family generates all recursive depths.\nIn practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.\nWe probe whether the depth signal persists under two relaxations of the single-model assumption.\n\n\\paragraph{Cross-model recursive chains.}\nWe construct a heterogeneous chain: human text (d0) $\\to$ Pythia-1.4B generates d1 $\\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.\nEach recursive step uses a \\emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.\nA 4-class Random Forest achieves 84.75\\% accuracy (95\\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).\nPairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.\nThese results suggest that distributional artifacts of recursive generation persist across model boundaries, providing preliminary evidence consistent with a process-level depth signal rather than individual generator artifacts.\n\n\\paragraph{Confound discussion.}\nThe heterogeneous chain confounds architecture identity with depth (d1=Pythia, d2=OLMo, d3=GPT-2~XL).\nHowever, if the classifier exploited architecture fingerprints rather than depth signal, near-perfect accuracy would be expected since architecture perfectly determines depth label.\nThe observed 84.75\\% with monotonically decreasing per-depth F1 (d0=0.98, d1=0.88, d2=0.76, d3=0.76) is more consistent with a depth-signal interpretation, as architecture fingerprinting would not produce this graded pattern.\nWe address this confound directly with a reverse-chain control below.\n\n\\paragraph{Reverse-chain control.}\nTo empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\\to$ OLMo $\\to$ Pythia) reversing the model-depth assignment.\nThe reverse chain achieves 85.75\\% (95\\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\\%, [81.0, 88.25]).\nIf the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.\n\n\\paragraph{Cross-domain transfer.}\nAll prior experiments use WikiText-103 as the seed corpus.\nTo test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).\nFive-fold cross-validation yields 74.1\\% $\\pm$ 2.0\\% accuracy, compared to ${\\sim}$78\\% on the WikiText seed.\nPer-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66, with d2 remaining the most challenging class.\nThe 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.\nThese results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.\n\n\\subsection{Cross-Seed Replication}\n\\label{app:seed_replication}\n\nTable~\\ref{tab:seed_replication} reports within-seed and cross-seed classification accuracy for Pythia-1.4B (nucleus, depths 0--3) under two independent LoRA training seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-seed transfer (Pythia-1.4B nucleus). Baseline seed=42 is the primary benchmark LoRA; seed=43 is an independent replication. $\\Delta$: difference from respective comparison point.}\n\\label{tab:seed_replication}\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nCondition & Acc (\\%) & $\\Delta$ (pp) \\\\\n\\midrule\nWithin-seed (seed=42) & 78.20 & --- \\\\\nWithin-seed (seed=43) & 77.15 & $-$1.05$^\\dagger$ \\\\\n\\midrule\nCross-seed (train 42$\\to$test 43) & 77.85 & \\\\\nCross-seed (train 43$\\to$test 42) & 75.68 & \\\\\nCross-seed avg & 76.76 & $-$1.30$^\\ddagger$ \\\\\n\\bottomrule\n\\multicolumn{3}{@{}l}{\\footnotesize $^\\dagger$vs.\\ baseline (78.20\\%). $^\\ddagger$vs.\\ within-seed avg (78.07\\%).}\n\\end{tabular}\n\\end{table}\n\nThe seed=43 LoRA achieves 77.15\\% (95\\% CI [76.4, 78.15]), within 1.05\\,pp of the seed=42 baseline.\nCross-seed transfer averages 76.76\\%, a 1.30\\,pp deficit relative to within-seed performance.\nTop-5 feature importance is identical across seeds (\\texttt{var\\_surprisal}, \\texttt{p90\\_ppl}, \\texttt{mean\\_ppl}, \\texttt{var\\_ppl}, \\texttt{p75\\_ppl}), confirming that depth signal arises from the recursive process itself rather than idiosyncratic LoRA weight configurations.\n\n\\subsection{Generation Length Ablation}\n\\label{app:length_ablation}\n\nTable~\\ref{tab:length_ablation} reports classification accuracy as a function of passage length (Pythia-1.4B nucleus, depths 0--3).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Generation length ablation (Pythia-1.4B nucleus, 5-fold CV). Accuracy increases monotonically with passage length; the 9.47\\,pp spread confirms that longer passages provide stronger statistical signal.}\n\\label{tab:length_ablation}\n\\begin{tabular}{@{}lc@{}}\n\\toprule\nPassage length (tokens) & Acc (\\%) \\\\\n\\midrule\n128 & 68.35 \\\\\n256 & 73.80 \\\\\n512 & 77.82 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nDepth signal is detectable from 128 tokens (2.7$\\times$ chance) and saturates near 500 tokens.\nThe monotonic increase reflects the statistical nature of the features: longer passages yield more stable estimates of perplexity percentiles and surprisal variance, reducing within-class overlap at adjacent depth boundaries.\n\n\\subsection{Mixed-Depth Corpus}\n\\label{app:mixed_depth}\n\nPer-passage classification is largely independent of corpus composition: evaluating on a corpus containing mixed proportions of d0--d3 passages (rather than balanced classes) yields macro-recall $\\Delta{=}{-}1.62$\\,pp relative to the balanced benchmark (within the 2\\,pp tolerance).\nIndividual class deltas range from $-$0.45\\,pp to $-$2.43\\,pp (d1 shows the largest shift), confirming that the RF classifier operates on per-sample features without sensitivity to the class distribution of the evaluation corpus.\nMacro-recall $\\Delta$ = $-$1.62\\,pp (within the 2\\,pp threshold); individual class variations (max 2.43\\,pp on d1) arise from held-out sample composition rather than classifier sensitivity to corpus distribution, as the Random Forest produces identical per-sample predictions regardless of batch context.\n\n\\subsection{Extended Discussion}\n\\label{app:extended_discussion}\n\n\\paragraph{Depth-graduated curation.}\nCurrent data curation operates on a binary human-vs-machine distinction \\cite{dsir2023,qurating2024}.\nRecursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.\nThe 70--85\\% in-distribution accuracy and $\\mathrm{EDD}_{0.75}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a pilot study (Appendix~\\ref{app:curation_poc}) yields an inconclusive RF-vs-unfiltered comparison ($p>0.4$), though RF-filtered subsets significantly outperform size-matched random subsampling ($p<0.001$--$0.02$); large-scale validation remains open.\nImportance weighting \\cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.\n\n\\paragraph{Toward a provenance toolkit.}\nDepth estimation complements existing provenance methods along orthogonal axes.\nWatermarking \\cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.\nSource attribution \\cite{uchendu2020_attribution} identifies the generating model but not the generation history.\nDepth estimation characterizes \\emph{iterative reuse} regardless of generator cooperation or identity.\nA layered provenance system combining these three signals (watermark presence, source model, and recursive generation depth) could support more nuanced data auditing than any single method.\n",
      "numLines": 505,
      "startLine": 1,
      "totalLines": 505
    }
  },
  "sourceToolAssistantUUID": "8dbb574a-c47e-43b9-bc0b-4e772ab6a353",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 113 · 2026-05-17T08:47:06.755Z_

<details open><summary>🔧 Tool call — Read · `toolu_01TUP7cj5G2hwHAo8qNYy553`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f39ae071-6676-4f42-8121-898ebea2b675",
  "isSidechain": false,
  "requestId": "req_011Cb7rET7xV6ur1TUuZAVou",
  "type": "assistant",
  "uuid": "b8f1df3c-848e-413e-8032-a6671bf6c59a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lrz6pdD1sSg8ZMo5adrP9v",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 92328,
      "cache_read_input_tokens": 11841,
      "output_tokens": 1222,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 92328,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1222,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 92328,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 92328
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Runtime record

_source line 114 · 2026-05-17T08:47:06.822Z_

```json
{
  "parentUuid": "9fd6d868-df92-4918-955a-3c8e180cab09",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "1cbe5d40-f6bf-444a-a7d9-7578b91c5cae",
  "timestamp": "2026-05-17T08:47:06.822Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---


### Runtime record

_source line 115_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Review Assignment: R2 — Novelty & Related Work  **Venue:** EMNLP 2026 Main (via ACL Rolling Review) **Paper:** \"Ordinal Depth Estimation for Recursive Language Model Generations: A…",
  "leafUuid": "1cbe5d40-f6bf-444a-a7d9-7578b91c5cae",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 116_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Assistant

_source line 117 · 2026-05-17T08:48:00.397Z_

<details><summary>Logged reasoning block</summary>

```text
The paper has been significantly revised since my Round 8 review. Let me note the key changes:

1. **Title**: Still "How Deep Is Your Data?" (not the new title mentioned in the Director's task description - "Ordinal Depth Estimation for Recursive Language Model Generations" - interesting discrepancy)

2. **Abstract**: Significantly revised - em-dashes removed (line 2: "arises, yet" instead of "arises---yet"), no more §4.4 internal reference, fewer numbers overall. But it still says "70--85%" (previously flagged for the 69.6% issue).
   
3. **Introduction**: The em-dashes have been replaced with semicolons throughout, and the language around universality has been tightened to "consistent in direction but scale-dependent in magnitude," which addresses the earlier feedback. The contributions section now explicitly mentions LoRA-rank ablation studies and reference model robustness metrics.

4. **Related Work**: There are new citations being added, including references to synthetic data work and additional foundational papers.

5. **Method**: The reference model ablation section is being expanded to include results from alternative models like OLMo-1B and GPT-2 XL.

6. **Generalization**: I'm keeping the "signal universality" framing and adding a new paragraph on LoRA rank sensitivity.

7. **Discussion**: Changing the language around pilot results to be more cautious—now explicitly noting they're inconclusive rather than claiming they enable something.

8. **Limitations**: Expanding the reference model dependency discussion with specific accuracy spreads and more detail on the three-reference ablation.

9. **references.bib**: Adding several key citations including Schaeffer's position paper on model collapse, foundational ordinal classification papers, and data source references like CCNet and C2PA.

10. **AI writing traces**: Checking through the document and removing em-dashes that create a particular stylistic pattern—most have been cleaned up across abstract, introduction, atlas, and discussion sections.

Now I'm adding more references on content provenance, diversity decline in synthetic data, and related work on synthetic data analysis and SPIN training.

But there's a discrepancy here. The Director's task describes a paper titled "Ordinal Depth Estimation for Recursive Language Model Generations: A Depth Degradation Atlas Across Scales and Strategies" with specific results like 75.2% mean accuracy and 14B scale validation, yet the actual files still contain the older title "How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints." The Director seems to be referencing a future or different version of the paper than what's currently in the files. Let me check what's actually present in the document. I'm noticing some significant gaps between what the Director described and what's actually in the paper files—the Director mentions a two-stage pipeline implementation and 14B scale validation, but the paper only discusses these as future work or limitations, and only includes 7-8B models. I should focus my review on what's genuinely present in the files rather than the planned features, and flag where the descriptions diverge.

Now I'm checking the specific revisions from the previous round to see what's been addressed. Several key citations have been added (Schaeffer 2025, McCullagh, Frank, Rennie, Wenzek), and some language has been tightened—like changing "universal and scale-variant" to "consistent in direction but scale-dependent in magnitude," and softening claims about the Discussion's implications. I'll continue through the remaining fixes to get a complete picture of what's changed. I'm moving on from the previous paper's revisions and need to carefully read through this new submission to understand its actual contributions and structure before drafting the review.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1cbe5d40-f6bf-444a-a7d9-7578b91c5cae",
  "isSidechain": false,
  "requestId": "req_011Cb7rG34f7DkhwqitsmE6B",
  "type": "assistant",
  "uuid": "0822141c-ab4b-4229-855d-31731ea6af1e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015S6urG2d3B4xbzFvF7RHrU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 133819,
      "cache_read_input_tokens": 11841,
      "output_tokens": 2307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 133819,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2307,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 133819,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 133819
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


### Assistant

_source line 118 · 2026-05-17T08:48:01.538Z_

论文已有显著修订。我注意到 Director 描述的标题与实际论文标题不同（"Ordinal Depth Estimation..." vs 实际 "How Deep Is Your Data?"），且描述中提到的 "two-stage pipeline", "14B scale", "prompted generation" 在当前论文文件中未出现。我将基于实际论文文件进行审查。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0822141c-ab4b-4229-855d-31731ea6af1e",
  "isSidechain": false,
  "requestId": "req_011Cb7rG34f7DkhwqitsmE6B",
  "type": "assistant",
  "uuid": "d0a7f295-3c9d-4808-bfcd-111e708fbfd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015S6urG2d3B4xbzFvF7RHrU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 133819,
      "cache_read_input_tokens": 11841,
      "output_tokens": 2307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 133819,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2307,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 133819,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 133819
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


### Tool call

_source line 119 · 2026-05-17T08:48:03.486Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__verify_references · `toolu_01NK3e6tAB9HzYsNtZHYtXEz`</summary>

```json
{
  "paper_dir": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d0a7f295-3c9d-4808-bfcd-111e708fbfd5",
  "isSidechain": false,
  "requestId": "req_011Cb7rG34f7DkhwqitsmE6B",
  "type": "assistant",
  "uuid": "a39bf090-3f3b-4dd4-ac69-2573adada870",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015S6urG2d3B4xbzFvF7RHrU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 133819,
      "cache_read_input_tokens": 11841,
      "output_tokens": 2307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 133819,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2307,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 133819,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 133819
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


### Tool call

_source line 120 · 2026-05-17T08:48:04.434Z_

<details open><summary>🔧 Tool call — WebSearch · `toolu_0193gSNE9NNTenZckpiZc6Fg`</summary>

```json
{
  "query": "RAID benchmark AI text detection multi-class 2024 2025"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a39bf090-3f3b-4dd4-ac69-2573adada870",
  "isSidechain": false,
  "requestId": "req_011Cb7rG34f7DkhwqitsmE6B",
  "type": "assistant",
  "uuid": "1056bf63-a49d-479b-90a8-db4e829b22b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015S6urG2d3B4xbzFvF7RHrU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 133819,
      "cache_read_input_tokens": 11841,
      "output_tokens": 2307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 133819,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2307,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 133819,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 133819
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


### Tool call

_source line 121 · 2026-05-17T08:48:05.246Z_

<details open><summary>🔧 Tool call — WebSearch · `toolu_012jrVnpsEvB182tXUwE6KJ8`</summary>

```json
{
  "query": "PHD \"paraphrased human detection\" benchmark LLM detection 2024"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1056bf63-a49d-479b-90a8-db4e829b22b2",
  "isSidechain": false,
  "requestId": "req_011Cb7rG34f7DkhwqitsmE6B",
  "type": "assistant",
  "uuid": "de4e178f-1984-4646-a77c-303f92fb3965",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015S6urG2d3B4xbzFvF7RHrU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 133819,
      "cache_read_input_tokens": 11841,
      "output_tokens": 2307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 133819,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2307,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 133819,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 133819
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

_source line 122 · 2026-05-17T08:49:13.941Z_

<details><summary>↩ Tool result · `toolu_01NK3e6tAB9HzYsNtZHYtXEz`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 60, \"total_citations\": 87, \"unique_cited_keys\": 58, \"orphan_bib\": 2, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 49, \"online_not_found\": 7, \"online_mismatch\": 4}, \"cross_check\": {\"orphan_bib\": [\"c2pa2024\", \"chen2024spin\"], \"missing_bib\": [], \"orphan_count\": 2, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"shumailov2024_nature\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"type\": \"inproceedings\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"dohmatob2024_demystified\", \"type\": \"inproceedings\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"alemohammad2024_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"type\": \"misc\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"type\": \"inproceedings\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"authors\": \"Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo\", \"year\": \"2024\", \"venue\": \"Proceedings of ICASSP\"}, {\"key\": \"knowledge_collapse2025\", \"type\": \"misc\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"authors\": \"Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven,...\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"sigma2026_spectral\", \"type\": \"misc\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"authors\": \"Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and P...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"synthetic_eggs2026\", \"type\": \"inproceedings\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"authors\": \"Schaffelder, Max and Gatt, Albert\", \"year\": \"2026\", \"venue\": \"Findings of ACL\"}, {\"key\": \"shi2025_closer_look\", \"type\": \"inproceedings\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"authors\": \"Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and ...\", \"year\": \"2025\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"yi2026_escaping_collapse\", \"type\": \"inproceedings\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"authors\": \"Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng\", \"year\": \"2026\", \"venue\": \"3rd DATA-FM Workshop at ICLR 2026\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"type\": \"inproceedings\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"authors\": \"Drayson, George and Yilmaz, Emine and Lampos, Vasileios\", \"year\": \"2025\", \"venue\": \"Findings of EMNLP\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"type\": \"misc\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminate...\", \"authors\": \"Bakshi, Soham and Chakraborty, Sunrit\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wang2026_contamination\", \"type\": \"misc\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive T...\", \"authors\": \"Wang, Kevin and Niu, Hongqian and Li, Didong\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"falahati2026_curated\", \"type\": \"misc\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferenc...\", \"authors\": \"Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wu2025_detection_survey\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"gehrmann2019_gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of ACL: System Demonstrations\"}, {\"key\": \"mitchell2023_detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"fast_detectgpt2024\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"binoculars2024\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"diveye2026\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research (TMLR)\"}, {\"key\": \"sadasivan2023_paraphrase\", \"type\": \"misc\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2023\", \"venue\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"type\": \"misc\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"authors\": \"Pudasaini, Shushanta and Miralles-Pech\\\\'uan, Luis and Lillis, David and Llorens ...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"type\": \"misc\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"type\": \"inproceedings\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"authors\": \"Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin ...\", \"year\": \"2025\", \"venue\": \"Findings of the Association for Computational Linguistics: ACL 2025\"}, {\"key\": \"uchendu2020_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of EMNLP\"}, {\"key\": \"editlens2026\", \"type\": \"inproceedings\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"authors\": \"Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit\", \"year\": \"2026\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"loki2025\", \"type\": \"inproceedings\", \"title\": \"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\", \"authors\": \"Ye, Junyan and Zhou, Baichuan and Huang, Zilong and Zhang, Junan and Bai, Tianyi...\", \"year\": \"2025\", \"venue\": \"Proceedings of ICLR (Spotlight)\"}, {\"key\": \"verma2024_ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of NAACL\"}, {\"key\": \"wang2024_m4_semeval\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2...\"}, {\"key\": \"yang2024_dnagpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"kirchenbauer2023_watermark\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"holtzman2020_nucleus\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"finlayson2024_closing\", \"type\": \"inproceedings\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"authors\": \"Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabh...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"type\": \"inproceedings\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"authors\": \"Garces Arias, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher,...\", \"year\": \"2025\", \"venue\": \"Proceedings of COLING\"}, {\"key\": \"wiher2022_decoding\", \"type\": \"article\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"authors\": \"Wiher, Gian and Meister, Clara and Cotterell, Ryan\", \"year\": \"2022\", \"venue\": \"Transactions of the Association for Computational Linguistics\"}, {\"key\": \"basu2021_mirostat\", \"type\": \"inproceedings\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"authors\": \"Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shiris...\", \"year\": \"2021\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"coral2020\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"cloc2025\", \"type\": \"inproceedings\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"authors\": \"Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting\", \"year\": \"2025\", \"venue\": \"Proceedings of CVPR\"}, {\"key\": \"hu2022lora\", \"type\": \"inproceedings\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"authors\": \"Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li,...\", \"year\": \"2022\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"he2021_deberta_v3\", \"type\": \"inproceedings\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"authors\": \"He, Pengcheng and Gao, Jianfeng and Chen, Weizhu\", \"year\": \"2023\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"liu2019_roberta\", \"type\": \"article\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"authors\": \"Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and...\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1907.11692\"}, {\"key\": \"dsir2023\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"qurating2024\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"type\": \"article\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"authors\": \"Sugiyama, Masashi and Krauledat, Matthias and M\\\\\\\"uller, Klaus-Robert\", \"year\": \"2007\", \"venue\": \"Journal of Machine Learning Research\"}, {\"key\": \"qwen2.5\", \"type\": \"misc\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"llama3\", \"type\": \"misc\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"schaeffer2025\", \"type\": \"article\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"authors\": \"Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Alvan Caleb and Koyejo, Sanmi\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2503.03150\"}, {\"key\": \"frank2001\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of ECML\"}, {\"key\": \"rennie2005\", \"type\": \"inproceedings\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"authors\": \"Rennie, Jason D. M. and Srebro, Nathan\", \"year\": \"2005\", \"venue\": \"Proceedings of IJCAI Workshop on Advances in Preference Handling\"}, {\"key\": \"c2pa2024\", \"type\": \"misc\", \"title\": \"C2PA Technical Specification v2.1\", \"authors\": \"Coalition for Content Provenance and Authenticity\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"mccullagh1980_ordinal\", \"type\": \"article\", \"title\": \"Regression Models for Ordinal Data\", \"authors\": \"McCullagh, Peter\", \"year\": \"1980\", \"venue\": \"Journal of the Royal Statistical Society: Series B\"}, {\"key\": \"wenzek2020_ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of LREC\"}, {\"key\": \"guo2024curious\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of NAACL\"}, {\"key\": \"padmakumar2024diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"briesch2024selfconsuming\", \"type\": \"misc\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"authors\": \"Briesch, Martin and Sobania, Dominik and Rothlauf, Franz\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"chen2024spin\", \"type\": \"inproceedings\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"authors\": \"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"seddik2024synthetic\", \"type\": \"misc\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"authors\": \"Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pie...\", \"year\": \"2024\", \"venue\": \"\"}], \"tex_citations\": [{\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"citet\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"seddik2024synthetic\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"yi2026_escaping_collapse\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"wenzek2020_ccnet\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"marchi2024_heat_death\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"wang2026_contamination\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"knowledge_collapse2025\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_demystified\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"guo2024curious\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"briesch2024selfconsuming\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"padmakumar2024diversity\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"sigma2026_spectral\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"synthetic_eggs2026\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"schaeffer2025\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"citet\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citep\"}, {\"key\": \"wu2025_detection_survey\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"gehrmann2019_gltr\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"verma2024_ghostbuster\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"yang2024_dnagpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pu2026_generator_barrier\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"wang2024_m4_semeval\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"editlens2026\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"citet\"}, {\"key\": \"loki2025\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"mohamed2025_broken_telephone\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"citet\"}, {\"key\": \"mccullagh1980_ordinal\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"frank2001\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"rennie2005\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"coral2020\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"finlayson2024_closing\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"wiher2022_decoding\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"basu2021_mirostat\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"method.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"hu2022lora\", \"file\": \"method.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 62, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 164, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"qwen2.5\", \"file\": \"generalization.tex\", \"line\": 100, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"generalization.tex\", \"line\": 100, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"discussion.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"shi2025_closer_look\", \"file\": \"discussion.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dsir2023\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"qurating2024\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"conclusion.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"conclusion.tex\", \"line\": 29, \"command\": \"citet\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"conclusion.tex\", \"line\": 50, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"conclusion.tex\", \"line\": 51, \"command\": \"citet\"}, {\"key\": \"he2021_deberta_v3\", \"file\": \"section_appendix.tex\", \"line\": 161, \"command\": \"cite\"}, {\"key\": \"liu2019_roberta\", \"file\": \"section_appendix.tex\", \"line\": 161, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"section_appendix.tex\", \"line\": 187, \"command\": \"cite\"}, {\"key\": \"dsir2023\", \"file\": \"section_appendix.tex\", \"line\": 494, \"command\": \"cite\"}, {\"key\": \"qurating2024\", \"file\": \"section_appendix.tex\", \"line\": 494, \"command\": \"cite\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"file\": \"section_appendix.tex\", \"line\": 497, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"section_appendix.tex\", \"line\": 501, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"section_appendix.tex\", \"line\": 502, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"shumailov2024_nature\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_demystified\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Model Collapse Demystified: The Case of Regression\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"alemohammad2024_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"knowledge_collapse2025\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"status\": \"not_found\", \"confidence\": 0.288, \"matched_title\": \"A predictive human model of language challenges traditional views in linguistics and pretrained transformer research\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.29 below threshold 0.82\"}, {\"key\": \"sigma2026_spectral\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthetic_eggs2026\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shi2025_closer_look\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yi2026_escaping_collapse\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Machine-generated text detection prevents language model collapse\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2026_contamination\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"falahati2026_curated\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences\", \"status\": \"not_found\", \"confidence\": 0.0, \"matched_title\": \"\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"no results from OpenAlex\"}, {\"key\": \"wu2025_detection_survey\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gehrmann2019_gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mitchell2023_detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"fast_detectgpt2024\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars2024\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye2026\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sadasivan2023_paraphrase\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can AI-Generated Text be Reliably Detected?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu2020_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"editlens2026\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"loki2025\", \"title\": \"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"verma2024_ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2024_m4_semeval\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yang2024_dnagpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"kirchenbauer2023_watermark\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"holtzman2020_nucleus\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"finlayson2024_closing\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Closing the Curious Case of Neural Text Degeneration\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=garces arias vs api=arias\"], \"note\": \"\"}, {\"key\": \"wiher2022_decoding\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On Decoding Strategies for Neural Text Generators\", \"matched_year\": \"2022\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"basu2021_mirostat\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"coral2020\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cloc2025\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"hu2022lora\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"he2021_deberta_v3\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"matched_year\": \"2021\", \"mismatch_fields\": [\"year: bib=2023 vs api=2021\"], \"note\": \"\"}, {\"key\": \"liu2019_roberta\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"status\": \"not_found\", \"confidence\": 0.495, \"matched_title\": \"Use of Bidirectional Encoder Representations from Transformers (BERT) and Robustly Optimized Bert Pretraining Approach (RoBERTa) for Nepali News Classification\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"dsir2023\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating2024\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"matched_year\": \"2007\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qwen2.5\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"status\": \"not_found\", \"confidence\": 0.333, \"matched_title\": \"Can Open Large Language Models Catch Vulnerabilities?\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.33 below threshold 0.82\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"schaeffer2025\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Position: Model Collapse Does Not Mean What You Think\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank2001\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"rennie2005\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"status\": \"not_found\", \"confidence\": 0.373, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.37 below threshold 0.82\"}, {\"key\": \"c2pa2024\", \"title\": \"C2PA Technical Specification v2.1\", \"status\": \"not_found\", \"confidence\": 0.304, \"matched_title\": \"Protecting Context and Prompts: Deterministic Security for Non-Deterministic AI\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.30 below threshold 0.82\"}, {\"key\": \"mccullagh1980_ordinal\", \"title\": \"Regression Models for Ordinal Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Regression Models for Ordinal Data\", \"matched_year\": \"1980\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wenzek2020_ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"guo2024curious\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"padmakumar2024diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"briesch2024selfconsuming\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"chen2024spin\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"seddik2024synthetic\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a39bf090-3f3b-4dd4-ac69-2573adada870",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "afb57afc-eddb-42e5-b564-57cd7d7e5712",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 60, \\\"total_citations\\\": 87, \\\"unique_cited_keys\\\": 58, \\\"orphan_bib\\\": 2, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 49, \\\"online_not_found\\\": 7, \\\"online_mismatch\\\": 4}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [\\\"c2pa2024\\\", \\\"chen2024spin\\\"], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 2, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"authors\\\": \\\"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"authors\\\": \\\"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"authors\\\": \\\"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"authors\\\": \\\"Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICASSP\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\\\", \\\"authors\\\": \\\"Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven,...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"authors\\\": \\\"Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and P...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"authors\\\": \\\"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of ACL\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"authors\\\": \\\"Schaffelder, Max and Gatt, Albert\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Findings of ACL\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"authors\\\": \\\"Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and ...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"authors\\\": \\\"Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"3rd DATA-FM Workshop at ICLR 2026\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"authors\\\": \\\"Drayson, George and Yilmaz, Emine and Lampos, Vasileios\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Findings of EMNLP\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminate...\\\", \\\"authors\\\": \\\"Bakshi, Soham and Chakraborty, Sunrit\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive T...\\\", \\\"authors\\\": \\\"Wang, Kevin and Niu, Hongqian and Li, Didong\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferenc...\\\", \\\"authors\\\": \\\"Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"authors\\\": \\\"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Computational Linguistics\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"authors\\\": \\\"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of ACL: System Demonstrations\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"authors\\\": \\\"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"authors\\\": \\\"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"authors\\\": \\\"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Basani, Advik Raj and Chen, Pin-Yu\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research (TMLR)\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"authors\\\": \\\"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"authors\\\": \\\"Pudasaini, Shushanta and Miralles-Pech\\\\\\\\'uan, Luis and Lillis, David and Llorens ...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"authors\\\": \\\"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"authors\\\": \\\"Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin ...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Findings of the Association for Computational Linguistics: ACL 2025\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"authors\\\": \\\"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of EMNLP\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"authors\\\": \\\"Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"loki2025\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\\\", \\\"authors\\\": \\\"Ye, Junyan and Zhou, Baichuan and Huang, Zilong and Zhang, Junan and Bai, Tianyi...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of ICLR (Spotlight)\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"authors\\\": \\\"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of NAACL\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"authors\\\": \\\"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2...\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"authors\\\": \\\"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"authors\\\": \\\"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabh...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"authors\\\": \\\"Garces Arias, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher,...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of COLING\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"authors\\\": \\\"Wiher, Gian and Meister, Clara and Cotterell, Ryan\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"Transactions of the Association for Computational Linguistics\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"authors\\\": \\\"Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shiris...\\\", \\\"year\\\": \\\"2021\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"authors\\\": \\\"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Pattern Recognition Letters\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"authors\\\": \\\"Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of CVPR\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"authors\\\": \\\"Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li,...\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"authors\\\": \\\"He, Pengcheng and Gao, Jianfeng and Chen, Weizhu\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"RoBERTa: A Robustly Optimized BERT Pretraining Approach\\\", \\\"authors\\\": \\\"Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:1907.11692\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"authors\\\": \\\"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of NeurIPS\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"authors\\\": \\\"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"authors\\\": \\\"Sugiyama, Masashi and Krauledat, Matthias and M\\\\\\\\\\\\\\\"uller, Klaus-Robert\\\", \\\"year\\\": \\\"2007\\\", \\\"venue\\\": \\\"Journal of Machine Learning Research\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Qwen2.5: A Party of Foundation Models\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"authors\\\": \\\"Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Alvan Caleb and Koyejo, Sanmi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2503.03150\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"authors\\\": \\\"Frank, Eibe and Hall, Mark\\\", \\\"year\\\": \\\"2001\\\", \\\"venue\\\": \\\"Proceedings of ECML\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\\\", \\\"authors\\\": \\\"Rennie, Jason D. M. and Srebro, Nathan\\\", \\\"year\\\": \\\"2005\\\", \\\"venue\\\": \\\"Proceedings of IJCAI Workshop on Advances in Preference Handling\\\"}, {\\\"key\\\": \\\"c2pa2024\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"C2PA Technical Specification v2.1\\\", \\\"authors\\\": \\\"Coalition for Content Provenance and Authenticity\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"authors\\\": \\\"McCullagh, Peter\\\", \\\"year\\\": \\\"1980\\\", \\\"venue\\\": \\\"Journal of the Royal Statistical Society: Series B\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"authors\\\": \\\"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of LREC\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"authors\\\": \\\"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\\\\\'e\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of NAACL\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"authors\\\": \\\"Padmakumar, Vishakh and He, He\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICLR\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"authors\\\": \\\"Briesch, Martin and Sobania, Dominik and Rothlauf, Franz\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"chen2024spin\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"authors\\\": \\\"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of ICML\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"authors\\\": \\\"Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pie...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 9, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citep\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"loki2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 18, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 22, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 27, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 27, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 27, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 27, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 27, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 24, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 33, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 104, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 104, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"atlas.tex\\\", \\\"line\\\": 62, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"atlas.tex\\\", \\\"line\\\": 164, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 10, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 100, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"file\\\": \\\"generalization.tex\\\", \\\"line\\\": 100, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 50, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"file\\\": \\\"conclusion.tex\\\", \\\"line\\\": 51, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 161, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 161, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 187, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 494, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 494, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 497, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 501, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"file\\\": \\\"section_appendix.tex\\\", \\\"line\\\": 502, \\\"command\\\": \\\"cite\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"shumailov2024_nature\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2024_tale_of_tails\\\", \\\"title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Tale of Tails: Model Collapse as a Change of Scaling Laws\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2025_strong_collapse\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Strong Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dohmatob2024_demystified\\\", \\\"title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Model Collapse Demystified: The Case of Regression\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"alemohammad2024_mad\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Consuming Generative Models go MAD\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=alemohammad vs api=casco-rodriguez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gerstgrasser2024_accumulate\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"marchi2024_heat_death\\\", \\\"title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Heat Death of Generative Models in Closed-Loop Learning\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"knowledge_collapse2025\\\", \\\"title\\\": \\\"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.288, \\\"matched_title\\\": \\\"A predictive human model of language challenges traditional views in linguistics and pretrained transformer research\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.29 below threshold 0.82\\\"}, {\\\"key\\\": \\\"sigma2026_spectral\\\", \\\"title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SIGMA: Scalable Spectral Insights for LLM Model Collapse\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mohamed2025_broken_telephone\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"synthetic_eggs2026\\\", \\\"title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"shi2025_closer_look\\\", \\\"title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"yi2026_escaping_collapse\\\", \\\"title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"drayson2025_detection_prevents_collapse\\\", \\\"title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Machine-generated text detection prevents language model collapse\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bakshi2026_collapse_improvement\\\", \\\"title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2026_contamination\\\", \\\"title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"falahati2026_curated\\\", \\\"title\\\": \\\"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.0, \\\"matched_title\\\": \\\"\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"no results from OpenAlex\\\"}, {\\\"key\\\": \\\"wu2025_detection_survey\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"gehrmann2019_gltr\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mitchell2023_detectgpt\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.382, \\\"matched_title\\\": \\\"Regulating ChatGPT and other Large Generative AI Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.38 below threshold 0.82\\\"}, {\\\"key\\\": \\\"fast_detectgpt2024\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"binoculars2024\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"diveye2026\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sadasivan2023_paraphrase\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Can AI-Generated Text be Reliably Detected?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pudasaini2026_detection_fails\\\", \\\"title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pu2026_generator_barrier\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"bevendorff2025_two_paradigms\\\", \\\"title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"uchendu2020_attribution\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"editlens2026\\\", \\\"title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"EditLens: Quantifying the Extent of AI Editing in Text\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"loki2025\\\", \\\"title\\\": \\\"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"verma2024_ghostbuster\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wang2024_m4_semeval\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"yang2024_dnagpt\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"kirchenbauer2023_watermark\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Watermark for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"holtzman2020_nucleus\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"finlayson2024_closing\\\", \\\"title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Closing the Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"garces_arias2025_decoding_decoded\\\", \\\"title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=garces arias vs api=arias\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wiher2022_decoding\\\", \\\"title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"On Decoding Strategies for Neural Text Generators\\\", \\\"matched_year\\\": \\\"2022\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"basu2021_mirostat\\\", \\\"title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"coral2020\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Rank consistent ordinal regression for neural networks with application to age estimation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"cloc2025\\\", \\\"title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"hu2022lora\\\", \\\"title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LoRA: Low-Rank Adaptation of Large Language Models\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"he2021_deberta_v3\\\", \\\"title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [\\\"year: bib=2023 vs api=2021\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"liu2019_roberta\\\", \\\"title\\\": \\\"RoBERTa: A Robustly Optimized BERT Pretraining Approach\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.495, \\\"matched_title\\\": \\\"Use of Bidirectional Encoder Representations from Transformers (BERT) and Robustly Optimized Bert Pretraining Approach (RoBERTa) for Nepali News Classification\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.50 below threshold 0.82\\\"}, {\\\"key\\\": \\\"dsir2023\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qurating2024\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"sugiyama2007_importance_weighting\\\", \\\"title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Covariate Shift Adaptation by Importance Weighted Cross Validation\\\", \\\"matched_year\\\": \\\"2007\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen2.5\\\", \\\"title\\\": \\\"Qwen2.5: A Party of Foundation Models\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.333, \\\"matched_title\\\": \\\"Can Open Large Language Models Catch Vulnerabilities?\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.33 below threshold 0.82\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"schaeffer2025\\\", \\\"title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Position: Model Collapse Does Not Mean What You Think\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank2001\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"matched_year\\\": \\\"2001\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"rennie2005\\\", \\\"title\\\": \\\"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.373, \\\"matched_title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.37 below threshold 0.82\\\"}, {\\\"key\\\": \\\"c2pa2024\\\", \\\"title\\\": \\\"C2PA Technical Specification v2.1\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.304, \\\"matched_title\\\": \\\"Protecting Context and Prompts: Deterministic Security for Non-Deterministic AI\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.30 below threshold 0.82\\\"}, {\\\"key\\\": \\\"mccullagh1980_ordinal\\\", \\\"title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Regression Models for Ordinal Data\\\", \\\"matched_year\\\": \\\"1980\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wenzek2020_ccnet\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"guo2024curious\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"padmakumar2024diversity\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"briesch2024selfconsuming\\\", \\\"title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"chen2024spin\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"seddik2024synthetic\\\", \\\"title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 60, \"total_citations\": 87, \"unique_cited_keys\": 58, \"orphan_bib\": 2, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 49, \"online_not_found\": 7, \"online_mismatch\": 4}, \"cross_check\": {\"orphan_bib\": [\"c2pa2024\", \"chen2024spin\"], \"missing_bib\": [], \"orphan_count\": 2, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"shumailov2024_nature\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"type\": \"inproceedings\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Yang, Pu and Charton, Francois and Kempe, ...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"dohmatob2024_demystified\", \"type\": \"inproceedings\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Kempe, Julia\", \"year\": \"2024\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"alemohammad2024_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"type\": \"misc\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"type\": \"inproceedings\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"authors\": \"Marchi, Matteo and Soatto, Stefano and Chaudhari, Pratik and Tabuada, Paulo\", \"year\": \"2024\", \"venue\": \"Proceedings of ICASSP\"}, {\"key\": \"knowledge_collapse2025\", \"type\": \"misc\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"authors\": \"Keisha, Figarri and Wu, Zekun and Wang, Ze and Koshiyama, Adriano and Treleaven,...\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"sigma2026_spectral\", \"type\": \"misc\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"authors\": \"Gu, Yi and Pang, Lingyou and Ye, Xiangkun and Wang, Tianyu and Lin, Jianyu and P...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of ACL\"}, {\"key\": \"synthetic_eggs2026\", \"type\": \"inproceedings\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"authors\": \"Schaffelder, Max and Gatt, Albert\", \"year\": \"2026\", \"venue\": \"Findings of ACL\"}, {\"key\": \"shi2025_closer_look\", \"type\": \"inproceedings\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"authors\": \"Shi, Lianghe and Wu, Meng and Zhang, Huijie and Zhang, Zekai and Tao, Molei and ...\", \"year\": \"2025\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"yi2026_escaping_collapse\", \"type\": \"inproceedings\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"authors\": \"Yi, Bingji and Liu, Qiyuan and Cheng, Yuwei and Xu, Haifeng\", \"year\": \"2026\", \"venue\": \"3rd DATA-FM Workshop at ICLR 2026\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"type\": \"inproceedings\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"authors\": \"Drayson, George and Yilmaz, Emine and Lampos, Vasileios\", \"year\": \"2025\", \"venue\": \"Findings of EMNLP\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"type\": \"misc\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminate...\", \"authors\": \"Bakshi, Soham and Chakraborty, Sunrit\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wang2026_contamination\", \"type\": \"misc\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive T...\", \"authors\": \"Wang, Kevin and Niu, Hongqian and Li, Didong\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"falahati2026_curated\", \"type\": \"misc\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferenc...\", \"authors\": \"Falahati, Ali and Mohammadi Amiri, Mohammad and Larson, Kate and Golab, Lukasz\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"wu2025_detection_survey\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"gehrmann2019_gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of ACL: System Demonstrations\"}, {\"key\": \"mitchell2023_detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"fast_detectgpt2024\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"binoculars2024\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"diveye2026\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research (TMLR)\"}, {\"key\": \"sadasivan2023_paraphrase\", \"type\": \"misc\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2023\", \"venue\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"type\": \"misc\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"authors\": \"Pudasaini, Shushanta and Miralles-Pech\\\\'uan, Luis and Lillis, David and Llorens ...\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"type\": \"misc\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"type\": \"inproceedings\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"authors\": \"Bevendorff, Janek and Wiegmann, Matti and Richter, Emmelie and Potthast, Martin ...\", \"year\": \"2025\", \"venue\": \"Findings of the Association for Computational Linguistics: ACL 2025\"}, {\"key\": \"uchendu2020_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of EMNLP\"}, {\"key\": \"editlens2026\", \"type\": \"inproceedings\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"authors\": \"Thai, Katherine and Emi, Bradley and Masrour, Elyas and Iyyer, Mohit\", \"year\": \"2026\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"loki2025\", \"type\": \"inproceedings\", \"title\": \"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\", \"authors\": \"Ye, Junyan and Zhou, Baichuan and Huang, Zilong and Zhang, Junan and Bai, Tianyi...\", \"year\": \"2025\", \"venue\": \"Proceedings of ICLR (Spotlight)\"}, {\"key\": \"verma2024_ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Klein, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of NAACL\"}, {\"key\": \"wang2024_m4_semeval\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the 18th International Workshop on Semantic Evaluation (SemEval-2...\"}, {\"key\": \"yang2024_dnagpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"kirchenbauer2023_watermark\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"holtzman2020_nucleus\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"finlayson2024_closing\", \"type\": \"inproceedings\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"authors\": \"Finlayson, Matthew and Hewitt, John and Koller, Alexander and Swayamdipta, Swabh...\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"type\": \"inproceedings\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"authors\": \"Garces Arias, Esteban and Li, Meimingwei and Heumann, Christian and Assenmacher,...\", \"year\": \"2025\", \"venue\": \"Proceedings of COLING\"}, {\"key\": \"wiher2022_decoding\", \"type\": \"article\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"authors\": \"Wiher, Gian and Meister, Clara and Cotterell, Ryan\", \"year\": \"2022\", \"venue\": \"Transactions of the Association for Computational Linguistics\"}, {\"key\": \"basu2021_mirostat\", \"type\": \"inproceedings\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"authors\": \"Basu, Sourya and Ramachandran, Govardana Sachitanandam and Keskar, Nitish Shiris...\", \"year\": \"2021\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"coral2020\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"cloc2025\", \"type\": \"inproceedings\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"authors\": \"Pitawela, Dileepa and Carneiro, Gustavo and Chen, Hsiang-Ting\", \"year\": \"2025\", \"venue\": \"Proceedings of CVPR\"}, {\"key\": \"hu2022lora\", \"type\": \"inproceedings\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"authors\": \"Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li,...\", \"year\": \"2022\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"he2021_deberta_v3\", \"type\": \"inproceedings\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"authors\": \"He, Pengcheng and Gao, Jianfeng and Chen, Weizhu\", \"year\": \"2023\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"liu2019_roberta\", \"type\": \"article\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"authors\": \"Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and...\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1907.11692\"}, {\"key\": \"dsir2023\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Proceedings of NeurIPS\"}, {\"key\": \"qurating2024\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"type\": \"article\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"authors\": \"Sugiyama, Masashi and Krauledat, Matthias and M\\\\\\\"uller, Klaus-Robert\", \"year\": \"2007\", \"venue\": \"Journal of Machine Learning Research\"}, {\"key\": \"qwen2.5\", \"type\": \"misc\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"\"}, {\"key\": \"llama3\", \"type\": \"misc\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"schaeffer2025\", \"type\": \"article\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"authors\": \"Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Alvan Caleb and Koyejo, Sanmi\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2503.03150\"}, {\"key\": \"frank2001\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of ECML\"}, {\"key\": \"rennie2005\", \"type\": \"inproceedings\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"authors\": \"Rennie, Jason D. M. and Srebro, Nathan\", \"year\": \"2005\", \"venue\": \"Proceedings of IJCAI Workshop on Advances in Preference Handling\"}, {\"key\": \"c2pa2024\", \"type\": \"misc\", \"title\": \"C2PA Technical Specification v2.1\", \"authors\": \"Coalition for Content Provenance and Authenticity\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"mccullagh1980_ordinal\", \"type\": \"article\", \"title\": \"Regression Models for Ordinal Data\", \"authors\": \"McCullagh, Peter\", \"year\": \"1980\", \"venue\": \"Journal of the Royal Statistical Society: Series B\"}, {\"key\": \"wenzek2020_ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of LREC\"}, {\"key\": \"guo2024curious\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of NAACL\"}, {\"key\": \"padmakumar2024diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of ICLR\"}, {\"key\": \"briesch2024selfconsuming\", \"type\": \"misc\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"authors\": \"Briesch, Martin and Sobania, Dominik and Rothlauf, Franz\", \"year\": \"2024\", \"venue\": \"\"}, {\"key\": \"chen2024spin\", \"type\": \"inproceedings\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"authors\": \"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\", \"year\": \"2024\", \"venue\": \"Proceedings of ICML\"}, {\"key\": \"seddik2024synthetic\", \"type\": \"misc\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"authors\": \"Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pie...\", \"year\": \"2024\", \"venue\": \"\"}], \"tex_citations\": [{\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"introduction.tex\", \"line\": 9, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"introduction.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"introduction.tex\", \"line\": 11, \"command\": \"citet\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"seddik2024synthetic\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"citet\"}, {\"key\": \"alemohammad2024_mad\", \"file\": \"related_work.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"yi2026_escaping_collapse\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"wenzek2020_ccnet\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"marchi2024_heat_death\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"wang2026_contamination\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"knowledge_collapse2025\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"dohmatob2024_demystified\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"guo2024curious\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"briesch2024selfconsuming\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"padmakumar2024diversity\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"sigma2026_spectral\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"synthetic_eggs2026\", \"file\": \"related_work.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"schaeffer2025\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"citet\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citep\"}, {\"key\": \"wu2025_detection_survey\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"mitchell2023_detectgpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"binoculars2024\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"gehrmann2019_gltr\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"verma2024_ghostbuster\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"yang2024_dnagpt\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"pu2026_generator_barrier\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"cite\"}, {\"key\": \"wang2024_m4_semeval\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"editlens2026\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"citet\"}, {\"key\": \"loki2025\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"mohamed2025_broken_telephone\", \"file\": \"related_work.tex\", \"line\": 18, \"command\": \"citet\"}, {\"key\": \"mccullagh1980_ordinal\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"cite\"}, {\"key\": \"frank2001\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"rennie2005\", \"file\": \"related_work.tex\", \"line\": 22, \"command\": \"citet\"}, {\"key\": \"coral2020\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"finlayson2024_closing\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"wiher2022_decoding\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"basu2021_mirostat\", \"file\": \"related_work.tex\", \"line\": 27, \"command\": \"cite\"}, {\"key\": \"holtzman2020_nucleus\", \"file\": \"method.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"hu2022lora\", \"file\": \"method.tex\", \"line\": 33, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"method.tex\", \"line\": 104, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 62, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"atlas.tex\", \"line\": 164, \"command\": \"cite\"}, {\"key\": \"coral2020\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"diveye2026\", \"file\": \"generalization.tex\", \"line\": 10, \"command\": \"cite\"}, {\"key\": \"qwen2.5\", \"file\": \"generalization.tex\", \"line\": 100, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"generalization.tex\", \"line\": 100, \"command\": \"cite\"}, {\"key\": \"shumailov2024_nature\", \"file\": \"discussion.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"shi2025_closer_look\", \"file\": \"discussion.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"dsir2023\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"qurating2024\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"file\": \"discussion.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"sadasivan2023_paraphrase\", \"file\": \"conclusion.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"file\": \"conclusion.tex\", \"line\": 29, \"command\": \"citet\"}, {\"key\": \"pudasaini2026_detection_fails\", \"file\": \"conclusion.tex\", \"line\": 50, \"command\": \"cite\"}, {\"key\": \"falahati2026_curated\", \"file\": \"conclusion.tex\", \"line\": 51, \"command\": \"citet\"}, {\"key\": \"he2021_deberta_v3\", \"file\": \"section_appendix.tex\", \"line\": 161, \"command\": \"cite\"}, {\"key\": \"liu2019_roberta\", \"file\": \"section_appendix.tex\", \"line\": 161, \"command\": \"cite\"}, {\"key\": \"cloc2025\", \"file\": \"section_appendix.tex\", \"line\": 187, \"command\": \"cite\"}, {\"key\": \"dsir2023\", \"file\": \"section_appendix.tex\", \"line\": 494, \"command\": \"cite\"}, {\"key\": \"qurating2024\", \"file\": \"section_appendix.tex\", \"line\": 494, \"command\": \"cite\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"file\": \"section_appendix.tex\", \"line\": 497, \"command\": \"cite\"}, {\"key\": \"kirchenbauer2023_watermark\", \"file\": \"section_appendix.tex\", \"line\": 501, \"command\": \"cite\"}, {\"key\": \"uchendu2020_attribution\", \"file\": \"section_appendix.tex\", \"line\": 502, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"shumailov2024_nature\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_tale_of_tails\", \"title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Tale of Tails: Model Collapse as a Change of Scaling Laws\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2025_strong_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dohmatob2024_demystified\", \"title\": \"Model Collapse Demystified: The Case of Regression\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Model Collapse Demystified: The Case of Regression\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"alemohammad2024_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"gerstgrasser2024_accumulate\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"marchi2024_heat_death\", \"title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Heat Death of Generative Models in Closed-Loop Learning\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"knowledge_collapse2025\", \"title\": \"Knowledge Collapse in LLMs: When Fluency Survives but Facts Fail under Recursive Synthetic Training\", \"status\": \"not_found\", \"confidence\": 0.288, \"matched_title\": \"A predictive human model of language challenges traditional views in linguistics and pretrained transformer research\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.29 below threshold 0.82\"}, {\"key\": \"sigma2026_spectral\", \"title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SIGMA: Scalable Spectral Insights for LLM Model Collapse\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mohamed2025_broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthetic_eggs2026\", \"title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Synthetic Eggs in Many Baskets: The Impact of Synthetic Data Diversity on LLM Fine-Tuning\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"shi2025_closer_look\", \"title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yi2026_escaping_collapse\", \"title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Escaping Model Collapse via Synthetic Data Verification: Near-term Improvements and Long-term Convergence\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"drayson2025_detection_prevents_collapse\", \"title\": \"Machine-generated text detection prevents language model collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Machine-generated text detection prevents language model collapse\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bakshi2026_collapse_improvement\", \"title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"From Collapse to Improvement: Statistical Perspectives on the Evolutionary Dynamics of Iterative Training on Contaminated Sources\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2026_contamination\", \"title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can Generative Artificial Intelligence Survive Data Contamination? Theoretical Guarantees under Contaminated Recursive Training\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"falahati2026_curated\", \"title\": \"Curated Synthetic Data Doesn't Have to Collapse: A Theoretical Study of Generative Retraining with Pluralistic Preferences\", \"status\": \"not_found\", \"confidence\": 0.0, \"matched_title\": \"\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"no results from OpenAlex\"}, {\"key\": \"wu2025_detection_survey\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"gehrmann2019_gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"mitchell2023_detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"fast_detectgpt2024\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars2024\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye2026\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sadasivan2023_paraphrase\", \"title\": \"Can AI-Generated Text be Reliably Detected?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Can AI-Generated Text be Reliably Detected?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pudasaini2026_detection_fails\", \"title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Why AI-Generated Text Detection Fails: Evidence from Explainable AI Beyond Benchmark Accuracy\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pu2026_generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"bevendorff2025_two_paradigms\", \"title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Two Paradigms of LLM Detection: Authorship Attribution vs. Authorship Verification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu2020_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"editlens2026\", \"title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"EditLens: Quantifying the Extent of AI Editing in Text\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"loki2025\", \"title\": \"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LOKI: A Comprehensive Synthetic Data Detection Benchmark using Large Multimodal Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"verma2024_ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wang2024_m4_semeval\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"yang2024_dnagpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"kirchenbauer2023_watermark\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"holtzman2020_nucleus\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"finlayson2024_closing\", \"title\": \"Closing the Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Closing the Curious Case of Neural Text Degeneration\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"garces_arias2025_decoding_decoded\", \"title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Decoding Decoded: Understanding Hyperparameter Effects in Open-Ended Text Generation\", \"matched_year\": \"2024\", \"mismatch_fields\": [\"first_author: bib=garces arias vs api=arias\"], \"note\": \"\"}, {\"key\": \"wiher2022_decoding\", \"title\": \"On Decoding Strategies for Neural Text Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"On Decoding Strategies for Neural Text Generators\", \"matched_year\": \"2022\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"basu2021_mirostat\", \"title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mirostat: A Neural Text Decoding Algorithm that Directly Controls Perplexity\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"coral2020\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cloc2025\", \"title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CLOC: Contrastive Learning for Ordinal Classification with Multi-Margin N-pair Loss\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"hu2022lora\", \"title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LoRA: Low-Rank Adaptation of Large Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"he2021_deberta_v3\", \"title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"DeBERTaV3: Improving DeBERTa using ELECTRA-Style Pre-Training with Gradient-Disentangled Embedding Sharing\", \"matched_year\": \"2021\", \"mismatch_fields\": [\"year: bib=2023 vs api=2021\"], \"note\": \"\"}, {\"key\": \"liu2019_roberta\", \"title\": \"RoBERTa: A Robustly Optimized BERT Pretraining Approach\", \"status\": \"not_found\", \"confidence\": 0.495, \"matched_title\": \"Use of Bidirectional Encoder Representations from Transformers (BERT) and Robustly Optimized Bert Pretraining Approach (RoBERTa) for Nepali News Classification\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"dsir2023\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating2024\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"sugiyama2007_importance_weighting\", \"title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Covariate Shift Adaptation by Importance Weighted Cross Validation\", \"matched_year\": \"2007\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qwen2.5\", \"title\": \"Qwen2.5: A Party of Foundation Models\", \"status\": \"not_found\", \"confidence\": 0.333, \"matched_title\": \"Can Open Large Language Models Catch Vulnerabilities?\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.33 below threshold 0.82\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"schaeffer2025\", \"title\": \"Position: Model Collapse Does Not Mean What You Think\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Position: Model Collapse Does Not Mean What You Think\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank2001\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"rennie2005\", \"title\": \"Loss Functions for Preference Levels: Regression with Discrete Ordered Labels\", \"status\": \"not_found\", \"confidence\": 0.373, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.37 below threshold 0.82\"}, {\"key\": \"c2pa2024\", \"title\": \"C2PA Technical Specification v2.1\", \"status\": \"not_found\", \"confidence\": 0.304, \"matched_title\": \"Protecting Context and Prompts: Deterministic Security for Non-Deterministic AI\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.30 below threshold 0.82\"}, {\"key\": \"mccullagh1980_ordinal\", \"title\": \"Regression Models for Ordinal Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Regression Models for Ordinal Data\", \"matched_year\": \"1980\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wenzek2020_ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"guo2024curious\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"padmakumar2024diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"briesch2024selfconsuming\", \"title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"chen2024spin\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"seddik2024synthetic\", \"title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "a39bf090-3f3b-4dd4-ac69-2573adada870",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Runtime record

_source line 123_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Review Assignment: R2 — Novelty & Related Work  **Venue:** EMNLP 2026 Main (via ACL Rolling Review) **Paper:** \"Ordinal Depth Estimation for Recursive Language Model Generations: A…",
  "leafUuid": "afb57afc-eddb-42e5-b564-57cd7d7e5712",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 124_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Tool result

_source line 125 · 2026-05-17T08:49:19.787Z_

<details><summary>↩ Tool result · `toolu_0193gSNE9NNTenZckpiZc6Fg`</summary>

```text
Web search results for query: "RAID benchmark AI text detection multi-class 2024 2025"

Links: [{"title":"GitHub - liamdugan/raid: RAID is the largest and most challenging benchmark for AI-generated text detection. (ACL 2024) · GitHub","url":"https://github.com/liamdugan/raid"},{"title":"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors | Request PDF","url":"https://www.researchgate.net/publication/384214327_RAID_A_Shared_Benchmark_for_Robust_Evaluation_of_Machine-Generated_Text_Detectors"},{"title":"[2405.07940] RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors","url":"https://arxiv.org/abs/2405.07940"},{"title":"liamdugan/raid · Datasets at Hugging Face","url":"https://huggingface.co/datasets/liamdugan/raid"},{"title":"RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors","url":"https://arxiv.org/html/2405.07940v1"},{"title":"Review - RAID | Benchmark for machine-generated text review | Henry Zhu","url":"https://maknee.github.io/blog/2024/RAID-most-challenging-benchmark-for-machine-generated-text-detectors/"},{"title":"It’s AI benchmarks It’s AI official website March 2025 1 Introduction","url":"https://its-ai.org/benchmarks.pdf"},{"title":"RAID: A Shared Benchmark for Robust Evaluation of ...","url":"https://aclanthology.org/2024.acl-long.674.pdf"},{"title":"RAID Benchmark","url":"https://raid-bench.xyz/"},{"title":"[Quick Review] RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors","url":"https://liner.com/review/raid-shared-benchmark-for-robust-evaluation-machinegenerated-text-detectors"}]

Based on the search results, here's what I found about RAID benchmark for AI text detection:

## Overview

RAID is the largest and most challenging benchmark dataset for machine-generated text detection, including over 6 million generations spanning 11 models, 8 domains, 11 adversarial attacks and 4 decoding strategies.

## Key Features

The RAID dataset is the only one that contains a diverse selection of domains, sampling strategies, and adversarial attacks across recent generative models. The benchmark facilitates evaluation of 12 detectors (8 open-source and 4 closed-source), revealing their vulnerabilities to adversarial attacks and sampling variations.

## Shared Tasks and Timeline

RAID was announced to appear as a Shared Task at COLING 2025, with a submission deadline of October 25th 2024.

## Important Research Findings

Current detectors are easily fooled by adversarial attacks, variations in sampling strategies, repetition penalties, and unseen generative models. Binoculars and other metric-based methods experienced a substantial 36.1% drop in accuracy when words were swapped with synonyms, highlighting their vulnerability to semantic perturbations.

The RAID benchmark was published as an ACL 2024 paper and includes both a dataset and public leaderboard for standardized evaluation of machine-generated text detectors.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1056bf63-a49d-479b-90a8-db4e829b22b2",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "9e540a04-2ed6-4a1c-a9ef-8a7b38551ab3",
  "toolUseResult": {
    "query": "RAID benchmark AI text detection multi-class 2024 2025",
    "results": [
      {
        "tool_use_id": "srvtoolu_01RdsaF1Fw7RCMjnyywU7hR4",
        "content": [
          {
            "title": "GitHub - liamdugan/raid: RAID is the largest and most challenging benchmark for AI-generated text detection. (ACL 2024) · GitHub",
            "url": "https://github.com/liamdugan/raid"
          },
          {
            "title": "RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors | Request PDF",
            "url": "https://www.researchgate.net/publication/384214327_RAID_A_Shared_Benchmark_for_Robust_Evaluation_of_Machine-Generated_Text_Detectors"
          },
          {
            "title": "[2405.07940] RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors",
            "url": "https://arxiv.org/abs/2405.07940"
          },
          {
            "title": "liamdugan/raid · Datasets at Hugging Face",
            "url": "https://huggingface.co/datasets/liamdugan/raid"
          },
          {
            "title": "RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors",
            "url": "https://arxiv.org/html/2405.07940v1"
          },
          {
            "title": "Review - RAID | Benchmark for machine-generated text review | Henry Zhu",
            "url": "https://maknee.github.io/blog/2024/RAID-most-challenging-benchmark-for-machine-generated-text-detectors/"
          },
          {
            "title": "It’s AI benchmarks It’s AI official website March 2025 1 Introduction",
            "url": "https://its-ai.org/benchmarks.pdf"
          },
          {
            "title": "RAID: A Shared Benchmark for Robust Evaluation of ...",
            "url": "https://aclanthology.org/2024.acl-long.674.pdf"
          },
          {
            "title": "RAID Benchmark",
            "url": "https://raid-bench.xyz/"
          },
          {
            "title": "[Quick Review] RAID: A Shared Benchmark for Robust Evaluation of Machine-Generated Text Detectors",
            "url": "https://liner.com/review/raid-shared-benchmark-for-robust-evaluation-machinegenerated-text-detectors"
          }
        ]
      },
      "Based on the search results, here's what I found about RAID benchmark for AI text detection:\n\n## Overview\n\nRAID is the largest and most challenging benchmark dataset for machine-generated text detection, including over 6 million generations spanning 11 models, 8 domains, 11 adversarial attacks and 4 decoding strategies.\n\n## Key Features\n\nThe RAID dataset is the only one that contains a diverse selection of domains, sampling strategies, and adversarial attacks across recent generative models. The benchmark facilitates evaluation of 12 detectors (8 open-source and 4 closed-source), revealing their vulnerabilities to adversarial attacks and sampling variations.\n\n## Shared Tasks and Timeline\n\nRAID was announced to appear as a Shared Task at COLING 2025, with a submission deadline of October 25th 2024.\n\n## Important Research Findings\n\nCurrent detectors are easily fooled by adversarial attacks, variations in sampling strategies, repetition penalties, and unseen generative models. Binoculars and other metric-based methods experienced a substantial 36.1% drop in accuracy when words were swapped with synonyms, highlighting their vulnerability to semantic perturbations.\n\nThe RAID benchmark was published as an ACL 2024 paper and includes both a dataset and public leaderboard for standardized evaluation of machine-generated text detectors."
    ],
    "durationSeconds": 5.835694091999991
  },
  "sourceToolAssistantUUID": "1056bf63-a49d-479b-90a8-db4e829b22b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool result

_source line 126 · 2026-05-17T08:49:20.226Z_

<details><summary>↩ Tool result · `toolu_012jrVnpsEvB182tXUwE6KJ8`</summary>

```text
Web search results for query: "PHD "paraphrased human detection" benchmark LLM detection 2024"

Links: [{"title":"DetectRL: Benchmarking LLM-Generated Text Detection in Real-World Scenarios","url":"https://proceedings.neurips.cc/paper_files/paper/2024/file/b61bdf7e9f64c04ec75a26e781e2ad51-Paper-Datasets_and_Benchmarks_Track.pdf"},{"title":"Benchmarking AI Text Detection: Assessing Detectors ...","url":"https://aclanthology.org/2025.genaidetect-1.4.pdf"},{"title":"Understanding the effects of human-written paraphrases in LLM-generated text detection | Request PDF","url":"https://www.researchgate.net/publication/391789166_Understanding_the_effects_of_human-written_paraphrases_in_LLM-generated_text_detection"},{"title":"Understanding the effects of human-written paraphrases in LLM-generated text detection - ScienceDirect","url":"https://www.sciencedirect.com/science/article/pii/S2949719125000275"},{"title":"Understanding the Effects of Human-written Paraphrases in LLM-generated Text Detection","url":"https://arxiv.org/html/2411.03806v1"},{"title":"GitHub - NLP2CT/DetectRL: [NeurIPS 2024 D&B] DetectRL: Benchmarking LLM-Generated Text Detection in Real-World Scenarios","url":"https://github.com/NLP2CT/DetectRL"},{"title":"GitHub - Xianjun-Yang/Awesome_papers_on_LLMs_detection: The lastest paper about detection of LLM-generated text and code · GitHub","url":"https://github.com/Xianjun-Yang/Awesome_papers_on_LLMs_detection"},{"title":"BUST: Benchmark for the evaluation of detectors of LLM- ...","url":"https://aclanthology.org/2024.naacl-long.444.pdf"},{"title":"Is Your Paper Being Reviewed by an LLM? A New Benchmark Dataset and Approach for Detecting AI Text in Peer Review","url":"https://arxiv.org/html/2502.19614v1"},{"title":"DetectRL: Benchmarking LLM-Generated Text Detection in Real-World Scenarios","url":"https://arxiv.org/html/2410.23746v2"}]

Based on the web search results, I found relevant information about benchmarks and datasets for LLM detection with paraphrasing. Here's what I discovered:

## Key Benchmarks and Research

DetectRL was presented at the NeurIPS 2024 Conference on Neural Information Processing Systems in the Datasets and Benchmarks track. This dataset comprises 100,800 human-written samples (including 11,200 raw samples and 89,600 samples modified via attack manipulations), and 134,400 samples generated by LLMs, including 33,600 with paraphrase attacks.

## Paraphrasing Impact on Detection

Research found that paraphrasing attacks on human-written texts effectively confused zero-shot detectors, reducing the AUROC by an average of 7.95%. Additionally, attack methods like prompt-based attacks, paraphrasing, adversarial perturbations, and data mixing have been incorporated into detection benchmarks.

## Related Research on Human Paraphrases

Another relevant 2024 study created the Human & LLM Paraphrase Collection (HLPC), a first-of-its-kind dataset that incorporates human-written texts and paraphrases, as well as LLM-generated texts and paraphrases. The results show that the inclusion of human-written paraphrases has a significant impact on LLM-generated detector performance.

These benchmarks demonstrate that paraphrasing—particularly human-written paraphrases—remains a significant challenge for LLM detection systems in 2024.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "de4e178f-1984-4646-a77c-303f92fb3965",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "fa2281f2-049a-4bca-a85d-80b53a7e2273",
  "toolUseResult": {
    "query": "PHD \"paraphrased human detection\" benchmark LLM detection 2024",
    "results": [
      {
        "tool_use_id": "srvtoolu_01HMkdzba3doAuaKYphC9xFK",
        "content": [
          {
            "title": "DetectRL: Benchmarking LLM-Generated Text Detection in Real-World Scenarios",
            "url": "https://proceedings.neurips.cc/paper_files/paper/2024/file/b61bdf7e9f64c04ec75a26e781e2ad51-Paper-Datasets_and_Benchmarks_Track.pdf"
          },
          {
            "title": "Benchmarking AI Text Detection: Assessing Detectors ...",
            "url": "https://aclanthology.org/2025.genaidetect-1.4.pdf"
          },
          {
            "title": "Understanding the effects of human-written paraphrases in LLM-generated text detection | Request PDF",
            "url": "https://www.researchgate.net/publication/391789166_Understanding_the_effects_of_human-written_paraphrases_in_LLM-generated_text_detection"
          },
          {
            "title": "Understanding the effects of human-written paraphrases in LLM-generated text detection - ScienceDirect",
            "url": "https://www.sciencedirect.com/science/article/pii/S2949719125000275"
          },
          {
            "title": "Understanding the Effects of Human-written Paraphrases in LLM-generated Text Detection",
            "url": "https://arxiv.org/html/2411.03806v1"
          },
          {
            "title": "GitHub - NLP2CT/DetectRL: [NeurIPS 2024 D&B] DetectRL: Benchmarking LLM-Generated Text Detection in Real-World Scenarios",
            "url": "https://github.com/NLP2CT/DetectRL"
          },
          {
            "title": "GitHub - Xianjun-Yang/Awesome_papers_on_LLMs_detection: The lastest paper about detection of LLM-generated text and code · GitHub",
            "url": "https://github.com/Xianjun-Yang/Awesome_papers_on_LLMs_detection"
          },
          {
            "title": "BUST: Benchmark for the evaluation of detectors of LLM- ...",
            "url": "https://aclanthology.org/2024.naacl-long.444.pdf"
          },
          {
            "title": "Is Your Paper Being Reviewed by an LLM? A New Benchmark Dataset and Approach for Detecting AI Text in Peer Review",
            "url": "https://arxiv.org/html/2502.19614v1"
          },
          {
            "title": "DetectRL: Benchmarking LLM-Generated Text Detection in Real-World Scenarios",
            "url": "https://arxiv.org/html/2410.23746v2"
          }
        ]
      },
      "Based on the web search results, I found relevant information about benchmarks and datasets for LLM detection with paraphrasing. Here's what I discovered:\n\n## Key Benchmarks and Research\n\nDetectRL was presented at the NeurIPS 2024 Conference on Neural Information Processing Systems in the Datasets and Benchmarks track. This dataset comprises 100,800 human-written samples (including 11,200 raw samples and 89,600 samples modified via attack manipulations), and 134,400 samples generated by LLMs, including 33,600 with paraphrase attacks.\n\n## Paraphrasing Impact on Detection\n\nResearch found that paraphrasing attacks on human-written texts effectively confused zero-shot detectors, reducing the AUROC by an average of 7.95%. Additionally, attack methods like prompt-based attacks, paraphrasing, adversarial perturbations, and data mixing have been incorporated into detection benchmarks.\n\n## Related Research on Human Paraphrases\n\nAnother relevant 2024 study created the Human & LLM Paraphrase Collection (HLPC), a first-of-its-kind dataset that incorporates human-written texts and paraphrases, as well as LLM-generated texts and paraphrases. The results show that the inclusion of human-written paraphrases has a significant impact on LLM-generated detector performance.\n\nThese benchmarks demonstrate that paraphrasing—particularly human-written paraphrases—remains a significant challenge for LLM detection systems in 2024."
    ],
    "durationSeconds": 6.274750520000001
  },
  "sourceToolAssistantUUID": "de4e178f-1984-4646-a77c-303f92fb3965",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Assistant

_source line 127 · 2026-05-17T08:49:54.937Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the information to compile my review. Let me note the key changes in this revised version and provide my assessment.

Key observations on the revised paper:

**Major improvements since Round 8:**
1. Schaeffer 2025 now cited and discussed (related_work.tex line 7-8) ← was my N1 critical
2. Explicit Dohmatob positioning added (related_work.tex line 8) ← was my N2 critical
3. McCullagh 1980, Frank 2001, Rennie 2005 now in ordinal classification section


4. Wenzek CCNet citation added, language in the intro refined from "universal and scale-variant" to "consistent in direction but scale-dependent in magnitude," and the discussion now appropriately characterizes pilot results as inconclusive rather than enabling
5. Abstract streamlined with removed subsections and reduced em-dashes, LoRA rank sensitivity ablation incorporated, and reference model ablation expanded to cover three models
6. Multiple AI writing markers cleaned up throughout, with several new citations added including work on curiosity, self-consuming models, and diversity
7. Author list for alemohammad2024_mad corrected to reflect Babaei instead of the previous names, though I'm noticing a few lingering issues: "signal universality" still appears in generalization.tex, the abstract percentage rounds up slightly from the actual 69.6%, the third contribution bullet remains dense, and there are two orphan bibliography entries that were added but never actually cited in the text
8. The reference model ablation table shows only two models while method.tex claims three, so I need to verify whether the text at line 41 actually completes the claim about GPT-2 XL results

, and if so, ensure those results appear in the appendix table where they're referenced

. The Limitations section also repeats this same claim about three architectures, so this needs to be resolved consistently across the document.

Now I'm checking whether there's a mismatch between what the Director described and what's actually in the paper—the title and scope seem different from what was outlined in the task description, so I should focus my review on the actual paper content rather than the proposed version.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fa2281f2-049a-4bca-a85d-80b53a7e2273",
  "isSidechain": false,
  "requestId": "req_011Cb7rRsS12tdgX4Mtwx2Px",
  "type": "assistant",
  "uuid": "4ca1faaa-24ea-4f7b-93d9-7a8949124103",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016tdNsHjsRVyt8vNuVptVAY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21182,
      "cache_read_input_tokens": 145660,
      "output_tokens": 1355,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21182,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1355,
          "cache_read_input_tokens": 145660,
          "cache_creation_input_tokens": 21182,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21182
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


### Assistant

_source line 128 · 2026-05-17T08:49:54.949Z_

论文已大幅修订。让我检查一个关键的数据一致性问题。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4ca1faaa-24ea-4f7b-93d9-7a8949124103",
  "isSidechain": false,
  "requestId": "req_011Cb7rRsS12tdgX4Mtwx2Px",
  "type": "assistant",
  "uuid": "766bfefb-c23e-452a-97d1-29cb62b2a3e8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016tdNsHjsRVyt8vNuVptVAY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21182,
      "cache_read_input_tokens": 145660,
      "output_tokens": 1355,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21182,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1355,
          "cache_read_input_tokens": 145660,
          "cache_creation_input_tokens": 21182,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21182
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


### Tool call

_source line 129 · 2026-05-17T08:49:56.959Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01UJtXtmHVYCLmVx9gGVfqdX`</summary>

```json
{
  "pattern": "67.*79|three reference|GPT-2.*reference|ref_ablation",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "766bfefb-c23e-452a-97d1-29cb62b2a3e8",
  "isSidechain": false,
  "requestId": "req_011Cb7rRsS12tdgX4Mtwx2Px",
  "type": "assistant",
  "uuid": "5d5138f9-5162-4c7a-babd-3406d79153c3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016tdNsHjsRVyt8vNuVptVAY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21182,
      "cache_read_input_tokens": 145660,
      "output_tokens": 1355,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21182,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1355,
          "cache_read_input_tokens": 145660,
          "cache_creation_input_tokens": 21182,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21182
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

_source line 130 · 2026-05-17T08:49:59.114Z_

<details><summary>↩ Tool result · `toolu_01AXGo7rreN4PwkNGcY7mQvy`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:7:%% ----------------------------------------------------------------
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:42:%% ----------------------------------------------------------------
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:94:%% ----------------------------------------------------------------
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:108:%% ----------------------------------------------------------------
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:158:%% ----------------------------------------------------------------
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex:96:%% ----------------------------------------------------------------
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:176:RF (19 feat.) & 78.2 & --- & --- & .596$^\dagger$ & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:229:Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:232:GPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:235:OLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:265:unfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:444:Within-seed (seed=42) & 78.20 & --- \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5120fd11-dda0-4438-8f49-76791169f96e",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "2b9119fa-3b70-491b-93fd-330dd2c40c44",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:7:%% ----------------------------------------------------------------\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:42:%% ----------------------------------------------------------------\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:94:%% ----------------------------------------------------------------\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:108:%% ----------------------------------------------------------------\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex:158:%% ----------------------------------------------------------------\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex:96:%% ----------------------------------------------------------------\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:176:RF (19 feat.) & 78.2 & --- & --- & .596$^\\dagger$ & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:229:Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:232:GPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:235:OLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:265:unfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:444:Within-seed (seed=42) & 78.20 & --- \\\\",
    "numLines": 12
  },
  "sourceToolAssistantUUID": "5120fd11-dda0-4438-8f49-76791169f96e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool result

_source line 131 · 2026-05-17T08:49:56.989Z_

<details><summary>↩ Tool result · `toolu_01UJtXtmHVYCLmVx9gGVfqdX`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:39:An ablation with OLMo-1B and GPT-2 XL as alternative references shows accuracy ranging from 67--79\% across three reference architectures (Appendix~\ref{app:ref_ablation}), all exceeding $2.5\times$ chance; same-family reference yields optimal performance ($\Delta{\leq}$11\,pp).
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:41:Ablations with OLMo-1B and GPT-2 XL as alternative references yield 67--79\% accuracy (Appendix~\ref{app:ref_ablation}), confirming reference model robustness; further discussion in Limitations.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:296:\label{app:ref_ablation}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:301:\label{tab:ref_ablation}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:41:  "/usr/share/texlive/texmf-dist/fonts/tfm/public/cm/cmex10.tfm" 1136768653 992 662f679a0b3d2d53c1b94050fdaa3f50 ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:49:  "/usr/share/texlive/texmf-dist/fonts/tfm/public/cm/cmr6.tfm" 1136768653 1300 b62933e007d01cfd073f79b963c01526 ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:55:  "/usr/share/texlive/texmf-dist/fonts/tfm/public/cm/cmsy9.tfm" 1136768653 1116 25a7bf822c58caf309a702ef79f4afbb ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:59:  "/usr/share/texlive/texmf-dist/fonts/tfm/public/latex-fonts/lasy7.tfm" 1136768653 520 a74c6ed8cb48679fdc3ea874d9d34a7e ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:81:  "/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmb8a.pfb" 1136849748 44729 811d6c62865936705a31c797a1d5dada ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:146:  "/usr/share/texlive/texmf-dist/tex/latex/latexconfig/epstopdf-sys.cfg" 1279039959 678 4792914a8f45be57bb98413425e4c7af ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:155:  "/usr/share/texlive/texmf-dist/tex/latex/multirow/multirow.sty" 1731446765 6696 886c9f3087d0b973ed2c19aa79cb3023 ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:162:  "/usr/share/texlive/texmf-dist/tex/latex/rerunfilecheck/rerunfilecheck.sty" 1750533675 9684 a33a14b82ce60d6e77cb9be689d79ee6 ""
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex:28:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1602:\newlabel{tab:ref_ablation}{{16}{16}{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction}{table.caption.61}{}}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1605:\newlabel{app:ref_ablation}{{A.12}{16}{Reference Model Ablation}{subsection.A.12}{}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5d5138f9-5162-4c7a-babd-3406d79153c3",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "17eb20b5-9c44-467d-8359-18494439c79d",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:39:An ablation with OLMo-1B and GPT-2 XL as alternative references shows accuracy ranging from 67--79\\% across three reference architectures (Appendix~\\ref{app:ref_ablation}), all exceeding $2.5\\times$ chance; same-family reference yields optimal performance ($\\Delta{\\leq}$11\\,pp).\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:41:Ablations with OLMo-1B and GPT-2 XL as alternative references yield 67--79\\% accuracy (Appendix~\\ref{app:ref_ablation}), confirming reference model robustness; further discussion in Limitations.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:296:\\label{app:ref_ablation}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:301:\\label{tab:ref_ablation}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:41:  \"/usr/share/texlive/texmf-dist/fonts/tfm/public/cm/cmex10.tfm\" 1136768653 992 662f679a0b3d2d53c1b94050fdaa3f50 \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:49:  \"/usr/share/texlive/texmf-dist/fonts/tfm/public/cm/cmr6.tfm\" 1136768653 1300 b62933e007d01cfd073f79b963c01526 \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:55:  \"/usr/share/texlive/texmf-dist/fonts/tfm/public/cm/cmsy9.tfm\" 1136768653 1116 25a7bf822c58caf309a702ef79f4afbb \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:59:  \"/usr/share/texlive/texmf-dist/fonts/tfm/public/latex-fonts/lasy7.tfm\" 1136768653 520 a74c6ed8cb48679fdc3ea874d9d34a7e \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:81:  \"/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmb8a.pfb\" 1136849748 44729 811d6c62865936705a31c797a1d5dada \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:146:  \"/usr/share/texlive/texmf-dist/tex/latex/latexconfig/epstopdf-sys.cfg\" 1279039959 678 4792914a8f45be57bb98413425e4c7af \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:155:  \"/usr/share/texlive/texmf-dist/tex/latex/multirow/multirow.sty\" 1731446765 6696 886c9f3087d0b973ed2c19aa79cb3023 \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.fdb_latexmk:162:  \"/usr/share/texlive/texmf-dist/tex/latex/rerunfilecheck/rerunfilecheck.sty\" 1750533675 9684 a33a14b82ce60d6e77cb9be689d79ee6 \"\"\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex:28:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1602:\\newlabel{tab:ref_ablation}{{16}{16}{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction}{table.caption.61}{}}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1605:\\newlabel{app:ref_ablation}{{A.12}{16}{Reference Model Ablation}{subsection.A.12}{}}",
    "numLines": 15
  },
  "sourceToolAssistantUUID": "5d5138f9-5162-4c7a-babd-3406d79153c3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 132 · 2026-05-17T08:49:58.390Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01BEimeqdHN3JBMYet32U52z`</summary>

```json
{
  "pattern": "signal universality|universality",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "17eb20b5-9c44-467d-8359-18494439c79d",
  "isSidechain": false,
  "requestId": "req_011Cb7rRsS12tdgX4Mtwx2Px",
  "type": "assistant",
  "uuid": "03cfda5e-df01-4e32-af55-294e7a996d7d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016tdNsHjsRVyt8vNuVptVAY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21182,
      "cache_read_input_tokens": 145660,
      "output_tokens": 1355,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21182,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1355,
          "cache_read_input_tokens": 145660,
          "cache_creation_input_tokens": 21182,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21182
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

_source line 133 · 2026-05-17T08:49:58.415Z_

<details><summary>↩ Tool result · `toolu_01BEimeqdHN3JBMYet32U52z`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex:108:Cross-model recursive chains (84.75\%), validated by a reverse-chain control (85.75\%; Appendix~\ref{app:cross_boundary}), and cross-domain transfer (arXiv 74.1\%) further confirm signal universality.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "03cfda5e-df01-4e32-af55-294e7a996d7d",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "809922e1-a948-48c6-b1bf-2ec5e9d915fa",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex:108:Cross-model recursive chains (84.75\\%), validated by a reverse-chain control (85.75\\%; Appendix~\\ref{app:cross_boundary}), and cross-domain transfer (arXiv 74.1\\%) further confirm signal universality.",
    "numLines": 1
  },
  "sourceToolAssistantUUID": "03cfda5e-df01-4e32-af55-294e7a996d7d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---


### Tool call

_source line 134 · 2026-05-17T08:49:59.087Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01AXGo7rreN4PwkNGcY7mQvy`</summary>

```json
{
  "pattern": "---",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "809922e1-a948-48c6-b1bf-2ec5e9d915fa",
  "isSidechain": false,
  "requestId": "req_011Cb7rRsS12tdgX4Mtwx2Px",
  "type": "assistant",
  "uuid": "5120fd11-dda0-4438-8f49-76791169f96e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016tdNsHjsRVyt8vNuVptVAY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21182,
      "cache_read_input_tokens": 145660,
      "output_tokens": 1355,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21182,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1355,
          "cache_read_input_tokens": 145660,
          "cache_creation_input_tokens": 21182,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21182
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


### Runtime record

_source line 135_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Review Assignment: R2 — Novelty & Related Work  **Venue:** EMNLP 2026 Main (via ACL Rolling Review) **Paper:** \"Ordinal Depth Estimation for Recursive Language Model Generations: A…",
  "leafUuid": "2b9119fa-3b70-491b-93fd-330dd2c40c44",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 136_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 137_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Review Assignment: R2 — Novelty & Related Work  **Venue:** EMNLP 2026 Main (via ACL Rolling Review) **Paper:** \"Ordinal Depth Estimation for Recursive Language Model Generations: A…",
  "leafUuid": "2b9119fa-3b70-491b-93fd-330dd2c40c44",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 138_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### System

_source line 139 · 2026-05-17T08:51:56.660Z_

```json
{
  "parentUuid": null,
  "logicalParentUuid": "2b9119fa-3b70-491b-93fd-330dd2c40c44",
  "isSidechain": false,
  "type": "system",
  "subtype": "compact_boundary",
  "content": "Conversation compacted",
  "isMeta": false,
  "timestamp": "2026-05-17T08:51:56.660Z",
  "uuid": "8c055e8d-fe6a-40ad-bd54-0af8d24b95f8",
  "level": "info",
  "compactMetadata": {
    "trigger": "auto",
    "preTokens": 169816,
    "preCompactDiscoveredTools": [
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "postTokens": 6361,
    "durationMs": 117487
  },
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


## Round 6

## Round 6

36 recorded events


### User

_source line 140 · 2026-05-17T08:51:56.661Z_

This session is being continued from a previous conversation that ran out of context. The summary below covers the earlier portion of the conversation.

Summary:
1. Primary Request and Intent:
   I am Reviewer 2 in a multi-reviewer academic paper review system for the paper "How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints" targeting EMNLP 2026 Findings (ARR May 2026 cycle). My role is to simulate a real peer reviewer with focus on novelty positioning, writing quality, and citation completeness. I communicate exclusively via `review_reviewer_post_to_director` tool. Three review tasks were assigned:
   - **Round 8**: Full review focusing on novelty positioning in model collapse literature, writing quality (AI traces, overclaim), and citation completeness. Also verify historical open issues from Rounds 2-7.
   - **Cross-review**: Respond [AGREE]/[REBUT] to Reviewer 1's complete review (N1, N2, W1-W3 + historical issues).
   - **Round 1 (new revision)**: Fresh review of revised paper focusing on Novelty, Related Work, Significance, Writing Quality, Community Fit, and Citation Adequacy. The Director described a paper with different title and features not yet present in the files.

2. Key Technical Concepts:
   - Recursive generation depth estimation as ordinal classification (d0-d3)
   - Depth Degradation Atlas: 3×3 grid (model families × decoding strategies)
   - Effective Discriminable Depth (EDD) metric with threshold T
   - Perplexity tail statistics (p90_ppl, var_surprisal) as dominant features
   - Random Forest classifier with 19 features (effective dimensionality ~4-5)
   - Cross-model/cross-strategy/cross-scale transfer evaluation
   - Model collapse theory (Shumailov 2024, Dohmatob 2024 "A Tale of Tails")
   - ARR 2025+ review form: Soundness (1-5), Excitement (1-5), Overall (1-5), Reproducibility (1-5)
   - LoRA finetuning for recursive chain generation (r=16, α=32)
   - Curation PoC with RF-filtered vs unfiltered comparison (p>0.4, non-significant)

3. Files and Code Sections:
   - **main.tex** (`/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex`)
     - Root document. Title: "How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints". Uses `\usepackage[review]{acl}`, anonymous author. Inputs all section files.
   
   - **abstract.tex** (revised version)
     - Round 8: Had em-dashes ("arises---yet"), §4.4 internal reference, 20+ numbers
     - Current revision: Em-dashes removed ("arises, yet"), §4.4 removed, numbers reduced to ~10. Still says "70--85%" (69.6% rounds up). Now 7 lines instead of 9.
   
   - **introduction.tex** (revised version)
     - Round 8: Line 14 "universal and scale-variant" (contradictory), em-dashes on line 6
     - Current revision: Line 14 → "consistent in direction but scale-dependent in magnitude". Em-dashes replaced with semicolons. Contribution bullet 3 now includes "LoRA-rank ablation" and "reference model robustness (67--79%)" but still packed with 7+ axes.
   
   - **related_work.tex** (revised version)
     - Major additions: Line 5 adds seddik2024synthetic; Line 6 adds wenzek2020_ccnet, guo2024curious, briesch2024selfconsuming, padmakumar2024diversity; Line 7 NEW: Schaeffer 2025 cited ("argue that 'model collapse' conflates multiple distinct phenomena"); Line 8 NEW: Explicit Dohmatob positioning ("we operationalize this prediction into a deployable ordinal classifier, revealing strategy-dependent trajectories and non-monotonic 7B behavior that the theory does not predict"); Line 22: McCullagh 1980, Frank 2001, Rennie 2005 now in Ordinal Classification paragraph.
   
   - **method.tex** (revised version)
     - Line 41: Reference model ablation expanded: "Ablations with OLMo-1B and GPT-2 XL as alternative references yield 67--79% accuracy" — but Table 16 only shows 2 reference models (Pythia 78.6%, OLMo 74.5%), GPT-2 XL results MISSING from table.
   
   - **atlas.tex** — Unchanged from Round 8. Contains main results (Table 2, 69.6-85.4%), EDD analysis, strategy trajectories.
   
   - **generalization.tex** (revised version)
     - Line 108: "signal universality" STILL present (unfixed overclaim)
     - Lines 110-111: NEW LoRA rank sensitivity paragraph: "Depth signal persists across LoRA ranks 4--64 (accuracy spread 4.65pp)"
   
   - **discussion.tex** (revised version)
     - Line 7: Changed from "enables depth-graduated data curation" to "pilot results are inconclusive (Appendix~\ref{app:curation_poc})"
   
   - **conclusion.tex** (Limitations section)
     - Line 35: Reference model dependency expanded: "Reference model choice affects classification accuracy by up to 11pp"
     - Line 39: Claims "67--79% across three reference architectures" but table only has 2
   
   - **section_appendix.tex** — Contains all appendix sections. Key tables: Table 14 (curation PoC, rf_soft vs unfiltered p=0.407), Table 16 (ref_ablation, only 2 models listed).
   
   - **references.bib** (revised version)
     - Grew from 49 to 60 entries. New additions: schaeffer2025, frank2001, rennie2005, mccullagh1980_ordinal, wenzek2020_ccnet, c2pa2024, chen2024spin, guo2024curious, padmakumar2024diversity, briesch2024selfconsuming, seddik2024synthetic.
     - 2 orphan entries: c2pa2024 and chen2024spin (in bib but never cited in tex)
     - alemohammad2024_mad author list corrected (Babaei instead of previous names)

4. Errors and fixes:
   - **Title/content discrepancy**: Director's Round 1 task describes paper as "Ordinal Depth Estimation for Recursive Language Model Generations: A Depth Degradation Atlas Across Scales and Strategies" with features (two-stage pipeline 75.2%, 14B scale, prompted generation) not present in actual paper files. The paper still has title "How Deep Is Your Data?" and only 7-8B models. I noted this discrepancy and proceeded to review the actual paper content.
   - **Reference model table inconsistency**: method.tex line 41 and conclusion.tex line 39 claim "67-79% across three reference architectures" but Table 16 (app:ref_ablation) only contains 2 rows (Pythia-1.4B: 78.6%, OLMo-1B: 74.5%). GPT-2 XL reference results are missing. This is a critical data inconsistency I identified but hadn't yet reported.

5. Problem Solving:
   - **Round 8 review completed**: Submitted comprehensive review with Overall 3.5/5, identified 3 Must-Fix (missing Schaeffer 2025, novelty positioning unclear, Abstract §4.4 + number overload) and 6 Should-Fix issues.
   - **Cross-review completed**: Responded to all of R1's issues with [AGREE] (7) and [REBUT] (2, on CI in tables and partial mixing severity).
   - **Round 1 review in progress**: Read all revised files, ran reference verification (60 entries, 2 orphans, 7 not_found on OpenAlex, 4 mismatches), searched for RAID/PHD benchmarks. Identified remaining issues but had NOT yet composed or submitted the review report.

6. All user messages:
   - **Round 8 审稿请求**: Detailed review assignment with paper info, venue (EMNLP 2026 Findings), focus areas (novelty, writing, citations), and 12+ historical open issues to verify with specific issue IDs and descriptions.
   - **"Continue from where you left off."** (after Round 8 review submission)
   - **Cross-review request**: "请逐条回应 Reviewer 1 的审稿意见" — Full text of Reviewer 1's review (Overall 3.0, 2 Must-Fix, 3 Should-Fix, 10 historical issue verifications, 5 strengths). Asked for [AGREE]/[REBUT] on each.
   - **"Continue from where you left off."** (after cross-review submission)
   - **Round 1 审稿请求**: New review assignment with different paper title ("Ordinal Depth Estimation..."), same venue, 6 evaluation dimensions (A-F: Novelty, Related Work, Significance, Writing, Community Fit, Citations). Asked for numbered strengths, weaknesses, questions, preliminary scores.

7. Pending Tasks:
   - **Compose and submit Round 1 review report** via `review_reviewer_post_to_director` — I have read all files, run reference verification, and identified key issues but have NOT yet written or posted the review.

8. Current Work:
   I was in the process of conducting the Round 1 review of the revised paper. I had completed all data gathering:
   - Read all 10 tex files + bib file (revised versions)
   - Ran verify_references (60 entries, 2 orphans: c2pa2024/chen2024spin)
   - Searched for RAID benchmark (ACL 2024, relevant but not cited)
   - Searched for PHD/paraphrase detection benchmarks
   - Confirmed "signal universality" still at generalization.tex line 108
   - Confirmed no em-dashes remain in main text
   - Found reference model table inconsistency (claims 3 models, shows 2)
   
   Key findings for the pending review:
   - Most Round 8 critical issues RESOLVED (Schaeffer cited, Dohmatob positioned, McCullagh/Rennie/CCNet added, "universal and scale-variant" fixed, Discussion "enables" fixed, em-dashes removed)
   - Remaining issues: "signal universality" (gen.tex:108), "70-85%" rounding (abstract), contribution bullet 3 density, ref table inconsistency, 2 orphan bib entries, RAID benchmark missing
   - Paper significantly improved from Round 8; scores should be higher

9. Optional Next Step:
   Compose and submit the Round 1 review report via `review_reviewer_post_to_director`. The Director's last message asked: "Provide: (1) numbered strengths, (2) numbered weaknesses, (3) questions for authors, (4) preliminary scores (Soundness, Excitement, Overall) with justification." I need to write this structured review covering all 6 dimensions (A-F: Novelty Assessment, Related Work, Significance & Impact, Writing Quality, Community Fit, Citation Adequacy) based on the data I've already gathered, noting the title/content discrepancy between the Director's description and actual paper files.

If you need specific details from before compaction (like exact code snippets, error messages, or content you generated), read the full transcript at: /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est--claude-sessions-review-reviewer-2-2744903e/02e198f0-2bdb-4a54-8265-4044096f8661.jsonl
Continue the conversation from where it left off without asking the user any further questions. Resume directly — do not acknowledge the summary, do not recap what was happening, do not preface with "I'll continue" or similar. Pick up the last task as if the break never happened.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8c055e8d-fe6a-40ad-bd54-0af8d24b95f8",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "isVisibleInTranscriptOnly": true,
  "isCompactSummary": true,
  "uuid": "07d8c6bd-863e-4d68-b0b3-dfe40460a7e0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Runtime record

_source line 141 · 2026-05-17T08:51:56.280Z_

```json
{
  "parentUuid": "07d8c6bd-863e-4d68-b0b3-dfe40460a7e0",
  "isSidechain": false,
  "attachment": {
    "type": "file",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex",
    "content": {
      "type": "text",
      "file": {
        "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex",
        "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Model Collapse Theory.}\n\\citet{shumailov2024_nature} demonstrate that recursive training on model outputs erodes distributional tails; \\citet{dohmatob2024_tale_of_tails} formalize this via scaling laws \\cite{seddik2024synthetic}, \\citet{dohmatob2025_strong_collapse} establish strong collapse guarantees, and the MAD framework \\cite{alemohammad2024_mad} extends the analysis to self-consuming models.\nSubsequent work addresses mitigation \\cite{gerstgrasser2024_accumulate,drayson2025_detection_prevents_collapse,yi2026_escaping_collapse,falahati2026_curated,wenzek2020_ccnet}, non-monotonic dynamics \\cite{bakshi2026_collapse_improvement}, convergence \\cite{marchi2024_heat_death,wang2026_contamination,knowledge_collapse2025,dohmatob2024_demystified}, and diversity decline \\cite{guo2024curious,briesch2024selfconsuming,padmakumar2024diversity,sigma2026_spectral,synthetic_eggs2026}.\n\\citet{schaeffer2025} argue that ``model collapse'' conflates multiple distinct phenomena, underscoring the need for operationally precise metrics.\nDohmatob et al.\\ predict that recursive training erodes distributional tails as a theoretical scaling law \\citep{dohmatob2024_tale_of_tails}; we operationalize this prediction into a deployable ordinal classifier, revealing strategy-dependent trajectories and non-monotonic 7B behavior that the theory does not predict.\nAll assume depth is known a priori; we address the inverse problem of estimating depth from text alone.\n\n\\paragraph{AI Text Detection.}\nThe detection literature \\cite{wu2025_detection_survey} spans statistical methods (DetectGPT \\cite{mitchell2023_detectgpt}, Fast-DetectGPT \\cite{fast_detectgpt2024}, Binoculars \\cite{binoculars2024}, DivEye \\cite{diveye2026}, GLTR \\cite{gehrmann2019_gltr}, Ghostbuster \\cite{verma2024_ghostbuster}, DNA-GPT \\cite{yang2024_dnagpt}) and watermarking \\cite{kirchenbauer2023_watermark}, with known limits from paraphrasing \\cite{sadasivan2023_paraphrase}, distribution shift \\cite{pudasaini2026_detection_fails}, and generator barriers \\cite{pu2026_generator_barrier}.\nM4-SemEval \\cite{wang2024_m4_semeval} benchmarks multilingual detection.\nAll these methods perform binary classification, discarding ordinal depth information; our approach outputs ordinal depth labels, complementing rather than replacing binary detection.\n\n\\paragraph{Adjacent Tasks.}\nEditLens \\cite{editlens2026} estimates editing extent but does not model recursive chains; \\citet{uchendu2020_attribution} classify \\emph{which} model generated text; LOKI \\cite{loki2025} benchmarks synthetic data detection across modalities.\n\\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, characterizing \\emph{how} text degrades without classifying which iteration a passage comes from.\nOur task performs the inverse, ordinal depth estimation from text alone, discriminating between adjacent depths rather than merely detecting aggregate degradation.\n\n\\paragraph{Ordinal Classification.}\nOrdinal classification has a long history \\cite{mccullagh1980_ordinal}: \\citet{frank2001} reduce ordinal problems to nested binary tasks, and \\citet{rennie2005} introduce loss functions tailored to discrete ordered labels.\nCORAL \\cite{coral2020} enforces rank consistency via ordered binary tasks; CLOC \\cite{cloc2025} extends contrastive learning with multi-margin ordinal losses.\nWe adopt both as baselines (\\S\\ref{sec:generalization}) to confirm the signal is accessible to principled ordinal methods.\n\n\\paragraph{Decoding Strategy Effects.}\nDecoding strategies shape text statistics in ways that interact with depth signals \\cite{holtzman2020_nucleus,finlayson2024_closing,garces_arias2025_decoding_decoded,wiher2022_decoding,basu2021_mirostat}.\nOur Depth Degradation Atlas (\\S\\ref{sec:atlas}) reveals that these strategies induce qualitatively different degradation trajectories under recursive generation: temperature sampling accelerates convergence to a low-entropy attractor while top-$k$ attenuates the depth signal, effects beyond single-pass text quality.",
        "numLines": 28,
        "startLine": 1,
        "totalLines": 28
      }
    },
    "displayPath": "../../../docs/paper/related_work.tex"
  },
  "type": "attachment",
  "uuid": "c0f7195a-6fa0-4432-8d31-e041c8c26071",
  "timestamp": "2026-05-17T08:51:56.280Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Runtime record

_source line 142 · 2026-05-17T08:51:56.510Z_

```json
{
  "parentUuid": "c0f7195a-6fa0-4432-8d31-e041c8c26071",
  "isSidechain": false,
  "attachment": {
    "type": "file",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
    "content": {
      "type": "text",
      "file": {
        "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
        "content": "\\section{Generalization and Robustness}\n\\label{sec:generalization}\n\nWe test whether atlas accuracy (69.6--85.4\\%) reflects genuine statistical regularities, evaluating along seven axes: four below (\\S\\ref{sec:gen:baselines}--\\S\\ref{sec:gen:crossscale}) and three in the Appendix (end-to-end learning, temperature robustness, cross-boundary transfer).\n\n\\subsection{Classifier Comparison and Surface-Text Ablation}\n\\label{sec:gen:baselines}\n\nTable~\\ref{tab:baselines} evaluates bagging (RF) and gradient boosting (XGBoost, LightGBM) on the same 19 features; per-cell spread is $\\leq$0.4pp, establishing a feature-determined ceiling.\nOn Pythia nucleus, CORAL ordinal regression \\cite{coral2020} (78.1\\%) and DivEye \\cite{diveye2026} (78.2\\%) match the within-cell RF of Table~\\ref{tab:main_matrix} within 0.1\\,pp (bootstrap $p>0.05$, Bonferroni-corrected); all feature-based methods significantly outperform CE-MLP (74.9\\%, $p<0.001$) and logistic regression (75.0\\%).\n\n\\paragraph{Surface-text ablation.}\nSingle-feature regression on mean perplexity performs at chance (25.1\\%); two zero-shot LLMs (DeepSeek V3.2, 36.2\\%; Qwen2.5-7B-Instruct, 30.4\\%; each 500 samples, prompt in Appendix~\\ref{app:zeroshot_prompt}) also fail, confirming that the depth signal resides in distributional statistics inaccessible from surface text alone (42\\,pp gap vs.\\ RF at 78.2\\%).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Classifier convergence: 4-class accuracy (\\%) across three atlas cells. RF (bagging), XGBoost and LightGBM (gradient boosting) operate on the same 19 features; $\\Delta_{\\max}$: largest per-cell spread. Chance = 25\\%. RF values differ from Table~\\ref{tab:main_matrix} by $\\leq$0.7pp due to matched-fold evaluation.}\n\\label{tab:baselines}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & RF & XGB & LGBM & $\\Delta_{\\max}$ \\\\\n\\midrule\nPythia, nuc. & 78.8 & 79.0 & 78.9 & 0.2 \\\\\nGPT-2~XL, $\\tau$ & 85.8 & 86.2 & 86.2 & 0.4 \\\\\nPythia, top-$k$ & 68.9 & 68.9 & 68.7 & 0.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nConvergence confirms the signal resides in the features, not the classifier.\nFigure~\\ref{fig:confusion_matrix} shows d0 near-perfectly identified; errors concentrate at d2/d3 in-distribution and spread to d1--d3 under transfer.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_confusion_matrix.pdf}\n\\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\\tau{=}0.9$, 85.4\\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\\%). d0 recall exceeds 99\\% in both; errors spread across the d1--d3 range under transfer.}\n\\label{fig:confusion_matrix}\n\\end{figure}\n\n\\subsection{Cross-Model Transfer}\n\\label{sec:gen:crossmodel}\n\nWe perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\\ref{tab:cross_model}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-model transfer (leave-one-out, nucleus only). Chance = 25\\% / 33\\% (d1--d3). d1--d3 bal.\\ acc: Pythia 49.9\\%, OLMo 59.2\\%, GPT-2~XL 57.2\\% (mean 55.4\\%).}\n\\label{tab:cross_model}\n\\begin{tabular}{lccccc}\n\\toprule\nHoldout & Acc & d0 & d1 & d2 & d3 \\\\\n & (\\%) & Rec. & Rec. & Rec. & Rec. \\\\\n\\midrule\nPythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\\\\nOLMo & \\textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\\\\nGPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\\\\n\\midrule\nMean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean transfer accuracy is 66.4\\% (2.7$\\times$ chance); d0 recall ($>$98\\%) inflates the headline while d2 drops to 26.8\\% (Pythia holdout); excluding d0, d1--d3 balanced accuracy averages 55.4\\%.\n\n\\subsection{Cross-Strategy Transfer}\n\\label{sec:gen:crossstrategy}\n\nWe train on two decoding strategies and test on the held-out third (Table~\\ref{tab:cross_strategy}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-strategy transfer (leave-one-out). Chance = 25\\% / 33\\% (d1--d3). d0 recall $\\geq$89\\% inflates headline; d1--d3 mean: 45.9\\%.}\n\\label{tab:cross_strategy}\n\\begin{tabular}{lccc}\n\\toprule\nHoldout & Pythia & OLMo & GPT-2 XL \\\\\n & Acc (\\%) & Acc (\\%) & Acc (\\%) \\\\\n\\midrule\nnucleus & \\textbf{69.4} & \\textbf{65.4} & \\textbf{59.9} \\\\\ntemp ($\\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\\\\ntop-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean cross-strategy accuracy (59.1\\%) falls 7pp below cross-model transfer (66.4\\%); excluding d0, d1--d3 accuracy drops to 45.9\\% (chance = 33\\%).\nd2 recall varies sharply: nucleus holdouts retain 30--54\\%, top-$k$ holdouts fall to 8--19\\%, and temperature holdouts span 3.7--39.5\\% (median 8.9\\%).\nTraining on nucleus + top-$k$ and testing on temperature inverts the d1/d2 boundary (d1v2 AUC $<$ 0.5); per-strategy z-score normalization partially recovers it but leaves a residual gap (Limitations).\nA multi-temperature ablation (Appendix~\\ref{app:multi_tau}) confirms that within-$\\tau$ depth signal holds for $\\tau \\leq 0.9$ (d1v2 AUC $>0.80$, accuracy within 3pp of $\\tau{=}0.7$) but collapses at $\\tau{=}1.1$; cross-$\\tau$ LOO transfer (mean 46.7\\%) is harder than cross-strategy transfer.\n\nEnd-to-end PLMs (DeBERTa-v3, RoBERTa) achieve only ${\\sim}$59\\%, lagging RF by 19pp, confirming depth signal is inaccessible to standard PLM representations (Appendix~\\ref{app:e2e}).\n\n%% ----------------------------------------------------------------\n\\subsection{Preliminary Cross-Scale Observations}\n\\label{sec:gen:crossscale}\n\nTo test whether depth signal persists at larger scale, we extend the benchmark to Qwen2.5-7B-Instruct~\\cite{qwen2.5} and Llama-3.1-8B-Instruct~\\cite{llama3} under 4-bit NF4 QLoRA (nucleus $p{=}0.95$, 500 samples/depth, depths 0--5).\nBoth models exceed chance: Llama-3.1-8B achieves 70.2\\% (95\\% CI $[68.3, 72.4]$, $\\mathrm{EDD}_{0.70}{=}4$) and Qwen2.5-7B 60.1\\% ($[58.0, 62.1]$, $\\mathrm{EDD}_{0.70}{>}5$), with weaker per-step signal than 1--1.5B models (mean consecutive AUC ${\\approx}$0.78 vs.\\ 0.85).\nThe two instruction-tuned models exhibit divergent AUC trajectories: Llama-3.1-8B decays monotonically (consistent with 1--1.5B), while Qwen2.5-7B shows a U-shaped recovery.\n\n\\paragraph{Base vs.\\ Instruction-Tuned Control.}\nA base-model control (Llama-3.1-8B) achieves 59.9\\% with non-monotonic AUC decay, while the instruction-tuned variant reaches 70.2\\% with strictly monotonic decay, suggesting instruction-tuning \\emph{regularizes} recursive degradation patterns rather than introducing confounding artifacts.\n\nFour confounds (quantization, reduced $n$, single strategy, vocabulary mismatch) limit causal attribution; full results including per-pair AUC tables appear in Appendix~\\ref{app:cross_scale_full}.\nCross-model recursive chains (84.75\\%), validated by a reverse-chain control (85.75\\%; Appendix~\\ref{app:cross_boundary}), and cross-domain transfer (arXiv 74.1\\%) further confirm signal universality.\n\n\\paragraph{LoRA rank sensitivity.}\nDepth signal persists across LoRA ranks 4--64 (accuracy spread 4.65\\,pp; Appendix~\\ref{app:cross_scale_full}), confirming the phenomenon is not an artifact of a specific fine-tuning configuration.",
        "numLines": 111,
        "startLine": 1,
        "totalLines": 111
      }
    },
    "displayPath": "../../../docs/paper/generalization.tex"
  },
  "type": "attachment",
  "uuid": "a572710a-bdb8-47b5-ac05-370b04332d38",
  "timestamp": "2026-05-17T08:51:56.510Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Runtime record

_source line 143 · 2026-05-17T08:51:56.281Z_

```json
{
  "parentUuid": "a572710a-bdb8-47b5-ac05-370b04332d38",
  "isSidechain": false,
  "attachment": {
    "type": "file",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
    "content": {
      "type": "text",
      "file": {
        "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
        "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nWe formalized recursive generation depth estimation and showed that perplexity tail statistics achieve 70--85\\% four-class accuracy ($\\mathrm{EDD}_{0.75}{=}4$), with five features sufficing for 97.6\\% of full performance and classifier-agnostic convergence within $\\leq$0.4pp.\nThese features generalize across model families without retraining, positioning depth estimation as an early-warning signal for model collapse~\\cite{shumailov2024_nature,shi2025_closer_look}; zero-shot LLMs at 30--36\\% (\\S\\ref{sec:gen:baselines}) confirm the signal is inaccessible from surface text alone.\nCross-strategy transfer remains the primary bottleneck; see Limitations for detailed analysis.\nDepth-graduated curation complements binary detection~\\cite{dsir2023,qurating2024} and watermarking~\\cite{kirchenbauer2023_watermark} as a provenance signal~\\cite{bevendorff2025_two_paradigms}; pilot results are inconclusive (Appendix~\\ref{app:curation_poc}) and adversarial robustness remains untested.\n",
        "numLines": 8,
        "startLine": 1,
        "totalLines": 8
      }
    },
    "displayPath": "../../../docs/paper/discussion.tex"
  },
  "type": "attachment",
  "uuid": "dc83beab-8e09-420b-9830-bf9975bb033c",
  "timestamp": "2026-05-17T08:51:56.281Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Runtime record

_source line 144 · 2026-05-17T08:51:56.658Z_

```json
{
  "parentUuid": "dc83beab-8e09-420b-9830-bf9975bb033c",
  "isSidechain": false,
  "attachment": {
    "type": "compact_file_reference",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/references.bib",
    "displayPath": "../../../docs/paper/references.bib"
  },
  "type": "attachment",
  "uuid": "0b5cf510-fa30-44a4-acba-978090b9a8a9",
  "timestamp": "2026-05-17T08:51:56.658Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Runtime record

_source line 145 · 2026-05-17T08:51:56.522Z_

```json
{
  "parentUuid": "0b5cf510-fa30-44a4-acba-978090b9a8a9",
  "isSidechain": false,
  "attachment": {
    "type": "compact_file_reference",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
    "displayPath": "../../../docs/paper/section_appendix.tex"
  },
  "type": "attachment",
  "uuid": "52e7da87-0a1f-4310-b484-b8d53bc52a68",
  "timestamp": "2026-05-17T08:51:56.522Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Runtime record

_source line 146 · 2026-05-17T08:51:56.659Z_

```json
{
  "parentUuid": "52e7da87-0a1f-4310-b484-b8d53bc52a68",
  "isSidechain": false,
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "addedLines": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "cdf0e63f-1ed9-4ce3-a075-256070d6f86f",
  "timestamp": "2026-05-17T08:51:56.659Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Runtime record

_source line 147 · 2026-05-17T08:51:56.659Z_

```json
{
  "parentUuid": "cdf0e63f-1ed9-4ce3-a075-256070d6f86f",
  "isSidechain": false,
  "attachment": {
    "type": "mcp_instructions_delta",
    "addedNames": [
      "agent-ml-research"
    ],
    "addedBlocks": [
      "## agent-ml-research\nML research experiment management tools"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "e6a7022d-58ca-4641-97ea-6ce8046e3504",
  "timestamp": "2026-05-17T08:51:56.659Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Assistant

_source line 148 · 2026-05-17T08:52:02.239Z_

<details><summary>Logged reasoning block</summary>

```text
I need to compose and submit the Round 1 review report. I have all the data gathered from my previous analysis. Let me compile the review now and submit it via `review_reviewer_post_to_director`.

Let me re-read a few key files to make sure I have the latest content fresh before writing the review.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6a7022d-58ca-4641-97ea-6ce8046e3504",
  "isSidechain": false,
  "requestId": "req_011Cb7rdQJgp23PWoLUcwE7E",
  "type": "assistant",
  "uuid": "7c35ae9c-503b-49c7-98e5-303cee740253",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019L43kn9DMt8E4Mc3f838VN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 21451,
      "cache_read_input_tokens": 11841,
      "output_tokens": 338,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21451,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 338,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 21451,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21451
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


### Assistant

_source line 149 · 2026-05-17T08:52:02.324Z_

Let me re-read a few critical sections to ensure accuracy before composing the review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7c35ae9c-503b-49c7-98e5-303cee740253",
  "isSidechain": false,
  "requestId": "req_011Cb7rdQJgp23PWoLUcwE7E",
  "type": "assistant",
  "uuid": "32a746a5-5c16-4fa8-a4ef-7e8cff5a328f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019L43kn9DMt8E4Mc3f838VN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 21451,
      "cache_read_input_tokens": 11841,
      "output_tokens": 338,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21451,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 338,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 21451,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21451
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


### Tool call

_source line 150 · 2026-05-17T08:52:02.611Z_

<details open><summary>🔧 Tool call — Read · `toolu_01G418cqqH5jicsJZmodUdb7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "32a746a5-5c16-4fa8-a4ef-7e8cff5a328f",
  "isSidechain": false,
  "requestId": "req_011Cb7rdQJgp23PWoLUcwE7E",
  "type": "assistant",
  "uuid": "3e86174f-0081-42f0-94bd-92d5c98d598d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019L43kn9DMt8E4Mc3f838VN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 21451,
      "cache_read_input_tokens": 11841,
      "output_tokens": 338,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21451,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 338,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 21451,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21451
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

_source line 151 · 2026-05-17T08:52:03.356Z_

<details><summary>↩ Tool result · `toolu_019vj7fCC9mDP4rxkgyweZ2F`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Problem Definition}
5	\label{sec:method:problem}
6	
7	Let $f_\theta$ denote a language model and $\mathcal{D}_0$ a corpus of human-written seed text.
8	We define a \emph{recursive generation chain} of depth $K$ as the sequence $\mathcal{D}_0, \mathcal{D}_1, \dots, \mathcal{D}_K$, where each $\mathcal{D}_k$ ($k \geq 1$) is produced by finetuning $f_\theta$ on $\mathcal{D}_{k-1}$ and sampling from the resulting model.
9	Depth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.
10	
11	Given a text passage $x$, the task is to estimate its recursive generation depth $d \in \{0, 1, \dots, K\}$.
12	This is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.
13	
14	\subsection{Multi-Generational Benchmark Construction}
15	\label{sec:method:benchmark}
16	
17	We construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.
18	
19	\paragraph{Model families.}
20	We select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).
21	Restricting to a narrow parameter range isolates the effect of architecture and training data from scale.
22	
23	\paragraph{Decoding strategies.}
24	Each model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \cite{holtzman2020_nucleus}, temperature sampling ($\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).
25	These span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.
26	Our findings on feature importance and discriminability are limited to this grid; transfer to untested models, scales, or strategies is not established.
27	
28	\paragraph{Depth and scale.}
29	The primary benchmark covers depths d0--d3 across all $3 \times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).
30	For depth extension experiments (\S\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.
31	
32	\paragraph{Generation pipeline.}
33	Starting from a Wikipedia subset as seed text ($\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \cite{hu2022lora} on $\mathcal{D}_{k-1}$, freezing base model weights and training low-rank update matrices ($<$1\% additional parameters; $r{=}16$, $\alpha{=}32$, lr $2{\times}10^{-4}$, batch size 8, 3 epochs, dropout $0.05$, architecture-specific targets); (2)~sampling 5{,}000 passages from the LoRA-finetuned model (max 512 tokens, BOS-seeded, no prompt conditioning) under the specified decoding strategy; (3)~the generated corpus becomes $\mathcal{D}_k$ for the next cycle.
34	Each depth is produced by a model explicitly trained on the prior depth's data, not by sampling from the unmodified base model.
35	Our BOS-seeded generation may amplify depth signal relative to prompted settings; extending to prompt-conditioned generation is future work.
36	There is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.
37	
38	\paragraph{Reference model.}
39	All statistical features (\S\ref{sec:method:features}) are computed using Pythia-1.4B as fixed reference model, the smallest generator whose training corpus partially overlaps with the others.
40	For Pythia this constitutes self-model measurement, yet its accuracy (78.2\%) does not exceed GPT-2~XL (85.4\%), indicating no systematic self-model advantage.
41	Ablations with OLMo-1B and GPT-2 XL as alternative references yield 67--79\% accuracy (Appendix~\ref{app:ref_ablation}), confirming reference model robustness; further discussion in Limitations.
42	
43	\subsection{Statistical Feature Design}
44	\label{sec:method:features}
45	
46	We extract a feature vector $\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\S\ref{sec:atlas:features}) shows the top 5 achieve 97.6\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features, placing the effective independent dimensionality at ${\approx}$4--5.
47	The features fall into four categories (Table~\ref{tab:features}).
48	
49	\begin{table}[t]
50	\centering
51	\small
52	\caption{The 19 statistical features comprising $\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}
53	\label{tab:features}
54	\begin{tabular}{@{}llr@{}}
55	\toprule
56	Category & Features & $n$ \\
57	\midrule
58	Perplexity & mean, var, skewness, kurtosis, & 9 \\
59	statistics & p10, p25, p50, p75, p90 & \\
60	\addlinespace
61	Surprisal & mean, var, entropy & 3 \\
62	statistics & & \\
63	\addlinespace
64	Lexical & type--token ratio, hapax ratio, & 4 \\
65	diversity & bigram entropy, trigram entropy & \\
66	\addlinespace
67	Repetition & repeated 2/3/4-gram fractions & 3 \\
68	\bottomrule
69	\end{tabular}
70	\end{table}
71	
72	\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments (mean, variance, skewness, kurtosis) and quantiles (p10--p90); tail quantiles prove especially informative as recursive finetuning erodes the high-perplexity tail (\S\ref{sec:atlas}).
73	\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\log p(\text{token})$; surprisal variance captures second-order structure not redundant with perplexity moments.
74	\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.
75	\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \in \{2, 3, 4\}$.
76	
77	\subsection{Effective Discriminable Depth}
78	\label{sec:method:edd}
79	
80	Aggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.
81	We introduce the \emph{Effective Discriminable Depth} (EDD) to formalize the frontier beyond which adjacent depths become statistically indistinguishable.
82	
83	\paragraph{Pairwise discriminability.}
84	Let $\mathcal{D} = \{0, 1, \dots, K\}$ denote the depth set and $T \in (0.5, 1.0]$ a discrimination threshold.
85	For each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\lfloor\sqrt{19}\rfloor$ candidate features per split) trained on class-balanced data from $\mathbf{f}(x)$ (\S\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.
86	Each pair uses an independent classifier, avoiding the decision boundary dilution that arises in multi-class settings (\S\ref{sec:atlas:edd}).
87	
88	\begin{definition}[Effective Discriminable Depth]
89	\label{def:edd}
90	The \emph{Effective Discriminable Depth} at threshold $T$ is:
91	\begin{equation}
92	\mathrm{EDD}_T = \max \bigl\{ d^*{+}1 \,:\, \forall\, d' \leq d^*,\; \mathrm{AUC}(d', d'{+}1) \geq T \bigr\}
93	\label{eq:edd}
94	\end{equation}
95	where $d^* \in \{0, \dots, K{-}1\}$. If\, $\mathrm{AUC}(0,1) < T$, then $\mathrm{EDD}_T = 0$.
96	\end{definition}
97	
98	$\mathrm{EDD}_T$ is the deepest depth $d$ such that every adjacent pair from $(0,1)$ through $(d{-}1, d)$ remains discriminable at level $T$.
99	The universal quantifier ensures EDD reports the longest \emph{contiguous} discriminable prefix rather than an isolated high-AUC pair at greater depth.\footnote{Our AUC profiles are empirically monotonically decreasing for the 1--1.5B base models (\S\ref{sec:atlas}), so in practice $\mathrm{EDD}_T = \max\{d'{+}1 : \mathrm{AUC}(d', d'{+}1) \geq T\}$. Qwen2.5-7B exhibits a U-shaped AUC pattern rather than monotonic decay; a base-model control shows non-monotonic decay persists without instruction tuning (\S\ref{sec:gen:crossscale}). For non-monotonic profiles, the contiguous formulation is more conservative (see Limitations).}
100	We set $T{=}0.75$ as default; sensitivity at $T \in \{0.65, 0.70, 0.75, 0.80\}$ is reported in \S\ref{sec:atlas}.
101	
102	\paragraph{Classifiers.}
103	Our primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).
104	We compare against CORAL ordinal regression \cite{coral2020}, DivEye \cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \S\ref{sec:generalization}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3fa5dfef-3411-49be-a860-4706e5e7dc32",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "a1e14b3c-2092-4d4b-99ee-cc1b21779a8c",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Problem Definition}\n\\label{sec:method:problem}\n\nLet $f_\\theta$ denote a language model and $\\mathcal{D}_0$ a corpus of human-written seed text.\nWe define a \\emph{recursive generation chain} of depth $K$ as the sequence $\\mathcal{D}_0, \\mathcal{D}_1, \\dots, \\mathcal{D}_K$, where each $\\mathcal{D}_k$ ($k \\geq 1$) is produced by finetuning $f_\\theta$ on $\\mathcal{D}_{k-1}$ and sampling from the resulting model.\nDepth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \\geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.\n\nGiven a text passage $x$, the task is to estimate its recursive generation depth $d \\in \\{0, 1, \\dots, K\\}$.\nThis is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.\n\n\\subsection{Multi-Generational Benchmark Construction}\n\\label{sec:method:benchmark}\n\nWe construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.\n\n\\paragraph{Model families.}\nWe select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).\nRestricting to a narrow parameter range isolates the effect of architecture and training data from scale.\n\n\\paragraph{Decoding strategies.}\nEach model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \\cite{holtzman2020_nucleus}, temperature sampling ($\\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).\nThese span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.\nOur findings on feature importance and discriminability are limited to this grid; transfer to untested models, scales, or strategies is not established.\n\n\\paragraph{Depth and scale.}\nThe primary benchmark covers depths d0--d3 across all $3 \\times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).\nFor depth extension experiments (\\S\\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.\n\n\\paragraph{Generation pipeline.}\nStarting from a Wikipedia subset as seed text ($\\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \\cite{hu2022lora} on $\\mathcal{D}_{k-1}$, freezing base model weights and training low-rank update matrices ($<$1\\% additional parameters; $r{=}16$, $\\alpha{=}32$, lr $2{\\times}10^{-4}$, batch size 8, 3 epochs, dropout $0.05$, architecture-specific targets); (2)~sampling 5{,}000 passages from the LoRA-finetuned model (max 512 tokens, BOS-seeded, no prompt conditioning) under the specified decoding strategy; (3)~the generated corpus becomes $\\mathcal{D}_k$ for the next cycle.\nEach depth is produced by a model explicitly trained on the prior depth's data, not by sampling from the unmodified base model.\nOur BOS-seeded generation may amplify depth signal relative to prompted settings; extending to prompt-conditioned generation is future work.\nThere is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.\n\n\\paragraph{Reference model.}\nAll statistical features (\\S\\ref{sec:method:features}) are computed using Pythia-1.4B as fixed reference model, the smallest generator whose training corpus partially overlaps with the others.\nFor Pythia this constitutes self-model measurement, yet its accuracy (78.2\\%) does not exceed GPT-2~XL (85.4\\%), indicating no systematic self-model advantage.\nAblations with OLMo-1B and GPT-2 XL as alternative references yield 67--79\\% accuracy (Appendix~\\ref{app:ref_ablation}), confirming reference model robustness; further discussion in Limitations.\n\n\\subsection{Statistical Feature Design}\n\\label{sec:method:features}\n\nWe extract a feature vector $\\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\\S\\ref{sec:atlas:features}) shows the top 5 achieve 97.6\\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features, placing the effective independent dimensionality at ${\\approx}$4--5.\nThe features fall into four categories (Table~\\ref{tab:features}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{The 19 statistical features comprising $\\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}\n\\label{tab:features}\n\\begin{tabular}{@{}llr@{}}\n\\toprule\nCategory & Features & $n$ \\\\\n\\midrule\nPerplexity & mean, var, skewness, kurtosis, & 9 \\\\\nstatistics & p10, p25, p50, p75, p90 & \\\\\n\\addlinespace\nSurprisal & mean, var, entropy & 3 \\\\\nstatistics & & \\\\\n\\addlinespace\nLexical & type--token ratio, hapax ratio, & 4 \\\\\ndiversity & bigram entropy, trigram entropy & \\\\\n\\addlinespace\nRepetition & repeated 2/3/4-gram fractions & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments (mean, variance, skewness, kurtosis) and quantiles (p10--p90); tail quantiles prove especially informative as recursive finetuning erodes the high-perplexity tail (\\S\\ref{sec:atlas}).\n\\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\\log p(\\text{token})$; surprisal variance captures second-order structure not redundant with perplexity moments.\n\\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.\n\\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \\in \\{2, 3, 4\\}$.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:method:edd}\n\nAggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.\nWe introduce the \\emph{Effective Discriminable Depth} (EDD) to formalize the frontier beyond which adjacent depths become statistically indistinguishable.\n\n\\paragraph{Pairwise discriminability.}\nLet $\\mathcal{D} = \\{0, 1, \\dots, K\\}$ denote the depth set and $T \\in (0.5, 1.0]$ a discrimination threshold.\nFor each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\\lfloor\\sqrt{19}\\rfloor$ candidate features per split) trained on class-balanced data from $\\mathbf{f}(x)$ (\\S\\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.\nEach pair uses an independent classifier, avoiding the decision boundary dilution that arises in multi-class settings (\\S\\ref{sec:atlas:edd}).\n\n\\begin{definition}[Effective Discriminable Depth]\n\\label{def:edd}\nThe \\emph{Effective Discriminable Depth} at threshold $T$ is:\n\\begin{equation}\n\\mathrm{EDD}_T = \\max \\bigl\\{ d^*{+}1 \\,:\\, \\forall\\, d' \\leq d^*,\\; \\mathrm{AUC}(d', d'{+}1) \\geq T \\bigr\\}\n\\label{eq:edd}\n\\end{equation}\nwhere $d^* \\in \\{0, \\dots, K{-}1\\}$. If\\, $\\mathrm{AUC}(0,1) < T$, then $\\mathrm{EDD}_T = 0$.\n\\end{definition}\n\n$\\mathrm{EDD}_T$ is the deepest depth $d$ such that every adjacent pair from $(0,1)$ through $(d{-}1, d)$ remains discriminable at level $T$.\nThe universal quantifier ensures EDD reports the longest \\emph{contiguous} discriminable prefix rather than an isolated high-AUC pair at greater depth.\\footnote{Our AUC profiles are empirically monotonically decreasing for the 1--1.5B base models (\\S\\ref{sec:atlas}), so in practice $\\mathrm{EDD}_T = \\max\\{d'{+}1 : \\mathrm{AUC}(d', d'{+}1) \\geq T\\}$. Qwen2.5-7B exhibits a U-shaped AUC pattern rather than monotonic decay; a base-model control shows non-monotonic decay persists without instruction tuning (\\S\\ref{sec:gen:crossscale}). For non-monotonic profiles, the contiguous formulation is more conservative (see Limitations).}\nWe set $T{=}0.75$ as default; sensitivity at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ is reported in \\S\\ref{sec:atlas}.\n\n\\paragraph{Classifiers.}\nOur primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).\nWe compare against CORAL ordinal regression \\cite{coral2020}, DivEye \\cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \\S\\ref{sec:generalization}.",
      "numLines": 104,
      "startLine": 1,
      "totalLines": 104
    }
  },
  "sourceToolAssistantUUID": "3fa5dfef-3411-49be-a860-4706e5e7dc32",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool result

_source line 152 · 2026-05-17T08:52:02.621Z_

<details><summary>↩ Tool result · `toolu_01G418cqqH5jicsJZmodUdb7`</summary>

```text
1	\begin{abstract}
2	As large language models increasingly train on web text containing their own outputs, a recursive model$\to$data$\to$model loop arises, yet no method estimates how many such iterations a text has undergone.
3	We formalize \emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.
4	A Random Forest over 19 perplexity-based features achieves 70--85\% four-class accuracy (chance = 25\%), with perplexity tail statistics emerging as consistent depth markers; a parsimonious subset of 5 features retains 97.6\% of full performance.
5	We define the \emph{Effective Discriminable Depth} (EDD) metric, finding $\mathrm{EDD}_{0.75}{=}4$ for the best-characterized family, and show that cross-model transfer reaches 66.4\% (2.7$\times$ chance).
6	Systematic generalization across seven axes (including cross-scale with 7B models at 70.2\%, cross-domain, and LoRA-rank ablation) confirms that depth signal is robust and resides in distributional statistics inaccessible from surface text (zero-shot LLMs: 30--36\%, 42\,pp below RF).
7	\end{abstract}
8	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3e86174f-0081-42f0-94bd-92d5c98d598d",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "6b43210a-4fb6-46d7-adc5-46497dc58423",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nAs large language models increasingly train on web text containing their own outputs, a recursive model$\\to$data$\\to$model loop arises, yet no method estimates how many such iterations a text has undergone.\nWe formalize \\emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.\nA Random Forest over 19 perplexity-based features achieves 70--85\\% four-class accuracy (chance = 25\\%), with perplexity tail statistics emerging as consistent depth markers; a parsimonious subset of 5 features retains 97.6\\% of full performance.\nWe define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.75}{=}4$ for the best-characterized family, and show that cross-model transfer reaches 66.4\\% (2.7$\\times$ chance).\nSystematic generalization across seven axes (including cross-scale with 7B models at 70.2\\%, cross-domain, and LoRA-rank ablation) confirms that depth signal is robust and resides in distributional statistics inaccessible from surface text (zero-shot LLMs: 30--36\\%, 42\\,pp below RF).\n\\end{abstract}\n",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  },
  "sourceToolAssistantUUID": "3e86174f-0081-42f0-94bd-92d5c98d598d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool call

_source line 153 · 2026-05-17T08:52:03.177Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FS36QtfqVxCHHYfBoEBByv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6b43210a-4fb6-46d7-adc5-46497dc58423",
  "isSidechain": false,
  "requestId": "req_011Cb7rdQJgp23PWoLUcwE7E",
  "type": "assistant",
  "uuid": "331a601e-486f-49d9-a1c4-cf8ec685d7f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019L43kn9DMt8E4Mc3f838VN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 21451,
      "cache_read_input_tokens": 11841,
      "output_tokens": 338,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21451,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 338,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 21451,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21451
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

_source line 154 · 2026-05-17T08:52:03.187Z_

<details><summary>↩ Tool result · `toolu_01FS36QtfqVxCHHYfBoEBByv`</summary>

```text
1	\section{Introduction}
2	\label{sec:intro}
3	
4	The text on which large language models are trained increasingly contains their own outputs.
5	As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \cite{shumailov2024_nature,alemohammad2024_mad}.
6	This model$\to$data$\to$model cycle is no longer hypothetical; it is already occurring in the wild. Yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \cite{dohmatob2024_tale_of_tails}.
7	
8	Existing tools address adjacent but distinct problems.
9	Binary detectors such as Binoculars \cite{binoculars2024}, Fast-DetectGPT \cite{fast_detectgpt2024}, and DivEye \cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \geq 1$ into a single category.
10	Watermarking \cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.
11	The model collapse literature \cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.
12	No existing method estimates the ordinal recursive generation depth of a text passage from its content alone.
13	
14	We find that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \textbf{consistent in direction but scale-dependent in magnitude} across the three model families and three decoding strategies studied.
15	Specifically, perplexity tail statistics (the 90th-percentile perplexity, \textsc{p90\_ppl}, and surprisal variance, \textsc{var\_surprisal}) emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.
16	Instruction-tuned variants exhibit monotonically decreasing AUC (regularization), whereas base models can show non-monotonic trajectories, suggesting that instruction tuning acts as a regularizer on the depth signal rather than introducing degradation.
17	
18	We formalize recursive generation depth estimation as ordinal classification and introduce a lightweight pipeline: compute 19 reference-model perplexity features (effective dimensionality ${\approx}$4--5 due to multicollinearity; \S\ref{sec:atlas:features}) and classify with a Random Forest into $K{+}1$ depth classes.
19	To characterize how recursive generation reshapes these features, we construct the \emph{Depth Degradation Atlas}: a $3 \times 3$ grid of model families $\times$ decoding strategies spanning 4 depths (180K samples).
20	The atlas reveals strategy-dependent degradation trajectories and we introduce the \emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.
21	
22	Our contributions are:
23	\begin{itemize}
24	    \item \textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark spanning 3 model families $\times$ 3 decoding strategies $\times$ 4 depths.
25	
26	    \item \textbf{Depth Degradation Atlas.} A systematic $3 \times 3$ characterization reveals that perplexity tail statistics dominate depth discrimination (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and $\mathrm{EDD}_{0.75}{=}4$ for the best-characterized family (Pythia, $p{=}0.001$; consistent across all three families).
27	
28	    \item \textbf{Generalization across seven axes.} Cross-model recursive chains (84.75\%), cross-scale observations on two 7B models (70.2\% and 60.1\%), cross-domain transfer (arXiv 74.1\%), temperature robustness ($\tau \in [0.5, 0.9]$), and reference model robustness (67--79\% accuracy across three reference models). A surface-text ablation (zero-shot LLMs at 30--36\%, 42\,pp below RF) confirms the signal resides in distributional statistics, while requiring only 19 features and a Random Forest for GPU-free inference.
29	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "331a601e-486f-49d9-a1c4-cf8ec685d7f1",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "0cdc6bfc-2c43-4817-9aa3-5aea4fdcd262",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical; it is already occurring in the wild. Yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive generation depth of a text passage from its content alone.\n\nWe find that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \\textbf{consistent in direction but scale-dependent in magnitude} across the three model families and three decoding strategies studied.\nSpecifically, perplexity tail statistics (the 90th-percentile perplexity, \\textsc{p90\\_ppl}, and surprisal variance, \\textsc{var\\_surprisal}) emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.\nInstruction-tuned variants exhibit monotonically decreasing AUC (regularization), whereas base models can show non-monotonic trajectories, suggesting that instruction tuning acts as a regularizer on the depth signal rather than introducing degradation.\n\nWe formalize recursive generation depth estimation as ordinal classification and introduce a lightweight pipeline: compute 19 reference-model perplexity features (effective dimensionality ${\\approx}$4--5 due to multicollinearity; \\S\\ref{sec:atlas:features}) and classify with a Random Forest into $K{+}1$ depth classes.\nTo characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families $\\times$ decoding strategies spanning 4 depths (180K samples).\nThe atlas reveals strategy-dependent degradation trajectories and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\\begin{itemize}\n    \\item \\textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark spanning 3 model families $\\times$ 3 decoding strategies $\\times$ 4 depths.\n\n    \\item \\textbf{Depth Degradation Atlas.} A systematic $3 \\times 3$ characterization reveals that perplexity tail statistics dominate depth discrimination (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and $\\mathrm{EDD}_{0.75}{=}4$ for the best-characterized family (Pythia, $p{=}0.001$; consistent across all three families).\n\n    \\item \\textbf{Generalization across seven axes.} Cross-model recursive chains (84.75\\%), cross-scale observations on two 7B models (70.2\\% and 60.1\\%), cross-domain transfer (arXiv 74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model robustness (67--79\\% accuracy across three reference models). A surface-text ablation (zero-shot LLMs at 30--36\\%, 42\\,pp below RF) confirms the signal resides in distributional statistics, while requiring only 19 features and a Random Forest for GPU-free inference.\n\\end{itemize}",
      "numLines": 29,
      "startLine": 1,
      "totalLines": 29
    }
  },
  "sourceToolAssistantUUID": "331a601e-486f-49d9-a1c4-cf8ec685d7f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool call

_source line 155 · 2026-05-17T08:52:03.346Z_

<details open><summary>🔧 Tool call — Read · `toolu_019vj7fCC9mDP4rxkgyweZ2F`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0cdc6bfc-2c43-4817-9aa3-5aea4fdcd262",
  "isSidechain": false,
  "requestId": "req_011Cb7rdQJgp23PWoLUcwE7E",
  "type": "assistant",
  "uuid": "3fa5dfef-3411-49be-a860-4706e5e7dc32",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019L43kn9DMt8E4Mc3f838VN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 21451,
      "cache_read_input_tokens": 11841,
      "output_tokens": 338,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21451,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 338,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 21451,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21451
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


### Runtime record

_source line 156_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Review Assignment: R2 — Novelty & Related Work  **Venue:** EMNLP 2026 Main (via ACL Rolling Review) **Paper:** \"Ordinal Depth Estimation for Recursive Language Model Generations: A…",
  "leafUuid": "a1e14b3c-2092-4d4b-99ee-cc1b21779a8c",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 157_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Tool call

_source line 158 · 2026-05-17T08:52:07.205Z_

<details open><summary>🔧 Tool call — Read · `toolu_01QmxgtAETkxNcJkTZzrJcLv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a1e14b3c-2092-4d4b-99ee-cc1b21779a8c",
  "isSidechain": false,
  "requestId": "req_011Cb7rdu3aEXUcpz4sFtKTX",
  "type": "assistant",
  "uuid": "c2cacbc8-b842-481d-b1c2-f8ef4a994466",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Y2sYrov5ExPEo3FGB47thc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4898,
      "cache_read_input_tokens": 33292,
      "output_tokens": 198,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4898,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 198,
          "cache_read_input_tokens": 33292,
          "cache_creation_input_tokens": 4898,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4898
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

_source line 159 · 2026-05-17T08:52:07.209Z_

<details><summary>↩ Tool result · `toolu_01QmxgtAETkxNcJkTZzrJcLv`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	\paragraph{Cross-strategy deployment constraint.}
5	Cross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.
6	Per-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\to}0.56$, OLMo $0.19{\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\Delta < 0.02$\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\sim}0.83$), indicating that a two-stage pipeline (strategy identification + strategy-conditioned classification) is needed for reliable cross-strategy deployment.
7	
8	\paragraph{d0 inflation of headline metrics.}
9	Depth~0 (human-written text) is near-perfectly separable (recall $>$98\% across all nine model--strategy settings), inflating headline accuracy.
10	Cross-model transfer accuracy of 66.4\% is substantially driven by d0; d2 recall drops to 26.8\% in the worst case (Pythia holdout).
11	
12	\paragraph{Controlled vs.\ ecological setting.}
13	The primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\S\ref{sec:gen:crossscale}).
14	This protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.
15	Depth signal is the dominant classification factor (5-fold CV 59--82\%, up to 2.5$\times$ chance): LOGO accuracy (72.1\%) matches standard CV (72.0\%), and seed-group prediction is at chance (10.2\% vs.\ 10\%; Appendix~\ref{app:domain_bias}).
16	Cross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\% vs.\ 70.2\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.
17	Real-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.
18	
19	\paragraph{Domain-dependent false positive rate.}
20	On editorial text (WikiText-103), all classifiers achieve $\geq$98.5\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL).
21	Misclassifications concentrate in template/SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\ Pythia/GPT-2~XL's Wikipedia/WebText).
22	Deployment on heterogeneous web corpora requires model- and domain-specific calibration.
23	
24	\paragraph{Adversarial robustness.}
25	Adversarial paraphrasing \cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.
26	
27	\paragraph{EDD monotonicity assumption.}
28	Our EDD definition (Eq.~\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically, as observed in all our configurations.
29	However, \citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).
30	Our cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.
31	In such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.
32	The choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.
33	
34	\paragraph{Reference model dependency.}
35	Reference model choice affects classification accuracy by up to 11\,pp; same-family references yield optimal performance, though all configurations exceed $2.5\times$ chance.
36	Surprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.
37	For the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.
38	Empirically, the self-model configuration does not yield the highest accuracy (Pythia 78.2\% vs.\ GPT-2~XL 85.4\%), suggesting the overlap does not confer a systematic advantage.
39	An ablation with OLMo-1B and GPT-2 XL as alternative references shows accuracy ranging from 67--79\% across three reference architectures (Appendix~\ref{app:ref_ablation}), all exceeding $2.5\times$ chance; same-family reference yields optimal performance ($\Delta{\leq}$11\,pp).
40	The choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.
41	Reference-free surface features alone achieve 53.7\% (confirming partial signal in lexical statistics) but 25pp below the full pipeline, underscoring that surprisal-based features are essential.
42	Simple multi-reference ensembling does not outperform the best single reference (73.7\% vs.\ 78.6\%).
43	
44	\paragraph{Single LoRA instance.}
45	Independent replication with seed=43 yields 77.15\% (95\% CI [76.4, 78.15], $\Delta{=}{-}1.05$\,pp vs.\ baseline); cross-seed transfer retains 76.76\% ($\Delta{=}{-}1.30$\,pp vs.\ within-seed avg), confirming depth signal is inherent to the recursive process rather than specific LoRA weights (Appendix~\ref{app:seed_replication}).
46	Top-5 feature importance is identical across seeds.
47	
48	\paragraph{Additional caveats.}
49	Depth signal scales with passage length (128 tokens: 68.4\%, 512 tokens: 77.8\%; Appendix~\ref{app:length_ablation}), saturating near 500 tokens; shorter passages remain above chance but with reduced discriminability.
50	Detection features degrade under domain shift \cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.
51	\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.
52	
53	\section*{Ethics Statement}
54	
55	This work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.
56	No human subjects were involved, no private or sensitive data were collected, and no new models were released.
57	Our method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.
58	Code and data will be released upon acceptance.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c2cacbc8-b842-481d-b1c2-f8ef4a994466",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "bce2acec-bb09-4f4b-8c03-0641907d7925",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\n\\paragraph{Cross-strategy deployment constraint.}\nCross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.\nPer-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\\to}0.56$, OLMo $0.19{\\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\\Delta < 0.02$\\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\\sim}0.83$), indicating that a two-stage pipeline (strategy identification + strategy-conditioned classification) is needed for reliable cross-strategy deployment.\n\n\\paragraph{d0 inflation of headline metrics.}\nDepth~0 (human-written text) is near-perfectly separable (recall $>$98\\% across all nine model--strategy settings), inflating headline accuracy.\nCross-model transfer accuracy of 66.4\\% is substantially driven by d0; d2 recall drops to 26.8\\% in the worst case (Pythia holdout).\n\n\\paragraph{Controlled vs.\\ ecological setting.}\nThe primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\\S\\ref{sec:gen:crossscale}).\nThis protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.\nDepth signal is the dominant classification factor (5-fold CV 59--82\\%, up to 2.5$\\times$ chance): LOGO accuracy (72.1\\%) matches standard CV (72.0\\%), and seed-group prediction is at chance (10.2\\% vs.\\ 10\\%; Appendix~\\ref{app:domain_bias}).\nCross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\\% vs.\\ 70.2\\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.\nReal-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.\n\n\\paragraph{Domain-dependent false positive rate.}\nOn editorial text (WikiText-103), all classifiers achieve $\\geq$98.5\\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL).\nMisclassifications concentrate in template/SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\\ Pythia/GPT-2~XL's Wikipedia/WebText).\nDeployment on heterogeneous web corpora requires model- and domain-specific calibration.\n\n\\paragraph{Adversarial robustness.}\nAdversarial paraphrasing \\cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.\n\n\\paragraph{EDD monotonicity assumption.}\nOur EDD definition (Eq.~\\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically, as observed in all our configurations.\nHowever, \\citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \\emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).\nOur cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.\nIn such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.\nThe choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.\n\n\\paragraph{Reference model dependency.}\nReference model choice affects classification accuracy by up to 11\\,pp; same-family references yield optimal performance, though all configurations exceed $2.5\\times$ chance.\nSurprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.\nFor the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.\nEmpirically, the self-model configuration does not yield the highest accuracy (Pythia 78.2\\% vs.\\ GPT-2~XL 85.4\\%), suggesting the overlap does not confer a systematic advantage.\nAn ablation with OLMo-1B and GPT-2 XL as alternative references shows accuracy ranging from 67--79\\% across three reference architectures (Appendix~\\ref{app:ref_ablation}), all exceeding $2.5\\times$ chance; same-family reference yields optimal performance ($\\Delta{\\leq}$11\\,pp).\nThe choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.\nReference-free surface features alone achieve 53.7\\% (confirming partial signal in lexical statistics) but 25pp below the full pipeline, underscoring that surprisal-based features are essential.\nSimple multi-reference ensembling does not outperform the best single reference (73.7\\% vs.\\ 78.6\\%).\n\n\\paragraph{Single LoRA instance.}\nIndependent replication with seed=43 yields 77.15\\% (95\\% CI [76.4, 78.15], $\\Delta{=}{-}1.05$\\,pp vs.\\ baseline); cross-seed transfer retains 76.76\\% ($\\Delta{=}{-}1.30$\\,pp vs.\\ within-seed avg), confirming depth signal is inherent to the recursive process rather than specific LoRA weights (Appendix~\\ref{app:seed_replication}).\nTop-5 feature importance is identical across seeds.\n\n\\paragraph{Additional caveats.}\nDepth signal scales with passage length (128 tokens: 68.4\\%, 512 tokens: 77.8\\%; Appendix~\\ref{app:length_ablation}), saturating near 500 tokens; shorter passages remain above chance but with reduced discriminability.\nDetection features degrade under domain shift \\cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.\n\\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.\n\n\\section*{Ethics Statement}\n\nThis work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.\nNo human subjects were involved, no private or sensitive data were collected, and no new models were released.\nOur method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.\nCode and data will be released upon acceptance.",
      "numLines": 58,
      "startLine": 1,
      "totalLines": 58
    }
  },
  "sourceToolAssistantUUID": "c2cacbc8-b842-481d-b1c2-f8ef4a994466",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool call

_source line 160 · 2026-05-17T08:52:07.691Z_

<details open><summary>🔧 Tool call — Read · `toolu_01T5zDQbxnijax1pYzpP5VcQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
  "offset": 0,
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bce2acec-bb09-4f4b-8c03-0641907d7925",
  "isSidechain": false,
  "requestId": "req_011Cb7rdu3aEXUcpz4sFtKTX",
  "type": "assistant",
  "uuid": "b7e1c621-2c8e-4823-8ed3-1e32ef7cee11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Y2sYrov5ExPEo3FGB47thc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4898,
      "cache_read_input_tokens": 33292,
      "output_tokens": 198,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4898,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 198,
          "cache_read_input_tokens": 33292,
          "cache_creation_input_tokens": 4898,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4898
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

_source line 161 · 2026-05-17T08:52:07.696Z_

<details><summary>↩ Tool result · `toolu_01T5zDQbxnijax1pYzpP5VcQ`</summary>

```text
0	\section{Additional Results}
1	\label{app:additional}
2	
3	\subsection{Top-$k$ Feature Trajectories}
4	\label{app:topk_trajectories}
5	
6	Figure~\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\tau{=}0.9$) sampling.
7	Top-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \S\ref{sec:atlas:strategy}.
8	Concretely, the d0$\to$d1 drop in \textsc{p90\_ppl} under top-$k$ is 78\% (vs.\ 87\% for nucleus), and the d2$\to$d3 reduction is 31\% (vs.\ 39\% for nucleus).
9	Despite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.
10	
11	\subsection{Permutation Importance}
12	\label{app:permutation}
13	
14	To verify that the Gini-based importance rankings in \S\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.
15	The top-2 features are stable across measures: \textsc{p90\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \textsc{var\_surprisal} in 8/9 (vs.\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \textsc{p75\_ppl} displaces \textsc{var\_surprisal} to rank 3).
16	Kendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).
17	Pairwise Spearman correlations are: SHAP--Gini $\rho{=}0.93$, SHAP--permutation $\rho{=}0.84$, Gini--permutation $\rho{=}0.76$.
18	Per-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.
19	
20	\subsection{Per-Class Recall}
21	\label{app:per_class}
22	
23	Table~\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).
24	Depth~0 recall exceeds 98\% uniformly.
25	Among generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.
26	
27	\begin{table}[h]
28	\centering
29	\small
30	\caption{Per-class recall (\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}
31	\label{tab:per_class_recall}
32	\begin{tabular}{@{}lcccc@{}}
33	\toprule
34	Cell & d0 & d1 & d2 & d3 \\
35	\midrule
36	Pythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\
37	Pythia, $\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\
38	Pythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\
39	OLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\
40	OLMo, $\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\
41	OLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\
42	GPT-2~XL, nuc.     & 99.2 & 85.9 & \textbf{73.3} & 77.5 \\
43	GPT-2~XL, $\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\
44	GPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\
45	\bottomrule
46	\end{tabular}
47	\end{table}
48	
49	\subsection{DCOL Iteration Details}
50	\label{app:dcol_iterations}
51	
52	Table~\ref{tab:dcol_iterations} summarizes all six DCOL iterations.
53	DeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.
54	
55	\begin{table}[h]
56	\centering
57	\small
58	\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\%.}
59	\label{tab:dcol_iterations}
60	\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}
61	\toprule
62	Ver. & Backbone & Config & Outcome \\
63	\midrule
64	v1 & DeBERTa & FT, m\_lr $10^{-3}$ & Embed.\ collapse (31.5\%) \\
65	v2 & DeBERTa & FT, m\_lr $10^{-4}$ & OOM \\
66	v3 & DeBERTa & FT, m\_lr $10^{-4}$ & Forgetting + OOM \\
67	v4 & DeBERTa & LoRA, m\_lr $10^{-3}$ & Embed.\ collapse \\
68	v5 & DeBERTa & LoRA, m\_lr $10^{-4}$ & NaN gradients \\
69	v6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\% ($-$13.7pp) \\
70	\bottomrule
71	\end{tabular}
72	\end{table}
73	
74	\subsection{Zero-Shot LLM Prompt Template}
75	\label{app:zeroshot_prompt}
76	
77	Both DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.
78	The system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).
79	The user message presents the passage (truncated to ${\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.
80	No in-context examples are provided.
81	
82	\begin{quote}
83	\small
84	\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\ldots]''
85	
86	\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \{text\}. Respond with ONLY a JSON object: \{\texttt{"depth"}: $\langle$int 0--3$\rangle$, \texttt{"confidence"}: $\langle$float 0--1$\rangle$, \texttt{"reasoning"}: $\langle$str$\rangle$\}''
87	\end{quote}
88	
89	\subsection{Temperature Robustness}
90	\label{app:multi_tau}
91	
92	The cross-strategy results in \S\ref{sec:gen:crossstrategy} use a single temperature ($\tau{=}0.9$).
93	To test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\tau \in \{0.5, 0.7, 0.9, 1.1\}$ on Pythia-1.4B.
94	
95	\paragraph{Within-$\tau$ robustness.}
96	For $\tau \in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\% to 77.3\% (Table~\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.
97	The same top-5 features (\texttt{var\_surprisal}, \texttt{p90\_ppl}, \texttt{mean\_ppl}, \texttt{mean\_surprisal}, \texttt{p75\_ppl}) dominate across all $\tau$ values with only minor rank-order variation.
98	
99	\paragraph{Collapse at $\tau{=}1.1$: memorization as prerequisite.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b7e1c621-2c8e-4823-8ed3-1e32ef7cee11",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "31b289fa-ab44-4997-a262-8a9c87296f06",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
      "content": "\\section{Additional Results}\n\\label{app:additional}\n\n\\subsection{Top-$k$ Feature Trajectories}\n\\label{app:topk_trajectories}\n\nFigure~\\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\\tau{=}0.9$) sampling.\nTop-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \\S\\ref{sec:atlas:strategy}.\nConcretely, the d0$\\to$d1 drop in \\textsc{p90\\_ppl} under top-$k$ is 78\\% (vs.\\ 87\\% for nucleus), and the d2$\\to$d3 reduction is 31\\% (vs.\\ 39\\% for nucleus).\nDespite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.\n\n\\subsection{Permutation Importance}\n\\label{app:permutation}\n\nTo verify that the Gini-based importance rankings in \\S\\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.\nThe top-2 features are stable across measures: \\textsc{p90\\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \\textsc{var\\_surprisal} in 8/9 (vs.\\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \\textsc{p75\\_ppl} displaces \\textsc{var\\_surprisal} to rank 3).\nKendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).\nPairwise Spearman correlations are: SHAP--Gini $\\rho{=}0.93$, SHAP--permutation $\\rho{=}0.84$, Gini--permutation $\\rho{=}0.76$.\nPer-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.\n\n\\subsection{Per-Class Recall}\n\\label{app:per_class}\n\nTable~\\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).\nDepth~0 recall exceeds 98\\% uniformly.\nAmong generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class recall (\\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}\n\\label{tab:per_class_recall}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & d0 & d1 & d2 & d3 \\\\\n\\midrule\nPythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\\\\nPythia, $\\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\\\\nPythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\\\\nOLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\\\\nOLMo, $\\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\\\\nOLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\\\\nGPT-2~XL, nuc.     & 99.2 & 85.9 & \\textbf{73.3} & 77.5 \\\\\nGPT-2~XL, $\\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\\\\nGPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{DCOL Iteration Details}\n\\label{app:dcol_iterations}\n\nTable~\\ref{tab:dcol_iterations} summarizes all six DCOL iterations.\nDeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\\%.}\n\\label{tab:dcol_iterations}\n\\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}\n\\toprule\nVer. & Backbone & Config & Outcome \\\\\n\\midrule\nv1 & DeBERTa & FT, m\\_lr $10^{-3}$ & Embed.\\ collapse (31.5\\%) \\\\\nv2 & DeBERTa & FT, m\\_lr $10^{-4}$ & OOM \\\\\nv3 & DeBERTa & FT, m\\_lr $10^{-4}$ & Forgetting + OOM \\\\\nv4 & DeBERTa & LoRA, m\\_lr $10^{-3}$ & Embed.\\ collapse \\\\\nv5 & DeBERTa & LoRA, m\\_lr $10^{-4}$ & NaN gradients \\\\\nv6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\\% ($-$13.7pp) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Zero-Shot LLM Prompt Template}\n\\label{app:zeroshot_prompt}\n\nBoth DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.\nThe system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).\nThe user message presents the passage (truncated to ${\\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.\nNo in-context examples are provided.\n\n\\begin{quote}\n\\small\n\\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\\ldots]''\n\n\\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \\{text\\}. Respond with ONLY a JSON object: \\{\\texttt{\"depth\"}: $\\langle$int 0--3$\\rangle$, \\texttt{\"confidence\"}: $\\langle$float 0--1$\\rangle$, \\texttt{\"reasoning\"}: $\\langle$str$\\rangle$\\}''\n\\end{quote}\n\n\\subsection{Temperature Robustness}\n\\label{app:multi_tau}\n\nThe cross-strategy results in \\S\\ref{sec:gen:crossstrategy} use a single temperature ($\\tau{=}0.9$).\nTo test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\\tau \\in \\{0.5, 0.7, 0.9, 1.1\\}$ on Pythia-1.4B.\n\n\\paragraph{Within-$\\tau$ robustness.}\nFor $\\tau \\in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\\% to 77.3\\% (Table~\\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.\nThe same top-5 features (\\texttt{var\\_surprisal}, \\texttt{p90\\_ppl}, \\texttt{mean\\_ppl}, \\texttt{mean\\_surprisal}, \\texttt{p75\\_ppl}) dominate across all $\\tau$ values with only minor rank-order variation.\n\n\\paragraph{Collapse at $\\tau{=}1.1$: memorization as prerequisite.}",
      "numLines": 100,
      "startLine": 0,
      "totalLines": 505
    }
  },
  "sourceToolAssistantUUID": "b7e1c621-2c8e-4823-8ed3-1e32ef7cee11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Runtime record

_source line 162_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Review Assignment: R2 — Novelty & Related Work  **Venue:** EMNLP 2026 Main (via ACL Rolling Review) **Paper:** \"Ordinal Depth Estimation for Recursive Language Model Generations: A…",
  "leafUuid": "31b289fa-ab44-4997-a262-8a9c87296f06",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 163_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Tool call

_source line 164 · 2026-05-17T08:52:12.204Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01M6mEWnH6k7Rc4K4PgGqf9K`</summary>

```json
{
  "pattern": "ref_ablation|app:ref_ablation",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
  "output_mode": "content",
  "-n": true,
  "-A": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "31b289fa-ab44-4997-a262-8a9c87296f06",
  "isSidechain": false,
  "requestId": "req_011Cb7reDdGWcjFKvuaus9zm",
  "type": "assistant",
  "uuid": "d5edf8b0-213f-429b-836a-ab20a83e962c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fhnw2HQJ4nv9y2UbvB86NF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5038,
      "cache_read_input_tokens": 38190,
      "output_tokens": 173,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5038,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 173,
          "cache_read_input_tokens": 38190,
          "cache_creation_input_tokens": 5038,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5038
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

_source line 165 · 2026-05-17T08:52:12.220Z_

<details><summary>↩ Tool result · `toolu_01M6mEWnH6k7Rc4K4PgGqf9K`</summary>

```text
296:\label{app:ref_ablation}
297-
298-\begin{table}[h]
299-\centering
300-\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}
301:\label{tab:ref_ablation}
302-\begin{tabular}{lcc}
303-\toprule
304-Reference Model & Architecture & Accuracy (\%) \\
305-\midrule
306-Pythia-1.4B (self) & GPT-NeoX & 78.6 $\pm$ 0.6 \\
307-OLMo-1B (cross) & OLMo & 74.5 $\pm$ 0.7 \\
308-\bottomrule
309-\end{tabular}
310-\end{table}
311-
312-\subsection{Cross-Scale Full Results}
313-\label{app:cross_scale_full}
314-
315-This section provides the full cross-scale analysis summarized in \S\ref{sec:gen:crossscale}.
316-We extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \in \{0, 1, \ldots, 5\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).
317-Feature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.
318-
319-\paragraph{Scale comparison.}
320-Table~\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).
321-
322-\begin{table}[h]
323-\centering
324-\small
325-\caption{Cross-scale comparison: 4-class RF accuracy (\%, depths 0--3, nucleus), $\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\% bootstrap. Chance = 25\%.}
326-\label{tab:cross_scale}
327-\begin{tabular}{@{}lccc@{}}
328-\toprule
329-Model & 4-class acc & $\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\
330-\midrule
331-GPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d5edf8b0-213f-429b-836a-ab20a83e962c",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "e925d121-5c09-468b-851e-8cb581b02e4d",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "296:\\label{app:ref_ablation}\n297-\n298-\\begin{table}[h]\n299-\\centering\n300-\\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}\n301:\\label{tab:ref_ablation}\n302-\\begin{tabular}{lcc}\n303-\\toprule\n304-Reference Model & Architecture & Accuracy (\\%) \\\\\n305-\\midrule\n306-Pythia-1.4B (self) & GPT-NeoX & 78.6 $\\pm$ 0.6 \\\\\n307-OLMo-1B (cross) & OLMo & 74.5 $\\pm$ 0.7 \\\\\n308-\\bottomrule\n309-\\end{tabular}\n310-\\end{table}\n311-\n312-\\subsection{Cross-Scale Full Results}\n313-\\label{app:cross_scale_full}\n314-\n315-This section provides the full cross-scale analysis summarized in \\S\\ref{sec:gen:crossscale}.\n316-We extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \\in \\{0, 1, \\ldots, 5\\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).\n317-Feature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.\n318-\n319-\\paragraph{Scale comparison.}\n320-Table~\\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).\n321-\n322-\\begin{table}[h]\n323-\\centering\n324-\\small\n325-\\caption{Cross-scale comparison: 4-class RF accuracy (\\%, depths 0--3, nucleus), $\\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\\% bootstrap. Chance = 25\\%.}\n326-\\label{tab:cross_scale}\n327-\\begin{tabular}{@{}lccc@{}}\n328-\\toprule\n329-Model & 4-class acc & $\\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\\\\n330-\\midrule\n331-GPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\\\",
    "numLines": 36
  },
  "sourceToolAssistantUUID": "d5edf8b0-213f-429b-836a-ab20a83e962c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Assistant

_source line 166 · 2026-05-17T08:52:17.647Z_

Confirmed: Table 16 (ref_ablation) only has 2 rows (Pythia-1.4B and OLMo-1B), but method.tex line 41 and conclusion.tex line 39 claim "three reference architectures" with "67--79%" range. GPT-2 XL reference results are missing from the table.

Now I'll compose and submit the review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e925d121-5c09-468b-851e-8cb581b02e4d",
  "isSidechain": false,
  "requestId": "req_011Cb7reYteDsbcrTG3eoegX",
  "type": "assistant",
  "uuid": "86ba23e9-4969-47d4-93b5-223261ca0d6e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LuUQLr5VBYMuDFibpgYjea",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 897,
      "cache_read_input_tokens": 43228,
      "output_tokens": 185,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 897,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 185,
          "cache_read_input_tokens": 43228,
          "cache_creation_input_tokens": 897,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 897
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


### Tool call

_source line 167 · 2026-05-17T08:52:18.688Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01K4DeaunrqvRNJCSXHFDiVM`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__review_reviewer_post_to_director",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "86ba23e9-4969-47d4-93b5-223261ca0d6e",
  "isSidechain": false,
  "requestId": "req_011Cb7reYteDsbcrTG3eoegX",
  "type": "assistant",
  "uuid": "10d8f5c3-a9da-4788-9ad1-f9b511afbeba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LuUQLr5VBYMuDFibpgYjea",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 897,
      "cache_read_input_tokens": 43228,
      "output_tokens": 185,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 897,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 185,
          "cache_read_input_tokens": 43228,
          "cache_creation_input_tokens": 897,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 897
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

_source line 168 · 2026-05-17T08:52:18.697Z_

<details><summary>↩ Tool result · `toolu_01K4DeaunrqvRNJCSXHFDiVM`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__review_reviewer_post_to_director"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "10d8f5c3-a9da-4788-9ad1-f9b511afbeba",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "8a1518bc-40e8-49dd-b95d-cbfeea9c9a78",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__review_reviewer_post_to_director"
    ],
    "query": "select:mcp__agent-ml-research__review_reviewer_post_to_director",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "10d8f5c3-a9da-4788-9ad1-f9b511afbeba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Assistant

_source line 169 · 2026-05-17T08:52:35.227Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the information I need to compose the Round 1 review. Let me write a comprehensive review covering the 6 dimensions the Director specified:

A. Novelty Assessment
B. Related Work
C. Significance & Impact
D. Writing Quality
E. Community Fit
F. Citation Adequacy

Key findings from my analysis:

**Strengths:**
1. Novel task formalization (recursive depth estimation as ordinal classification)
2. EDD metric is well-defined and useful
3. Thorough generalization across 7 axes
4. Surface-text ablation convincingly demonstrates signal is in distributional statistics


5. Honest limitations section included
6. Schaeffer 2025 now properly cited with explicit Dohmatob positioning
7. Writing quality improved overall with reduced overclaims and cleaner formatting

**Weaknesses:**
1. "Signal universality" overclaim still present in generalization.tex line 108
2. Reference model table shows inconsistency between claimed count and actual entries
3. Abstract rounds up the lower bound of the performance range
4. Contribution bullet 3 packs too many axes together densely
5. A couple of orphan bibliography entries need cleanup

, plus the RAID benchmark from ACL 2024 isn't cited in the detection section
6. Cross-strategy transfer results are underwhelming at 45.9%, barely exceeding random chance
7. The curation proof-of-concept shows marginal statistical significance that appropriately tempers practical impact claims
8. The 7B model experiments remain preliminary with several acknowledged confounds

Now I'm ready to write the review.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8a1518bc-40e8-49dd-b95d-cbfeea9c9a78",
  "isSidechain": false,
  "requestId": "req_011Cb7rf2RrZkHCGcjLLk63P",
  "type": "assistant",
  "uuid": "e38fb658-2946-4d25-b67d-422a4c977370",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017X8yLAXQdqm22J3PDtytA2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 499,
      "cache_read_input_tokens": 44125,
      "output_tokens": 4790,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 499,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 4790,
          "cache_read_input_tokens": 44125,
          "cache_creation_input_tokens": 499,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 499
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


### Tool call

_source line 170 · 2026-05-17T08:54:18.254Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_01JtRPJ8LUzuTBhAoVTr8pvw`</summary>

```json
{
  "text": "## Round 1 审稿报告（修订版论文）\n\n**论文**: \"How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\"\n**Venue**: EMNLP 2026 Findings (ARR May 2026)\n\n> **注意**: Director 任务描述中的论文标题（\"Ordinal Depth Estimation for Recursive Language Model Generations...\"）与实际论文文件不一致。论文实际标题仍为 \"How Deep Is Your Data?\"，且不包含 Director 描述中的部分特征（two-stage pipeline 75.2%、14B scale、prompted generation）。以下审查基于实际论文文件内容。\n\n---\n\n## 总体评分\n**Overall**: 3.5/5 (Borderline accept — leaning accept for Findings)\n**一句话总结**: 任务定义新颖、实验覆盖系统，修订版解决了大部分前轮问题，但仍存在一处数据不一致（reference model 表格）和少量overclaim，跨策略迁移的实用性瓶颈未充分解决。\n\n---\n\n## 官方维度打分（ARR 2025+ Review Form）\n\n| 维度 | 分数 | 理由摘要 |\n|------|------|----------|\n| Soundness | 3.5/5 | 核心实验设计扎实，但 Table 16 与正文 claim 存在数据不一致（详见 N1）；跨策略迁移 d1-d3 仅 45.9%（chance=33%），实用价值有限 |\n| Excitement | 3.5/5 | 任务定义有原创性，EDD 指标有概念价值；但 practical impact 受限于跨策略瓶颈和 curation PoC 不显著（p=0.407） |\n| Overall | 3.5/5 | 适合 Findings track：系统性强，limitations 诚实，但核心 claim 的实际应用场景尚不清晰 |\n| Reproducibility | 4/5 | 超参数、数据量、CV 设置均有详细报告；承诺 code release |\n\n---\n\n## 编号优势 (Strengths)\n\n**S1. 任务形式化具有原创性。** 将递归生成深度估计定义为 ordinal classification 是一个清晰的 problem formulation，填补了 binary detection 与 model collapse theory 之间的空白。EDD 指标（Definition 1, §2.4）提供了可操作的 discriminability frontier 量化方式。\n\n**S2. 系统性实验设计。** 3×3 Atlas（3 model families × 3 decoding strategies × 4 depths, 180K samples）提供了充分的控制变量实验，7 轴 generalization 测试（§4）覆盖面广。\n\n**S3. Surface-text ablation 有说服力。** Zero-shot LLM 仅达 30-36%（§4.1），与 RF 的 78.2% 形成 42pp 差距，有力证明 depth signal 不在表面文本而在分布统计量中。这是论文最有说服力的实验之一。\n\n**S4. 诚实的 Limitations 讨论。** Limitations section 对 d0 inflation、cross-strategy inversion、controlled vs. ecological setting、C4 false positive rate 等问题的讨论详尽，展现了实验诚信。Discussion 中 curation PoC 改为 \"pilot results are inconclusive\"（discussion.tex line 7）是正确的修正。\n\n**S5. 特征重要性分析三重验证。** Gini、permutation、SHAP 三种 importance measure 的 Kendall's W=0.90（Appendix B），aggregate top-5 一致，增强了 p90_ppl 和 var_surprisal 作为核心 depth marker 的可信度。\n\n**S6. Model collapse 文献定位改善。** 修订版新增 Schaeffer (2025) 引用（related_work.tex line 7），明确指出 \"model collapse\" 概念的多义性；对 Dohmatob et al. 的定位从理论到操作化的叙事更加清晰（line 8）。\n\n---\n\n## Must-Fix 问题（影响接收决定）\n\n**N1** [critical] Reference model 消融表格与正文 claim 不一致\n- 具体位置：method.tex line 41, conclusion.tex line 39, Table 16 (Appendix §C.5)\n- 问题：正文两处声称 \"67--79% across three reference architectures\"（method.tex: \"Ablations with OLMo-1B and GPT-2 XL as alternative references yield 67--79% accuracy\"；conclusion.tex line 39: \"67--79% across three reference architectures\"），但 Table 16 (app:ref_ablation) 仅包含 2 行数据（Pythia-1.4B: 78.6%, OLMo-1B: 74.5%），GPT-2 XL 作为 reference model 的结果完全缺失。\n- 为什么影响接收：这构成 claim 与 evidence 的直接矛盾。读者无法从表格 verify \"three reference architectures\" 这一断言。如果 GPT-2 XL reference 实验确实做了，需补入表格；如果未做，正文必须改为 \"two reference architectures\"。\n- 建议：补全 GPT-2 XL reference model 行到 Table 16，或将所有相关 claim 修改为 \"two\"。\n\n---\n\n## Should-Fix 问题（影响评分但不一票否决）\n\n**W1** [warning] \"signal universality\" overclaim 未修正\n- 具体位置：generalization.tex line 108\n- 问题：原文 \"further confirm signal universality\" 仍在。论文自身数据显示：cross-strategy d1-d3 仅 45.9%（chance=33%），temperature holdout d2 recall 低至 3.7%，cross-scale 有 4 个 confounds。\"universality\" 与这些限制不匹配。\n- 建议：改为 \"further confirm signal generality across these tested conditions\" 或 \"signal robustness within the tested model families\"。\n\n**W2** [warning] Abstract 下界 rounding\n- 具体位置：abstract.tex line 4\n- 问题：\"70--85% four-class accuracy\" 但 Table 2 实际下界为 69.6%（Pythia top-k）。70% 是向上取整。学术论文应精确报告或明确标注 \"approximately\"。\n- 建议：改为 \"69.6--85.4%\" 或 \"approximately 70--85%\"。\n\n**W3** [warning] Contribution bullet 3 信息过载\n- 具体位置：introduction.tex lines 28\n- 问题：第三条 contribution 在一段中堆叠了 7+ 个 generalization axis（cross-model chains 84.75%, cross-scale 70.2%/60.1%, cross-domain 74.1%, temperature robustness, reference model robustness 67-79%, surface-text ablation 30-36%）。这不是一个可消化的 contribution statement，而是一个 results summary。\n- 建议：拆分为两条 contribution（\"Generalization\" + \"Ablation and diagnostic analyses\"），或将具体数字移至正文，contribution 只保留轴名称。\n\n**W4** [warning] 跨策略迁移的实用性瓶颈讨论不足\n- 具体位置：§4.3 (generalization.tex lines 89-92), Limitations §1\n- 问题：Cross-strategy d1-d3 accuracy 仅 45.9%（chance=33%），这意味着在 decoding strategy 未知的真实场景中，深度 1-3 的区分几乎失效。论文在 Limitations 中提到了 two-stage pipeline（strategy identification + conditioned classification）作为解决方案，但未提供任何实验或 feasibility analysis。对于一个声称面向 \"deployable\" 场景的方法，这是核心实用性缺口。\n- 建议：至少添加一段讨论 strategy identification 的可行性（现有方法能否可靠区分 decoding strategy？），或在 Discussion 中更明确地将此定位为 open problem。\n\n**W5** [warning] 2 个 orphan bib 条目\n- 具体位置：references.bib\n- 问题：c2pa2024 和 chen2024spin 存在于 bib 文件中但未被任何 tex 文件引用。\n- 建议：移除或在适当位置引用（c2pa2024 与 provenance 相关，可在 Discussion 中引用；chen2024spin 与 self-play 相关，可在 Related Work 中引用）。\n\n---\n\n## 提问 (Questions for Authors)\n\n**Q1**: Table 16 中 GPT-2 XL 作为 reference model 的结果是否已经完成实验？如果是，为什么未列入表格？如果结果在 67-79% 范围外，是否会改变 reference model robustness 的 claim？\n\n**Q2**: Cross-strategy transfer 中 d1/d2 boundary inversion（AUC < 0.5）的根本原因是什么？论文提到 z-score normalization 对 RF 无效（Δ < 0.02pp），是否尝试过其他 feature normalization 或 domain adaptation 方法？\n\n**Q3**: Curation PoC（Table 14, p=0.407）不显著。作者是否有计划在更大规模或更多 depth 组合上验证 curation 的实用价值？如果 curation 不 work，depth estimation 的主要应用场景是什么？\n\n**Q4**: 7B 实验中 Qwen2.5-7B 的 U-shaped AUC recovery（§4.4）与所有 1-1.5B 模型的 monotonic decay 不一致。作者如何解释这一现象？这是否暗示 EDD 的 contiguous formulation 在更大模型上可能系统性低估 discriminable range？\n\n---\n\n## 各维度详细评估\n\n### A. Novelty Assessment (3.5/5)\n\n任务定义（ordinal depth estimation）是新的，此前无人系统地将 recursive generation 建模为 ordinal classification 问题。EDD 指标有概念贡献。但方法本身（RF + hand-crafted perplexity features）技术创新有限，主要贡献在于 empirical discovery 而非方法论突破。修订版对 Dohmatob \"Tale of Tails\" 的定位（related_work.tex line 8：\"we operationalize this prediction into a deployable ordinal classifier, revealing strategy-dependent trajectories and non-monotonic 7B behavior that the theory does not predict\"）准确且有力。\n\n### B. Related Work (4/5)\n\n修订版显著改善：新增 Schaeffer (2025) 对 \"model collapse\" 多义性的讨论（line 7），McCullagh (1980) / Frank (2001) / Rennie (2005) 补全了 ordinal classification 的经典文献（lines 22-23），Mohamed (2025) \"broken telephone\" 的 positioning 清晰（line 18-19）。\n遗漏：RAID benchmark（Dugan et al., ACL 2024）是 AI text detection 领域的重要 benchmark，未被引用。考虑到论文 §4.1 与 detection baselines 做对比，RAID 的缺失是一个 minor gap。\n\n### C. Significance & Impact (3/5)\n\n论文的核心 practical claim 面临两个挑战：(1) 跨策略迁移 d1-d3 仅 45.9%，意味着 decoding strategy 未知时深度区分近乎失效；(2) curation PoC 不显著（p=0.407），削弱了 \"depth-graduated curation\" 的应用叙事。论文诚实地报告了这些限制，但这意味着当前的 practical impact 主要停留在 \"early-warning signal\" 和 \"provenance annotation\" 层面，缺乏具体的 downstream task improvement 证据。\n对 model collapse 理论研究有 empirical 贡献（strategy-dependent trajectories, non-monotonic 7B behavior）。\n\n### D. Writing Quality (4/5)\n\n修订版写作质量明显提升：\n- Em-dashes 已全部清除（全文无解释性 — 或 –）\n- \"universal and scale-variant\" 矛盾修正为 \"consistent in direction but scale-dependent in magnitude\"（introduction.tex line 14）\n- Discussion 中 \"enables depth-graduated data curation\" 改为 \"pilot results are inconclusive\"（discussion.tex line 7）\n残留问题：\n- \"signal universality\"（generalization.tex line 108）仍为 overclaim（见 W1）\n- Contribution bullet 3 信息密度过高（见 W3）\n- 整体叙事连贯性良好，Limitations 讨论诚实详尽\n\n### E. Community Fit (3.5/5)\n\n适合 EMNLP Findings：\n- 与 NLP 社区关心的 data contamination / provenance 问题直接相关\n- 方法轻量（RF + 19 features, GPU-free inference），实用导向\n- 与 binary detection 文献（DetectGPT, Binoculars, DivEye）形成互补\n- 但核心分析工具（perplexity statistics）更偏 ML/statistics，方法论创新对 NLP 社区的技术贡献有限\n\n### F. Citation Adequacy (3.5/5)\n\n修订版从 49 增至 60 条引用，覆盖显著改善：\n- Model collapse: Shumailov, Dohmatob (两篇), Alemohammad, Schaeffer, Bakshi, Marchi 等\n- Detection: Mitchell, Bao, Hans, Gehrmann, Verma, Yang, DivEye, Kirchenbauer\n- Ordinal: McCullagh, Frank, Rennie, CORAL, CLOC\n- Decoding: Holtzman, Finlayson, Garcés-Arias, Wiher, Basu\n遗漏：RAID (Dugan et al., ACL 2024)；2 个 orphan entries（c2pa2024, chen2024spin）需清理。\nReference verification 显示 7 条 entries 在 OpenAlex 未找到（多为 2026 preprints），4 条有 metadata mismatch（可能是 preprint→camera-ready 版本差异），整体可接受。\n\n---\n\n## 小问题（不影响接收）\n\n- abstract.tex line 6: \"seven axes (including cross-scale with 7B models at 70.2%, cross-domain, and LoRA-rank ablation)\" 括号内列举不完整（只列了 3 个），不如删除括号内容或完整列出\n- method.tex line 35: \"BOS-seeded generation may amplify depth signal relative to prompted settings\" 是重要 caveat，建议在 Abstract 或 Introduction 中也简要提及\n- Appendix 中 Table 14 (curation PoC) 的 rf_soft filter 只用了 RF posterior > 0.5 的 threshold，没有 sensitivity analysis on threshold choice",
  "reviewer_id": "2",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e38fb658-2946-4d25-b67d-422a4c977370",
  "isSidechain": false,
  "requestId": "req_011Cb7rf2RrZkHCGcjLLk63P",
  "type": "assistant",
  "uuid": "2a59ae6a-a470-48f6-8e6a-7bfaa4077689",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017X8yLAXQdqm22J3PDtytA2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 499,
      "cache_read_input_tokens": 44125,
      "output_tokens": 4790,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 499,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 4790,
          "cache_read_input_tokens": 44125,
          "cache_creation_input_tokens": 499,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 499
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

_source line 171 · 2026-05-17T08:54:22.207Z_

<details><summary>↩ Tool result · `toolu_01JtRPJ8LUzuTBhAoVTr8pvw`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2a59ae6a-a470-48f6-8e6a-7bfaa4077689",
  "isSidechain": false,
  "promptId": "5f16fa88-080d-4926-8617-0c9e02ecdde7",
  "type": "user",
  "uuid": "3c4f2ec2-f98d-440c-a924-8aee5127c10d",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "2a59ae6a-a470-48f6-8e6a-7bfaa4077689",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Runtime record

_source line 172 · 2026-05-17T08:54:22.211Z_

```json
{
  "parentUuid": "3c4f2ec2-f98d-440c-a924-8aee5127c10d",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "823c5e2d-7507-4ac1-8775-3c2d8fa119fa",
  "timestamp": "2026-05-17T08:54:22.211Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Runtime record

_source line 173_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 174 · 2026-05-17T08:55:18.873Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-17T08:55:18.873Z",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "content": "[Round 9 审稿请求]:\n## 交叉分享 — 请逐条回应 Reviewer 1 的修订版审稿意见\n\n以下是 Reviewer 1 对修订版论文的完整审稿。请逐条回应 moderate 及以上问题：\n- **[AGREE]** 同意并说明理由\n- **[REBUT]** 反驳并提供证据（cite 具体 Section/Table/Figure）\n\n---\n\n## Reviewer 1 报告摘要\n\n**Overall**: 3.5/5\n\n### Moderate 及以上问题\n\n**W2** [moderate] BOS-seeded generation 显著生态效度限制。无 prompted generation 数据点。Director summary 提到 92.8% retention 但论文中不存在。\n\n**W5** [moderate] Table 2 和 Table 5 仍缺 std/CI。这是多轮 persistent issue。5-fold CV 天然产生 fold-level variance。\n\n**W7** [moderate] Cross-scale 仅两个 7B + 4-bit QLoRA 模型。60.1% lower CI bound (58.0%) marginally above chance at d1-d3。两模型 divergent AUC trajectories 无法判断哪个是 dominant pattern。\n\n**W8** [moderate] Wild-data C4 FPR 分析假设所有 passages 为 human-written (d0)，但 2023+ web crawl 可能已含 LLM text，使 FPR 成为 upper bound。\n\n**W12** [moderate] Accumulation/mixing 场景完全未测试。Appendix §A.9 仅测试 eval set class balance 变化。\n\n**W13** [moderate] Depth vs quality estimation confound 未控制。无 matched-quality control 实验。\n\n### Minor\n\n**W1** EDD 未显式声明为 operational measure\n**W3** Full fine-tuning vs LoRA 未对比\n**W4** Reference model circularity 已讨论但未完全解决\n**W6** DeBERTa/RoBERTa baselines 仅 ~125M\n**W10** Wild-data 仅在 Appendix，无时间维度\n**W11** Code \"will be released upon acceptance\"\n**W14** Abstract \"70-85%\" 取整\n\n### R1 对修订版的评价\n\n- Related Work 显著改善 ✅\n- LoRA rank ablation 新增 ✅\n- 三个 reference model ablation ✅\n- Discussion curation 诚实化 ✅\n- Abstract 精简 ✅\n- Director 描述的 14B/prompted/two-stage/RedPajama 内容不在 tex 中 ⚠️\n\n### R1 关键判断\n\n- 如果 Director 描述的计划内容能纳入论文，Overall 可从 3.5 升至 4.0\n- 当前版本 solid for Findings\n\n---\n\n请特别关注：\n1. 你是否同意 W5（Table CI persistent issue）的判断？\n2. W12（accumulation）和 W13（quality confound）是否仍是 blocking issues？\n3. R1 提出的 Director summary 与论文不一致问题——你独立验证的结论是什么？"
}
```

---


### Runtime record

_source line 175 · 2026-05-17T08:55:18.873Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-17T08:55:18.873Z",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


## Round 7

## Round 7

2 recorded events


### User

_source line 176 · 2026-05-17T08:55:18.863Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "823c5e2d-7507-4ac1-8775-3c2d8fa119fa",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "isMeta": true,
  "uuid": "10788bf2-829b-4ee3-86e1-7b3b7e6536a2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Assistant

_source line 177 · 2026-05-17T08:55:18.863Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "10788bf2-829b-4ee3-86e1-7b3b7e6536a2",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "784a2aef-b27c-4856-827b-ec1de15569c1",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "id": "d9a8c217-76a3-4a83-8fd7-5eabd729b763",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 8

## Round 8

26 recorded events


### User

_source line 178 · 2026-05-17T08:55:18.970Z_

[Round 9 审稿请求]:
## 交叉分享 — 请逐条回应 Reviewer 1 的修订版审稿意见

以下是 Reviewer 1 对修订版论文的完整审稿。请逐条回应 moderate 及以上问题：
- **[AGREE]** 同意并说明理由
- **[REBUT]** 反驳并提供证据（cite 具体 Section/Table/Figure）

---

## Reviewer 1 报告摘要

**Overall**: 3.5/5

### Moderate 及以上问题

**W2** [moderate] BOS-seeded generation 显著生态效度限制。无 prompted generation 数据点。Director summary 提到 92.8% retention 但论文中不存在。

**W5** [moderate] Table 2 和 Table 5 仍缺 std/CI。这是多轮 persistent issue。5-fold CV 天然产生 fold-level variance。

**W7** [moderate] Cross-scale 仅两个 7B + 4-bit QLoRA 模型。60.1% lower CI bound (58.0%) marginally above chance at d1-d3。两模型 divergent AUC trajectories 无法判断哪个是 dominant pattern。

**W8** [moderate] Wild-data C4 FPR 分析假设所有 passages 为 human-written (d0)，但 2023+ web crawl 可能已含 LLM text，使 FPR 成为 upper bound。

**W12** [moderate] Accumulation/mixing 场景完全未测试。Appendix §A.9 仅测试 eval set class balance 变化。

**W13** [moderate] Depth vs quality estimation confound 未控制。无 matched-quality control 实验。

### Minor

**W1** EDD 未显式声明为 operational measure
**W3** Full fine-tuning vs LoRA 未对比
**W4** Reference model circularity 已讨论但未完全解决
**W6** DeBERTa/RoBERTa baselines 仅 ~125M
**W10** Wild-data 仅在 Appendix，无时间维度
**W11** Code "will be released upon acceptance"
**W14** Abstract "70-85%" 取整

### R1 对修订版的评价

- Related Work 显著改善 ✅
- LoRA rank ablation 新增 ✅
- 三个 reference model ablation ✅
- Discussion curation 诚实化 ✅
- Abstract 精简 ✅
- Director 描述的 14B/prompted/two-stage/RedPajama 内容不在 tex 中 ⚠️

### R1 关键判断

- 如果 Director 描述的计划内容能纳入论文，Overall 可从 3.5 升至 4.0
- 当前版本 solid for Findings

---

请特别关注：
1. 你是否同意 W5（Table CI persistent issue）的判断？
2. W12（accumulation）和 W13（quality confound）是否仍是 blocking issues？
3. R1 提出的 Director summary 与论文不一致问题——你独立验证的结论是什么？

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "784a2aef-b27c-4856-827b-ec1de15569c1",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "9395c8eb-c751-42ff-8668-5251c101d1a9",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Runtime record

_source line 179 · 2026-05-17T08:55:18.969Z_

```json
{
  "parentUuid": "9395c8eb-c751-42ff-8668-5251c101d1a9",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "49951ab0-4f6c-44fe-8aaa-80a29137bc91",
  "timestamp": "2026-05-17T08:55:18.969Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---


### Assistant

_source line 180 · 2026-05-17T08:55:28.664Z_

<details><summary>Logged reasoning block</summary>

```text
The Director is asking me to do a cross-review response to Reviewer 1's revised review. I need to respond to each moderate+ issue with [AGREE] or [REBUT], and specifically address the 3 questions at the end.

Let me go through each issue:

**W2** - BOS-seeded generation ecological validity. I need to check what the paper says about this.

**W5** - Table 2 and Table 5 missing std/CI. Let me check these tables.

**W7** - Cross-scale only 2 7B models + QLoRA. 


**W8** - C4 FPR analysis assumes all passages are human-written.

**W12** - Accumulation/mixing scenario untested.

**W13** - Depth vs quality confound.

Now I'm reviewing the remaining issues and need to examine the relevant sections of the paper to formulate informed responses to each of these concerns.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "49951ab0-4f6c-44fe-8aaa-80a29137bc91",
  "isSidechain": false,
  "requestId": "req_011Cb7rtKKDhBXNP7rByjtn3",
  "type": "assistant",
  "uuid": "cea8e49c-2ab3-4d9e-aa38-b88efc02d618",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RnrHM5wBURsAaJaZ9CULpX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1689,
      "cache_read_input_tokens": 49592,
      "output_tokens": 484,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1689,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 484,
          "cache_read_input_tokens": 49592,
          "cache_creation_input_tokens": 1689,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1689
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


### Assistant

_source line 181 · 2026-05-17T08:55:28.669Z_

Let me re-read the relevant tables and sections to give evidence-based responses.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cea8e49c-2ab3-4d9e-aa38-b88efc02d618",
  "isSidechain": false,
  "requestId": "req_011Cb7rtKKDhBXNP7rByjtn3",
  "type": "assistant",
  "uuid": "5a72503a-2d5d-4bf8-a2df-8a4adcac5f01",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RnrHM5wBURsAaJaZ9CULpX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1689,
      "cache_read_input_tokens": 49592,
      "output_tokens": 484,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1689,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 484,
          "cache_read_input_tokens": 49592,
          "cache_creation_input_tokens": 1689,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1689
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


### Tool call

_source line 182 · 2026-05-17T08:55:30.450Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UsTFXxRNh7nGdkfMU9QhGC`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5a72503a-2d5d-4bf8-a2df-8a4adcac5f01",
  "isSidechain": false,
  "requestId": "req_011Cb7rtKKDhBXNP7rByjtn3",
  "type": "assistant",
  "uuid": "17d36291-fdb1-48bb-b592-596364509802",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RnrHM5wBURsAaJaZ9CULpX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1689,
      "cache_read_input_tokens": 49592,
      "output_tokens": 484,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1689,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 484,
          "cache_read_input_tokens": 49592,
          "cache_creation_input_tokens": 1689,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1689
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

_source line 183 · 2026-05-17T08:55:32.201Z_

<details><summary>↩ Tool result · `toolu_01RTysDHkwoTpTASkkyfr6LR`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0822e772-9a31-45f3-bb35-90814db8f973",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "1383c970-a381-4308-9ebb-eded07cbb0ae",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "0822e772-9a31-45f3-bb35-90814db8f973",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool result

_source line 184 · 2026-05-17T08:55:30.462Z_

<details><summary>↩ Tool result · `toolu_01UsTFXxRNh7nGdkfMU9QhGC`</summary>

```text
1	\section{The Depth Degradation Atlas}
2	\label{sec:atlas}
3	
4	We present the Depth Degradation Atlas: a systematic empirical map of how statistical fingerprints evolve across recursive generation depths, models, and decoding strategies.
5	The atlas spans $3 \times 3 = 9$ model--strategy cells evaluated at depths $d \in \{0, 1, 2, 3\}$, with depth extensions to $d{=}5$ for cross-model EDD validation (\S\ref{sec:atlas:edd}).
6	
7	%% ----------------------------------------------------------------
8	\subsection{In-Distribution Performance}
9	\label{sec:atlas:id}
10	
11	Table~\ref{tab:main_matrix} reports four-class Random Forest accuracy (5-fold CV, 200 trees) across all nine cells.
12	Accuracy ranges from 69.6\% (Pythia, top-$k$) to 85.4\% (GPT-2~XL, temperature), all exceeding the 25\% chance baseline by a wide margin.
13	Two axis effects emerge.
14	GPT-2~XL achieves the highest accuracy under every strategy (76.6--85.4\%), followed by OLMo (74.2--82.0\%) and Pythia (69.6--78.2\%).
15	Top-$k$ sampling yields the lowest accuracy in every model.
16	The mean within-model strategy gap is 8.4~pp, comparable to the 7.1~pp mean within-strategy model gap; decoding strategy and model family contribute roughly equally to performance variance.
17	
18	\begin{table}[t]
19	\centering
20	\small
21	\caption{Four-class RF accuracy (\%) across the $3 \times 3$ atlas, with d1--d3 three-class accuracy in parentheses (chance = 25\% / 33\%). Depth-0 recall exceeds 98\% in all cells.}
22	\label{tab:main_matrix}
23	\begin{tabular}{@{}lccc@{}}
24	\toprule
25	& Nucleus & Temp.\ $\tau{=}0.9$ & Top-$k$ \\
26	\midrule
27	Pythia-1.4B  & 78.2\,(71.2) & 76.3\,(70.6) & 69.6\,(58.8) \\
28	OLMo-1B     & 78.8\,(75.0) & 82.0\,(76.3) & 74.2\,(66.1) \\
29	GPT-2~XL    & 83.3\,(79.0) & 85.4\,(82.6) & 76.6\,(69.5) \\
30	\bottomrule
31	\end{tabular}
32	\end{table}
33	
34	\paragraph{Per-class recall distribution.}
35	Depth-0 recall exceeds 98\% in all 9 cells, confirming that human-written text is trivially separable from any generation depth.
36	Among generated depths, d2 consistently yields the lowest recall (46--73\% across cells), followed by d3 (58--82\%) and d1 (72--91\%).
37	For example, Pythia-1.4B nucleus achieves per-class recall of d0$\,{=}\,$99\%, d1$\,{=}\,$82\%, d2$\,{=}\,$59\%, d3$\,{=}\,$72\%.
38	The strongest d2 recall is obtained by GPT-2~XL nucleus (73\%).
39	The d2 trough reflects its position at the center of the depth gradient: d2 features overlap with both the d1 distribution above and d3 below, making it the most confusable class, consistent with the d2-vs-d3 pair being the EDD bottleneck (\S\ref{sec:atlas:edd}).
40	Full per-class recall for all cells appears in Appendix~\ref{app:per_class}.
41	
42	%% ----------------------------------------------------------------
43	\subsection{Feature Consistency Across the Grid}
44	\label{sec:atlas:features}
45	
46	Despite the 15.8~pp accuracy spread across cells, a small feature family dominates in every setting.
47	Perplexity tail statistics as a feature group dominate depth discrimination: the 90th-percentile perplexity (\texttt{p90\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\texttt{var\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\ref{app:permutation}).\footnote{Individual feature rankings should be interpreted cautiously given high multicollinearity (VIF${>}$10 for 14--16/19 features); the group-level dominance of perplexity tail statistics is robust across importance measures.}
48	Table~\ref{tab:feature_importance} shows the full per-cell ranking.
49	
50	Cross-model feature-rank Spearman correlation averages $\bar{\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.
51	Among strategies, top-$k$ yields the highest cross-model rank correlation ($\rho = 0.811$): the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\S\ref{sec:atlas:strategy}).
52	
53	Percentile-based features outperform their moment-based counterparts.
54	Token-level perplexity distributions are heavy-tailed: individual outlier passages can dominate the arithmetic mean of their depth class, whereas \texttt{p90\_ppl} is robust to such extremes while still capturing the tail erosion that signals generation depth.
55	
56	Feature ablation confirms this concentration: the top-2 features (\texttt{p90\_ppl} + \texttt{var\_surprisal}) alone reach 91.1\% of full accuracy (71.5\%), and the top-5 features achieve 97.6\% (76.5\% vs.\ 78.4\%), with perplexity statistics alone reaching 76.6\% (vs.\ surprisal 73.2\%, other categories ${\leq}$47\%).
57	Variance inflation analysis reveals VIF${>}$10 for 14--16 of 19 features, placing the effective independent dimensionality at ${\approx}$4--5.
58	Forward selection independently confirms the dominant pair: \texttt{p90\_ppl} is selected first in 6/9 cells, \texttt{var\_surprisal} in 3/9.
59	
60	The feature hierarchy also shifts with depth.
61	At shallow boundaries (d1 vs.\ d2), \texttt{var\_surprisal} dominates importance; at deeper boundaries (d3 vs.\ d4, d4 vs.\ d5), tail perplexity statistics (\texttt{p90\_ppl}, \texttt{kurtosis\_ppl}) take over.
62	This transition aligns with model-collapse dynamics~\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).
63	
64	\begin{table}[t]
65	\centering
66	\small
67	\caption{Top-5 features by Gini importance. \textbf{Bold}: top-2. \texttt{p90\_ppl} top-2 in 9/9; \texttt{var\_surprisal} 8/9 under SHAP (7/9 under Gini).}
68	\label{tab:feature_importance}
69	\resizebox{\columnwidth}{!}{%
70	\begin{tabular}{@{}l l@{}}
71	\toprule
72	Cell & Top-5 features (Gini importance, ranked) \\
73	\midrule
74	Pythia, nuc.       & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.15)}, m\_ppl\,(.11), var\_ppl\,(.08), p75\,(.07) \\
75	Pythia, $\tau$     & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.14)}, m\_ppl\,(.11), p75\,(.07), m\_surp\,(.07) \\
76	Pythia, top-$k$    & \textbf{var\_surp\,(.16)}, \textbf{p90\_ppl\,(.12)}, m\_ppl\,(.11), var\_ppl\,(.07), m\_surp\,(.06) \\
77	GPT-2\,XL, nuc.    & \textbf{var\_surp\,(.21)}, \textbf{p90\_ppl\,(.21)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.06) \\
78	GPT-2\,XL, $\tau$  & \textbf{p90\_ppl\,(.25)}, \textbf{p75\,(.15)}, m\_surp\,(.13), var\_surp\,(.12), p50\,(.05) \\
79	GPT-2\,XL, top-$k$ & \textbf{p90\_ppl\,(.24)}, \textbf{p75\,(.12)}, var\_surp\,(.10), m\_surp\,(.09), ttr\,(.04) \\
80	OLMo, nuc.         & \textbf{p90\_ppl\,(.18)}, \textbf{var\_surp\,(.15)}, p75\,(.11), m\_surp\,(.07), ttr\,(.06) \\
81	OLMo, $\tau$       & \textbf{p90\_ppl\,(.21)}, \textbf{var\_surp\,(.16)}, p75\,(.12), m\_surp\,(.09), ttr\,(.05) \\
82	OLMo, top-$k$      & \textbf{p90\_ppl\,(.20)}, \textbf{var\_surp\,(.17)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.05) \\
83	\bottomrule
84	\end{tabular}}
85	\end{table}
86	
87	\begin{figure}[t]
88	\centering
89	\includegraphics[width=\columnwidth]{figures/fig_atlas_heatmap.pdf}
90	\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\S\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}
91	\label{fig:atlas_heatmap}
92	\end{figure}
93	
94	%% ----------------------------------------------------------------
95	\subsection{Monotonicity and Inter-Depth Distances}
96	\label{sec:atlas:monotonicity}
97	
98	Depth features exhibit strong monotonic trends: perplexity tail statistics (\texttt{p90\_ppl}, \texttt{mean\_surprisal}) decrease with depth (Spearman $\rho = -1.0$ across cell-level medians) while repetition features increase, reflecting the complementary narrowing and self-repetition of distribution collapse.
99	Inter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89; separating adjacent deep generations requires the tail statistics identified in \S\ref{sec:atlas:features}.
100	
101	\begin{figure}[t]
102	\centering
103	\includegraphics[width=\columnwidth]{figures/fig_feature_trajectory.pdf}
104	\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \texttt{p90\_ppl} (monotonically decreasing). Middle: \texttt{var\_surprisal} (decreasing). Bottom: \texttt{rep\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \to d{=}1$ gap exceeds all subsequent inter-depth gaps.}
105	\label{fig:feature_trajectory}
106	\end{figure}
107	
108	%% ----------------------------------------------------------------
109	\subsection{EDD Analysis}
110	\label{sec:atlas:edd}
111	
112	We extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.
113	Each model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).
114	We train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\ref{eq:edd}.
115	
116	\paragraph{AUC decay profile.}
117	Figure~\ref{fig:auc_decay} plots the binary pairwise AUC decay curves.
118	For Pythia-1.4B (nucleus), AUC decays monotonically: d0-vs-d1 $= 0.999$, d1-vs-d2 $= 0.925$, d2-vs-d3 $= 0.823$, d3-vs-d4 $= 0.784$, d4-vs-d5 $= 0.683$.
119	The steepest drop occurs between the d1-vs-d2 and d2-vs-d3 pairs; the curve then flattens as the system approaches an indistinguishable regime gradually rather than crossing a sharp boundary.
120	
121	\paragraph{Cross-model convergence at depth 4--5.}
122	The d3-vs-d4 AUC consistently clusters near the $T{=}0.75$ threshold across all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$ ($0.681$--$0.684$).
123	The directional pattern is consistent, but statistical strength is stratified: bootstrap testing ($10{,}000$ resamples, $H_0{:}\, \mathrm{AUC} \leq 0.75$) yields $p = 0.001$ for Pythia (significant), $p = 0.091$ for OLMo (marginal), and $p = 0.505$ for GPT-2~XL (non-significant).
124	All three models cross the $T{=}0.75$ threshold within the d3--d4 region, establishing a consistent depth-4 decay boundary with graded confidence rather than uniform statistical significance.
125	The d4-vs-d5 saturation is unambiguous across models, supporting the interpretation of d3--d4 as a \emph{transition zone} from discriminable to indistinguishable regime.
126	
127	\paragraph{EDD threshold sensitivity.}
128	Table~\ref{tab:edd_sensitivity} reports $\mathrm{EDD}_T$ across the primary 9-cell benchmark (depths 0--3) at four threshold values.
129	At $T{=}0.65$, all 9 cells achieve $\mathrm{EDD} = 3$; at $T{=}0.75$, 7 of 9 cells maintain $\mathrm{EDD} \geq 3$; at $T{=}0.80$, the count drops to 5 of 9.
130	The cells losing $\mathrm{EDD}{=}3$ first are consistently the top-$k$ configurations (Pythia top-$k$ at $T{=}0.70$, then OLMo top-$k$ at $T{=}0.75$), where the d2-vs-d3 pair is the consistent bottleneck across all 9 cells.
131	
132	\begin{table}[t]
133	\centering
134	\small
135	\caption{Number of atlas cells achieving $\mathrm{EDD} \geq 3$ at each threshold $T$, across 9 model--strategy cells (depths 0--3). The d2-vs-d3 boundary is the bottleneck; top-$k$ cells drop first.}
136	\label{tab:edd_sensitivity}
137	\begin{tabular}{@{}lcccc@{}}
138	\toprule
139	& $T{=}0.65$ & $T{=}0.70$ & $T{=}0.75$ & $T{=}0.80$ \\
140	\midrule
141	Cells with $\mathrm{EDD} \geq 3$ & 9/9 & 8/9 & 7/9 & 5/9 \\
142	\bottomrule
143	\end{tabular}
144	\end{table}
145	
146	\begin{figure}[t]
147	\centering
148	\includegraphics[width=\columnwidth]{figures/fig_auc_decay.pdf}
149	\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \in \{0.65, 0.70, 0.75, 0.80\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\% CIs.}
150	\label{fig:auc_decay}
151	\end{figure}
152	
153	\paragraph{Decision boundary dilution.}
154	\label{sec:atlas:edd:dilution}
155	EDD uses binary-pair classifiers to avoid \emph{decision boundary dilution}: in Pythia nucleus, d2\,vs.\,d3 AUC degrades from 0.804 (4-class) to 0.689 (6-class), a 14.3\% relative decline despite identical data, because shared decision boundaries dilute per-pair capacity.
156	Binary classifiers eliminate this confound, isolating true adjacent-pair discriminability.
157	
158	%% ----------------------------------------------------------------
159	\subsection{Strategy-Dependent Trajectories}
160	\label{sec:atlas:strategy}
161	
162	The three decoding strategies induce qualitatively distinct degradation trajectories.
163	Nucleus ($p{=}0.95$) produces the most consistent accuracy (78.2--83.3\%) and serves as the reference trajectory.
164	Temperature ($\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.4\%, OLMo 82.0\%) because uniform logit scaling accelerates convergence to an attractor distribution~\cite{shumailov2024_nature}, amplifying the statistical fingerprint. However, this acceleration creates a boundary reversal risk: temperature depth-$N$ features approximate nucleus/top-$k$ depth-$(N{+}1)$ features, causing cross-strategy classifiers to systematically overpredict depth (\S\ref{sec:generalization}).
165	Top-$k$ ($k{=}50$) produces the lowest accuracy (69.6--76.6\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens, though feature direction is preserved (cross-model $\rho = 0.811$).
166	The strategy effect (8.4~pp range) exceeds the model effect (7.1~pp), indicating deployment-time knowledge of the decoding strategy matters at least as much as the generator model.
167	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "17d36291-fdb1-48bb-b592-596364509802",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "37fce4c0-5fa1-4525-ac79-1434d3e28006",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex",
      "content": "\\section{The Depth Degradation Atlas}\n\\label{sec:atlas}\n\nWe present the Depth Degradation Atlas: a systematic empirical map of how statistical fingerprints evolve across recursive generation depths, models, and decoding strategies.\nThe atlas spans $3 \\times 3 = 9$ model--strategy cells evaluated at depths $d \\in \\{0, 1, 2, 3\\}$, with depth extensions to $d{=}5$ for cross-model EDD validation (\\S\\ref{sec:atlas:edd}).\n\n%% ----------------------------------------------------------------\n\\subsection{In-Distribution Performance}\n\\label{sec:atlas:id}\n\nTable~\\ref{tab:main_matrix} reports four-class Random Forest accuracy (5-fold CV, 200 trees) across all nine cells.\nAccuracy ranges from 69.6\\% (Pythia, top-$k$) to 85.4\\% (GPT-2~XL, temperature), all exceeding the 25\\% chance baseline by a wide margin.\nTwo axis effects emerge.\nGPT-2~XL achieves the highest accuracy under every strategy (76.6--85.4\\%), followed by OLMo (74.2--82.0\\%) and Pythia (69.6--78.2\\%).\nTop-$k$ sampling yields the lowest accuracy in every model.\nThe mean within-model strategy gap is 8.4~pp, comparable to the 7.1~pp mean within-strategy model gap; decoding strategy and model family contribute roughly equally to performance variance.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Four-class RF accuracy (\\%) across the $3 \\times 3$ atlas, with d1--d3 three-class accuracy in parentheses (chance = 25\\% / 33\\%). Depth-0 recall exceeds 98\\% in all cells.}\n\\label{tab:main_matrix}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n& Nucleus & Temp.\\ $\\tau{=}0.9$ & Top-$k$ \\\\\n\\midrule\nPythia-1.4B  & 78.2\\,(71.2) & 76.3\\,(70.6) & 69.6\\,(58.8) \\\\\nOLMo-1B     & 78.8\\,(75.0) & 82.0\\,(76.3) & 74.2\\,(66.1) \\\\\nGPT-2~XL    & 83.3\\,(79.0) & 85.4\\,(82.6) & 76.6\\,(69.5) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Per-class recall distribution.}\nDepth-0 recall exceeds 98\\% in all 9 cells, confirming that human-written text is trivially separable from any generation depth.\nAmong generated depths, d2 consistently yields the lowest recall (46--73\\% across cells), followed by d3 (58--82\\%) and d1 (72--91\\%).\nFor example, Pythia-1.4B nucleus achieves per-class recall of d0$\\,{=}\\,$99\\%, d1$\\,{=}\\,$82\\%, d2$\\,{=}\\,$59\\%, d3$\\,{=}\\,$72\\%.\nThe strongest d2 recall is obtained by GPT-2~XL nucleus (73\\%).\nThe d2 trough reflects its position at the center of the depth gradient: d2 features overlap with both the d1 distribution above and d3 below, making it the most confusable class, consistent with the d2-vs-d3 pair being the EDD bottleneck (\\S\\ref{sec:atlas:edd}).\nFull per-class recall for all cells appears in Appendix~\\ref{app:per_class}.\n\n%% ----------------------------------------------------------------\n\\subsection{Feature Consistency Across the Grid}\n\\label{sec:atlas:features}\n\nDespite the 15.8~pp accuracy spread across cells, a small feature family dominates in every setting.\nPerplexity tail statistics as a feature group dominate depth discrimination: the 90th-percentile perplexity (\\texttt{p90\\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\\texttt{var\\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\\ref{app:permutation}).\\footnote{Individual feature rankings should be interpreted cautiously given high multicollinearity (VIF${>}$10 for 14--16/19 features); the group-level dominance of perplexity tail statistics is robust across importance measures.}\nTable~\\ref{tab:feature_importance} shows the full per-cell ranking.\n\nCross-model feature-rank Spearman correlation averages $\\bar{\\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.\nAmong strategies, top-$k$ yields the highest cross-model rank correlation ($\\rho = 0.811$): the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\\S\\ref{sec:atlas:strategy}).\n\nPercentile-based features outperform their moment-based counterparts.\nToken-level perplexity distributions are heavy-tailed: individual outlier passages can dominate the arithmetic mean of their depth class, whereas \\texttt{p90\\_ppl} is robust to such extremes while still capturing the tail erosion that signals generation depth.\n\nFeature ablation confirms this concentration: the top-2 features (\\texttt{p90\\_ppl} + \\texttt{var\\_surprisal}) alone reach 91.1\\% of full accuracy (71.5\\%), and the top-5 features achieve 97.6\\% (76.5\\% vs.\\ 78.4\\%), with perplexity statistics alone reaching 76.6\\% (vs.\\ surprisal 73.2\\%, other categories ${\\leq}$47\\%).\nVariance inflation analysis reveals VIF${>}$10 for 14--16 of 19 features, placing the effective independent dimensionality at ${\\approx}$4--5.\nForward selection independently confirms the dominant pair: \\texttt{p90\\_ppl} is selected first in 6/9 cells, \\texttt{var\\_surprisal} in 3/9.\n\nThe feature hierarchy also shifts with depth.\nAt shallow boundaries (d1 vs.\\ d2), \\texttt{var\\_surprisal} dominates importance; at deeper boundaries (d3 vs.\\ d4, d4 vs.\\ d5), tail perplexity statistics (\\texttt{p90\\_ppl}, \\texttt{kurtosis\\_ppl}) take over.\nThis transition aligns with model-collapse dynamics~\\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Top-5 features by Gini importance. \\textbf{Bold}: top-2. \\texttt{p90\\_ppl} top-2 in 9/9; \\texttt{var\\_surprisal} 8/9 under SHAP (7/9 under Gini).}\n\\label{tab:feature_importance}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}l l@{}}\n\\toprule\nCell & Top-5 features (Gini importance, ranked) \\\\\n\\midrule\nPythia, nuc.       & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.15)}, m\\_ppl\\,(.11), var\\_ppl\\,(.08), p75\\,(.07) \\\\\nPythia, $\\tau$     & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.14)}, m\\_ppl\\,(.11), p75\\,(.07), m\\_surp\\,(.07) \\\\\nPythia, top-$k$    & \\textbf{var\\_surp\\,(.16)}, \\textbf{p90\\_ppl\\,(.12)}, m\\_ppl\\,(.11), var\\_ppl\\,(.07), m\\_surp\\,(.06) \\\\\nGPT-2\\,XL, nuc.    & \\textbf{var\\_surp\\,(.21)}, \\textbf{p90\\_ppl\\,(.21)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.06) \\\\\nGPT-2\\,XL, $\\tau$  & \\textbf{p90\\_ppl\\,(.25)}, \\textbf{p75\\,(.15)}, m\\_surp\\,(.13), var\\_surp\\,(.12), p50\\,(.05) \\\\\nGPT-2\\,XL, top-$k$ & \\textbf{p90\\_ppl\\,(.24)}, \\textbf{p75\\,(.12)}, var\\_surp\\,(.10), m\\_surp\\,(.09), ttr\\,(.04) \\\\\nOLMo, nuc.         & \\textbf{p90\\_ppl\\,(.18)}, \\textbf{var\\_surp\\,(.15)}, p75\\,(.11), m\\_surp\\,(.07), ttr\\,(.06) \\\\\nOLMo, $\\tau$       & \\textbf{p90\\_ppl\\,(.21)}, \\textbf{var\\_surp\\,(.16)}, p75\\,(.12), m\\_surp\\,(.09), ttr\\,(.05) \\\\\nOLMo, top-$k$      & \\textbf{p90\\_ppl\\,(.20)}, \\textbf{var\\_surp\\,(.17)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.05) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_atlas_heatmap.pdf}\n\\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\\S\\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}\n\\label{fig:atlas_heatmap}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{Monotonicity and Inter-Depth Distances}\n\\label{sec:atlas:monotonicity}\n\nDepth features exhibit strong monotonic trends: perplexity tail statistics (\\texttt{p90\\_ppl}, \\texttt{mean\\_surprisal}) decrease with depth (Spearman $\\rho = -1.0$ across cell-level medians) while repetition features increase, reflecting the complementary narrowing and self-repetition of distribution collapse.\nInter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89; separating adjacent deep generations requires the tail statistics identified in \\S\\ref{sec:atlas:features}.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_feature_trajectory.pdf}\n\\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \\texttt{p90\\_ppl} (monotonically decreasing). Middle: \\texttt{var\\_surprisal} (decreasing). Bottom: \\texttt{rep\\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \\to d{=}1$ gap exceeds all subsequent inter-depth gaps.}\n\\label{fig:feature_trajectory}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{EDD Analysis}\n\\label{sec:atlas:edd}\n\nWe extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.\nEach model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).\nWe train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\\ref{eq:edd}.\n\n\\paragraph{AUC decay profile.}\nFigure~\\ref{fig:auc_decay} plots the binary pairwise AUC decay curves.\nFor Pythia-1.4B (nucleus), AUC decays monotonically: d0-vs-d1 $= 0.999$, d1-vs-d2 $= 0.925$, d2-vs-d3 $= 0.823$, d3-vs-d4 $= 0.784$, d4-vs-d5 $= 0.683$.\nThe steepest drop occurs between the d1-vs-d2 and d2-vs-d3 pairs; the curve then flattens as the system approaches an indistinguishable regime gradually rather than crossing a sharp boundary.\n\n\\paragraph{Cross-model convergence at depth 4--5.}\nThe d3-vs-d4 AUC consistently clusters near the $T{=}0.75$ threshold across all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$ ($0.681$--$0.684$).\nThe directional pattern is consistent, but statistical strength is stratified: bootstrap testing ($10{,}000$ resamples, $H_0{:}\\, \\mathrm{AUC} \\leq 0.75$) yields $p = 0.001$ for Pythia (significant), $p = 0.091$ for OLMo (marginal), and $p = 0.505$ for GPT-2~XL (non-significant).\nAll three models cross the $T{=}0.75$ threshold within the d3--d4 region, establishing a consistent depth-4 decay boundary with graded confidence rather than uniform statistical significance.\nThe d4-vs-d5 saturation is unambiguous across models, supporting the interpretation of d3--d4 as a \\emph{transition zone} from discriminable to indistinguishable regime.\n\n\\paragraph{EDD threshold sensitivity.}\nTable~\\ref{tab:edd_sensitivity} reports $\\mathrm{EDD}_T$ across the primary 9-cell benchmark (depths 0--3) at four threshold values.\nAt $T{=}0.65$, all 9 cells achieve $\\mathrm{EDD} = 3$; at $T{=}0.75$, 7 of 9 cells maintain $\\mathrm{EDD} \\geq 3$; at $T{=}0.80$, the count drops to 5 of 9.\nThe cells losing $\\mathrm{EDD}{=}3$ first are consistently the top-$k$ configurations (Pythia top-$k$ at $T{=}0.70$, then OLMo top-$k$ at $T{=}0.75$), where the d2-vs-d3 pair is the consistent bottleneck across all 9 cells.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Number of atlas cells achieving $\\mathrm{EDD} \\geq 3$ at each threshold $T$, across 9 model--strategy cells (depths 0--3). The d2-vs-d3 boundary is the bottleneck; top-$k$ cells drop first.}\n\\label{tab:edd_sensitivity}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n& $T{=}0.65$ & $T{=}0.70$ & $T{=}0.75$ & $T{=}0.80$ \\\\\n\\midrule\nCells with $\\mathrm{EDD} \\geq 3$ & 9/9 & 8/9 & 7/9 & 5/9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_auc_decay.pdf}\n\\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\\% CIs.}\n\\label{fig:auc_decay}\n\\end{figure}\n\n\\paragraph{Decision boundary dilution.}\n\\label{sec:atlas:edd:dilution}\nEDD uses binary-pair classifiers to avoid \\emph{decision boundary dilution}: in Pythia nucleus, d2\\,vs.\\,d3 AUC degrades from 0.804 (4-class) to 0.689 (6-class), a 14.3\\% relative decline despite identical data, because shared decision boundaries dilute per-pair capacity.\nBinary classifiers eliminate this confound, isolating true adjacent-pair discriminability.\n\n%% ----------------------------------------------------------------\n\\subsection{Strategy-Dependent Trajectories}\n\\label{sec:atlas:strategy}\n\nThe three decoding strategies induce qualitatively distinct degradation trajectories.\nNucleus ($p{=}0.95$) produces the most consistent accuracy (78.2--83.3\\%) and serves as the reference trajectory.\nTemperature ($\\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.4\\%, OLMo 82.0\\%) because uniform logit scaling accelerates convergence to an attractor distribution~\\cite{shumailov2024_nature}, amplifying the statistical fingerprint. However, this acceleration creates a boundary reversal risk: temperature depth-$N$ features approximate nucleus/top-$k$ depth-$(N{+}1)$ features, causing cross-strategy classifiers to systematically overpredict depth (\\S\\ref{sec:generalization}).\nTop-$k$ ($k{=}50$) produces the lowest accuracy (69.6--76.6\\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens, though feature direction is preserved (cross-model $\\rho = 0.811$).\nThe strategy effect (8.4~pp range) exceeds the model effect (7.1~pp), indicating deployment-time knowledge of the decoding strategy matters at least as much as the generator model.\n",
      "numLines": 167,
      "startLine": 1,
      "totalLines": 167
    }
  },
  "sourceToolAssistantUUID": "17d36291-fdb1-48bb-b592-596364509802",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool call

_source line 185 · 2026-05-17T08:55:32.187Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01RTysDHkwoTpTASkkyfr6LR`</summary>

```json
{
  "pattern": "app:class_balance|accumulation|mixing|A\\.9|class.balance",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
  "output_mode": "content",
  "-n": true,
  "-C": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "37fce4c0-5fa1-4525-ac79-1434d3e28006",
  "isSidechain": false,
  "requestId": "req_011Cb7rtKKDhBXNP7rByjtn3",
  "type": "assistant",
  "uuid": "0822e772-9a31-45f3-bb35-90814db8f973",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RnrHM5wBURsAaJaZ9CULpX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1689,
      "cache_read_input_tokens": 49592,
      "output_tokens": 484,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1689,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 484,
          "cache_read_input_tokens": 49592,
          "cache_creation_input_tokens": 1689,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1689
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


### Runtime record

_source line 186_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 9 审稿请求]: ## 交叉分享 — 请逐条回应 Reviewer 1 的修订版审稿意见  以下是 Reviewer 1 对修订版论文的完整审稿。请逐条回应 moderate 及以上问题： - **[AGREE]** 同意并说明理由 - **[REBUT]** 反驳并提供证据（cite 具体 Section/Table/Figure）  ---  ## Reviewer 1 报告摘要…",
  "leafUuid": "1383c970-a381-4308-9ebb-eded07cbb0ae",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 187_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Tool call

_source line 188 · 2026-05-17T08:55:40.732Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01LmU7g3NG6MXrsBJgjh2HFU`</summary>

```json
{
  "pattern": "class.balance|imbalance|prior|prevalence|mixing|accumul",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
  "output_mode": "content",
  "-n": true,
  "-C": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1383c970-a381-4308-9ebb-eded07cbb0ae",
  "isSidechain": false,
  "requestId": "req_011Cb7ruJ1ru3qPocHZQ5tCc",
  "type": "assistant",
  "uuid": "fdefdaee-b9cf-46d3-9ff6-075bb78ebf03",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NYDxTQAdRZjZwGWfRjYFQt",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5693,
      "cache_read_input_tokens": 51281,
      "output_tokens": 329,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5693,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 329,
          "cache_read_input_tokens": 51281,
          "cache_creation_input_tokens": 5693,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5693
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

_source line 189 · 2026-05-17T08:55:40.751Z_

<details><summary>↩ Tool result · `toolu_01LmU7g3NG6MXrsBJgjh2HFU`</summary>

```text
98-The same top-5 features (\texttt{var\_surprisal}, \texttt{p90\_ppl}, \texttt{mean\_ppl}, \texttt{mean\_surprisal}, \texttt{p75\_ppl}) dominate across all $\tau$ values with only minor rank-order variation.
99-
100-\paragraph{Collapse at $\tau{=}1.1$: memorization as prerequisite.}
101-At $\tau{=}1.1$, 4-class accuracy drops to 57.2\% and d1v2 AUC falls to 0.528.
102-Training loss reveals the mechanism: at low temperature ($\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \to 0.42 \to 0.16$), indicating rapid memorization of the model's own output.
103:At $\tau{=}1.1$, loss remains nearly flat ($2.27 \to 1.91 \to 1.85$); high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.
104-This establishes \emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.
105-
106-\paragraph{Cross-$\tau$ non-transferability.}
107-Leave-one-$\tau$-out transfer yields mean accuracy of 46.7\% with mean d1v2 AUC of 0.319 (Table~\ref{tab:multi_tau_cross}), worse than cross-strategy transfer (59.1\%; \S\ref{sec:gen:crossstrategy}).
108-Holdout $\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.
--
312-\subsection{Cross-Scale Full Results}
313-\label{app:cross_scale_full}
314-
315-This section provides the full cross-scale analysis summarized in \S\ref{sec:gen:crossscale}.
316-We extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \in \{0, 1, \ldots, 5\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).
317:Feature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.
318-
319-\paragraph{Scale comparison.}
320-Table~\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).
321-
322-\begin{table}[h]
--
418-To empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\to$ OLMo $\to$ Pythia) reversing the model-depth assignment.
419-The reverse chain achieves 85.75\% (95\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\%, [81.0, 88.25]).
420-If the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.
421-
422-\paragraph{Cross-domain transfer.}
423:All prior experiments use WikiText-103 as the seed corpus.
424-To test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).
425-Five-fold cross-validation yields 74.1\% $\pm$ 2.0\% accuracy, compared to ${\sim}$78\% on the WikiText seed.
426-Per-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66, with d2 remaining the most challenging class.
427-The 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.
428-These results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fdefdaee-b9cf-46d3-9ff6-075bb78ebf03",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "9abbd756-9046-4002-925e-9730acab15b0",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "98-The same top-5 features (\\texttt{var\\_surprisal}, \\texttt{p90\\_ppl}, \\texttt{mean\\_ppl}, \\texttt{mean\\_surprisal}, \\texttt{p75\\_ppl}) dominate across all $\\tau$ values with only minor rank-order variation.\n99-\n100-\\paragraph{Collapse at $\\tau{=}1.1$: memorization as prerequisite.}\n101-At $\\tau{=}1.1$, 4-class accuracy drops to 57.2\\% and d1v2 AUC falls to 0.528.\n102-Training loss reveals the mechanism: at low temperature ($\\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \\to 0.42 \\to 0.16$), indicating rapid memorization of the model's own output.\n103:At $\\tau{=}1.1$, loss remains nearly flat ($2.27 \\to 1.91 \\to 1.85$); high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.\n104-This establishes \\emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.\n105-\n106-\\paragraph{Cross-$\\tau$ non-transferability.}\n107-Leave-one-$\\tau$-out transfer yields mean accuracy of 46.7\\% with mean d1v2 AUC of 0.319 (Table~\\ref{tab:multi_tau_cross}), worse than cross-strategy transfer (59.1\\%; \\S\\ref{sec:gen:crossstrategy}).\n108-Holdout $\\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.\n--\n312-\\subsection{Cross-Scale Full Results}\n313-\\label{app:cross_scale_full}\n314-\n315-This section provides the full cross-scale analysis summarized in \\S\\ref{sec:gen:crossscale}.\n316-We extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \\in \\{0, 1, \\ldots, 5\\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).\n317:Feature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.\n318-\n319-\\paragraph{Scale comparison.}\n320-Table~\\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).\n321-\n322-\\begin{table}[h]\n--\n418-To empirically test the architecture confound hypothesis, we constructed a reverse chain (GPT-2~XL $\\to$ OLMo $\\to$ Pythia) reversing the model-depth assignment.\n419-The reverse chain achieves 85.75\\% (95\\% CI [82.0, 89.25]), statistically indistinguishable from the forward chain (84.75\\%, [81.0, 88.25]).\n420-If the classifier exploited architecture fingerprints rather than depth signal, reversing the chain should invert depth predictions; the equivalent accuracy under both orderings provides empirical evidence against the architecture confound.\n421-\n422-\\paragraph{Cross-domain transfer.}\n423:All prior experiments use WikiText-103 as the seed corpus.\n424-To test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).\n425-Five-fold cross-validation yields 74.1\\% $\\pm$ 2.0\\% accuracy, compared to ${\\sim}$78\\% on the WikiText seed.\n426-Per-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66, with d2 remaining the most challenging class.\n427-The 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.\n428-These results provide preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.",
    "numLines": 35
  },
  "sourceToolAssistantUUID": "fdefdaee-b9cf-46d3-9ff6-075bb78ebf03",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool call

_source line 190 · 2026-05-17T08:55:41.833Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01T3hyFp8bvqVnvuo9X8HCKU`</summary>

```json
{
  "pattern": "quality|confound|controlled|matched",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex",
  "output_mode": "content",
  "-n": true,
  "-C": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9abbd756-9046-4002-925e-9730acab15b0",
  "isSidechain": false,
  "requestId": "req_011Cb7ruJ1ru3qPocHZQ5tCc",
  "type": "assistant",
  "uuid": "f031f1d0-46d3-4081-8e43-7833b7fffa29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NYDxTQAdRZjZwGWfRjYFQt",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5693,
      "cache_read_input_tokens": 51281,
      "output_tokens": 329,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5693,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 329,
          "cache_read_input_tokens": 51281,
          "cache_creation_input_tokens": 5693,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5693
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

_source line 191 · 2026-05-17T08:55:41.847Z_

<details><summary>↩ Tool result · `toolu_01T3hyFp8bvqVnvuo9X8HCKU`</summary>

```text
10-Cross-model transfer accuracy of 66.4\% is substantially driven by d0; d2 recall drops to 26.8\% in the worst case (Pythia holdout).
11-
12-\paragraph{Controlled vs.\ ecological setting.}
13:The primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\S\ref{sec:gen:crossscale}).
14-This protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.
15-Depth signal is the dominant classification factor (5-fold CV 59--82\%, up to 2.5$\times$ chance): LOGO accuracy (72.1\%) matches standard CV (72.0\%), and seed-group prediction is at chance (10.2\% vs.\ 10\%; Appendix~\ref{app:domain_bias}).
16-Cross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\% vs.\ 70.2\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.
--
26-
27-\paragraph{EDD monotonicity assumption.}
28-Our EDD definition (Eq.~\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically, as observed in all our configurations.
29:However, \citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).
30-Our cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.
31-In such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.
32-The choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f031f1d0-46d3-4081-8e43-7833b7fffa29",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "243132db-1a08-48c0-b0a8-3dec9ebde863",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "10-Cross-model transfer accuracy of 66.4\\% is substantially driven by d0; d2 recall drops to 26.8\\% in the worst case (Pythia holdout).\n11-\n12-\\paragraph{Controlled vs.\\ ecological setting.}\n13:The primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\\S\\ref{sec:gen:crossscale}).\n14-This protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.\n15-Depth signal is the dominant classification factor (5-fold CV 59--82\\%, up to 2.5$\\times$ chance): LOGO accuracy (72.1\\%) matches standard CV (72.0\\%), and seed-group prediction is at chance (10.2\\% vs.\\ 10\\%; Appendix~\\ref{app:domain_bias}).\n16-Cross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\\% vs.\\ 70.2\\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.\n--\n26-\n27-\\paragraph{EDD monotonicity assumption.}\n28-Our EDD definition (Eq.~\\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically, as observed in all our configurations.\n29:However, \\citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \\emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).\n30-Our cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.\n31-In such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.\n32-The choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.",
    "numLines": 15
  },
  "sourceToolAssistantUUID": "f031f1d0-46d3-4081-8e43-7833b7fffa29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool call

_source line 192 · 2026-05-17T08:55:47.274Z_

<details open><summary>🔧 Tool call — Grep · `toolu_012eo9vygjSovK3STuSndaCC`</summary>

```json
{
  "pattern": "C4|false.positive|FPR|web.crawl|wild",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "output_mode": "content",
  "-n": true,
  "-C": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "243132db-1a08-48c0-b0a8-3dec9ebde863",
  "isSidechain": false,
  "requestId": "req_011Cb7rv18suEMfZJht9GLQH",
  "type": "assistant",
  "uuid": "31af3e01-981c-4a0f-922a-9a4568861138",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LdQySFRNSrgeuHyjeeBLfn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2205,
      "cache_read_input_tokens": 56974,
      "output_tokens": 318,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2205,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 318,
          "cache_read_input_tokens": 56974,
          "cache_creation_input_tokens": 2205,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2205
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

_source line 193 · 2026-05-17T08:55:47.288Z_

<details><summary>↩ Tool result · `toolu_012eo9vygjSovK3STuSndaCC`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-11-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-12-\paragraph{Controlled vs.\ ecological setting.}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-13-The primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\S\ref{sec:gen:crossscale}).
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:14:This protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-15-Depth signal is the dominant classification factor (5-fold CV 59--82\%, up to 2.5$\times$ chance): LOGO accuracy (72.1\%) matches standard CV (72.0\%), and seed-group prediction is at chance (10.2\% vs.\ 10\%; Appendix~\ref{app:domain_bias}).
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-16-Cross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\% vs.\ 70.2\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-17-Real-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-18-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:19:\paragraph{Domain-dependent false positive rate.}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:20:On editorial text (WikiText-103), all classifiers achieve $\geq$98.5\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL).
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-21-Misclassifications concentrate in template/SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\ Pythia/GPT-2~XL's Wikipedia/WebText).
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-22-Deployment on heterogeneous web corpora requires model- and domain-specific calibration.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-23-
--
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-110-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-111-\paragraph{Ecological validity.}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-112-On WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\geq$98.5\% d0 accuracy despite $+$621\% domain shift in mean perplexity, partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:113:On noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-114-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-115-\begin{table}[h]
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-116-\centering
--
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-215-\subsection{Wild-Data Calibration}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-216-\label{app:calibration}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-217-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:218:Table~\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-219-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-220-\begin{table}[h]
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-221-\centering
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-222-\small
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:223:\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\% Wilson CIs computed for C4 ($n{=}5{,}000$).}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-224-\label{tab:calibration}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-225-\begin{tabular}{@{}llrccc@{}}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-226-\toprule
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:227:Model & Source & $n$ & d0 (\%) & FPR (\%) & 95\% Wilson CI \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-228-\midrule
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-229-Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:230: & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-231-\addlinespace
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-232-GPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:233: & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-234-\addlinespace
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-235-OLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:236: & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-237-\bottomrule
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-238-\end{tabular}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-239-\end{table}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-240-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-241-On WikiText-103, all three classifiers achieve $\geq$98.5\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:242:On C4, FPR varies sharply: OLMo (4.7\%) vs.\ Pythia (20.2\%) and GPT-2~XL (22.4\%).
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:243:C4 misclassifications concentrate in template and SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0 passages), rather than in random noise.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:244:The model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:245:Among C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\%), d2 (3.7\%), d3 (9.6\%); for OLMo, d1 (2.9\%), d2 (0.5\%), d3 (1.3\%). The non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-246-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-247-\subsection{Downstream Curation PoC}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-248-\label{app:curation_poc}
--
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-3-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-4-The text on which large language models are trained increasingly contains their own outputs.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-5-As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \cite{shumailov2024_nature,alemohammad2024_mad}.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex:6:This model$\to$data$\to$model cycle is no longer hypothetical; it is already occurring in the wild. Yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \cite{dohmatob2024_tale_of_tails}.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-7-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-8-Existing tools address adjacent but distinct problems.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-9-Binary detectors such as Binoculars \cite{binoculars2024}, Fast-DetectGPT \cite{fast_detectgpt2024}, and DivEye \cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \geq 1$ into a single category.
--
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-836-\@LN{667}{8}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-837-\@LN{668}{8}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-838-\@LN{669}{8}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:839:\@writefile{toc}{\contentsline {paragraph}{Domain-dependent false positive rate.}{9}{section*.36}\protected@file@percent }
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-840-\@LN{670}{8}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-841-\@LN{671}{8}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-842-\@LN{672}{8}
--
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1553-\@LN{1261}{14}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1554-\@LN{1262}{14}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1555-\@LN{1263}{14}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1556:\@writefile{lot}{\contentsline {table}{\numberline {13}{\ignorespaces Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\% Wilson CIs computed for C4 ($n{=}5{,}000$).}}{15}{table.caption.58}\protected@file@percent }
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1557:\newlabel{tab:calibration}{{13}{15}{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\% Wilson CIs computed for C4 ($n{=}5{,}000$)}{table.caption.58}{}}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1558-\@LN{1264}{14}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1559-\@LN{1265}{14}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1560-\@LN{1266}{14}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "31af3e01-981c-4a0f-922a-9a4568861138",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "1f392124-0fd6-4bb9-b663-ffc5d306f95f",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-11-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-12-\\paragraph{Controlled vs.\\ ecological setting.}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-13-The primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\\S\\ref{sec:gen:crossscale}).\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:14:This protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-15-Depth signal is the dominant classification factor (5-fold CV 59--82\\%, up to 2.5$\\times$ chance): LOGO accuracy (72.1\\%) matches standard CV (72.0\\%), and seed-group prediction is at chance (10.2\\% vs.\\ 10\\%; Appendix~\\ref{app:domain_bias}).\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-16-Cross-scale experiments include both instruction-tuned and base variants; the base model shows weaker but above-chance depth signal (59.9\\% vs.\\ 70.2\\%) with non-monotonic AUC decay, suggesting instruction-tuning regularizes degradation patterns.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-17-Real-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-18-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:19:\\paragraph{Domain-dependent false positive rate.}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex:20:On editorial text (WikiText-103), all classifiers achieve $\\geq$98.5\\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL).\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-21-Misclassifications concentrate in template/SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\\ Pythia/GPT-2~XL's Wikipedia/WebText).\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-22-Deployment on heterogeneous web corpora requires model- and domain-specific calibration.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex-23-\n--\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-110-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-111-\\paragraph{Ecological validity.}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-112-On WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity, partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:113:On noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-114-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-115-\\begin{table}[h]\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-116-\\centering\n--\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-215-\\subsection{Wild-Data Calibration}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-216-\\label{app:calibration}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-217-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:218:Table~\\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-219-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-220-\\begin{table}[h]\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-221-\\centering\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-222-\\small\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:223:\\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\\% Wilson CIs computed for C4 ($n{=}5{,}000$).}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-224-\\label{tab:calibration}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-225-\\begin{tabular}{@{}llrccc@{}}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-226-\\toprule\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:227:Model & Source & $n$ & d0 (\\%) & FPR (\\%) & 95\\% Wilson CI \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-228-\\midrule\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-229-Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:230: & C4 & 5{,}000 & 79.8 & 20.2 & [19.1, 21.3] \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-231-\\addlinespace\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-232-GPT-2~XL & WikiText & 546 & 99.3 & 0.7 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:233: & C4 & 5{,}000 & 77.6 & 22.4 & [21.3, 23.6] \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-234-\\addlinespace\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-235-OLMo-1B & WikiText & 546 & 98.5 & 1.5 & --- \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:236: & C4 & 5{,}000 & 95.3 & 4.7 & [4.2, 5.3] \\\\\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-237-\\bottomrule\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-238-\\end{tabular}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-239-\\end{table}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-240-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-241-On WikiText-103, all three classifiers achieve $\\geq$98.5\\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:242:On C4, FPR varies sharply: OLMo (4.7\\%) vs.\\ Pythia (20.2\\%) and GPT-2~XL (22.4\\%).\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:243:C4 misclassifications concentrate in template and SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0 passages), rather than in random noise.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:244:The model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex:245:Among C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\\%), d2 (3.7\\%), d3 (9.6\\%); for OLMo, d1 (2.9\\%), d2 (0.5\\%), d3 (1.3\\%). The non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-246-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-247-\\subsection{Downstream Curation PoC}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex-248-\\label{app:curation_poc}\n--\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-3-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-4-The text on which large language models are trained increasingly contains their own outputs.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-5-As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex:6:This model$\\to$data$\\to$model cycle is no longer hypothetical; it is already occurring in the wild. Yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-7-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-8-Existing tools address adjacent but distinct problems.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex-9-Binary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\n--\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-836-\\@LN{667}{8}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-837-\\@LN{668}{8}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-838-\\@LN{669}{8}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:839:\\@writefile{toc}{\\contentsline {paragraph}{Domain-dependent false positive rate.}{9}{section*.36}\\protected@file@percent }\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-840-\\@LN{670}{8}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-841-\\@LN{671}{8}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-842-\\@LN{672}{8}\n--\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1553-\\@LN{1261}{14}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1554-\\@LN{1262}{14}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1555-\\@LN{1263}{14}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1556:\\@writefile{lot}{\\contentsline {table}{\\numberline {13}{\\ignorespaces Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\\% Wilson CIs computed for C4 ($n{=}5{,}000$).}}{15}{table.caption.58}\\protected@file@percent }\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux:1557:\\newlabel{tab:calibration}{{13}{15}{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+. 95\\% Wilson CIs computed for C4 ($n{=}5{,}000$)}{table.caption.58}{}}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1558-\\@LN{1264}{14}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1559-\\@LN{1265}{14}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.aux-1560-\\@LN{1266}{14}",
    "numLines": 81
  },
  "sourceToolAssistantUUID": "31af3e01-981c-4a0f-922a-9a4568861138",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Tool call

_source line 194 · 2026-05-17T08:55:48.578Z_

<details open><summary>🔧 Tool call — Grep · `toolu_013bwBz2mzG9i4N7MrFvcFBh`</summary>

```json
{
  "pattern": "BOS|prompted|prompt.condition",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "output_mode": "content",
  "-n": true,
  "-C": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1f392124-0fd6-4bb9-b663-ffc5d306f95f",
  "isSidechain": false,
  "requestId": "req_011Cb7rv18suEMfZJht9GLQH",
  "type": "assistant",
  "uuid": "e75b5ad6-7148-4afb-8df5-7996d02c9d61",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LdQySFRNSrgeuHyjeeBLfn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2205,
      "cache_read_input_tokens": 56974,
      "output_tokens": 318,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2205,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 318,
          "cache_read_input_tokens": 56974,
          "cache_creation_input_tokens": 2205,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2205
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

_source line 195 · 2026-05-17T08:55:48.600Z_

<details><summary>↩ Tool result · `toolu_013bwBz2mzG9i4N7MrFvcFBh`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-31-
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-32-\paragraph{Generation pipeline.}
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:33:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-34-Each depth is produced by a model explicitly trained on the prior depth's data, not by sampling from the unmodified base model.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:35:Our BOS-seeded generation may amplify depth signal relative to prompted settings; extending to prompt-conditioned generation is future work.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-36-There is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.
/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-37-
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e75b5ad6-7148-4afb-8df5-7996d02c9d61",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "5d3a7587-9f42-4ac7-bda8-b2420fcfaa91",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-31-\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-32-\\paragraph{Generation pipeline.}\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:33:[Omitted long matching line]\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-34-Each depth is produced by a model explicitly trained on the prior depth's data, not by sampling from the unmodified base model.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex:35:Our BOS-seeded generation may amplify depth signal relative to prompted settings; extending to prompt-conditioned generation is future work.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-36-There is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.\n/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex-37-",
    "numLines": 7
  },
  "sourceToolAssistantUUID": "e75b5ad6-7148-4afb-8df5-7996d02c9d61",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Runtime record

_source line 196_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 9 审稿请求]: ## 交叉分享 — 请逐条回应 Reviewer 1 的修订版审稿意见  以下是 Reviewer 1 对修订版论文的完整审稿。请逐条回应 moderate 及以上问题： - **[AGREE]** 同意并说明理由 - **[REBUT]** 反驳并提供证据（cite 具体 Section/Table/Figure）  ---  ## Reviewer 1 报告摘要…",
  "leafUuid": "5d3a7587-9f42-4ac7-bda8-b2420fcfaa91",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Runtime record

_source line 197_

```json
{
  "type": "ai-title",
  "aiTitle": "Round 8 paper review for recursive generation depth estimation",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661"
}
```

---


### Tool call

_source line 198 · 2026-05-17T08:55:51.479Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Dyb5FoYubBNzz5cBtUx7te`</summary>

```json
{
  "pattern": "92\\.8|retention",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5d3a7587-9f42-4ac7-bda8-b2420fcfaa91",
  "isSidechain": false,
  "requestId": "req_011Cb7rvWJpGnc5gJYYFyMxA",
  "type": "assistant",
  "uuid": "2afd459b-6ac9-4f64-9cb8-2860140c79d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TtgTvNDtPtgFPYXezqBX2W",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6140,
      "cache_read_input_tokens": 59179,
      "output_tokens": 142,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6140,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 142,
          "cache_read_input_tokens": 59179,
          "cache_creation_input_tokens": 6140,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6140
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

_source line 199 · 2026-05-17T08:55:51.495Z_

<details><summary>↩ Tool result · `toolu_01Dyb5FoYubBNzz5cBtUx7te`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2afd459b-6ac9-4f64-9cb8-2860140c79d4",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "07984135-4770-4eb8-baba-829c3d2d5920",
  "toolUseResult": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  },
  "sourceToolAssistantUUID": "2afd459b-6ac9-4f64-9cb8-2860140c79d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Assistant

_source line 200 · 2026-05-17T08:55:54.662Z_

Confirmed: "92.8% retention" does not exist in the paper. Now submitting the cross-review response.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "07984135-4770-4eb8-baba-829c3d2d5920",
  "isSidechain": false,
  "requestId": "req_011Cb7rviS4tX3dCBk3wVGyQ",
  "type": "assistant",
  "uuid": "87f1c02a-a245-45d7-87c3-3931cbcceecc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CNBRRY6EupmZQekwSTnffR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 157,
      "cache_read_input_tokens": 65319,
      "output_tokens": 4032,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 4032,
          "cache_read_input_tokens": 65319,
          "cache_creation_input_tokens": 157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 157
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


### Tool call

_source line 201 · 2026-05-17T08:57:34.480Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__review_reviewer_post_to_director · `toolu_01WY2um5wgewaAcHiFD4Q2cU`</summary>

```json
{
  "text": "## 交叉回应 Reviewer 1 修订版审稿意见\n\n---\n\n### Moderate 问题逐条回应\n\n**[AGREE] R1-W2: BOS-seeded generation 生态效度限制**\n\n同意这是一个实质性限制。论文仅在 method.tex line 35 以一句话承认（\"Our BOS-seeded generation may amplify depth signal relative to prompted settings; extending to prompt-conditioned generation is future work\"），但未量化 BOS 与 prompted generation 之间 depth signal 的差异。BOS-seeded 生成产生的文本缺乏主题连贯性，可能使 depth fingerprint 更容易被检测（因为没有 prompt conditioning 来 \"锚定\" 输出分布）。\n\n关于 \"92.8% retention\"：我独立验证，全文搜索 \"92.8\" 和 \"retention\" 均无匹配。该数字不存在于论文中，应为 Director summary 描述的计划内容而非实际论文数据。\n\n补充：prompted generation 不仅是 ecological validity 问题，也关系到方法的实用性。现实中几乎所有 LLM 输出都有 prompt conditioning；如果 depth signal 在 prompted setting 下显著衰减，整个方法的部署价值将大打折扣。建议至少做一个小规模 pilot（例如 500 samples × 1 model × prompted vs. BOS），量化 signal retention rate。\n\n**[AGREE] R1-W5: Table 2 和 Table 5 缺少 std/CI**\n\n同意。这是一个合理的统计报告要求。5-fold CV 天然产生 fold-level variance，报告 std 或 95% CI 是标准做法。论文在 cross-scale 部分（§4.4, generalization.tex line 101）报告了 bootstrap CI（如 Llama \"[68.3, 72.4]\"），在 seed replication（conclusion.tex line 45）也报告了 CI（\"77.15% (95% CI [76.4, 78.15])\"），说明作者有能力计算 CI。主表 Table 2 和 classifier comparison Table 5 作为核心结果表却缺少 CI，确实不一致。\n\n不过我认为这是 should-fix 而非 blocking issue：Table 5 已经通过三个 classifier 的 convergence（spread ≤ 0.4pp）间接证明了结果稳定性，但这不能替代直接报告 fold variance。\n\n**[REBUT] R1-W7: Cross-scale 仅两个 7B 模型，60.1% lower CI marginally above chance at d1-d3**\n\n部分反驳。\n\n(1) \"marginally above chance\" 需要更精确的计算。Qwen2.5-7B 的 60.1% 是 4-class accuracy（chance=25%），即便 lower CI 58.0% 仍为 2.32× chance。R1 的担忧是 \"d1-d3 marginally above chance\"（chance=33%），但论文未单独报告 7B 的 d1-d3 accuracy。从 1-1.5B 的规律看（Table 2 括号中的 d1-d3 accuracy 约为 4-class 减去 7-10pp），Qwen 的 d1-d3 accuracy 估计在 50-53% 范围，仍为 1.5-1.6× chance。\"marginally\" 措辞偏强。\n\n(2) 但我同意 R1 关于 \"divergent AUC trajectories 无法判断 dominant pattern\" 的判断。Llama monotonic decay vs. Qwen U-shaped recovery（§4.4, generalization.tex lines 102）确实是两个 n=1 观测，无法得出一般性结论。论文标题使用 \"Preliminary\" 是适当的（§4.4 title: \"Preliminary Cross-Scale Observations\"），但 Abstract line 6 中 \"cross-scale with 7B models at 70.2%\" 只报告了较好的那个模型，选择性引用了更高的数字。\n\n建议：Abstract 应同时报告两个 7B 结果（70.2% 和 60.1%），或改为 \"60-70%\" range。\n\n**[AGREE] R1-W8: C4 FPR 分析中 ground truth 假设问题**\n\n同意，这是一个有洞察力的观察。Table 13（Appendix §A.6）的 caption 明确写 \"All passages are human-written (true d0)\"（section_appendix.tex line 223），C4 使用的是 2019 crawl snapshot，其中 LLM 生成文本比例可能较低。但 R1 的 concern 是正确的：如果 C4 中确实包含 LLM 生成的文本（尤其是 2023+ 的 crawl），那么部分 \"false positives\" 实际上可能是 true positives，使得报告的 FPR 成为 upper bound。\n\n论文在 Limitations（conclusion.tex line 20-22）讨论了 FPR 数字但未讨论 ground truth 假设的可靠性。不过这不是 blocking issue：(1) C4 原始版本为 2019 crawl，当时 LLM 污染较少；(2) 论文已经对 FPR 来源做了特征分析（template/SEO content 的 rep_3gram +37%, rep_4gram +75%），这些特征更像是 human-written template content 而非 LLM generation。\n\n建议：在 Appendix 中增加一句说明 C4 crawl 年份及其对 ground truth 可靠性的影响。\n\n**[AGREE] R1-W12: Accumulation/mixing 场景未测试**\n\n同意，且我在自己的 Round 1 审稿（W4）中也从不同角度提出了类似 concern（跨策略迁移的实用性瓶颈）。\n\n现实中的 recursive contamination 不是 \"pure depth\" 场景，而是混合场景：一个训练语料可能同时包含 d0, d1, d2 文本，模型在混合数据上训练后生成的文本不属于任何单一 depth class。论文的 benchmark 构建（method.tex line 33）假设每个 depth 是纯净的递归链（\"each $\\mathcal{D}_k$ is produced by finetuning $f_\\theta$ on $\\mathcal{D}_{k-1}$\"），没有 depth-mixing。\n\nR1 正确指出 Appendix §A.9 仅测试了 eval set 的 class balance 变化。我搜索了全文，未找到任何 accumulation/mixing 实验。\n\n不过我认为这是 future work 而非 blocking issue for Findings：论文已经在 Limitations（conclusion.tex line 14: \"wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions\"）明确承认了这一差距。作为第一个 formalizing 这个 task 的工作，要求覆盖 mixing scenario 的标准偏高。\n\n**[REBUT] R1-W13: Depth vs quality estimation confound 未控制**\n\n部分反驳。\n\nR1 的 concern 是：classifier 可能在区分 text quality（fluency, coherence）而非 recursive depth per se。这个 concern 在概念上合理，但论文已提供了间接证据反驳 quality-as-sole-confound 假说：\n\n(1) **Zero-shot LLM ablation**（§4.1, generalization.tex line 13）：DeepSeek V3.2 和 Qwen2.5-7B-Instruct 被明确要求判断 text quality/generation depth，只达到 30-36%。如果 depth signal 等同于 quality signal，surface-level quality 判断应该表现更好。\n\n(2) **Cross-model recursive chains**（generalization.tex line 108, Appendix）：cross-model chains（GPT-2 XL → OLMo → Pythia）达到 84.75%，且 reverse chain 85.75%。如果 classifier 仅靠 quality decay，不同 model 序列应该产生不同的 quality trajectory，但分类精度保持稳定。\n\n(3) **Instruction-tuned vs base model control**（§4.4）：base Llama-3.1-8B 的 text quality 与 instruction-tuned 版本不同，但两者都展示了 above-chance depth signal（59.9% vs 70.2%），且 feature importance 一致。\n\n当然，这些都是间接证据，不等于 matched-quality control。一个理想的实验是：在每个 depth 生成一批文本，控制 perplexity/fluency 分布相同，仅 recursive depth 不同，看 classifier 是否仍能区分。这个实验确实缺失。但考虑到上述间接证据的一致性，我认为 quality confound 不构成 blocking issue。\n\n---\n\n### Minor 问题简评\n\n**W1 (EDD operational measure)**: [AGREE] 小问题。EDD definition（method.tex §2.4）已有数学定义，但缺少一句显式声明其为 operational measure 而非 theoretical bound。不影响接收。\n\n**W3 (Full FT vs LoRA)**: [AGREE] 合理但非 blocking。新增的 LoRA rank ablation（generalization.tex lines 110-111, \"accuracy spread 4.65pp across ranks 4-64\"）部分回应了这个 concern，但 full FT 对比确实缺失。\n\n**W4 (Reference model circularity)**: [AGREE] 已在 Limitations 中充分讨论（conclusion.tex lines 34-42），包括 cross-reference ablation 和 self-model 不占优的证据。讨论充分但 circularity 本身未完全解决。\n\n**W6 (DeBERTa/RoBERTa 仅 125M)**: [AGREE] Appendix Table 11 仅测试了 ~125M 级别 PLM。但这个 negative result（59%, -19pp vs RF）的结论是 \"depth signal inaccessible to standard PLM representations\"，用更大 PLM 可能会改变结论。不过这属于 nice-to-have。\n\n**W10 (Wild-data 无时间维度)**: [AGREE] C4 calibration 用的是单一 snapshot，没有 temporal analysis。合理的 future work direction。\n\n**W11 (Code release)**: [AGREE] \"will be released upon acceptance\" 是常见做法但不如提供 anonymous link。\n\n**W14 (Abstract 70-85% rounding)**: [AGREE] 与我的 Round 1 审稿 W2 一致。实际范围 69.6-85.4%，70% 是向上取整。\n\n---\n\n### Director 提出的三个具体问题\n\n**Q1: 是否同意 W5（Table CI persistent issue）？**\n\n同意这是一个合理要求，但我认为其严重程度为 should-fix 而非 must-fix。理由：(1) Table 5 的 classifier convergence（spread ≤ 0.4pp）已间接证明稳定性；(2) cross-scale 和 seed replication 部分已有 CI 报告，说明作者有意识但选择性遗漏了主表的 CI；(3) 添加 fold std 是纯技术操作，不改变任何 claim。如果在 rebuttal 中承诺补充，应可接受。\n\n**Q2: W12（accumulation）和 W13（quality confound）是否 blocking？**\n\n两者均非 blocking for Findings track：\n- W12（accumulation/mixing）：论文是第一个 formalize depth estimation task 的工作，pure-chain benchmark 是合理的起点。Limitations 已明确承认差距。但这确实是最重要的 future work direction。\n- W13（quality confound）：论文已有三条间接证据（zero-shot ablation、cross-model chains、base vs instruction-tuned）。缺少 matched-quality control 是一个遗憾但不致命。\n\n**Q3: Director summary 与论文不一致——独立验证结论**\n\n我独立确认以下内容**不存在于论文 tex 文件中**：\n- \"92.8% retention\" — 全文搜索无匹配\n- \"14B scale\" — 论文最大模型为 8B（Llama-3.1-8B-Instruct）\n- \"prompted generation\" 实验 — 仅有 BOS-seeded，method.tex line 35 明确标注 prompted generation 为 future work\n- \"two-stage pipeline 75.2%\" — Limitations 中提到 two-stage 概念但无实验数据\n- \"RedPajama\" — 全文无出现\n- 标题 \"Ordinal Depth Estimation for Recursive Language Model Generations...\" — 实际标题为 \"How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\"\n\n结论：Director summary 描述的是计划/路线图内容，而非当前论文实际内容。审查应基于论文实际文件，不应将未实现的计划纳入评分考量。\n\n---\n\n### 总体判断\n\n与 R1 的 Overall 3.5/5 一致。修订版解决了大部分前轮问题（Related Work ✅, LoRA rank ✅, Discussion 诚实化 ✅, Abstract 精简 ✅）。核心遗留问题（BOS-only、Table CI、accumulation/mixing）属于 should-fix 或 future work，不构成 rejection basis for Findings。\n\n我与 R1 分歧最大的是 W13（quality confound）：R1 认为缺少 matched-quality control 是 moderate 问题，我认为现有间接证据（特别是 zero-shot LLM ablation 的 42pp gap）已经足够有力，quality confound 的解释力有限。",
  "reviewer_id": "2",
  "project": "recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "87f1c02a-a245-45d7-87c3-3931cbcceecc",
  "isSidechain": false,
  "requestId": "req_011Cb7rviS4tX3dCBk3wVGyQ",
  "type": "assistant",
  "uuid": "35d491a7-be16-4ca5-8645-b7581a836cab",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CNBRRY6EupmZQekwSTnffR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 157,
      "cache_read_input_tokens": 65319,
      "output_tokens": 4032,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 157,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 4032,
          "cache_read_input_tokens": 65319,
          "cache_creation_input_tokens": 157,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 157
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

_source line 202 · 2026-05-17T08:57:38.389Z_

<details><summary>↩ Tool result · `toolu_01WY2um5wgewaAcHiFD4Q2cU`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "35d491a7-be16-4ca5-8645-b7581a836cab",
  "isSidechain": false,
  "promptId": "33880829-eb2b-4abf-b83d-dafe3ac99d1c",
  "type": "user",
  "uuid": "f878effc-ac93-43ff-87a4-0bae8c9b777c",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"review_director_key\\\": \\\"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"review_director_key\": \"feishu:group:oc_db3bd143165620ee6950e6ef0826eec8:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "35d491a7-be16-4ca5-8645-b7581a836cab",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

</details>

---


### Runtime record

_source line 203 · 2026-05-17T08:57:38.394Z_

```json
{
  "parentUuid": "f878effc-ac93-43ff-87a4-0bae8c9b777c",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "7fcdb40e-9bac-4616-b636-116f0c59a06d",
  "timestamp": "2026-05-17T08:57:38.394Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/.claude/sessions/review_reviewer_2_2744903e",
  "sessionId": "02e198f0-2bdb-4a54-8265-4044096f8661",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "proud-wobbling-gizmo"
}
```

---
