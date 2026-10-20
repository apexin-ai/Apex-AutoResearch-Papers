# Research conversation: 你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义： 含义：所有核心 claim 经受住审稿，novelty 被认可为 IE-specific 贡献而非简单迁移，CF 作为诚实 limitation 被接受 核心

**OntoCoDec: Type-Constrained Information Extraction via Compiled Schema Constraints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 28
- **Recorded user turns:** 1
- **Tool calls:** 4
- **Original source:** `logs/chats/exported-trajectories/account-3/9c4a0487-ad45-4ba9-84d2-909d5f582c6c.jsonl`
- **Structured JSON:** [`ab32b03aa3d470aff4b1.json`](../../sessions/ab/ab32b03aa3d470aff4b1.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-16T17:34:20.162Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-16T17:34:20.162Z",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "content": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：\n\n含义：所有核心 claim 经受住审稿，novelty 被认可为 IE-specific 贡献而非简单迁移，CF 作为诚实 limitation 被接受\n核心假设：['至少 2/3 审稿人认可 violation landscape study 作为独立贡献', 'enabling dependency（grammar→semantic）被视为 non-trivial 架构 insight，区别于 SynCode 的单层 CFG', 'tightness × RV baseline 双因子分析被认为是 deeper insight，非 post-hoc 解释', 'CF 主动披露 + type ambiguity 根因分析 + 消融归因被接受为充分的 limitation 处理', '3 模型 × 2 数据集矩阵 + FT ablation 8/8 被视为充分的 generalization 证据', 'zero-shot 设定被理解为方法论选择而非能力不足']\n关键指标范围：{'avg_reviewer_score': [3.75, 4.25], 'novelty_score': [3.5, 4.0], 'soundness_score': [4.0, 4.5], 'accept_probability_pct': [55, 75], 'major_revisions_requested': [0, 1], 'reviewer_concern_cf_severity': ['minor', 'minor']}\n叙事方向：原始 framing 完全成立。Title \"Type-Valid IE via Compiled Ontology Constraints\" 精准定位贡献。 §3 violation landscape 被引用为 empirical contribution。Claim 3 composable framework 的 enabling dependency 被视为关键设计 insight。DR↓94% (SciERC) / ↓90.2% (Llama DocRED) at zero/positive F1 cost 是 干净的主结果。CF 在 limitations 和 analysis 双重出现被审稿人正面评价为\"refreshingly honest\"。 FT regime 下 DR 1.95%→0% + F1 neutral 补全了\"method scales to supervised setting\"的叙事。 Post-hoc baseline 的多维对比（recall preservation + information coverage + ET residual） 构成完整的 defense。Rebuttal 只需回应小的澄清问题，不需要额外实验。\n\n\n基于以上定义，对 experiment_plan 中每个 planned 实验展开详细数据。\n每条预测都必须给出 result_rationale —— 解释为什么在这个档位下会得到这样的结果。\n\n# Project context\nproject: schema_semantic_constrained_ie\nvenue: EMNLP 2026\nfocus: 最终评估：54 实验全部完成，FT ablation 8/8 互补性确认，post-hoc defense 成立，latency ≤5.4%。关注：claim 强度是否匹配证据、limitations 是否充分、novelty 定位 vs SynCode/IterGen/BoostCD 差异化是否清晰。\n\n## paper_framing.md\n\n# OntoCoDec — Paper Framing\n\n## Target Venue\nEMNLP 2026 (ARR submission May 25, 2026)\n\n## Title\nOntoCoDec: Type-Valid Information Extraction via Compiled Ontology Constraints\n(D015: \"Near-Complete\" dropped — DocRED residual DR=10.21% (Qwen) 不算 near-complete。论文贡献是方法，不是特定消除率。SciERC 0.93% 和 DocRED 2.55% (Llama) 可在正文中描述为 near-complete，但 title 不宜 overclaim。)\n\n## Core Insight\nLLM-based IE systems produce systematic ontology constraint violations concentrated in specific relation types. Prompt-level intervention (schema-informed prompting) reduces violations by ~62% but cannot eliminate them — certain relation types retain 25-30% violation rates even with explicit constraint descriptions. OntoCoDec provides **near-complete elimination (DR 15.4%→0.93%, ↓94%) at zero or positive F1 impact** through automatic ontology-to-decoder constraint compilation with two complementary layers.\n\n**Phase 2 confirmed (D012 bootstrap CI, v2 fix)**: Grammar+Semantic dual-layer constrained decoding reduces domain/range violations by 94%, eliminates entity-type and relation-vocabulary violations entirely (→0%). F1 impact is **dataset-dependent**:\n- SciERC: Rel F1 neutral (+0.13pp, p=0.58), Ent F1 neutral (-0.03pp, p=0.53)\n- DocRED: Rel F1 **significantly improved** (+0.50pp, p<0.001, 95% CI [+0.23, +0.81]); Ent F1 **significantly improved** (+1.23pp, p<0.001, 95% CI [+0.94, +1.55])\n- Mechanism: grammar 消除 OOV relation names (DocRED RV 29.66%→0.03%) + 非标 entity types (ET 2.48%→0%)。all_set F1 方法下 OOV=FP → fewer FP → higher precision/F1。SciERC baseline RV/ET 已很低，效果不显著。\n- **Grammar 层是 F1 提升的唯一来源**: grammar_only Ent F1=59.38% ≈ full_s1 59.37% (Δ+0.01pp, p=0.66)。Semantic 层对 F1 无额外贡献，专注 DR reduction。\n\n## Core Claims\n\n### Claim 1 (Empirical): Violation Landscape\nLLM-based IE systems violate ontology type constraints at non-trivial rates (15.4% per-triple on SciERC, 18.7% on DocRED). Violations are **not uniformly distributed** — they concentrate on relation types with tight domain/range constraints (Feature-of 33.5%, Compare 42.4%) while loose-constraint relations show near-zero violation (Used-for 0.8%).\n\n**Key insight**: Violation rate is driven by **constraint tightness**, not ontology size. A small ontology with tight constraints can produce more violations than a large ontology with loose constraints.\n\n**D014 修订**: DR reduction ceiling 由 **tightness × model RV baseline** 共同决定，非 tightness 单因素。Llama DocRED DR↓90.2% vs Qwen DR↓44.7%（同一 ontology τ̄=0.842）。机制：Qwen RV=29.66% >> Llama RV=16.03% → grammar 层将 OOV triples 强制匹配有效关系名 → 揭露大量 latent DR violations → 残余 DR 更高。这是比单一 tightness 更深的 insight。\n\n**Evidence**: SciERC (7 relations) 15.4%; DocRED (96 relations) 18.7% — comparable rates despite 14× ontology size difference. Schema-informed prompt on DocRED only achieves DR↓32% (vs SciERC ↓62%), confirming **prompt-level intervention scales poorly with ontology complexity**.\n\n### Claim 2 (Empirical): Prompt Insufficiency\nSchema-informed prompting (explicitly describing domain/range constraints in the prompt) reduces but does not eliminate violations:\n- Overall: 15.4% → 5.78% (-62.4%), still above 5%\n- Per-relation: Compare 42.4% → 27.6%, Evaluate-for 24.1% → 29.9% (**worse**)\n- Prompt intervention is unreliable at the per-relation level — some relations improve, one regresses\n\n**Narrative**: This is NOT about \"5.78% barely above 5%\". The story is: **prompt-level intervention is fundamentally unreliable as a guarantee mechanism**. It works statistically but cannot provide per-instance compliance. Three specific relation types retain >10% violation rates with schema-informed prompts. For safety-critical IE (biomedical, legal, regulatory), statistical reduction is insufficient — guaranteed compliance is required.\n\n### Claim 3 (Methodological): Composable Constraint Framework\nOntoCoDec automatically compiles IE ontology schemas into two composable constraint layers:\n1. **Grammar layer** (XGrammar): JSON structure + type vocabulary constraints (CFG-expressible)\n2. **Semantic layer** (TypeConstraintProcessor): Cross-field domain/range constraints via stateful entity registry + dynamic logit masking\n\nThe two layers are **complementary with enabling dependency**: grammar ensures every generated relation type is in the valid vocabulary, which enables the semantic layer to look up and enforce domain/range rules for that type. Without grammar, the semantic layer encounters unknown relation types and cannot enforce constraints (explaining why semantic_only achieves only ↓24% vs full_s1 ↓94%). This is NOT \"synergistic\" (mutual amplification) — grammar is a prerequisite for semantic, not vice versa.\n\nThe two layers compose via bitwise AND of token masks. Recommended framing: \"Grammar and semantic constraints compose via bitwise AND with an enabling dependency: grammar ensures structural validity, enabling semantic constraints to enforce domain/range rules. When constraint tightness creates empty intersection between layers, the system degrades gracefully to grammar-only constraints, maintaining structural validity as a guaranteed floor.\"\n\n**Graceful degradation + Fallback 频率量化** (D008 + Reviewer 发现):\nWhen $M_{semantic} \\cap M_{grammar} = \\emptyset$, the system falls back to grammar-only control.\n\n**关键量化数据（Reviewer 从日志挖掘）**:\n- Llama DocRED full_s1: **32,921 次 fallback / 577 docs = ~57 次/doc**\n- Llama SciERC full_s1: **5,882 次 fallback / 550 docs = ~10.7 次/doc**\n- DocRED fallback 频率是 SciERC 的 **5.3×**\n- Qwen DocRED fallback 率未知（日志当时无 fallback logging，需估算）\n\n**这直接解释了 DocRED DR 残余 10.19% vs SciERC 0.93%**: 更多 token 位置退化为 grammar-only → grammar-only 的 DR 已知为 26.17% → 高 fallback = 高残余 DR。\n\n**论文建议**: 在 §5 tightness 段报告 fallback 率，定义 \"Constraint Coverage\" 指标（semantic masking 实际生效的 token 比例）。这把 \"10.19% DR 残余\" 从弱点变成可量化分析的 finding。Frame as \"engineering robustness\" in §4; fallback 频率 + tightness 作为 §5 定量分析。\n\n**Decidability taxonomy**: Constraints classified by prefix-decidability:\n- (a) Purely local: entity type ∈ vocabulary (grammar layer)\n- (b) Prefix-decidable with state: relation argument types compatible with domain/range (semantic layer, requires entity registry)\n- (c) Truly non-local: forward coreference — out of scope for forward-only decoding\n\n### Claim 4 (Methodological): S1 vs S2 Decoding Strategies — Architectural Ablation\n- S1 (single-pass): Both layers applied throughout generation. **Recommended primary strategy** — simpler, slightly better metrics across the board.\n- S2 (two-pass): Pass 1 extracts entities (grammar-only), Pass 2 generates relations with input-dependent grammar compiled from Pass 1 entities.\n\n**S2 full results (551/551 SciERC)**: DR 0.97% (vs S1 0.93%), CF 8.03% (vs S1 9.9%), R-F1 8.03% (vs S1 8.36%). S2 does NOT solve CF — the 1.87pp reduction is not significant. S2 also slightly worse on DR and F1. **S2 is an architectural variant demonstrating framework flexibility, not a CF solution.** Position in paper as ablation (Section 5 or Appendix), not as a core contribution.\n\n⚠️ **Do NOT cite pilot50 DR=0% as S2 evidence** — small-sample artifact; full run shows DR=0.97%. Per-relation S2 DR is worse than S1 on Compare (4.6% vs 2.82%), Part-of (1.25% vs 0%), Used-for (0.12% vs 0%).\n\n## Anticipated Reviewer Concerns\n\n### C1: \"5.78% is barely above 5% — threshold is arbitrary\"\n**Response**: Don't argue about the threshold. Argue about per-relation distribution: Compare (27.6%), Evaluate-for (29.9%), Feature-of (11.3%) have double-digit violation rates with schema-informed prompt. The value proposition is per-relation guaranteed compliance, not overall statistical rate.\n\n### C2: \"Why not just post-hoc filter?\"\n**Response (D013, 实验结果已出)**:\n\nPost-hoc filtering 实验结果：post-hoc F1 > OntoCoDec F1（SciERC 8.63 vs 8.36, DocRED 9.61 vs 8.24）——因 low F1 regime 下移除 FP 大幅提升 precision。\n\n**论文 framing（不以 F1 论高低，多维对比）**:\n1. **Recall 维度（核心论点）**: OntoCoDec recall 上升 (SciERC +0.20pp, DocRED +0.56pp) = 概率质量重分配到合法 token 生效。Post-hoc recall 下降 (SciERC -0.72pp, DocRED -1.06pp) = 正确 triple 被误删。\n2. **Information coverage**: DocRED post-hoc 丢弃 **48.1%** triples（近半数信息丢失），SciERC 16.8%。OntoCoDec 保留全部 triple slots。\n3. **Operational**: OntoCoDec 产出即合规、无需后处理、支持流式。Post-hoc 需额外管线、不适用实时场景。\n4. **Precision trade-off（诚实承认）**: \"Post-hoc achieves higher precision by removing a large fraction of triples, many of which are incorrect. This trades information coverage for precision — valid when FP are costly, but inadequate when completeness matters.\"\n\n数据表：SciERC post-hoc rejection 16.8%, OntoCoDec recall 11.60 vs post-hoc 10.68; DocRED post-hoc rejection 48.1%, OntoCoDec recall 10.02 vs post-hoc 8.40。\n\n**Reviewer 补充发现（D013 后）**:\n5. **ET 残余**：post-hoc 只删 triples 不改 entity list，残余 ET=0.4% (SciERC) / 2.47% (DocRED)。OntoCoDec ET=0%。Post-hoc 无法解决 entity type 违规。\n6. **127 个被删 TP (DocRED)**：过滤前 TP=1137，过滤后 TP=1010。丢失的 127 个 TP（11.2%）是正确提取但 entity type 违规的 triple。OntoCoDec 通过生成时强制合法 type 保留这些 TP——\"prevent vs detect\" 核心论据的具体数据。\n7. **OntoCoDec+post-hoc 组合**（future work idea）：先 constrain 再 filter 残余 DR。低优先级，May 19 前不做。\n\n### C3: \"Bitwise AND of two masks is not novel\"\n**Response**: The novelty is not the AND operation — it's (a) the automatic compilation from ontology definitions (zero-code schema compliance), (b) the stateful entity registry enabling cross-field constraints during autoregressive generation, (c) the decidability taxonomy providing theoretical guidance, and (d) the systematic violation landscape measurement motivating the approach.\n\n### C4: \"Evaluate-for violation rate increases with schema-informed prompt\"\n**Response (prior-constraint conflict framework)**: Evaluate-for has 23/36 valid pairs; Method→Task is invalid for Evaluate-for but natural in the LLM's distributional prior (\"Method X evaluates for Task Y\" is semantically plausible). Schema-informed prompting creates a **prior-constraint conflict**: the model learns to avoid Method→Task for Evaluate-for (reducing count 133→87, -34.6%), but the remaining instances are harder boundary cases where the model's type assignment strategy becomes less stable. This is not just \"harder instances\" — it's an active interference between prompt-level constraint signals and the model's learned type associations.\n\n**This strengthens the paper's claim**: prompt-level intervention is not merely insufficient but potentially **counterproductive** for specific constraint configurations. Decoding-time enforcement avoids this issue entirely — it operates on logits, not on the model's reasoning process, so there is no prior-constraint conflict.\n\n### C5: \"Only tested on one model (Qwen3-8B)\"\n**Response**: Cross-model validation DONE (D016 bootstrap verified). Llama-3.1-8B 零代码修改：\n- SciERC: DR 13.34%→0.08% (↓99.4%), R-F1 -0.14pp (p=0.011, negligible), E-F1 NS\n- DocRED: DR 26.07%→2.55% (↓90.2%), R-F1 +0.29pp (p=0.013, significant), E-F1 -0.64pp (p=0.022, modest decline)\n- Parse failures: unconstrained 68 vs full_s1 91 (6.8% vs 9.1%)\n\n**Cross-model claim 指导（Reviewer 专项评估）**:\n- ✅ 可声明：\"OntoCoDec generalizes across model families without code modification\"（程序性事实，铁证）\n- ❌ 不可声明：\"consistently achieves the same reduction rate\"（仅 2 模型，不足以量化声明）\n- **RV↓DR↑ 正交性 finding**: Llama RV baseline 低(16%) 但 DR baseline 高(26%)，反向于 Qwen。证明两层约束解决正交 failure modes——vocabulary compliance ≠ semantic compliance。应作为 §5 cross-model 独立 finding 展开。\n- **Parse failure 偏差**: checker skip parse failures (不计入 F1)，Llama 68/998=6.8% vs Qwen 12/998=1.2%。偏差方向保守（不利于 constrained），不威胁 claim。但需 footnote 披露 + cross-model 表增加 parse failure rate 行。\n- **Llama SciERC CF=6.56%**: 比 Qwen 同量级更高，non-local constraint 问题在 Llama 上更突出，limitations 提及。\n- 等 llama_docred_full_s1 出来后定最终 claim 措辞。\n\n### C6: \"Constrained decoding degrades generation quality (CRANE, Structure Snowballing)\"\n**Response**: OntoCoDec's semantic constraints are narrower than full grammar constraints — only type tokens are masked, free text is unconstrained. **Bootstrap CI (10000×, D012 Qwen + D016 Llama, all registry-aligned)**:\n\n**Qwen3-8B**: SciERC R-F1 +0.13pp (p=0.58, NS), E-F1 -0.03pp (NS). DocRED R-F1 +0.50pp (p<0.001), E-F1 +1.23pp (p<0.001).\n**Llama-3.1-8B**: SciERC R-F1 -0.14pp (p=0.011, negligible), E-F1 NS. DocRED R-F1 +0.29pp (p=0.013), E-F1 -0.64pp (p=0.022).\n\n**Cross-model pattern**: DocRED R-F1 显著提升（两个模型）。E-F1 model-dependent（Qwen +1.23pp, Llama -0.64pp）。\n- 机制：grammar 消除 OOV relation names + 非标 entity types → all_set 方法下减少 FP → precision 提升。Grammar 是 F1 提升的唯一来源（grammar_only Ent F1=59.38% ≈ full_s1 59.37%, Δ=0.01pp, p=0.66）。Semantic 层对 F1 无额外贡献。\n- Frame as: \"On DocRED, R-F1 gains are significant for both models. Entity F1 impact is model-dependent.\"\n- 不升级为 core claim，但如实报告。\n\n### C7: \"Your method trades DR violations for CF violations (cross-field consistency)\"\n**Response**: Both S1 and S2 show elevated CF (per-triple rate ~8-10%). This is an inherent limitation of per-relation independent type enforcement. Must be proactively reported as a limitation. Defense:\n\n**CF 子类型分析（根因已确认）**：\n- **EVR（entity-vs-relation type drift）**: 占 CF 的 >90%。同一 entity 在 entity list 和 relation triple 中被赋予不同 type。S1: 245 entities (7.34%), S2: 178 entities (5.54%, -27%)\n- **Within-rel（同 entity 跨 relation type 不一致）**: S1: 10 (0.36%), S2: 18 (0.72%)\n- S2 减少 EVR 但增加 within-rel——trade-off 更复杂，不是单纯好/差\n\n**Top 冲突模式**: Generic↔OtherScientificTerm (60次), Material↔OtherScientificTerm (28次), Material↔Method (20次)。**这些是 SciERC type system 固有的语义边界模糊区**——同一术语在不同学术语境下确实可以被合理归类为不同 type。CF 在相当程度上是 type system 模糊性的体现，非纯粹的方法缺陷。\n\n**论证层次**：\n1. DR violations = structurally invalid triples（下游系统不可用）→ hard constraint\n2. CF violations = same entity gets different types across relations → individual triples remain type-valid, only cross-triple consistency broken → soft preference\n3. CF 的根因是 type system 语义边界模糊 + per-relation 独立 enforcement，非 bug\n4. Future work: cross-relation global consistency pass (entity-level type consensus before relation-specific enforcement)\n\n**机制归因（口径对账确认）**：grammar_only CF=0.08%（与 unconstrained 持平），full_s1 CF=9.90%，full_s2 CF=8.03%。**CF 100% 由 semantic 层引入，grammar 层无贡献。** 这为 \"CF 是 semantic type enforcement 的系统性副作用\" 提供干净的消融证据。\n\n**论文数字口径**：CF rate 用 violation_checker 口径（denominator=total_entities，与 DR/RV/ET 一致）。分析段落额外给 entity-level EVR 率 + 受影响样本比例。注意：analyze_cf 脚本的 EVR/WR 两维度不是独立的（WR⊂EVR），论文中不要作为两个独立维度报告。\n\n**Do NOT hide this data.** Proactive disclosure + severity distinction + root cause analysis + type ambiguity evidence + 消融归因 = 最强防御策略。\n\n### C8: \"Absolute F1 is too low (~8%) — results are not meaningful\"\n**Response**: This is a zero-shot extraction setting (no training data, no fine-tuning). Low F1 is expected — supervised SOTA on SciERC relation F1 is ~40-50%. Our contribution is the constraint enforcement method, not extraction quality. F1 is a control variable verifying constraints don't degrade quality, not an optimization target. Recommended framing: \"We evaluate in a zero-shot setting to demonstrate that our constraint enforcement method works without task-specific training. F1 is reported to verify that constraint enforcement does not degrade extraction quality, not as a claim of state-of-the-art performance.\"\n\n## Paper Structure (Draft)\n1. Introduction: Violation landscape motivation + composable constraint framework overview\n2. Background: Grammar-constrained decoding (XGrammar) + IE ontology structure\n3. Violation Landscape Study (Phase 0 empirics — independent contribution)\n4. OntoCoDec Framework: Compiler + TypeConstraintProcessor + S1/S2 strategies\n5. Experiments: Constrained vs unconstrained vs post-hoc vs prompt-based\n6. Related Work: 5 constraint paradigms (grammar, vocabulary, structural, type-checking, ontology)\n7. Conclusion\n\n## Claim Calibration (per Reviewer assessment)\n\n**Safe to claim (sufficient evidence from Phase 2)**:\n- \"First systematic study of ontology constraint violations in LLM-based IE\"\n- \"Violation rate correlates with constraint tightness, not ontology size\" (D014: DR reduction ceiling 由 tightness × model RV baseline 共同决定)\n- \"Grammar+semantic constrained decoding eliminates 94% of DR violations at zero F1 cost\" ✅ Phase 2 confirmed\n- \"Two-layer architecture provides complementary coverage — grammar enables semantic\" ✅ Ablation confirmed\n- \"Prompt-level intervention scales poorly with ontology complexity\" ✅ SciERC ↓62% vs DocRED ↓32%\n\n**Claim with caution**:\n- \"Near-complete type-valid IE\" — S1 0.93%, S2 0.97% residual, not truly 0%. Title updated to \"Near-Complete\"\n- \"Principled framework applicable to arbitrary IE ontologies\" — validated on 2 datasets + 1 model only\n- \"F1 improvement\" — SciERC: not significant (p=0.58), frame as F1-neutral; DocRED: significant (+0.50pp, p<0.001), 可报告但不升级为 core claim，归因于 OOV elimination 而非约束解码本身的提升\n- \"CF reveals type system ambiguity\" — 可在 §5.3 作为 analysis finding 展开（Generic↔OtherScientificTerm 等模式有独立 insight 价值），但 §7 必须同时保留 CF 作为 limitation + future work。**两处都要有，缺一不可。** 不能暗示\"因为是 type ambiguity 所以 CF 可接受\"\n\n**Do NOT claim**:\n- \"General infrastructure for IE\" — only zero-shot extraction validated\n- \"State-of-the-art\" — F1 is control variable, not optimization target (see C8)\n- \"Synergistic effect\" — mechanism is enabling dependency, not mutual amplification (see Claim 3)\n- \"S2 solves CF\" or \"S2 mitigates Structure Snowballing\" — data shows S2 ≈ S1 on all metrics; position as architectural variant only\n- \"Pilot50 DR=0%\" — small-sample artifact, full S2 has DR=0.97%\n- \"Grammar-first invariant\" 作为独立 claim — 证据不足（仅 1 次崩溃触发，实现是 fallback 非形式化保证）。写入 §4 方法论设计原则（1-2 句），不升级为 claim\n- \"Robust dual-layer composition across schema complexities\" — 等 DocRED 完成。最终如 fallback ≤5/998，可写经验性陈述，不做泛化 claim\n\n## Risk Ranking (ordered by reject probability)\n\n1. **CF violation trade-off under-addressed** (MEDIUM-HIGH): S1 9.9%, S2 8.03% — both elevated. **S2 confirmed: does NOT solve CF.** This is the #1 attack surface. Mitigated by proactive disclosure + severity distinction + root cause analysis (C7). Must be reported as explicit limitation with future work direction (global entity-type consensus).\n2. ~~**Single model limitation**~~ (RESOLVED): Llama-3.1-8B SciERC ✅ (DR↓99.4%) + DocRED ✅ (DR↓90.2%). 2 模型 × 2 数据集全矩阵完成。\n3. **Novelty perception** (MEDIUM): \"PLDI'25 for code → OntoCoDec for IE\" attack line. Must argue IE constraint structure differs fundamentally.\n4. ~~**DocRED Phase 2 weak**~~ (RESOLVED → reframed as D014): Qwen DR↓44.7%, Llama DR↓90.2% — both substantial. Weaker Qwen reduction explained by RV baseline interaction (D014), not method failure.\n5. ~~**Phase 2 F1 drop**~~ (RESOLVED): F1 confirmed neutral (SciERC) or positive (DocRED, p<0.001). Bootstrap CI D012 confirms. No longer a risk.\n\n## Critical Path to EMNLP Submission (May 25)\n\n- **May 13-14**: Phase 0 + Phase 1 + Phase 2 SciERC ✅\n- **May 14**: Phase 2 DocRED 4-way ablation ✅ + Llama SciERC cross-model ✅ + Dream 完成 (3/6)\n- **May 14-15**: Llama DocRED 2 组实验 ✅ + Checker 修正 ✅ + post-hoc baseline ✅ + bootstrap CI ✅ + related work ✅\n- **May 14-15**: D014 tightness claim 修订 + §5 cross-model subsection + abstract/conclusion 修正 (Agent 执行中)\n- **May 15-17**: 全文校对 + Discussion 整合 + 最终数字确认\n- **May 19**: 内部稿 → submit_paper_to_review\n- **May 19-24**: Review 修改 + 最终提交\n\n**当前瓶颈**: 无技术 blocker。等 Reviewer 跨文件一致性审查 + 编译验证后即可 submit_paper_to_review。\n\n## Status\n- Phase 0 SciERC: ✅ Complete (minimal + schema-informed)\n- Phase 0 DocRED: ✅ Complete (minimal 18.7% DR + schema-informed 12.8% DR)\n- Phase 1 Compiler: ✅ Complete (grammar + semantic layers integrated)\n- Phase 2 SciERC (5 configs): ✅ Complete (S1 DR↓94% F1-neutral, S2 降级为 ablation)\n- Phase 2 DocRED (4 configs): ✅ Complete (full_s1 DR↓45%, grammar ET/RV→0%)\n- Llama SciERC cross-model: ✅ Complete (DR↓99.4%, F1-neutral, 零代码修改)\n- Llama DocRED cross-model: ✅ Complete (full_s1 DR↓90.2%, unconstrained DR=26.07%)\n- Checker v2 (D011): ✅ Fixed (ET triple-counting → unique entity dedup)\n- Bootstrap CI (D012): ✅ Fixed + confirmed (entity filter bug resolved)\n- Post-hoc baseline (D013): ✅ Complete (multi-dimensional framing)\n- Related work: ✅ 42 bib entries, 4 additions merged\n- Dream 6/6 actions: ✅ All complete\n- CF violation analysis: ✅ Confirmed inherent limitation (S1 9.9% SciERC / 2.57% DocRED / 12.02% Llama DocRED)\n- D014 tightness revision: ✅ Complete (tightness × RV baseline dual-factor)\n- Llama bootstrap CI (D016): ✅ Fixed + verified (registry-aligned ≤0.05pp, all p-values in paper)\n- Paper compilation: ✅ 8 pages正文 + appendix\n\n\n## registry (completed experiments)\n\n- exp_id: mvp_phase0_violation_rate\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_triples: 1724\n    total_entities: 2474\n    json_parse_rate: 1\n    entity_type_violation_rate: 0.004\n    relation_vocabulary_violation_rate: 0.0139\n    domain_range_violation_rate: 0.1537\n    cross_field_consistency_violation_rate: 0.0008\n    go_nogo_metric: 0.1537\n    entity_f1: 0.3101\n    relation_f1: 0.0823\n    per_relation:\n      Used-for:\n        total: 787\n        dr_violations: 6\n        rate: 0.0076\n      Conjunction:\n        total: 32\n        dr_violations: 0\n        rate: 0\n      Hyponym-of:\n        total: 124\n        dr_violations: 18\n        rate: 0.1452\n      Evaluate-for:\n        total: 133\n        dr_violations: 32\n        rate: 0.2406\n      Part-of:\n        total: 72\n        dr_violations: 18\n        rate: 0.25\n      Feature-of:\n        total: 486\n        dr_violations: 163\n        rate: 0.3354\n      Compare:\n        total: 66\n        dr_violations: 28\n        rate: 0.4242\n- exp_id: mvp_phase0_violation_rate_docred\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_docs: 998\n    parsed_docs: 962\n    json_parse_rate: 0.964\n    total_entities: 19099\n    total_triples: 16540\n    entity_type_violation_rate: 0.075\n    relation_vocabulary_violation_rate: 0.289\n    domain_range_violation_rate: 0.187\n    cross_field_consistency_violation_rate: 0.0008\n    go_nogo_metric: 0.187\n    fuzzy_matches: 126\n    top_dr_violations_by_rate:\n      P35_head_of_state: 1\n      P710_participant: 0.919\n      P172_ethnic_group: 0.875\n    top_dr_violations_by_count:\n      P31_instance_of:\n        violations: 322\n        total: 533\n        rate: 0.604\n      P1001_applies_to_jurisdiction:\n        violations: 264\n        total: 594\n        rate: 0.444\n      P1344_participant_in:\n        violations: 194\n        total: 312\n        rate: 0.622\n- exp_id: mvp_phase0_scierc_schema\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    domain_range_violation_rate: 0.0578\n    relation_vocabulary_violation_rate: 0.003\n    entity_type_violation_rate: 0\n    total_violation_rate: 0.0253\n    go_nogo_metric: 0.0578\n    total_triples: 1661\n    vs_minimal_dr_reduction: -0.624\n    per_relation:\n      Used-for:\n        rate: TBD\n      Feature-of:\n        delta_pp: -22.3\n      Part-of:\n        delta_pp: -22.5\n      Compare:\n        delta_pp: -14.8\n      Evaluate-for:\n        delta_pp: 5.8\n    mcnemar_all_significant: true\n- exp_id: mvp_phase0_docred_schema\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_documents: 998\n    documents_checked: 943\n    parse_failures: 55\n    json_parse_rate: 0.9449\n    total_entities: 19524\n    total_triples: 16782\n    entity_type_violations: 119\n    entity_type_violation_rate: 0.0061\n    relation_vocabulary_violations: 3090\n    relation_vocabulary_violation_rate: 0.1841\n    relation_fuzzy_matches: 85\n    domain_range_violations: 2154\n    domain_range_violation_rate: 0.1284\n    cross_field_consistency_violations: 29\n    cross_field_consistency_violation_rate: 0.0015\n    total_violations_any: 5392\n    total_violation_rate: 0.1485\n    go_nogo_metric_dr: 0.1284\n- exp_id: phase2_scierc_grammar_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_samples: 551\n    total_triples: 1725\n    total_entities: 2474\n    json_parse_rate: 1\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0\n    domain_range_violation_rate: 0.1484\n    cross_field_consistency_violation_rate: 0.0008\n    entity_f1: 0.3098\n    entity_precision: 0.2598\n    entity_recall: 0.3837\n    relation_f1: 0.0823\n    relation_precision: 0.0643\n    relation_recall: 0.114\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: phase2_scierc_semantic_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_samples: 551\n    total_triples: 1726\n    total_entities: 2474\n    json_parse_rate: 1\n    entity_type_violation_rate: 0.004\n    relation_vocabulary_violation_rate: 0.0151\n    domain_range_violation_rate: 0.1165\n    cross_field_consistency_violation_rate: 0.0271\n    entity_f1: 0.3101\n    entity_precision: 0.2605\n    entity_recall: 0.3831\n    relation_f1: 0.0815\n    relation_precision: 0.0637\n    relation_recall: 0.1129\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: phase2_scierc_full_s1\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_samples: 551\n    total_triples: 1729\n    total_entities: 2474\n    json_parse_rate: 1\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0\n    domain_range_violation_rate: 0.0093\n    cross_field_consistency_violation_rate: 0.099\n    entity_f1: 0.3098\n    entity_precision: 0.2598\n    entity_recall: 0.3837\n    relation_f1: 0.0836\n    relation_precision: 0.0654\n    relation_recall: 0.116\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: phase2_scierc_unconstrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    json_parse_rate: 1\n    entity_f1: 0.3101\n    entity_precision: 0.2605\n    entity_recall: 0.3831\n    relation_f1: 0.0823\n    relation_precision: 0.0644\n    relation_recall: 0.114\n    entity_type_violation_rate: 0.004\n    relation_vocabulary_violation_rate: 0.0139\n    domain_range_violation_rate: 0.1537\n    cross_field_consistency_violation_rate: 0.0008\n    total_triples: 1724\n    total_entities: 2474\n    total_samples: 551\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: phase2_s2_pilot50\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    domain_range_violation_rate: 0.0205\n    relation_vocabulary_violation_rate: 0\n    relation_f1: 0.1008\n    samples: 50\n    predicted_relations: 146\n    true_positives: 13\n    gold_relations: 112\n    entity_f1_approx: 0.29\n    note: 'DR 修正: 原值 0 来自 dryrun (n=25 triples)。实际 pilot50 DR=3/146=2.05% (来自 violation_report_s2_pilot50.json)。'\n- exp_id: mvp_phase0_docred_schema_r2\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: phase2_scierc_full_s2\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_samples: 551\n    total_triples: 1644\n    total_entities: 2228\n    json_parse_rate: 1\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0\n    domain_range_violation_rate: 0.0097\n    cross_field_consistency_violation_rate: 0.0803\n    entity_precision: 0.2797\n    entity_recall: 0.3712\n    entity_f1: 0.319\n    relation_precision: 0.064\n    relation_recall: 0.1078\n    relation_f1: 0.0803\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: phase2_docred_grammar_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    documents_checked: 985\n    parse_failures: 13\n    total_entities: 20150\n    total_triples: 17341\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0.0003\n    domain_range_violation_rate: 0.2617\n    cross_field_consistency_violation_rate: 0.0007\n    relation_f1: 8.31\n    relation_precision: 7.06\n    relation_recall: 10.12\n    entity_f1: 59.38\n    entity_precision: 58.47\n    entity_recall: 60.32\n    unrecognized_relations: 5\n    f1_method: all_set\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: phase2_docred_full_s1\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    documents_checked: 987\n    parse_failures: 11\n    total_entities: 20187\n    total_triples: 17341\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0.0003\n    domain_range_violation_rate: 0.1021\n    cross_field_consistency_violation_rate: 0.0257\n    entity_f1: 59.37\n    entity_precision: 58.45\n    entity_recall: 59.63\n    relation_f1: 8.23\n    relation_precision: 6.99\n    relation_recall: 10.01\n    unrecognized_relations: 5\n    f1_method: all_set\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: phase2_docred_unconstrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    documents_checked: 986\n    parse_failures: 12\n    total_entities: 20171\n    total_triples: 17497\n    entity_type_violation_rate: 0.0248\n    relation_vocabulary_violation_rate: 0.2966\n    domain_range_violation_rate: 0.1846\n    cross_field_consistency_violation_rate: 0.001\n    entity_f1: 58.15\n    entity_precision: 57.26\n    entity_recall: 58.32\n    relation_f1: 7.74\n    relation_precision: 6.55\n    relation_recall: 9.46\n    unrecognized_relations: 5189\n    f1_method: all_set (includes OOV predictions in denominator)\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n    et_v1: 0.0818\n    et_fix_note: v1 triple-counted ET across entity_list + relation head/tail; v2\n      deduplicates by (text, normalized_type)\n- exp_id: phase2_docred_semantic_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    documents_checked: 987\n    parse_failures: 11\n    total_entities: 20185\n    total_triples: 17571\n    entity_type_violation_rate: 0.0422\n    relation_vocabulary_violation_rate: 0.2987\n    domain_range_violation_rate: 0.1384\n    cross_field_consistency_violation_rate: 0.0105\n    entity_f1: 57.81\n    entity_precision: 57.27\n    entity_recall: 58.37\n    relation_f1: 7.7\n    relation_precision: 6.54\n    relation_recall: 9.37\n    f1_method: all_set\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n    et_v1: 0.1044\n    et_fix_note: v1 triple-counted ET across entity_list + relation head/tail; v2\n      deduplicates by (text, normalized_type)\n- exp_id: llama_scierc_unconstrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    entity_type_violation_rate: 0\n    relation_vocab_violation_rate: 0.0055\n    domain_range_violation_rate: 0.1334\n    cross_field_consistency_violations: 6\n    entity_f1: 0.2356\n    entity_precision: 0.1983\n    entity_recall: 0.2902\n    relation_f1: 0.0268\n    relation_precision: 0.0236\n    relation_recall: 0.031\n    total_entities: 2451\n    total_relations: 1274\n    json_parse_failures: 1\n    samples: 551\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: llama_scierc_full_s1\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    samples: 550\n    entities_extracted: 2469\n    relations_extracted: 1315\n    domain_range_violation_rate: 0.0008\n    relation_vocab_violation_rate: 0\n    entity_type_violation_rate: 0\n    cross_field_consistency_violation_rate: 0.0656\n    total_violation_rate: 0.0431\n    entity_f1: 0.2349\n    entity_precision: 0.1972\n    entity_recall: 0.2902\n    relation_f1: 0.0254\n    relation_precision: 0.0221\n    relation_recall: 0.0298\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n- exp_id: llama_docred_unconstrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    checker_version: fixed_20260514_v2\n    f1_method: all_set\n    documents: 998\n    documents_checked: 930\n    parse_failures: 68\n    unique_entities: 11525\n    total_triples: 16437\n    dr_eligible_triples: 13789\n    ET_rate_pct: 0.13\n    RV_rate_pct: 16.03\n    DR_rate_pct: 26.07\n    CF_rate_pct: 0.17\n    entity_precision: 61.22\n    entity_recall: 51.02\n    entity_f1: 55.65\n    relation_precision: 5.22\n    relation_recall: 7\n    relation_f1: 5.98\n    fuzzy_relation_matches: 121\n- exp_id: llama_docred_full_s1\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    checker_version: fixed_20260514_v2 (strip + alias + unique_et)\n    f1_method: all_set\n    violations:\n      ET: 0\n      RV: 0\n      DR: 2.55\n      CF: 12.02\n    f1:\n      entity_f1: 55.01\n      entity_precision: 61.41\n      entity_recall: 49.82\n      relation_f1: 6.27\n      relation_precision: 5.49\n      relation_recall: 7.32\n    counts:\n      documents: 998\n      documents_checked: 907\n      parse_failures: 91\n      unique_entities: 11296\n      triples: 16368\n- exp_id: posthoc_filtering_baseline\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    docred_f1_before: 7.74\n    docred_f1_after: 9.61\n    docred_precision_before: 6.55\n    docred_precision_after: 11.22\n    docred_recall_before: 9.46\n    docred_recall_after: 8.4\n    docred_rejection_rate: 0.481\n    docred_tp_before: 1137\n    docred_tp_after: 1010\n    docred_tp_lost: 127\n    docred_et_residual: 0.0247\n    scierc_f1_before: 8.23\n    scierc_f1_after: 8.63\n    scierc_rejection_rate: 0.168\n    scierc_recall_before: 11.4\n    scierc_recall_after: 10.68\n    scierc_tp_before: 111\n    scierc_tp_after: 104\n- exp_id: llama_docred_unconstrained_mt6144\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_rate: 0.13\n    RV_rate: 15.89\n    DR_rate: 26.18\n    DR_rate_eligible: 31.15\n    CF_rate: 0.17\n    entity_precision: 61.19\n    entity_recall: 51.06\n    entity_f1: 55.67\n    relation_precision: 5.18\n    relation_recall: 7\n    relation_f1: 5.95\n    parse_failures: 67\n    documents_checked: 931\n    total_documents: 998\n    unique_entities: 11534\n    total_triples: 16584\n    dr_eligible_triples: 13936\n    fuzzy_relation_matches: 121\n- exp_id: llama_docred_full_s1_mt6144\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    DR_rate_pct: 2.57\n    RV_rate_pct: 0\n    ET_rate_pct: 0\n    CF_rate_pct: 12.13\n    R_F1: 6.25\n    R_precision: 5.45\n    R_recall: 7.32\n    E_F1: 55.04\n    E_precision: 61.41\n    E_recall: 49.87\n    documents_total: 998\n    documents_checked: 908\n    parse_failures: 90\n    triples: 16471\n    unique_entities: 11307\n    fallback_events: 67911\n    wall_clock_seconds: 23926\n    vs_unconstrained_mt6144:\n      DR_delta_pp: -23.61\n      DR_reduction_pct: -90.2\n      R_F1_delta_pp: 0.3\n      E_F1_delta_pp: -0.63\n    vs_full_s1_mt4096:\n      DR_delta_pp: 0.02\n      R_F1_delta_pp: -0.02\n      E_F1_delta_pp: 0.03\n      CF_delta_pp: 0.11\n      parse_fail_delta: -1\n- exp_id: w1_cf_fallback_scierc_pilot\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    ET: 0\n    RV: 0\n    DR: 0.1478\n    CF: 0.0004\n    R_F1: 0.0823\n    R_P: 0.0643\n    R_R: 0.114\n    E_F1: 0.3098\n    E_P: 0.2598\n    E_R: 0.3837\n    entities: 2474\n    relations: 1725\n    samples: 551\n    grammar_first_fallback_rate: 0.3664\n    cf_registry_fallback_rate: 0.0448\n    total_mask_calls: 17024\n    violation_budget_DR_CF: 0.1482\n- exp_id: w1_cf_fallback_docred\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: w1_cf_fallback_llama_scierc\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: w1_cf_fallback_llama_docred\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: w5_lora_scierc_training\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    train_loss: 0.0634\n    eval_loss: 0.0586\n    eval_token_accuracy: 0.9816\n    eval_entropy: 0.9635\n    train_runtime_sec: 688.4\n    epochs: 3\n    checkpoint_path: /root/schema_semantic_constrained_ie/checkpoints/qwen3_8b_lora_scierc\n    merged_model_path: /root/schema_semantic_constrained_ie/checkpoints/qwen3_8b_lora_scierc_merged\n- exp_id: w5_lora_scierc_unconstrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    json_parse_rate: 1\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0\n    domain_range_violation_rate: 0.0195\n    cross_field_consistency_violation_rate: 0\n    entity_f1: 0.6705\n    entity_precision: 0.6523\n    entity_recall: 0.6898\n    relation_f1: 0.4386\n    relation_precision: 0.4087\n    relation_recall: 0.4733\n    total_entities: 1784\n    total_relations: 1128\n    domain_range_violations: 22\n    go_nogo_metric: 0.0195\n    dr_gate: FAILED\n- exp_id: w5_lora_scierc_constrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    json_parse_rate: 1\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0\n    domain_range_violation_rate: 0\n    cross_field_consistency_violation_rate: 0.0118\n    entity_f1: 0.6705\n    entity_precision: 0.6523\n    entity_recall: 0.6898\n    relation_f1: 0.4377\n    relation_precision: 0.4078\n    relation_recall: 0.4723\n    total_entities: 1784\n    total_relations: 1128\n    total_samples: 551\n    cross_field_consistency_violations: 21\n- exp_id: w5_llama_lora_scierc_training\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    eval_loss: 0.0595\n    eval_mean_token_accuracy: 0.9817\n    eval_entropy: 1.0565\n    train_loss: 0.0501\n    train_runtime_sec: 654.23\n    epochs: 3\n    train_samples_per_second: 8.08\n- exp_id: w5_llama_lora_scierc_unconstrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_samples: 551\n    total_entities: 1757\n    total_relations: 1082\n    json_parse_rate: 1\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0\n    domain_range_violation_rate: 0.0111\n    cross_field_consistency_violation_rate: 0\n    total_violation_rate: 0.0042\n    entity_precision: 0.6647\n    entity_recall: 0.691\n    entity_f1: 0.6776\n    relation_precision: 0.432\n    relation_recall: 0.4795\n    relation_f1: 0.4545\n- exp_id: w5_llama_lora_scierc_constrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    domain_range_violation_rate: 0.0009\n    relation_vocabulary_violation_rate: 0\n    entity_type_violation_rate: 0\n    cross_field_consistency_violation_rate: 0.0046\n    relation_f1: 0.4547\n    relation_precision: 0.432\n    relation_recall: 0.4795\n    entity_f1: 0.6776\n    entity_precision: 0.6647\n    entity_recall: 0.691\n    total_relations: 1081\n    total_entities: 1757\n    total_samples: 551\n    parse_failures: 0\n- exp_id: w5_qwen_docred_lora_training\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    eval_loss: 0.0614\n    eval_mean_token_accuracy: 0.9804\n    eval_entropy: 0.715\n    train_loss: 0.0682\n    train_runtime_s: 5825.6\n    epochs: 3\n    adapter_path: /root/schema_semantic_constrained_ie/checkpoints/qwen_lora_docred\n    merged_path: /root/autodl-tmp/checkpoints/qwen_lora_docred_merged\n- exp_id: w5_docred_sft_data_gen\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    train_samples: 3053\n    dev_samples: 998\n    train_entities: 59493\n    train_relations: 38180\n    dev_entities: 19528\n    dev_relations: 12275\n- exp_id: w5_llama_docred_sft_data_gen\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    train_samples: 3053\n    dev_samples: 998\n    train_size_mb: 19\n    dev_size_mb: 6.1\n- exp_id: w5_llama_docred_lora_training\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    train_loss: 0.0572\n    eval_loss: 0.0624\n    token_acc: 98.06\n- exp_id: w5_llama_docred_lora_unconstrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_pct: 0\n    RV_pct: 0.15\n    DR_pct: 0.49\n    E_F1: 83.93\n    E_P: 84.93\n    E_R: 82.96\n    R_F1: 43.72\n    R_P: 38.59\n    R_R: 50.41\n    parse_fail_rate: 2.3\n    total_samples: 998\n    total_entities_pred: 19106\n    total_relations_pred: 16171\n- exp_id: w5_llama_docred_lora_constrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total: 998\n    parse_failures: 25\n    parse_fail_rate: 2.51\n    entities: 19077\n    relations: 16074\n    entity_f1: 85.23\n    entity_precision: 85.04\n    entity_recall: 85.41\n    relation_f1_all_set: 44.23\n    relation_precision_all_set: 38.82\n    relation_recall_all_set: 51.4\n    et_violations: 0\n    et_violation_rate: 0\n    rv_violations: 0\n    rv_violation_rate: 0\n    dr_violations: 33\n    dr_violation_rate: 0.2\n    cross_field_consistency_violations: 41\n    delta_vs_unconstrained:\n      delta_e_f1: 1.3\n      delta_r_f1: 0.51\n      delta_dr: -0.29\n      delta_rv: -0.15\n      note: Computed as constrained - unconstrained on full-set metrics (not intersection\n        subset). Corrected 2026-05-16 per Reviewer audit.\n- exp_id: w5_qwen_docred_lora_unconstrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_pct: 0\n    RV_pct: 0.27\n    DR_pct: 0.76\n    CF_pct: 0.12\n    E_F1: 82.15\n    E_P: 85.44\n    E_R: 79.11\n    R_F1: 40.86\n    R_P: 36.41\n    R_R: 46.56\n    parse_fail_rate: 7.11\n    total_samples: 998\n    success_samples: 927\n    fail_samples: 71\n    total_entities_pred: 18091\n    total_relations_pred: 15870\n    ET_pct_excl_fail: 0\n    RV_pct_excl_fail: 0.27\n    DR_pct_excl_fail: 0.76\n    CF_pct_excl_fail: 0.12\n    E_F1_excl_fail: 85.72\n    E_P_excl_fail: 85.44\n    E_R_excl_fail: 86\n    R_F1_excl_fail: 42.2\n    R_P_excl_fail: 36.41\n    R_R_excl_fail: 50.17\n- exp_id: w5_qwen_docred_lora_constrained_eval\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 0.01\n    CF_pct: 0.41\n    E_F1: 81.43\n    E_P: 85.41\n    E_R: 77.81\n    R_F1: 40.56\n    R_P: 36.35\n    R_R: 45.86\n    parse_fail_rate: 8.52\n    total_samples: 998\n    success_samples: 913\n    fail_samples: 85\n    total_entities_pred: 17799\n    total_relations_pred: 15563\n    E_F1_excl_fail: 85.69\n    R_F1_excl_fail: 42.23\n    delta_vs_unconstrained:\n      delta_DR: -0.75\n      delta_RV: -0.27\n      delta_R_F1: -0.3\n      delta_R_F1_excl_fail: 0.03\n      DR_reduction_pct: 98.7\n      note: 'Constrained - unconstrained. Unconstrained: DR=0.76%, R_F1=40.86, R_F1_excl_fail=42.20'\n- exp_id: w6_mistral_scierc_unconstrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    E_P: 0.2402\n    E_R: 0.3156\n    E_F1: 0.2728\n    R_P: 0.0295\n    R_R: 0.0483\n    R_F1: 0.0366\n    ET_pct: 1.5\n    RV_pct: 0\n    DR_pct: 56.94\n    CF_pct: 56.87\n    parse_fail_rate: 0\n    total_samples: 551\n    total_pred_entities: 2202\n    total_pred_relations: 1593\n- exp_id: w6_mistral_scierc_constrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    E_P: 0.2437\n    E_R: 0.3144\n    E_F1: 0.2746\n    R_P: 0.0292\n    R_R: 0.0493\n    R_F1: 0.0367\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 13.4\n    CF_pct: 1.27\n    CF_count: 21\n    parse_fail_rate: 0\n    total_samples: 551\n    total_pred_entities: 2162\n    total_pred_relations: 1647\n    delta_vs_unconstrained:\n      delta_E_F1: 0.0018\n      delta_R_F1: 0.0001\n      delta_ET: -1.5\n      delta_RV: 0\n      delta_DR: -43.54\n      note: 'Constrained - unconstrained. Baseline: E_F1=0.2728, R_F1=0.0366, DR=56.94%,\n        ET=1.5%, RV=0%'\n- exp_id: w6_mistral_docred_unconstrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_samples: 998\n    parse_failures: 7\n    parse_fail_rate: 0.7\n    total_pred_entities: 12580\n    total_pred_relations: 11879\n    ET_pct: 7.58\n    RV_pct: 42.35\n    DR_pct: 57.42\n    CF_pct: 24.78\n    E_P: 0.6221\n    E_R: 0.3975\n    E_F1: 0.4851\n    R_P: 0.0447\n    R_R: 0.0432\n    R_F1: 0.0434\n    f1_method: fuzzy_normalized\n    f1_note: Relation matching uses case-insensitive normalization with token-overlap\n      >80% and edit-distance ≤2 fallback. Strict R_F1=3.50% (delta +0.84pp from 98\n      additional TPs via fuzzy matching of Mistral underscore/abbreviation variants).\n- exp_id: w6_mistral_docred_constrained\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 33.2\n    CF_pct: 0.19\n    E_P: 65.02\n    E_R: 41.4\n    E_F1: 50.59\n    R_P: 5.67\n    R_R: 5.37\n    R_F1: 5.52\n    parse_fail_rate: 0.8\n    total_samples: 998\n    total_pred_entities: 12535\n    total_pred_relations: 11554\n    delta_vs_unconstrained:\n      ET_pct: -7.58\n      RV_pct: -42.35\n      DR_pct: -24.22\n      CF_pct: -24.59\n      E_F1: 2.08\n      R_F1: 2.02\n- exp_id: w7_qwen_scierc_ft_grammar_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 1.9\n    CF_pct: 0\n    parse_fail_rate: 0\n    total_samples: 551\n    total_entities: 1784\n    total_relations: 1128\n    E_P: 0.6523\n    E_R: 0.6898\n    E_F1: 0.6705\n    R_P: 0.4087\n    R_R: 0.4733\n    R_F1: 0.4386\n    DR_violations: 22\n    tokenizer_warning: false_positive_transformers_4.57.6\n- exp_id: w7_qwen_scierc_ft_semantic_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 0.6\n    CF_count: 15\n    parse_fail_rate: 0\n    total_samples: 551\n    total_entities: 1784\n    total_relations: 1128\n    E_P: 0.6523\n    E_R: 0.6898\n    E_F1: 0.6705\n    R_P: 0.4073\n    R_R: 0.4713\n    R_F1: 0.4369\n    DR_violations: 7\n    delta_vs_grammar_only:\n      DR_delta: -1.3\n      note: semantic_only DR=0.6% vs grammar_only DR=1.9%, semantic layer reduces\n        DR by 68%\n    delta_vs_unconstrained:\n      DR_delta: -1.35\n      note: unconstrained DR=1.95% → semantic_only 0.6%\n- exp_id: w7_llama_scierc_ft_grammar_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    total_samples: 551\n    json_parse_failures: 0\n    total_entities: 1757\n    total_relations: 1082\n    entity_type_violation_rate: 0\n    relation_vocabulary_violation_rate: 0\n    domain_range_violation_rate: 0.0111\n    cross_field_consistency_violation_rate: 0\n    entity_f1:\n      precision: 0.6647\n      recall: 0.691\n      f1: 0.6776\n    relation_f1:\n      precision: 0.432\n      recall: 0.4795\n      f1: 0.4545\n- exp_id: w7_llama_scierc_ft_semantic_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 0.65\n    CF_count: 2\n    E_F1: 67.76\n    E_P: 66.47\n    E_R: 69.1\n    R_F1: 45.47\n    R_P: 43.24\n    R_R: 47.95\n    total_entities: 1757\n    total_relations: 1081\n    json_parse_failures: 0\n- exp_id: w8_ft_posthoc_baseline\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ft_regime:\n      qwen_scierc:\n        R_F1_before: 43.86\n        R_F1_posthoc: 43.94\n        R_F1_constrained: 43.77\n        reject_rate_pct: 1.95\n        TP_lost: 4\n      llama_scierc:\n        R_F1_before: 45.45\n        R_F1_posthoc: 45.23\n        R_F1_constrained: 45.47\n        reject_rate_pct: 1.11\n        TP_lost: 5\n      qwen_docred:\n        R_F1_before: 40.91\n        R_F1_posthoc: 41.11\n        R_F1_constrained: TBD\n        reject_rate_pct: 1.03\n        TP_lost: 1\n      llama_docred:\n        R_F1_before: 43.77\n        R_F1_posthoc: 43.92\n        R_F1_constrained: 44.23\n        reject_rate_pct: 0.64\n        TP_lost: 1\n    zs_regime:\n      mistral_scierc:\n        triples: 1584\n        reject_pct: 20.27\n        R_F1_before: 0.0376\n        R_F1_posthoc: 0.0394\n        R_F1_constrained: 0.0367\n        TP_before: 48\n        TP_after: 44\n        TP_lost: 4\n      qwen_scierc:\n        triples: 1724\n        reject_pct: 16.76\n        R_F1_before: 0.0823\n        R_F1_posthoc: 0.0863\n        R_F1_constrained: 0.0836\n        TP_before: 111\n        TP_after: 104\n        TP_lost: 7\n      llama_scierc:\n        triples: 1274\n        reject_pct: 13.89\n        R_F1_before: 0.0268\n        R_F1_posthoc: 0.0271\n        R_F1_constrained: 0.0254\n        TP_before: 30\n        TP_after: 28\n        TP_lost: 2\n      qwen_docred:\n        triples: 17497\n        reject_pct: 48.12\n        R_F1_before: 0.0774\n        R_F1_posthoc: 0.0961\n        R_F1_constrained: 0.0823\n        TP_before: 1137\n        TP_after: 1010\n        TP_lost: 127\n      llama_docred:\n        triples: 16437\n        reject_pct: 42.18\n        R_F1_before: 0.0598\n        R_F1_posthoc: 0.0744\n        R_F1_constrained: 0.0627\n        TP_before: 850\n        TP_after: 802\n        TP_lost: 48\n      mistral_docred:\n        triples: 11836\n        reject_pct: 73.73\n        R_F1_before: 0.0434\n        R_F1_posthoc: 0.0385\n        R_F1_constrained: 0.0552\n        TP_before: 518\n        TP_after: 292\n        TP_lost: 226\n        removed_RV: 4172\n        removed_ET: 3382\n        removed_DR: 1173\n        note: Only ZS case where posthoc HURTS R_F1 — 73.7% rejection rate loses 43.6%\n          of TPs\n    key_finding: 'ZS: post-hoc R_F1 >= constrained R_F1 in 5/6 groups. Exception:\n      Mistral DocRED where extreme rejection rate (73.7%) causes net F1 loss. Constrained\n      decoding value is in structural guarantee (0% violations) and composability,\n      not F1 preservation.'\n- exp_id: w8_llama_docred_ft_grammar_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    E_F1: 84.04\n    R_F1: 43.77\n    entity_precision: 84.99\n    entity_recall: 83.11\n    relation_precision: 38.6\n    relation_recall: 50.53\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 0.51\n    CF_pct: 0.12\n    parse_fail_rate: 2.3\n    total_samples: 998\n    total_relations: 16199\n    unique_entities: 13225\n    parse_failures: 23\n- exp_id: w8_qwen_docred_ft_grammar_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    E_F1: 82.19\n    E_P: 85.47\n    E_R: 79.16\n    R_F1: 40.85\n    R_P: 36.27\n    R_R: 46.77\n    ET_pct: 0\n    RV_pct: 0\n    DR_pct: 0.61\n    CF_pct: 0.11\n    parse_fail_rate: 7.01\n    total_samples: 998\n    parse_failures: 70\n- exp_id: w8_qwen_docred_ft_semantic_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    E_F1: 82.15\n    E_P: 85.58\n    E_R: 78.99\n    R_F1: 40.89\n    R_P: 36.35\n    R_R: 46.73\n    ET_pct: 0\n    RV_pct: 0.23\n    DR_pct: 0.21\n    CF_pct: 0.27\n    parse_fail_rate: 7.52\n    total_samples: 998\n    parse_failures: 75\n    documents_checked: 923\n    total_entities: 18025\n    total_triples: 15909\n    DR_violations: 34\n    RV_violations: 37\n    ET_violations: 0\n    CF_violations: 49\n- exp_id: w8_llama_docred_ft_semantic_only\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    E_F1: 84.02\n    E_P: 85.01\n    E_R: 83.06\n    R_F1: 43.9\n    R_P: 38.89\n    R_R: 50.4\n    ET_pct: 0\n    RV_pct: 0.15\n    DR_pct: 0.3\n    CF_pct: 0.16\n    parse_fail_rate: 2.4\n    total_samples: 998\n    parse_failures: 24\n    documents_checked: 974\n    total_entities: 19099\n    total_relations: 16038\n    DR_violations: 48\n    RV_violations: 24\n    ET_violations: 0\n    CF_violations: 31\n\n# 输出格式（YAML，仅输出一个 ```yaml 块）\n\n```yaml\ntier: best\nnarrative_guidance: \"...\"\nimagined_experiments:\n  - name: \"...\"\n    plan_id: \"...\"\n    description: \"...\"\n    expected_results: {metric: value, ...}\n    result_rationale: \"...\"\n    tables: []\n    figures_description: []\n    analysis: \"...\"\n```\n"
}
````

---

### Runtime record

_source line 2 · 2026-05-16T17:34:20.166Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-16T17:34:20.166Z",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

## Round 1

26 recorded events

### User

_source line 3 · 2026-05-16T17:34:20.189Z_

你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：

含义：所有核心 claim 经受住审稿，novelty 被认可为 IE-specific 贡献而非简单迁移，CF 作为诚实 limitation 被接受
核心假设：['至少 2/3 审稿人认可 violation landscape study 作为独立贡献', 'enabling dependency（grammar→semantic）被视为 non-trivial 架构 insight，区别于 SynCode 的单层 CFG', 'tightness × RV baseline 双因子分析被认为是 deeper insight，非 post-hoc 解释', 'CF 主动披露 + type ambiguity 根因分析 + 消融归因被接受为充分的 limitation 处理', '3 模型 × 2 数据集矩阵 + FT ablation 8/8 被视为充分的 generalization 证据', 'zero-shot 设定被理解为方法论选择而非能力不足']
关键指标范围：{'avg_reviewer_score': [3.75, 4.25], 'novelty_score': [3.5, 4.0], 'soundness_score': [4.0, 4.5], 'accept_probability_pct': [55, 75], 'major_revisions_requested': [0, 1], 'reviewer_concern_cf_severity': ['minor', 'minor']}
叙事方向：原始 framing 完全成立。Title "Type-Valid IE via Compiled Ontology Constraints" 精准定位贡献。 §3 violation landscape 被引用为 empirical contribution。Claim 3 composable framework 的 enabling dependency 被视为关键设计 insight。DR↓94% (SciERC) / ↓90.2% (Llama DocRED) at zero/positive F1 cost 是 干净的主结果。CF 在 limitations 和 analysis 双重出现被审稿人正面评价为"refreshingly honest"。 FT regime 下 DR 1.95%→0% + F1 neutral 补全了"method scales to supervised setting"的叙事。 Post-hoc baseline 的多维对比（recall preservation + information coverage + ET residual） 构成完整的 defense。Rebuttal 只需回应小的澄清问题，不需要额外实验。


基于以上定义，对 experiment_plan 中每个 planned 实验展开详细数据。
每条预测都必须给出 result_rationale —— 解释为什么在这个档位下会得到这样的结果。

# Project context
project: schema_semantic_constrained_ie
venue: EMNLP 2026
focus: 最终评估：54 实验全部完成，FT ablation 8/8 互补性确认，post-hoc defense 成立，latency ≤5.4%。关注：claim 强度是否匹配证据、limitations 是否充分、novelty 定位 vs SynCode/IterGen/BoostCD 差异化是否清晰。

## paper_framing.md

# OntoCoDec — Paper Framing

## Target Venue
EMNLP 2026 (ARR submission May 25, 2026)

## Title
OntoCoDec: Type-Valid Information Extraction via Compiled Ontology Constraints
(D015: "Near-Complete" dropped — DocRED residual DR=10.21% (Qwen) 不算 near-complete。论文贡献是方法，不是特定消除率。SciERC 0.93% 和 DocRED 2.55% (Llama) 可在正文中描述为 near-complete，但 title 不宜 overclaim。)

## Core Insight
LLM-based IE systems produce systematic ontology constraint violations concentrated in specific relation types. Prompt-level intervention (schema-informed prompting) reduces violations by ~62% but cannot eliminate them — certain relation types retain 25-30% violation rates even with explicit constraint descriptions. OntoCoDec provides **near-complete elimination (DR 15.4%→0.93%, ↓94%) at zero or positive F1 impact** through automatic ontology-to-decoder constraint compilation with two complementary layers.

**Phase 2 confirmed (D012 bootstrap CI, v2 fix)**: Grammar+Semantic dual-layer constrained decoding reduces domain/range violations by 94%, eliminates entity-type and relation-vocabulary violations entirely (→0%). F1 impact is **dataset-dependent**:
- SciERC: Rel F1 neutral (+0.13pp, p=0.58), Ent F1 neutral (-0.03pp, p=0.53)
- DocRED: Rel F1 **significantly improved** (+0.50pp, p<0.001, 95% CI [+0.23, +0.81]); Ent F1 **significantly improved** (+1.23pp, p<0.001, 95% CI [+0.94, +1.55])
- Mechanism: grammar 消除 OOV relation names (DocRED RV 29.66%→0.03%) + 非标 entity types (ET 2.48%→0%)。all_set F1 方法下 OOV=FP → fewer FP → higher precision/F1。SciERC baseline RV/ET 已很低，效果不显著。
- **Grammar 层是 F1 提升的唯一来源**: grammar_only Ent F1=59.38% ≈ full_s1 59.37% (Δ+0.01pp, p=0.66)。Semantic 层对 F1 无额外贡献，专注 DR reduction。

## Core Claims

### Claim 1 (Empirical): Violation Landscape
LLM-based IE systems violate ontology type constraints at non-trivial rates (15.4% per-triple on SciERC, 18.7% on DocRED). Violations are **not uniformly distributed** — they concentrate on relation types with tight domain/range constraints (Feature-of 33.5%, Compare 42.4%) while loose-constraint relations show near-zero violation (Used-for 0.8%).

**Key insight**: Violation rate is driven by **constraint tightness**, not ontology size. A small ontology with tight constraints can produce more violations than a large ontology with loose constraints.

**D014 修订**: DR reduction ceiling 由 **tightness × model RV baseline** 共同决定，非 tightness 单因素。Llama DocRED DR↓90.2% vs Qwen DR↓44.7%（同一 ontology τ̄=0.842）。机制：Qwen RV=29.66% >> Llama RV=16.03% → grammar 层将 OOV triples 强制匹配有效关系名 → 揭露大量 latent DR violations → 残余 DR 更高。这是比单一 tightness 更深的 insight。

**Evidence**: SciERC (7 relations) 15.4%; DocRED (96 relations) 18.7% — comparable rates despite 14× ontology size difference. Schema-informed prompt on DocRED only achieves DR↓32% (vs SciERC ↓62%), confirming **prompt-level intervention scales poorly with ontology complexity**.

### Claim 2 (Empirical): Prompt Insufficiency
Schema-informed prompting (explicitly describing domain/range constraints in the prompt) reduces but does not eliminate violations:
- Overall: 15.4% → 5.78% (-62.4%), still above 5%
- Per-relation: Compare 42.4% → 27.6%, Evaluate-for 24.1% → 29.9% (**worse**)
- Prompt intervention is unreliable at the per-relation level — some relations improve, one regresses

**Narrative**: This is NOT about "5.78% barely above 5%". The story is: **prompt-level intervention is fundamentally unreliable as a guarantee mechanism**. It works statistically but cannot provide per-instance compliance. Three specific relation types retain >10% violation rates with schema-informed prompts. For safety-critical IE (biomedical, legal, regulatory), statistical reduction is insufficient — guaranteed compliance is required.

### Claim 3 (Methodological): Composable Constraint Framework
OntoCoDec automatically compiles IE ontology schemas into two composable constraint layers:
1. **Grammar layer** (XGrammar): JSON structure + type vocabulary constraints (CFG-expressible)
2. **Semantic layer** (TypeConstraintProcessor): Cross-field domain/range constraints via stateful entity registry + dynamic logit masking

The two layers are **complementary with enabling dependency**: grammar ensures every generated relation type is in the valid vocabulary, which enables the semantic layer to look up and enforce domain/range rules for that type. Without grammar, the semantic layer encounters unknown relation types and cannot enforce constraints (explaining why semantic_only achieves only ↓24% vs full_s1 ↓94%). This is NOT "synergistic" (mutual amplification) — grammar is a prerequisite for semantic, not vice versa.

The two layers compose via bitwise AND of token masks. Recommended framing: "Grammar and semantic constraints compose via bitwise AND with an enabling dependency: grammar ensures structural validity, enabling semantic constraints to enforce domain/range rules. When constraint tightness creates empty intersection between layers, the system degrades gracefully to grammar-only constraints, maintaining structural validity as a guaranteed floor."

**Graceful degradation + Fallback 频率量化** (D008 + Reviewer 发现):
When $M_{semantic} \cap M_{grammar} = \emptyset$, the system falls back to grammar-only control.

**关键量化数据（Reviewer 从日志挖掘）**:
- Llama DocRED full_s1: **32,921 次 fallback / 577 docs = ~57 次/doc**
- Llama SciERC full_s1: **5,882 次 fallback / 550 docs = ~10.7 次/doc**
- DocRED fallback 频率是 SciERC 的 **5.3×**
- Qwen DocRED fallback 率未知（日志当时无 fallback logging，需估算）

**这直接解释了 DocRED DR 残余 10.19% vs SciERC 0.93%**: 更多 token 位置退化为 grammar-only → grammar-only 的 DR 已知为 26.17% → 高 fallback = 高残余 DR。

**论文建议**: 在 §5 tightness 段报告 fallback 率，定义 "Constraint Coverage" 指标（semantic masking 实际生效的 token 比例）。这把 "10.19% DR 残余" 从弱点变成可量化分析的 finding。Frame as "engineering robustness" in §4; fallback 频率 + tightness 作为 §5 定量分析。

**Decidability taxonomy**: Constraints classified by prefix-decidability:
- (a) Purely local: entity type ∈ vocabulary (grammar layer)
- (b) Prefix-decidable with state: relation argument types compatible with domain/range (semantic layer, requires entity registry)
- (c) Truly non-local: forward coreference — out of scope for forward-only decoding

### Claim 4 (Methodological): S1 vs S2 Decoding Strategies — Architectural Ablation
- S1 (single-pass): Both layers applied throughout generation. **Recommended primary strategy** — simpler, slightly better metrics across the board.
- S2 (two-pass): Pass 1 extracts entities (grammar-only), Pass 2 generates relations with input-dependent grammar compiled from Pass 1 entities.

**S2 full results (551/551 SciERC)**: DR 0.97% (vs S1 0.93%), CF 8.03% (vs S1 9.9%), R-F1 8.03% (vs S1 8.36%). S2 does NOT solve CF — the 1.87pp reduction is not significant. S2 also slightly worse on DR and F1. **S2 is an architectural variant demonstrating framework flexibility, not a CF solution.** Position in paper as ablation (Section 5 or Appendix), not as a core contribution.

⚠️ **Do NOT cite pilot50 DR=0% as S2 evidence** — small-sample artifact; full run shows DR=0.97%. Per-relation S2 DR is worse than S1 on Compare (4.6% vs 2.82%), Part-of (1.25% vs 0%), Used-for (0.12% vs 0%).

## Anticipated Reviewer Concerns

### C1: "5.78% is barely above 5% — threshold is arbitrary"
**Response**: Don't argue about the threshold. Argue about per-relation distribution: Compare (27.6%), Evaluate-for (29.9%), Feature-of (11.3%) have double-digit violation rates with schema-informed prompt. The value proposition is per-relation guaranteed compliance, not overall statistical rate.

### C2: "Why not just post-hoc filter?"
**Response (D013, 实验结果已出)**:

Post-hoc filtering 实验结果：post-hoc F1 > OntoCoDec F1（SciERC 8.63 vs 8.36, DocRED 9.61 vs 8.24）——因 low F1 regime 下移除 FP 大幅提升 precision。

**论文 framing（不以 F1 论高低，多维对比）**:
1. **Recall 维度（核心论点）**: OntoCoDec recall 上升 (SciERC +0.20pp, DocRED +0.56pp) = 概率质量重分配到合法 token 生效。Post-hoc recall 下降 (SciERC -0.72pp, DocRED -1.06pp) = 正确 triple 被误删。
2. **Information coverage**: DocRED post-hoc 丢弃 **48.1%** triples（近半数信息丢失），SciERC 16.8%。OntoCoDec 保留全部 triple slots。
3. **Operational**: OntoCoDec 产出即合规、无需后处理、支持流式。Post-hoc 需额外管线、不适用实时场景。
4. **Precision trade-off（诚实承认）**: "Post-hoc achieves higher precision by removing a large fraction of triples, many of which are incorrect. This trades information coverage for precision — valid when FP are costly, but inadequate when completeness matters."

数据表：SciERC post-hoc rejection 16.8%, OntoCoDec recall 11.60 vs post-hoc 10.68; DocRED post-hoc rejection 48.1%, OntoCoDec recall 10.02 vs post-hoc 8.40。

**Reviewer 补充发现（D013 后）**:
5. **ET 残余**：post-hoc 只删 triples 不改 entity list，残余 ET=0.4% (SciERC) / 2.47% (DocRED)。OntoCoDec ET=0%。Post-hoc 无法解决 entity type 违规。
6. **127 个被删 TP (DocRED)**：过滤前 TP=1137，过滤后 TP=1010。丢失的 127 个 TP（11.2%）是正确提取但 entity type 违规的 triple。OntoCoDec 通过生成时强制合法 type 保留这些 TP——"prevent vs detect" 核心论据的具体数据。
7. **OntoCoDec+post-hoc 组合**（future work idea）：先 constrain 再 filter 残余 DR。低优先级，May 19 前不做。

### C3: "Bitwise AND of two masks is not novel"
**Response**: The novelty is not the AND operation — it's (a) the automatic compilation from ontology definitions (zero-code schema compliance), (b) the stateful entity registry enabling cross-field constraints during autoregressive generation, (c) the decidability taxonomy providing theoretical guidance, and (d) the systematic violation landscape measurement motivating the approach.

### C4: "Evaluate-for violation rate increases with schema-informed prompt"
**Response (prior-constraint conflict framework)**: Evaluate-for has 23/36 valid pairs; Method→Task is invalid for Evaluate-for but natural in the LLM's distributional prior ("Method X evaluates for Task Y" is semantically plausible). Schema-informed prompting creates a **prior-constraint conflict**: the model learns to avoid Method→Task for Evaluate-for (reducing count 133→87, -34.6%), but the remaining instances are harder boundary cases where the model's type assignment strategy becomes less stable. This is not just "harder instances" — it's an active interference between prompt-level constraint signals and the model's learned type associations.

**This strengthens the paper's claim**: prompt-level intervention is not merely insufficient but potentially **counterproductive** for specific constraint configurations. Decoding-time enforcement avoids this issue entirely — it operates on logits, not on the model's reasoning process, so there is no prior-constraint conflict.

### C5: "Only tested on one model (Qwen3-8B)"
**Response**: Cross-model validation DONE (D016 bootstrap verified). Llama-3.1-8B 零代码修改：
- SciERC: DR 13.34%→0.08% (↓99.4%), R-F1 -0.14pp (p=0.011, negligible), E-F1 NS
- DocRED: DR 26.07%→2.55% (↓90.2%), R-F1 +0.29pp (p=0.013, significant), E-F1 -0.64pp (p=0.022, modest decline)
- Parse failures: unconstrained 68 vs full_s1 91 (6.8% vs 9.1%)

**Cross-model claim 指导（Reviewer 专项评估）**:
- ✅ 可声明："OntoCoDec generalizes across model families without code modification"（程序性事实，铁证）
- ❌ 不可声明："consistently achieves the same reduction rate"（仅 2 模型，不足以量化声明）
- **RV↓DR↑ 正交性 finding**: Llama RV baseline 低(16%) 但 DR baseline 高(26%)，反向于 Qwen。证明两层约束解决正交 failure modes——vocabulary compliance ≠ semantic compliance。应作为 §5 cross-model 独立 finding 展开。
- **Parse failure 偏差**: checker skip parse failures (不计入 F1)，Llama 68/998=6.8% vs Qwen 12/998=1.2%。偏差方向保守（不利于 constrained），不威胁 claim。但需 footnote 披露 + cross-model 表增加 parse failure rate 行。
- **Llama SciERC CF=6.56%**: 比 Qwen 同量级更高，non-local constraint 问题在 Llama 上更突出，limitations 提及。
- 等 llama_docred_full_s1 出来后定最终 claim 措辞。

### C6: "Constrained decoding degrades generation quality (CRANE, Structure Snowballing)"
**Response**: OntoCoDec's semantic constraints are narrower than full grammar constraints — only type tokens are masked, free text is unconstrained. **Bootstrap CI (10000×, D012 Qwen + D016 Llama, all registry-aligned)**:

**Qwen3-8B**: SciERC R-F1 +0.13pp (p=0.58, NS), E-F1 -0.03pp (NS). DocRED R-F1 +0.50pp (p<0.001), E-F1 +1.23pp (p<0.001).
**Llama-3.1-8B**: SciERC R-F1 -0.14pp (p=0.011, negligible), E-F1 NS. DocRED R-F1 +0.29pp (p=0.013), E-F1 -0.64pp (p=0.022).

**Cross-model pattern**: DocRED R-F1 显著提升（两个模型）。E-F1 model-dependent（Qwen +1.23pp, Llama -0.64pp）。
- 机制：grammar 消除 OOV relation names + 非标 entity types → all_set 方法下减少 FP → precision 提升。Grammar 是 F1 提升的唯一来源（grammar_only Ent F1=59.38% ≈ full_s1 59.37%, Δ=0.01pp, p=0.66）。Semantic 层对 F1 无额外贡献。
- Frame as: "On DocRED, R-F1 gains are significant for both models. Entity F1 impact is model-dependent."
- 不升级为 core claim，但如实报告。

### C7: "Your method trades DR violations for CF violations (cross-field consistency)"
**Response**: Both S1 and S2 show elevated CF (per-triple rate ~8-10%). This is an inherent limitation of per-relation independent type enforcement. Must be proactively reported as a limitation. Defense:

**CF 子类型分析（根因已确认）**：
- **EVR（entity-vs-relation type drift）**: 占 CF 的 >90%。同一 entity 在 entity list 和 relation triple 中被赋予不同 type。S1: 245 entities (7.34%), S2: 178 entities (5.54%, -27%)
- **Within-rel（同 entity 跨 relation type 不一致）**: S1: 10 (0.36%), S2: 18 (0.72%)
- S2 减少 EVR 但增加 within-rel——trade-off 更复杂，不是单纯好/差

**Top 冲突模式**: Generic↔OtherScientificTerm (60次), Material↔OtherScientificTerm (28次), Material↔Method (20次)。**这些是 SciERC type system 固有的语义边界模糊区**——同一术语在不同学术语境下确实可以被合理归类为不同 type。CF 在相当程度上是 type system 模糊性的体现，非纯粹的方法缺陷。

**论证层次**：
1. DR violations = structurally invalid triples（下游系统不可用）→ hard constraint
2. CF violations = same entity gets different types across relations → individual triples remain type-valid, only cross-triple consistency broken → soft preference
3. CF 的根因是 type system 语义边界模糊 + per-relation 独立 enforcement，非 bug
4. Future work: cross-relation global consistency pass (entity-level type consensus before relation-specific enforcement)

**机制归因（口径对账确认）**：grammar_only CF=0.08%（与 unconstrained 持平），full_s1 CF=9.90%，full_s2 CF=8.03%。**CF 100% 由 semantic 层引入，grammar 层无贡献。** 这为 "CF 是 semantic type enforcement 的系统性副作用" 提供干净的消融证据。

**论文数字口径**：CF rate 用 violation_checker 口径（denominator=total_entities，与 DR/RV/ET 一致）。分析段落额外给 entity-level EVR 率 + 受影响样本比例。注意：analyze_cf 脚本的 EVR/WR 两维度不是独立的（WR⊂EVR），论文中不要作为两个独立维度报告。

**Do NOT hide this data.** Proactive disclosure + severity distinction + root cause analysis + type ambiguity evidence + 消融归因 = 最强防御策略。

### C8: "Absolute F1 is too low (~8%) — results are not meaningful"
**Response**: This is a zero-shot extraction setting (no training data, no fine-tuning). Low F1 is expected — supervised SOTA on SciERC relation F1 is ~40-50%. Our contribution is the constraint enforcement method, not extraction quality. F1 is a control variable verifying constraints don't degrade quality, not an optimization target. Recommended framing: "We evaluate in a zero-shot setting to demonstrate that our constraint enforcement method works without task-specific training. F1 is reported to verify that constraint enforcement does not degrade extraction quality, not as a claim of state-of-the-art performance."

## Paper Structure (Draft)
1. Introduction: Violation landscape motivation + composable constraint framework overview
2. Background: Grammar-constrained decoding (XGrammar) + IE ontology structure
3. Violation Landscape Study (Phase 0 empirics — independent contribution)
4. OntoCoDec Framework: Compiler + TypeConstraintProcessor + S1/S2 strategies
5. Experiments: Constrained vs unconstrained vs post-hoc vs prompt-based
6. Related Work: 5 constraint paradigms (grammar, vocabulary, structural, type-checking, ontology)
7. Conclusion

## Claim Calibration (per Reviewer assessment)

**Safe to claim (sufficient evidence from Phase 2)**:
- "First systematic study of ontology constraint violations in LLM-based IE"
- "Violation rate correlates with constraint tightness, not ontology size" (D014: DR reduction ceiling 由 tightness × model RV baseline 共同决定)
- "Grammar+semantic constrained decoding eliminates 94% of DR violations at zero F1 cost" ✅ Phase 2 confirmed
- "Two-layer architecture provides complementary coverage — grammar enables semantic" ✅ Ablation confirmed
- "Prompt-level intervention scales poorly with ontology complexity" ✅ SciERC ↓62% vs DocRED ↓32%

**Claim with caution**:
- "Near-complete type-valid IE" — S1 0.93%, S2 0.97% residual, not truly 0%. Title updated to "Near-Complete"
- "Principled framework applicable to arbitrary IE ontologies" — validated on 2 datasets + 1 model only
- "F1 improvement" — SciERC: not significant (p=0.58), frame as F1-neutral; DocRED: significant (+0.50pp, p<0.001), 可报告但不升级为 core claim，归因于 OOV elimination 而非约束解码本身的提升
- "CF reveals type system ambiguity" — 可在 §5.3 作为 analysis finding 展开（Generic↔OtherScientificTerm 等模式有独立 insight 价值），但 §7 必须同时保留 CF 作为 limitation + future work。**两处都要有，缺一不可。** 不能暗示"因为是 type ambiguity 所以 CF 可接受"

**Do NOT claim**:
- "General infrastructure for IE" — only zero-shot extraction validated
- "State-of-the-art" — F1 is control variable, not optimization target (see C8)
- "Synergistic effect" — mechanism is enabling dependency, not mutual amplification (see Claim 3)
- "S2 solves CF" or "S2 mitigates Structure Snowballing" — data shows S2 ≈ S1 on all metrics; position as architectural variant only
- "Pilot50 DR=0%" — small-sample artifact, full S2 has DR=0.97%
- "Grammar-first invariant" 作为独立 claim — 证据不足（仅 1 次崩溃触发，实现是 fallback 非形式化保证）。写入 §4 方法论设计原则（1-2 句），不升级为 claim
- "Robust dual-layer composition across schema complexities" — 等 DocRED 完成。最终如 fallback ≤5/998，可写经验性陈述，不做泛化 claim

## Risk Ranking (ordered by reject probability)

1. **CF violation trade-off under-addressed** (MEDIUM-HIGH): S1 9.9%, S2 8.03% — both elevated. **S2 confirmed: does NOT solve CF.** This is the #1 attack surface. Mitigated by proactive disclosure + severity distinction + root cause analysis (C7). Must be reported as explicit limitation with future work direction (global entity-type consensus).
2. ~~**Single model limitation**~~ (RESOLVED): Llama-3.1-8B SciERC ✅ (DR↓99.4%) + DocRED ✅ (DR↓90.2%). 2 模型 × 2 数据集全矩阵完成。
3. **Novelty perception** (MEDIUM): "PLDI'25 for code → OntoCoDec for IE" attack line. Must argue IE constraint structure differs fundamentally.
4. ~~**DocRED Phase 2 weak**~~ (RESOLVED → reframed as D014): Qwen DR↓44.7%, Llama DR↓90.2% — both substantial. Weaker Qwen reduction explained by RV baseline interaction (D014), not method failure.
5. ~~**Phase 2 F1 drop**~~ (RESOLVED): F1 confirmed neutral (SciERC) or positive (DocRED, p<0.001). Bootstrap CI D012 confirms. No longer a risk.

## Critical Path to EMNLP Submission (May 25)

- **May 13-14**: Phase 0 + Phase 1 + Phase 2 SciERC ✅
- **May 14**: Phase 2 DocRED 4-way ablation ✅ + Llama SciERC cross-model ✅ + Dream 完成 (3/6)
- **May 14-15**: Llama DocRED 2 组实验 ✅ + Checker 修正 ✅ + post-hoc baseline ✅ + bootstrap CI ✅ + related work ✅
- **May 14-15**: D014 tightness claim 修订 + §5 cross-model subsection + abstract/conclusion 修正 (Agent 执行中)
- **May 15-17**: 全文校对 + Discussion 整合 + 最终数字确认
- **May 19**: 内部稿 → submit_paper_to_review
- **May 19-24**: Review 修改 + 最终提交

**当前瓶颈**: 无技术 blocker。等 Reviewer 跨文件一致性审查 + 编译验证后即可 submit_paper_to_review。

## Status
- Phase 0 SciERC: ✅ Complete (minimal + schema-informed)
- Phase 0 DocRED: ✅ Complete (minimal 18.7% DR + schema-informed 12.8% DR)
- Phase 1 Compiler: ✅ Complete (grammar + semantic layers integrated)
- Phase 2 SciERC (5 configs): ✅ Complete (S1 DR↓94% F1-neutral, S2 降级为 ablation)
- Phase 2 DocRED (4 configs): ✅ Complete (full_s1 DR↓45%, grammar ET/RV→0%)
- Llama SciERC cross-model: ✅ Complete (DR↓99.4%, F1-neutral, 零代码修改)
- Llama DocRED cross-model: ✅ Complete (full_s1 DR↓90.2%, unconstrained DR=26.07%)
- Checker v2 (D011): ✅ Fixed (ET triple-counting → unique entity dedup)
- Bootstrap CI (D012): ✅ Fixed + confirmed (entity filter bug resolved)
- Post-hoc baseline (D013): ✅ Complete (multi-dimensional framing)
- Related work: ✅ 42 bib entries, 4 additions merged
- Dream 6/6 actions: ✅ All complete
- CF violation analysis: ✅ Confirmed inherent limitation (S1 9.9% SciERC / 2.57% DocRED / 12.02% Llama DocRED)
- D014 tightness revision: ✅ Complete (tightness × RV baseline dual-factor)
- Llama bootstrap CI (D016): ✅ Fixed + verified (registry-aligned ≤0.05pp, all p-values in paper)
- Paper compilation: ✅ 8 pages正文 + appendix


## registry (completed experiments)

- exp_id: mvp_phase0_violation_rate
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_triples: 1724
    total_entities: 2474
    json_parse_rate: 1
    entity_type_violation_rate: 0.004
    relation_vocabulary_violation_rate: 0.0139
    domain_range_violation_rate: 0.1537
    cross_field_consistency_violation_rate: 0.0008
    go_nogo_metric: 0.1537
    entity_f1: 0.3101
    relation_f1: 0.0823
    per_relation:
      Used-for:
        total: 787
        dr_violations: 6
        rate: 0.0076
      Conjunction:
        total: 32
        dr_violations: 0
        rate: 0
      Hyponym-of:
        total: 124
        dr_violations: 18
        rate: 0.1452
      Evaluate-for:
        total: 133
        dr_violations: 32
        rate: 0.2406
      Part-of:
        total: 72
        dr_violations: 18
        rate: 0.25
      Feature-of:
        total: 486
        dr_violations: 163
        rate: 0.3354
      Compare:
        total: 66
        dr_violations: 28
        rate: 0.4242
- exp_id: mvp_phase0_violation_rate_docred
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_docs: 998
    parsed_docs: 962
    json_parse_rate: 0.964
    total_entities: 19099
    total_triples: 16540
    entity_type_violation_rate: 0.075
    relation_vocabulary_violation_rate: 0.289
    domain_range_violation_rate: 0.187
    cross_field_consistency_violation_rate: 0.0008
    go_nogo_metric: 0.187
    fuzzy_matches: 126
    top_dr_violations_by_rate:
      P35_head_of_state: 1
      P710_participant: 0.919
      P172_ethnic_group: 0.875
    top_dr_violations_by_count:
      P31_instance_of:
        violations: 322
        total: 533
        rate: 0.604
      P1001_applies_to_jurisdiction:
        violations: 264
        total: 594
        rate: 0.444
      P1344_participant_in:
        violations: 194
        total: 312
        rate: 0.622
- exp_id: mvp_phase0_scierc_schema
  name: ''
  status: DONE
  conclusion: success
  metrics:
    domain_range_violation_rate: 0.0578
    relation_vocabulary_violation_rate: 0.003
    entity_type_violation_rate: 0
    total_violation_rate: 0.0253
    go_nogo_metric: 0.0578
    total_triples: 1661
    vs_minimal_dr_reduction: -0.624
    per_relation:
      Used-for:
        rate: TBD
      Feature-of:
        delta_pp: -22.3
      Part-of:
        delta_pp: -22.5
      Compare:
        delta_pp: -14.8
      Evaluate-for:
        delta_pp: 5.8
    mcnemar_all_significant: true
- exp_id: mvp_phase0_docred_schema
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_documents: 998
    documents_checked: 943
    parse_failures: 55
    json_parse_rate: 0.9449
    total_entities: 19524
    total_triples: 16782
    entity_type_violations: 119
    entity_type_violation_rate: 0.0061
    relation_vocabulary_violations: 3090
    relation_vocabulary_violation_rate: 0.1841
    relation_fuzzy_matches: 85
    domain_range_violations: 2154
    domain_range_violation_rate: 0.1284
    cross_field_consistency_violations: 29
    cross_field_consistency_violation_rate: 0.0015
    total_violations_any: 5392
    total_violation_rate: 0.1485
    go_nogo_metric_dr: 0.1284
- exp_id: phase2_scierc_grammar_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_samples: 551
    total_triples: 1725
    total_entities: 2474
    json_parse_rate: 1
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0
    domain_range_violation_rate: 0.1484
    cross_field_consistency_violation_rate: 0.0008
    entity_f1: 0.3098
    entity_precision: 0.2598
    entity_recall: 0.3837
    relation_f1: 0.0823
    relation_precision: 0.0643
    relation_recall: 0.114
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: phase2_scierc_semantic_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_samples: 551
    total_triples: 1726
    total_entities: 2474
    json_parse_rate: 1
    entity_type_violation_rate: 0.004
    relation_vocabulary_violation_rate: 0.0151
    domain_range_violation_rate: 0.1165
    cross_field_consistency_violation_rate: 0.0271
    entity_f1: 0.3101
    entity_precision: 0.2605
    entity_recall: 0.3831
    relation_f1: 0.0815
    relation_precision: 0.0637
    relation_recall: 0.1129
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: phase2_scierc_full_s1
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_samples: 551
    total_triples: 1729
    total_entities: 2474
    json_parse_rate: 1
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0
    domain_range_violation_rate: 0.0093
    cross_field_consistency_violation_rate: 0.099
    entity_f1: 0.3098
    entity_precision: 0.2598
    entity_recall: 0.3837
    relation_f1: 0.0836
    relation_precision: 0.0654
    relation_recall: 0.116
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: phase2_scierc_unconstrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    json_parse_rate: 1
    entity_f1: 0.3101
    entity_precision: 0.2605
    entity_recall: 0.3831
    relation_f1: 0.0823
    relation_precision: 0.0644
    relation_recall: 0.114
    entity_type_violation_rate: 0.004
    relation_vocabulary_violation_rate: 0.0139
    domain_range_violation_rate: 0.1537
    cross_field_consistency_violation_rate: 0.0008
    total_triples: 1724
    total_entities: 2474
    total_samples: 551
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: phase2_s2_pilot50
  name: ''
  status: DONE
  conclusion: success
  metrics:
    domain_range_violation_rate: 0.0205
    relation_vocabulary_violation_rate: 0
    relation_f1: 0.1008
    samples: 50
    predicted_relations: 146
    true_positives: 13
    gold_relations: 112
    entity_f1_approx: 0.29
    note: 'DR 修正: 原值 0 来自 dryrun (n=25 triples)。实际 pilot50 DR=3/146=2.05% (来自 violation_report_s2_pilot50.json)。'
- exp_id: mvp_phase0_docred_schema_r2
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: phase2_scierc_full_s2
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_samples: 551
    total_triples: 1644
    total_entities: 2228
    json_parse_rate: 1
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0
    domain_range_violation_rate: 0.0097
    cross_field_consistency_violation_rate: 0.0803
    entity_precision: 0.2797
    entity_recall: 0.3712
    entity_f1: 0.319
    relation_precision: 0.064
    relation_recall: 0.1078
    relation_f1: 0.0803
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: phase2_docred_grammar_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    documents_checked: 985
    parse_failures: 13
    total_entities: 20150
    total_triples: 17341
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0.0003
    domain_range_violation_rate: 0.2617
    cross_field_consistency_violation_rate: 0.0007
    relation_f1: 8.31
    relation_precision: 7.06
    relation_recall: 10.12
    entity_f1: 59.38
    entity_precision: 58.47
    entity_recall: 60.32
    unrecognized_relations: 5
    f1_method: all_set
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: phase2_docred_full_s1
  name: ''
  status: DONE
  conclusion: success
  metrics:
    documents_checked: 987
    parse_failures: 11
    total_entities: 20187
    total_triples: 17341
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0.0003
    domain_range_violation_rate: 0.1021
    cross_field_consistency_violation_rate: 0.0257
    entity_f1: 59.37
    entity_precision: 58.45
    entity_recall: 59.63
    relation_f1: 8.23
    relation_precision: 6.99
    relation_recall: 10.01
    unrecognized_relations: 5
    f1_method: all_set
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: phase2_docred_unconstrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    documents_checked: 986
    parse_failures: 12
    total_entities: 20171
    total_triples: 17497
    entity_type_violation_rate: 0.0248
    relation_vocabulary_violation_rate: 0.2966
    domain_range_violation_rate: 0.1846
    cross_field_consistency_violation_rate: 0.001
    entity_f1: 58.15
    entity_precision: 57.26
    entity_recall: 58.32
    relation_f1: 7.74
    relation_precision: 6.55
    relation_recall: 9.46
    unrecognized_relations: 5189
    f1_method: all_set (includes OOV predictions in denominator)
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
    et_v1: 0.0818
    et_fix_note: v1 triple-counted ET across entity_list + relation head/tail; v2
      deduplicates by (text, normalized_type)
- exp_id: phase2_docred_semantic_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    documents_checked: 987
    parse_failures: 11
    total_entities: 20185
    total_triples: 17571
    entity_type_violation_rate: 0.0422
    relation_vocabulary_violation_rate: 0.2987
    domain_range_violation_rate: 0.1384
    cross_field_consistency_violation_rate: 0.0105
    entity_f1: 57.81
    entity_precision: 57.27
    entity_recall: 58.37
    relation_f1: 7.7
    relation_precision: 6.54
    relation_recall: 9.37
    f1_method: all_set
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
    et_v1: 0.1044
    et_fix_note: v1 triple-counted ET across entity_list + relation head/tail; v2
      deduplicates by (text, normalized_type)
- exp_id: llama_scierc_unconstrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    entity_type_violation_rate: 0
    relation_vocab_violation_rate: 0.0055
    domain_range_violation_rate: 0.1334
    cross_field_consistency_violations: 6
    entity_f1: 0.2356
    entity_precision: 0.1983
    entity_recall: 0.2902
    relation_f1: 0.0268
    relation_precision: 0.0236
    relation_recall: 0.031
    total_entities: 2451
    total_relations: 1274
    json_parse_failures: 1
    samples: 551
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: llama_scierc_full_s1
  name: ''
  status: DONE
  conclusion: success
  metrics:
    samples: 550
    entities_extracted: 2469
    relations_extracted: 1315
    domain_range_violation_rate: 0.0008
    relation_vocab_violation_rate: 0
    entity_type_violation_rate: 0
    cross_field_consistency_violation_rate: 0.0656
    total_violation_rate: 0.0431
    entity_f1: 0.2349
    entity_precision: 0.1972
    entity_recall: 0.2902
    relation_f1: 0.0254
    relation_precision: 0.0221
    relation_recall: 0.0298
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
- exp_id: llama_docred_unconstrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    checker_version: fixed_20260514_v2
    f1_method: all_set
    documents: 998
    documents_checked: 930
    parse_failures: 68
    unique_entities: 11525
    total_triples: 16437
    dr_eligible_triples: 13789
    ET_rate_pct: 0.13
    RV_rate_pct: 16.03
    DR_rate_pct: 26.07
    CF_rate_pct: 0.17
    entity_precision: 61.22
    entity_recall: 51.02
    entity_f1: 55.65
    relation_precision: 5.22
    relation_recall: 7
    relation_f1: 5.98
    fuzzy_relation_matches: 121
- exp_id: llama_docred_full_s1
  name: ''
  status: DONE
  conclusion: success
  metrics:
    checker_version: fixed_20260514_v2 (strip + alias + unique_et)
    f1_method: all_set
    violations:
      ET: 0
      RV: 0
      DR: 2.55
      CF: 12.02
    f1:
      entity_f1: 55.01
      entity_precision: 61.41
      entity_recall: 49.82
      relation_f1: 6.27
      relation_precision: 5.49
      relation_recall: 7.32
    counts:
      documents: 998
      documents_checked: 907
      parse_failures: 91
      unique_entities: 11296
      triples: 16368
- exp_id: posthoc_filtering_baseline
  name: ''
  status: DONE
  conclusion: success
  metrics:
    docred_f1_before: 7.74
    docred_f1_after: 9.61
    docred_precision_before: 6.55
    docred_precision_after: 11.22
    docred_recall_before: 9.46
    docred_recall_after: 8.4
    docred_rejection_rate: 0.481
    docred_tp_before: 1137
    docred_tp_after: 1010
    docred_tp_lost: 127
    docred_et_residual: 0.0247
    scierc_f1_before: 8.23
    scierc_f1_after: 8.63
    scierc_rejection_rate: 0.168
    scierc_recall_before: 11.4
    scierc_recall_after: 10.68
    scierc_tp_before: 111
    scierc_tp_after: 104
- exp_id: llama_docred_unconstrained_mt6144
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_rate: 0.13
    RV_rate: 15.89
    DR_rate: 26.18
    DR_rate_eligible: 31.15
    CF_rate: 0.17
    entity_precision: 61.19
    entity_recall: 51.06
    entity_f1: 55.67
    relation_precision: 5.18
    relation_recall: 7
    relation_f1: 5.95
    parse_failures: 67
    documents_checked: 931
    total_documents: 998
    unique_entities: 11534
    total_triples: 16584
    dr_eligible_triples: 13936
    fuzzy_relation_matches: 121
- exp_id: llama_docred_full_s1_mt6144
  name: ''
  status: DONE
  conclusion: success
  metrics:
    DR_rate_pct: 2.57
    RV_rate_pct: 0
    ET_rate_pct: 0
    CF_rate_pct: 12.13
    R_F1: 6.25
    R_precision: 5.45
    R_recall: 7.32
    E_F1: 55.04
    E_precision: 61.41
    E_recall: 49.87
    documents_total: 998
    documents_checked: 908
    parse_failures: 90
    triples: 16471
    unique_entities: 11307
    fallback_events: 67911
    wall_clock_seconds: 23926
    vs_unconstrained_mt6144:
      DR_delta_pp: -23.61
      DR_reduction_pct: -90.2
      R_F1_delta_pp: 0.3
      E_F1_delta_pp: -0.63
    vs_full_s1_mt4096:
      DR_delta_pp: 0.02
      R_F1_delta_pp: -0.02
      E_F1_delta_pp: 0.03
      CF_delta_pp: 0.11
      parse_fail_delta: -1
- exp_id: w1_cf_fallback_scierc_pilot
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    ET: 0
    RV: 0
    DR: 0.1478
    CF: 0.0004
    R_F1: 0.0823
    R_P: 0.0643
    R_R: 0.114
    E_F1: 0.3098
    E_P: 0.2598
    E_R: 0.3837
    entities: 2474
    relations: 1725
    samples: 551
    grammar_first_fallback_rate: 0.3664
    cf_registry_fallback_rate: 0.0448
    total_mask_calls: 17024
    violation_budget_DR_CF: 0.1482
- exp_id: w1_cf_fallback_docred
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: w1_cf_fallback_llama_scierc
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: w1_cf_fallback_llama_docred
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: w5_lora_scierc_training
  name: ''
  status: DONE
  conclusion: success
  metrics:
    train_loss: 0.0634
    eval_loss: 0.0586
    eval_token_accuracy: 0.9816
    eval_entropy: 0.9635
    train_runtime_sec: 688.4
    epochs: 3
    checkpoint_path: /root/schema_semantic_constrained_ie/checkpoints/qwen3_8b_lora_scierc
    merged_model_path: /root/schema_semantic_constrained_ie/checkpoints/qwen3_8b_lora_scierc_merged
- exp_id: w5_lora_scierc_unconstrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    json_parse_rate: 1
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0
    domain_range_violation_rate: 0.0195
    cross_field_consistency_violation_rate: 0
    entity_f1: 0.6705
    entity_precision: 0.6523
    entity_recall: 0.6898
    relation_f1: 0.4386
    relation_precision: 0.4087
    relation_recall: 0.4733
    total_entities: 1784
    total_relations: 1128
    domain_range_violations: 22
    go_nogo_metric: 0.0195
    dr_gate: FAILED
- exp_id: w5_lora_scierc_constrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    json_parse_rate: 1
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0
    domain_range_violation_rate: 0
    cross_field_consistency_violation_rate: 0.0118
    entity_f1: 0.6705
    entity_precision: 0.6523
    entity_recall: 0.6898
    relation_f1: 0.4377
    relation_precision: 0.4078
    relation_recall: 0.4723
    total_entities: 1784
    total_relations: 1128
    total_samples: 551
    cross_field_consistency_violations: 21
- exp_id: w5_llama_lora_scierc_training
  name: ''
  status: DONE
  conclusion: success
  metrics:
    eval_loss: 0.0595
    eval_mean_token_accuracy: 0.9817
    eval_entropy: 1.0565
    train_loss: 0.0501
    train_runtime_sec: 654.23
    epochs: 3
    train_samples_per_second: 8.08
- exp_id: w5_llama_lora_scierc_unconstrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_samples: 551
    total_entities: 1757
    total_relations: 1082
    json_parse_rate: 1
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0
    domain_range_violation_rate: 0.0111
    cross_field_consistency_violation_rate: 0
    total_violation_rate: 0.0042
    entity_precision: 0.6647
    entity_recall: 0.691
    entity_f1: 0.6776
    relation_precision: 0.432
    relation_recall: 0.4795
    relation_f1: 0.4545
- exp_id: w5_llama_lora_scierc_constrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    domain_range_violation_rate: 0.0009
    relation_vocabulary_violation_rate: 0
    entity_type_violation_rate: 0
    cross_field_consistency_violation_rate: 0.0046
    relation_f1: 0.4547
    relation_precision: 0.432
    relation_recall: 0.4795
    entity_f1: 0.6776
    entity_precision: 0.6647
    entity_recall: 0.691
    total_relations: 1081
    total_entities: 1757
    total_samples: 551
    parse_failures: 0
- exp_id: w5_qwen_docred_lora_training
  name: ''
  status: DONE
  conclusion: success
  metrics:
    eval_loss: 0.0614
    eval_mean_token_accuracy: 0.9804
    eval_entropy: 0.715
    train_loss: 0.0682
    train_runtime_s: 5825.6
    epochs: 3
    adapter_path: /root/schema_semantic_constrained_ie/checkpoints/qwen_lora_docred
    merged_path: /root/autodl-tmp/checkpoints/qwen_lora_docred_merged
- exp_id: w5_docred_sft_data_gen
  name: ''
  status: DONE
  conclusion: success
  metrics:
    train_samples: 3053
    dev_samples: 998
    train_entities: 59493
    train_relations: 38180
    dev_entities: 19528
    dev_relations: 12275
- exp_id: w5_llama_docred_sft_data_gen
  name: ''
  status: DONE
  conclusion: success
  metrics:
    train_samples: 3053
    dev_samples: 998
    train_size_mb: 19
    dev_size_mb: 6.1
- exp_id: w5_llama_docred_lora_training
  name: ''
  status: DONE
  conclusion: success
  metrics:
    train_loss: 0.0572
    eval_loss: 0.0624
    token_acc: 98.06
- exp_id: w5_llama_docred_lora_unconstrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_pct: 0
    RV_pct: 0.15
    DR_pct: 0.49
    E_F1: 83.93
    E_P: 84.93
    E_R: 82.96
    R_F1: 43.72
    R_P: 38.59
    R_R: 50.41
    parse_fail_rate: 2.3
    total_samples: 998
    total_entities_pred: 19106
    total_relations_pred: 16171
- exp_id: w5_llama_docred_lora_constrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total: 998
    parse_failures: 25
    parse_fail_rate: 2.51
    entities: 19077
    relations: 16074
    entity_f1: 85.23
    entity_precision: 85.04
    entity_recall: 85.41
    relation_f1_all_set: 44.23
    relation_precision_all_set: 38.82
    relation_recall_all_set: 51.4
    et_violations: 0
    et_violation_rate: 0
    rv_violations: 0
    rv_violation_rate: 0
    dr_violations: 33
    dr_violation_rate: 0.2
    cross_field_consistency_violations: 41
    delta_vs_unconstrained:
      delta_e_f1: 1.3
      delta_r_f1: 0.51
      delta_dr: -0.29
      delta_rv: -0.15
      note: Computed as constrained - unconstrained on full-set metrics (not intersection
        subset). Corrected 2026-05-16 per Reviewer audit.
- exp_id: w5_qwen_docred_lora_unconstrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_pct: 0
    RV_pct: 0.27
    DR_pct: 0.76
    CF_pct: 0.12
    E_F1: 82.15
    E_P: 85.44
    E_R: 79.11
    R_F1: 40.86
    R_P: 36.41
    R_R: 46.56
    parse_fail_rate: 7.11
    total_samples: 998
    success_samples: 927
    fail_samples: 71
    total_entities_pred: 18091
    total_relations_pred: 15870
    ET_pct_excl_fail: 0
    RV_pct_excl_fail: 0.27
    DR_pct_excl_fail: 0.76
    CF_pct_excl_fail: 0.12
    E_F1_excl_fail: 85.72
    E_P_excl_fail: 85.44
    E_R_excl_fail: 86
    R_F1_excl_fail: 42.2
    R_P_excl_fail: 36.41
    R_R_excl_fail: 50.17
- exp_id: w5_qwen_docred_lora_constrained_eval
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_pct: 0
    RV_pct: 0
    DR_pct: 0.01
    CF_pct: 0.41
    E_F1: 81.43
    E_P: 85.41
    E_R: 77.81
    R_F1: 40.56
    R_P: 36.35
    R_R: 45.86
    parse_fail_rate: 8.52
    total_samples: 998
    success_samples: 913
    fail_samples: 85
    total_entities_pred: 17799
    total_relations_pred: 15563
    E_F1_excl_fail: 85.69
    R_F1_excl_fail: 42.23
    delta_vs_unconstrained:
      delta_DR: -0.75
      delta_RV: -0.27
      delta_R_F1: -0.3
      delta_R_F1_excl_fail: 0.03
      DR_reduction_pct: 98.7
      note: 'Constrained - unconstrained. Unconstrained: DR=0.76%, R_F1=40.86, R_F1_excl_fail=42.20'
- exp_id: w6_mistral_scierc_unconstrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    E_P: 0.2402
    E_R: 0.3156
    E_F1: 0.2728
    R_P: 0.0295
    R_R: 0.0483
    R_F1: 0.0366
    ET_pct: 1.5
    RV_pct: 0
    DR_pct: 56.94
    CF_pct: 56.87
    parse_fail_rate: 0
    total_samples: 551
    total_pred_entities: 2202
    total_pred_relations: 1593
- exp_id: w6_mistral_scierc_constrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    E_P: 0.2437
    E_R: 0.3144
    E_F1: 0.2746
    R_P: 0.0292
    R_R: 0.0493
    R_F1: 0.0367
    ET_pct: 0
    RV_pct: 0
    DR_pct: 13.4
    CF_pct: 1.27
    CF_count: 21
    parse_fail_rate: 0
    total_samples: 551
    total_pred_entities: 2162
    total_pred_relations: 1647
    delta_vs_unconstrained:
      delta_E_F1: 0.0018
      delta_R_F1: 0.0001
      delta_ET: -1.5
      delta_RV: 0
      delta_DR: -43.54
      note: 'Constrained - unconstrained. Baseline: E_F1=0.2728, R_F1=0.0366, DR=56.94%,
        ET=1.5%, RV=0%'
- exp_id: w6_mistral_docred_unconstrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_samples: 998
    parse_failures: 7
    parse_fail_rate: 0.7
    total_pred_entities: 12580
    total_pred_relations: 11879
    ET_pct: 7.58
    RV_pct: 42.35
    DR_pct: 57.42
    CF_pct: 24.78
    E_P: 0.6221
    E_R: 0.3975
    E_F1: 0.4851
    R_P: 0.0447
    R_R: 0.0432
    R_F1: 0.0434
    f1_method: fuzzy_normalized
    f1_note: Relation matching uses case-insensitive normalization with token-overlap
      >80% and edit-distance ≤2 fallback. Strict R_F1=3.50% (delta +0.84pp from 98
      additional TPs via fuzzy matching of Mistral underscore/abbreviation variants).
- exp_id: w6_mistral_docred_constrained
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_pct: 0
    RV_pct: 0
    DR_pct: 33.2
    CF_pct: 0.19
    E_P: 65.02
    E_R: 41.4
    E_F1: 50.59
    R_P: 5.67
    R_R: 5.37
    R_F1: 5.52
    parse_fail_rate: 0.8
    total_samples: 998
    total_pred_entities: 12535
    total_pred_relations: 11554
    delta_vs_unconstrained:
      ET_pct: -7.58
      RV_pct: -42.35
      DR_pct: -24.22
      CF_pct: -24.59
      E_F1: 2.08
      R_F1: 2.02
- exp_id: w7_qwen_scierc_ft_grammar_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_pct: 0
    RV_pct: 0
    DR_pct: 1.9
    CF_pct: 0
    parse_fail_rate: 0
    total_samples: 551
    total_entities: 1784
    total_relations: 1128
    E_P: 0.6523
    E_R: 0.6898
    E_F1: 0.6705
    R_P: 0.4087
    R_R: 0.4733
    R_F1: 0.4386
    DR_violations: 22
    tokenizer_warning: false_positive_transformers_4.57.6
- exp_id: w7_qwen_scierc_ft_semantic_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_pct: 0
    RV_pct: 0
    DR_pct: 0.6
    CF_count: 15
    parse_fail_rate: 0
    total_samples: 551
    total_entities: 1784
    total_relations: 1128
    E_P: 0.6523
    E_R: 0.6898
    E_F1: 0.6705
    R_P: 0.4073
    R_R: 0.4713
    R_F1: 0.4369
    DR_violations: 7
    delta_vs_grammar_only:
      DR_delta: -1.3
      note: semantic_only DR=0.6% vs grammar_only DR=1.9%, semantic layer reduces
        DR by 68%
    delta_vs_unconstrained:
      DR_delta: -1.35
      note: unconstrained DR=1.95% → semantic_only 0.6%
- exp_id: w7_llama_scierc_ft_grammar_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    total_samples: 551
    json_parse_failures: 0
    total_entities: 1757
    total_relations: 1082
    entity_type_violation_rate: 0
    relation_vocabulary_violation_rate: 0
    domain_range_violation_rate: 0.0111
    cross_field_consistency_violation_rate: 0
    entity_f1:
      precision: 0.6647
      recall: 0.691
      f1: 0.6776
    relation_f1:
      precision: 0.432
      recall: 0.4795
      f1: 0.4545
- exp_id: w7_llama_scierc_ft_semantic_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ET_pct: 0
    RV_pct: 0
    DR_pct: 0.65
    CF_count: 2
    E_F1: 67.76
    E_P: 66.47
    E_R: 69.1
    R_F1: 45.47
    R_P: 43.24
    R_R: 47.95
    total_entities: 1757
    total_relations: 1081
    json_parse_failures: 0
- exp_id: w8_ft_posthoc_baseline
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ft_regime:
      qwen_scierc:
        R_F1_before: 43.86
        R_F1_posthoc: 43.94
        R_F1_constrained: 43.77
        reject_rate_pct: 1.95
        TP_lost: 4
      llama_scierc:
        R_F1_before: 45.45
        R_F1_posthoc: 45.23
        R_F1_constrained: 45.47
        reject_rate_pct: 1.11
        TP_lost: 5
      qwen_docred:
        R_F1_before: 40.91
        R_F1_posthoc: 41.11
        R_F1_constrained: TBD
        reject_rate_pct: 1.03
        TP_lost: 1
      llama_docred:
        R_F1_before: 43.77
        R_F1_posthoc: 43.92
        R_F1_constrained: 44.23
        reject_rate_pct: 0.64
        TP_lost: 1
    zs_regime:
      mistral_scierc:
        triples: 1584
        reject_pct: 20.27
        R_F1_before: 0.0376
        R_F1_posthoc: 0.0394
        R_F1_constrained: 0.0367
        TP_before: 48
        TP_after: 44
        TP_lost: 4
      qwen_scierc:
        triples: 1724
        reject_pct: 16.76
        R_F1_before: 0.0823
        R_F1_posthoc: 0.0863
        R_F1_constrained: 0.0836
        TP_before: 111
        TP_after: 104
        TP_lost: 7
      llama_scierc:
        triples: 1274
        reject_pct: 13.89
        R_F1_before: 0.0268
        R_F1_posthoc: 0.0271
        R_F1_constrained: 0.0254
        TP_before: 30
        TP_after: 28
        TP_lost: 2
      qwen_docred:
        triples: 17497
        reject_pct: 48.12
        R_F1_before: 0.0774
        R_F1_posthoc: 0.0961
        R_F1_constrained: 0.0823
        TP_before: 1137
        TP_after: 1010
        TP_lost: 127
      llama_docred:
        triples: 16437
        reject_pct: 42.18
        R_F1_before: 0.0598
        R_F1_posthoc: 0.0744
        R_F1_constrained: 0.0627
        TP_before: 850
        TP_after: 802
        TP_lost: 48
      mistral_docred:
        triples: 11836
        reject_pct: 73.73
        R_F1_before: 0.0434
        R_F1_posthoc: 0.0385
        R_F1_constrained: 0.0552
        TP_before: 518
        TP_after: 292
        TP_lost: 226
        removed_RV: 4172
        removed_ET: 3382
        removed_DR: 1173
        note: Only ZS case where posthoc HURTS R_F1 — 73.7% rejection rate loses 43.6%
          of TPs
    key_finding: 'ZS: post-hoc R_F1 >= constrained R_F1 in 5/6 groups. Exception:
      Mistral DocRED where extreme rejection rate (73.7%) causes net F1 loss. Constrained
      decoding value is in structural guarantee (0% violations) and composability,
      not F1 preservation.'
- exp_id: w8_llama_docred_ft_grammar_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    E_F1: 84.04
    R_F1: 43.77
    entity_precision: 84.99
    entity_recall: 83.11
    relation_precision: 38.6
    relation_recall: 50.53
    ET_pct: 0
    RV_pct: 0
    DR_pct: 0.51
    CF_pct: 0.12
    parse_fail_rate: 2.3
    total_samples: 998
    total_relations: 16199
    unique_entities: 13225
    parse_failures: 23
- exp_id: w8_qwen_docred_ft_grammar_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    E_F1: 82.19
    E_P: 85.47
    E_R: 79.16
    R_F1: 40.85
    R_P: 36.27
    R_R: 46.77
    ET_pct: 0
    RV_pct: 0
    DR_pct: 0.61
    CF_pct: 0.11
    parse_fail_rate: 7.01
    total_samples: 998
    parse_failures: 70
- exp_id: w8_qwen_docred_ft_semantic_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    E_F1: 82.15
    E_P: 85.58
    E_R: 78.99
    R_F1: 40.89
    R_P: 36.35
    R_R: 46.73
    ET_pct: 0
    RV_pct: 0.23
    DR_pct: 0.21
    CF_pct: 0.27
    parse_fail_rate: 7.52
    total_samples: 998
    parse_failures: 75
    documents_checked: 923
    total_entities: 18025
    total_triples: 15909
    DR_violations: 34
    RV_violations: 37
    ET_violations: 0
    CF_violations: 49
- exp_id: w8_llama_docred_ft_semantic_only
  name: ''
  status: DONE
  conclusion: success
  metrics:
    E_F1: 84.02
    E_P: 85.01
    E_R: 83.06
    R_F1: 43.9
    R_P: 38.89
    R_R: 50.4
    ET_pct: 0
    RV_pct: 0.15
    DR_pct: 0.3
    CF_pct: 0.16
    parse_fail_rate: 2.4
    total_samples: 998
    parse_failures: 24
    documents_checked: 974
    total_entities: 19099
    total_relations: 16038
    DR_violations: 48
    RV_violations: 24
    ET_violations: 0
    CF_violations: 31

# 输出格式（YAML，仅输出一个 ```yaml 块）

```yaml
tier: best
narrative_guidance: "..."
imagined_experiments:
  - name: "..."
    plan_id: "..."
    description: "..."
    expected_results: {metric: value, ...}
    result_rationale: "..."
    tables: []
    figures_description: []
    analysis: "..."
```


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "9892bc0f-ed9c-4ac7-ab74-05a30afa53d9",
  "type": "user",
  "uuid": "e196ea80-15d5-481d-bee7-52f0242ab512",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-16T17:34:20.187Z_

```json
{
  "parentUuid": "e196ea80-15d5-481d-bee7-52f0242ab512",
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
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch"
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
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "8156aee1-ff3f-4a02-bc46-10d052955c05",
  "timestamp": "2026-05-16T17:34:20.187Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-16T17:34:20.187Z_

```json
{
  "parentUuid": "8156aee1-ff3f-4a02-bc46-10d052955c05",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "3f4f6f06-7863-45da-b6ec-8a4d31067900",
  "timestamp": "2026-05-16T17:34:20.187Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：所有核心 claim 经受住审稿，novelty 被认可为 IE-specific 贡献而非简单迁移，CF 作为诚实 limitation 被接受 核心假设：['至少 2/3 审稿人认可 violation landscape study 作为独立贡献', 'enabling dependency（gramm…",
  "leafUuid": "3f4f6f06-7863-45da-b6ec-8a4d31067900",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

### Runtime record

_source line 7_

```json
{
  "type": "ai-title",
  "aiTitle": "OntoCoDec type-valid IE constraint enforcement",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

### Assistant

_source line 8 · 2026-05-16T17:34:24.509Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to generate detailed predicted data for each planned experiment in their experiment plan, under the "best" tier scenario they've defined. I need to first find the experiment_plan file to see what planned experiments exist.

Let me look for the experiment plan file in the project directory.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3f4f6f06-7863-45da-b6ec-8a4d31067900",
  "isSidechain": false,
  "requestId": "req_011Cb6eexDwianRakkKDpfXc",
  "type": "assistant",
  "uuid": "60c7f790-0ce4-4a4a-ae2b-fe4912d9ab01",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JSTMkH29br1TSbxBvdXjFQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 26133,
      "cache_read_input_tokens": 11841,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26133,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 184,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26133,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26133
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

_source line 9 · 2026-05-16T17:34:25.478Z_

Let me find the experiment plan to see all planned experiments.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "60c7f790-0ce4-4a4a-ae2b-fe4912d9ab01",
  "isSidechain": false,
  "requestId": "req_011Cb6eexDwianRakkKDpfXc",
  "type": "assistant",
  "uuid": "b9b66876-f20e-4f8a-b34c-67aab70ce0b2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JSTMkH29br1TSbxBvdXjFQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 26133,
      "cache_read_input_tokens": 11841,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26133,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 184,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26133,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26133
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

_source line 10 · 2026-05-16T17:34:25.787Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01HtMyx3pgSTmpt66G6Q6xAa`</summary>

```json
{
  "pattern": "**/*experiment_plan*"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b9b66876-f20e-4f8a-b34c-67aab70ce0b2",
  "isSidechain": false,
  "requestId": "req_011Cb6eexDwianRakkKDpfXc",
  "type": "assistant",
  "uuid": "ada8c2db-9130-45b6-b010-1a05e4bc1d1a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JSTMkH29br1TSbxBvdXjFQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 26133,
      "cache_read_input_tokens": 11841,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26133,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 184,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26133,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26133
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

_source line 11 · 2026-05-16T17:34:25.808Z_

<details open><summary>🔧 Tool call — Glob · `toolu_013rzHD7cs9yeotEfJVL4n6z`</summary>

```json
{
  "pattern": "**/*plan*"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ada8c2db-9130-45b6-b010-1a05e4bc1d1a",
  "isSidechain": false,
  "requestId": "req_011Cb6eexDwianRakkKDpfXc",
  "type": "assistant",
  "uuid": "f33b78ff-8b61-4bf1-9229-803e4e9942c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JSTMkH29br1TSbxBvdXjFQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 26133,
      "cache_read_input_tokens": 11841,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26133,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 184,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26133,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26133
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

_source line 12 · 2026-05-16T17:34:26.088Z_

<details><summary>↩ Tool result · `toolu_01HtMyx3pgSTmpt66G6Q6xAa`</summary>

```text
projects/prov_grounded_uie/experiment_plan.yaml
projects/schema_semantic_constrained_ie/experiment_plan.lock
projects/schema_semantic_constrained_ie/experiment_plan.yaml
projects/schema_semantic_constrained_ie/artifacts/llama_docred_maxtoken/experiment_plan.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ada8c2db-9130-45b6-b010-1a05e4bc1d1a",
  "isSidechain": false,
  "promptId": "9892bc0f-ed9c-4ac7-ab74-05a30afa53d9",
  "type": "user",
  "uuid": "ee9db3a7-5ef8-4ffd-905a-255f0c0011c6",
  "toolUseResult": {
    "filenames": [
      "projects/prov_grounded_uie/experiment_plan.yaml",
      "projects/schema_semantic_constrained_ie/experiment_plan.lock",
      "projects/schema_semantic_constrained_ie/experiment_plan.yaml",
      "projects/schema_semantic_constrained_ie/artifacts/llama_docred_maxtoken/experiment_plan.md"
    ],
    "durationMs": 285,
    "numFiles": 4,
    "truncated": false
  },
  "sourceToolAssistantUUID": "ada8c2db-9130-45b6-b010-1a05e4bc1d1a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-16T17:34:26.098Z_

<details><summary>↩ Tool result · `toolu_013rzHD7cs9yeotEfJVL4n6z`</summary>

```text
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/include/arrow/acero/exec_plan.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/include/arrow/dataset/plan.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/include/arrow/engine/substrait/test_plan_builder.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/tests/test_exec_plan.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/tests/__pycache__/test_exec_plan.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/plane.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/tests/test_plane.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/__pycache__/plane.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/tests/__pycache__/test_plane.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/planar_drawing.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/planarity.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/test_planar_drawing.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/test_planarity.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/__pycache__/planar_drawing.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/__pycache__/planarity.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/__pycache__/test_planar_drawing.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/__pycache__/test_planarity.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/_inductor/codegen/memory_planning.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/_dedup_save_plans.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/default_planner.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/planner.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/planner_helpers.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/elastic/control_plane.py
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache_compositeimplicitautograd_dispatch.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache_native.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache_ops.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size_compositeimplicitautograd_dispatch.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size_native.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size_ops.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size_compositeimplicitautograd_dispatch.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size_native.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size_ops.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size_compositeimplicitautograd_dispatch.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size_native.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size_ops.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/torch/csrc/jit/runtime/static/memory_planner.h
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/_inductor/codegen/__pycache__/memory_planning.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/_dedup_save_plans.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/default_planner.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/planner.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/planner_helpers.cpython-314.pyc
projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/elastic/__pycache__/control_plane.cpython-314.pyc
projects/prov_grounded_uie/logs/workers/worker_code_experiment-plan_20260512T114557.log
projects/prov_grounded_uie/logs/workers/worker_code_experiment-plan_20260512T114557_result.json
projects/prov_grounded_uie/experiment_plan.yaml
projects/schema_semantic_constrained_ie/experiment_plan.lock
projects/schema_semantic_constrained_ie/experiment_plan.yaml
projects/schema_semantic_constrained_ie/writing_plan.yaml
projects/schema_semantic_constrained_ie/artifacts/llama_docred_maxtoken/experiment_plan.md
projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200.log
projects/schema_semantic_constrained_ie/logs/chats/worker_research_pair_based_impl_plan_20260515T141200.lock
projects/schema_semantic_constrained_ie/logs/chats/worker_research_pair_based_impl_plan_20260515T141200.jsonl
projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200_retry1.log
projects/schema_semantic_constrained_ie/artifacts/pair_based_enforcement_plan.md
projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200_retry2.log
projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200_result.json
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f33b78ff-8b61-4bf1-9229-803e4e9942c2",
  "isSidechain": false,
  "promptId": "9892bc0f-ed9c-4ac7-ab74-05a30afa53d9",
  "type": "user",
  "uuid": "f0a3d4d3-3a4b-40e4-b797-ae5af6286988",
  "toolUseResult": {
    "filenames": [
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/include/arrow/acero/exec_plan.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/include/arrow/dataset/plan.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/include/arrow/engine/substrait/test_plan_builder.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/tests/test_exec_plan.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/pyarrow/tests/__pycache__/test_exec_plan.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/plane.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/tests/test_plane.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/__pycache__/plane.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/sympy/geometry/tests/__pycache__/test_plane.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/planar_drawing.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/planarity.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/test_planar_drawing.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/test_planarity.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/__pycache__/planar_drawing.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/__pycache__/planarity.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/__pycache__/test_planar_drawing.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/networkx/algorithms/tests/__pycache__/test_planarity.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/_inductor/codegen/memory_planning.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/_dedup_save_plans.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/default_planner.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/planner.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/planner_helpers.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/elastic/control_plane.py",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache_compositeimplicitautograd_dispatch.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache_native.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_clear_plan_cache_ops.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size_compositeimplicitautograd_dispatch.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size_native.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_max_size_ops.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size_compositeimplicitautograd_dispatch.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size_native.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_get_plan_cache_size_ops.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size_compositeimplicitautograd_dispatch.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size_native.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/ATen/ops/_cufft_set_plan_cache_max_size_ops.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/include/torch/csrc/jit/runtime/static/memory_planner.h",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/_inductor/codegen/__pycache__/memory_planning.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/_dedup_save_plans.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/default_planner.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/planner.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/checkpoint/__pycache__/planner_helpers.cpython-314.pyc",
      "projects/prov_grounded_uie/artifacts/.venv/lib/python3.14/site-packages/torch/distributed/elastic/__pycache__/control_plane.cpython-314.pyc",
      "projects/prov_grounded_uie/logs/workers/worker_code_experiment-plan_20260512T114557.log",
      "projects/prov_grounded_uie/logs/workers/worker_code_experiment-plan_20260512T114557_result.json",
      "projects/prov_grounded_uie/experiment_plan.yaml",
      "projects/schema_semantic_constrained_ie/experiment_plan.lock",
      "projects/schema_semantic_constrained_ie/experiment_plan.yaml",
      "projects/schema_semantic_constrained_ie/writing_plan.yaml",
      "projects/schema_semantic_constrained_ie/artifacts/llama_docred_maxtoken/experiment_plan.md",
      "projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200.log",
      "projects/schema_semantic_constrained_ie/logs/chats/worker_research_pair_based_impl_plan_20260515T141200.lock",
      "projects/schema_semantic_constrained_ie/logs/chats/worker_research_pair_based_impl_plan_20260515T141200.jsonl",
      "projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200_retry1.log",
      "projects/schema_semantic_constrained_ie/artifacts/pair_based_enforcement_plan.md",
      "projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200_retry2.log",
      "projects/schema_semantic_constrained_ie/logs/workers/worker_research_pair_based_impl_plan_20260515T141200_result.json"
    ],
    "durationMs": 281,
    "numFiles": 60,
    "truncated": false
  },
  "sourceToolAssistantUUID": "f33b78ff-8b61-4bf1-9229-803e4e9942c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-16T17:34:30.037Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NDN83tkWYnY8VSez8fat5T`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/experiment_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f0a3d4d3-3a4b-40e4-b797-ae5af6286988",
  "isSidechain": false,
  "requestId": "req_011Cb6efPWTqGMfp5b3agM5X",
  "type": "assistant",
  "uuid": "06abfce0-8538-41dd-9e21-2597d1b9f37c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G52VAVDRgQDFy9bg2YtJGf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2962,
      "cache_read_input_tokens": 37974,
      "output_tokens": 88,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2962,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 88,
          "cache_read_input_tokens": 37974,
          "cache_creation_input_tokens": 2962,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2962
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

_source line 15 · 2026-05-16T17:34:30.118Z_

<details><summary>↩ Tool result · `toolu_01NDN83tkWYnY8VSez8fat5T`</summary>

```text
1	## OntoCoDec Experiment Plan
2	## Target: EMNLP 2026 ARR (May 25, 2026)
3	## Last updated: 2026-05-14
4	
5	claims:
6	  C1_violation_landscape:
7	    description: "LLM-based IE violates ontology type constraints at non-trivial rates; violation rate driven by constraint tightness × model RV baseline, not ontology size"
8	    status: supported
9	    evidence_strength: strong
10	
11	  C2_prompt_insufficiency:
12	    description: "Schema-informed prompting reduces but cannot eliminate violations; unreliable per-relation"
13	    status: supported
14	    evidence_strength: strong
15	
16	  C3_composable_framework:
17	    description: "OntoCoDec compiles IE ontology schemas into two composable constraint layers (grammar+semantic) with enabling dependency; near-complete DR elimination"
18	    status: supported
19	    evidence_strength: strong
20	
21	  C4_s1_vs_s2:
22	    description: "S2 two-pass offers no advantage over S1 single-pass; S1 adopted as primary"
23	    status: supported_demoted
24	    evidence_strength: moderate
25	    note: "S2 demoted to ablation (D007). S1 simpler + marginally better F1."
26	
27	  C5_cross_model:
28	    description: "OntoCoDec generalizes across models without code modification; DR reduction magnitude varies with model RV baseline"
29	    status: supported
30	    evidence_strength: strong
31	
32	  C6_f1_impact:
33	    description: "Constraint enforcement preserves or improves F1; improvement is model/dataset-dependent (Qwen DocRED significant, SciERC neutral)"
34	    status: supported
35	    evidence_strength: strong
36	
37	experiments:
38	  # --- Phase 0: Violation Landscape (ALL COMPLETE) ---
39	  - plan_id: P001
40	    name: SciERC violation rate (minimal prompt)
41	    claim: C1_violation_landscape
42	    registry_id: mvp_phase0_violation_rate
43	    priority: 1
44	    result: "DR=15.4%, 1724 triples"
45	
46	  - plan_id: P002
47	    name: SciERC violation rate (schema-informed prompt)
48	    claim: C2_prompt_insufficiency
49	    registry_id: mvp_phase0_scierc_schema
50	    priority: 1
51	    result: "DR=5.78%, -62.4% reduction, Evaluate-for regression"
52	
53	  - plan_id: P003
54	    name: DocRED violation rate (minimal prompt)
55	    claim: C1_violation_landscape
56	    registry_id: mvp_phase0_violation_rate_docred
57	    priority: 1
58	    result: "DR=18.7%, RV=28.9%"
59	
60	  - plan_id: P004
61	    name: DocRED violation rate (schema-informed prompt)
62	    claim: C2_prompt_insufficiency
63	    registry_id: mvp_phase0_docred_schema
64	    priority: 1
65	    result: "DR=12.8%, -32% reduction (weaker than SciERC)"
66	
67	  # --- Phase 2: SciERC Ablation (ALL COMPLETE) ---
68	  - plan_id: P005a
69	    name: SciERC unconstrained baseline
70	    claim: C3_composable_framework
71	    registry_id: phase2_scierc_unconstrained
72	    priority: 1
73	    result: "DR=15.37%, RV=1.39%, ET=0.40%, R-F1=8.23%"
74	
75	  - plan_id: P005
76	    name: SciERC grammar-only
77	    claim: C3_composable_framework
78	    registry_id: phase2_scierc_grammar_only
79	    priority: 1
80	    result: "RV→0%, ET→0%, DR=14.84% (grammar alone doesn't reduce DR), E-F1=30.98%"
81	
82	  - plan_id: P006
83	    name: SciERC semantic-only
84	    claim: C3_composable_framework
85	    registry_id: phase2_scierc_semantic_only
86	    priority: 1
87	    result: "DR=11.65% (↓24%), RV/ET unchanged, demonstrates enabling dependency"
88	
89	  - plan_id: P007
90	    name: SciERC full S1
91	    claim: C3_composable_framework
92	    registry_id: phase2_scierc_full_s1
93	    priority: 1
94	    result: "DR=0.93% (↓94%), RV/ET→0%, CF=9.90%, R-F1=8.36% (+0.13pp, p=0.58)"
95	
96	  - plan_id: P008
97	    name: SciERC full S2 (ablation)
98	    claim: C4_s1_vs_s2
99	    registry_id: phase2_scierc_full_s2
100	    priority: 1
101	    result: "DR=0.97%, CF=8.03%, R-F1=8.03% (worse than S1). Demoted."
102	
103	  # --- Phase 2: DocRED Ablation (ALL COMPLETE) ---
104	  - plan_id: P009
105	    name: DocRED unconstrained baseline
106	    claim: C3_composable_framework
107	    registry_id: phase2_docred_unconstrained
108	    priority: 1
109	    result: "DR=18.46%, RV=29.66%, ET=2.48%, R-F1=7.73%"
110	
111	  - plan_id: P010
112	    name: DocRED grammar-only
113	    claim: C3_composable_framework
114	    registry_id: phase2_docred_grammar_only
115	    priority: 1
116	    result: "RV→0.03%, ET→0%, E-F1=59.38% (grammar drives all E-F1 gain)"
117	
118	  - plan_id: P011
119	    name: DocRED semantic-only
120	    claim: C3_composable_framework
121	    registry_id: phase2_docred_semantic_only
122	    priority: 1
123	    result: "DR=13.96%, ET=4.22%"
124	
125	  - plan_id: P012
126	    name: DocRED full S1
127	    claim: C3_composable_framework
128	    registry_id: phase2_docred_full_s1
129	    priority: 1
130	    result: "DR=10.21% (↓45%), RV→0.03%, ET→0%, CF=2.57%, R-F1=8.23% (+0.50pp, p<0.001), E-F1=59.37% (+1.22pp, p<0.001)"
131	
132	  # --- Phase 2: Cross-Model (ALL COMPLETE) ---
133	  - plan_id: P013
134	    name: Llama SciERC unconstrained
135	    claim: C5_cross_model
136	    registry_id: llama_scierc_unconstrained
137	    priority: 2
138	    result: "DR=17.53%, RV=0.23%, ET=0.27%"
139	
140	  - plan_id: P014
141	    name: Llama SciERC full S1
142	    claim: C5_cross_model
143	    registry_id: llama_scierc_full_s1
144	    priority: 2
145	    result: "DR=0.10% (↓99.4%), RV/ET→0%, R-F1 neutral"
146	
147	  - plan_id: P015
148	    name: Llama DocRED unconstrained
149	    claim: C5_cross_model
150	    registry_id: llama_docred_unconstrained
151	    priority: 2
152	    result: "DR=26.07%, RV=16.03%, ET=0.13%, R-F1=5.98%"
153	
154	  - plan_id: P016
155	    name: Llama DocRED full S1
156	    claim: C5_cross_model
157	    registry_id: llama_docred_full_s1
158	    priority: 2
159	    result: "DR=2.55% (↓90.2%), RV/ET→0%, CF=12.02%, R-F1=6.27% (+0.29pp), E-F1=55.01% (-0.64pp), parse_failures=91/998"
160	
161	  # --- Supplementary (ALL COMPLETE) ---
162	  - plan_id: P017
163	    name: S2 pilot (50 docs)
164	    claim: C4_s1_vs_s2
165	    registry_id: phase2_s2_pilot50
166	    priority: 3
167	    result: "Pilot confirmed S2 works, full run in P008"
168	
169	  - plan_id: P018
170	    name: Post-hoc filtering baseline
171	    claim: C6_f1_impact
172	    registry_id: posthoc_filtering_baseline
173	    priority: 2
174	    result: "Post-hoc F1 > OntoCoDec F1 on both datasets. Framing: multi-dimensional (D013)"
175	    note: "Not in registry — computed offline"
176	
177	  - plan_id: P019
178	    name: Bootstrap CI (10000 iterations)
179	    claim: C6_f1_impact
180	    registry_id: d012_bootstrap_ci
181	    priority: 1
182	    result: "SciERC R-F1 +0.13pp p=0.58; DocRED R-F1 +0.50pp p<0.001, E-F1 +1.23pp p<0.001"
183	    note: "Computed offline, not GPU experiment"
184	
185	  - plan_id: P020
186	    name: DocRED schema compilation (Phase 0 R2)
187	    claim: C1_violation_landscape
188	    registry_id: mvp_phase0_docred_schema_r2
189	    priority: 3
190	    result: "killed — superseded by P004"
191	
192	gpu_budget:
193	  allocated: "westd-16980 cuda:0, cuda:1 (2x RTX PRO 6000 96GB)"
194	  total_used: "~30 GPU-hours"
195	  status: "All experiments complete. GPUs idle."
196	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "06abfce0-8538-41dd-9e21-2597d1b9f37c",
  "isSidechain": false,
  "promptId": "9892bc0f-ed9c-4ac7-ab74-05a30afa53d9",
  "type": "user",
  "uuid": "881b29c6-9920-48f8-a25c-e5b8adc85d7e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/experiment_plan.yaml",
      "content": "## OntoCoDec Experiment Plan\n## Target: EMNLP 2026 ARR (May 25, 2026)\n## Last updated: 2026-05-14\n\nclaims:\n  C1_violation_landscape:\n    description: \"LLM-based IE violates ontology type constraints at non-trivial rates; violation rate driven by constraint tightness × model RV baseline, not ontology size\"\n    status: supported\n    evidence_strength: strong\n\n  C2_prompt_insufficiency:\n    description: \"Schema-informed prompting reduces but cannot eliminate violations; unreliable per-relation\"\n    status: supported\n    evidence_strength: strong\n\n  C3_composable_framework:\n    description: \"OntoCoDec compiles IE ontology schemas into two composable constraint layers (grammar+semantic) with enabling dependency; near-complete DR elimination\"\n    status: supported\n    evidence_strength: strong\n\n  C4_s1_vs_s2:\n    description: \"S2 two-pass offers no advantage over S1 single-pass; S1 adopted as primary\"\n    status: supported_demoted\n    evidence_strength: moderate\n    note: \"S2 demoted to ablation (D007). S1 simpler + marginally better F1.\"\n\n  C5_cross_model:\n    description: \"OntoCoDec generalizes across models without code modification; DR reduction magnitude varies with model RV baseline\"\n    status: supported\n    evidence_strength: strong\n\n  C6_f1_impact:\n    description: \"Constraint enforcement preserves or improves F1; improvement is model/dataset-dependent (Qwen DocRED significant, SciERC neutral)\"\n    status: supported\n    evidence_strength: strong\n\nexperiments:\n  # --- Phase 0: Violation Landscape (ALL COMPLETE) ---\n  - plan_id: P001\n    name: SciERC violation rate (minimal prompt)\n    claim: C1_violation_landscape\n    registry_id: mvp_phase0_violation_rate\n    priority: 1\n    result: \"DR=15.4%, 1724 triples\"\n\n  - plan_id: P002\n    name: SciERC violation rate (schema-informed prompt)\n    claim: C2_prompt_insufficiency\n    registry_id: mvp_phase0_scierc_schema\n    priority: 1\n    result: \"DR=5.78%, -62.4% reduction, Evaluate-for regression\"\n\n  - plan_id: P003\n    name: DocRED violation rate (minimal prompt)\n    claim: C1_violation_landscape\n    registry_id: mvp_phase0_violation_rate_docred\n    priority: 1\n    result: \"DR=18.7%, RV=28.9%\"\n\n  - plan_id: P004\n    name: DocRED violation rate (schema-informed prompt)\n    claim: C2_prompt_insufficiency\n    registry_id: mvp_phase0_docred_schema\n    priority: 1\n    result: \"DR=12.8%, -32% reduction (weaker than SciERC)\"\n\n  # --- Phase 2: SciERC Ablation (ALL COMPLETE) ---\n  - plan_id: P005a\n    name: SciERC unconstrained baseline\n    claim: C3_composable_framework\n    registry_id: phase2_scierc_unconstrained\n    priority: 1\n    result: \"DR=15.37%, RV=1.39%, ET=0.40%, R-F1=8.23%\"\n\n  - plan_id: P005\n    name: SciERC grammar-only\n    claim: C3_composable_framework\n    registry_id: phase2_scierc_grammar_only\n    priority: 1\n    result: \"RV→0%, ET→0%, DR=14.84% (grammar alone doesn't reduce DR), E-F1=30.98%\"\n\n  - plan_id: P006\n    name: SciERC semantic-only\n    claim: C3_composable_framework\n    registry_id: phase2_scierc_semantic_only\n    priority: 1\n    result: \"DR=11.65% (↓24%), RV/ET unchanged, demonstrates enabling dependency\"\n\n  - plan_id: P007\n    name: SciERC full S1\n    claim: C3_composable_framework\n    registry_id: phase2_scierc_full_s1\n    priority: 1\n    result: \"DR=0.93% (↓94%), RV/ET→0%, CF=9.90%, R-F1=8.36% (+0.13pp, p=0.58)\"\n\n  - plan_id: P008\n    name: SciERC full S2 (ablation)\n    claim: C4_s1_vs_s2\n    registry_id: phase2_scierc_full_s2\n    priority: 1\n    result: \"DR=0.97%, CF=8.03%, R-F1=8.03% (worse than S1). Demoted.\"\n\n  # --- Phase 2: DocRED Ablation (ALL COMPLETE) ---\n  - plan_id: P009\n    name: DocRED unconstrained baseline\n    claim: C3_composable_framework\n    registry_id: phase2_docred_unconstrained\n    priority: 1\n    result: \"DR=18.46%, RV=29.66%, ET=2.48%, R-F1=7.73%\"\n\n  - plan_id: P010\n    name: DocRED grammar-only\n    claim: C3_composable_framework\n    registry_id: phase2_docred_grammar_only\n    priority: 1\n    result: \"RV→0.03%, ET→0%, E-F1=59.38% (grammar drives all E-F1 gain)\"\n\n  - plan_id: P011\n    name: DocRED semantic-only\n    claim: C3_composable_framework\n    registry_id: phase2_docred_semantic_only\n    priority: 1\n    result: \"DR=13.96%, ET=4.22%\"\n\n  - plan_id: P012\n    name: DocRED full S1\n    claim: C3_composable_framework\n    registry_id: phase2_docred_full_s1\n    priority: 1\n    result: \"DR=10.21% (↓45%), RV→0.03%, ET→0%, CF=2.57%, R-F1=8.23% (+0.50pp, p<0.001), E-F1=59.37% (+1.22pp, p<0.001)\"\n\n  # --- Phase 2: Cross-Model (ALL COMPLETE) ---\n  - plan_id: P013\n    name: Llama SciERC unconstrained\n    claim: C5_cross_model\n    registry_id: llama_scierc_unconstrained\n    priority: 2\n    result: \"DR=17.53%, RV=0.23%, ET=0.27%\"\n\n  - plan_id: P014\n    name: Llama SciERC full S1\n    claim: C5_cross_model\n    registry_id: llama_scierc_full_s1\n    priority: 2\n    result: \"DR=0.10% (↓99.4%), RV/ET→0%, R-F1 neutral\"\n\n  - plan_id: P015\n    name: Llama DocRED unconstrained\n    claim: C5_cross_model\n    registry_id: llama_docred_unconstrained\n    priority: 2\n    result: \"DR=26.07%, RV=16.03%, ET=0.13%, R-F1=5.98%\"\n\n  - plan_id: P016\n    name: Llama DocRED full S1\n    claim: C5_cross_model\n    registry_id: llama_docred_full_s1\n    priority: 2\n    result: \"DR=2.55% (↓90.2%), RV/ET→0%, CF=12.02%, R-F1=6.27% (+0.29pp), E-F1=55.01% (-0.64pp), parse_failures=91/998\"\n\n  # --- Supplementary (ALL COMPLETE) ---\n  - plan_id: P017\n    name: S2 pilot (50 docs)\n    claim: C4_s1_vs_s2\n    registry_id: phase2_s2_pilot50\n    priority: 3\n    result: \"Pilot confirmed S2 works, full run in P008\"\n\n  - plan_id: P018\n    name: Post-hoc filtering baseline\n    claim: C6_f1_impact\n    registry_id: posthoc_filtering_baseline\n    priority: 2\n    result: \"Post-hoc F1 > OntoCoDec F1 on both datasets. Framing: multi-dimensional (D013)\"\n    note: \"Not in registry — computed offline\"\n\n  - plan_id: P019\n    name: Bootstrap CI (10000 iterations)\n    claim: C6_f1_impact\n    registry_id: d012_bootstrap_ci\n    priority: 1\n    result: \"SciERC R-F1 +0.13pp p=0.58; DocRED R-F1 +0.50pp p<0.001, E-F1 +1.23pp p<0.001\"\n    note: \"Computed offline, not GPU experiment\"\n\n  - plan_id: P020\n    name: DocRED schema compilation (Phase 0 R2)\n    claim: C1_violation_landscape\n    registry_id: mvp_phase0_docred_schema_r2\n    priority: 3\n    result: \"killed — superseded by P004\"\n\ngpu_budget:\n  allocated: \"westd-16980 cuda:0, cuda:1 (2x RTX PRO 6000 96GB)\"\n  total_used: \"~30 GPU-hours\"\n  status: \"All experiments complete. GPUs idle.\"\n",
      "numLines": 196,
      "startLine": 1,
      "totalLines": 196
    }
  },
  "sourceToolAssistantUUID": "06abfce0-8538-41dd-9e21-2597d1b9f37c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 16_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：所有核心 claim 经受住审稿，novelty 被认可为 IE-specific 贡献而非简单迁移，CF 作为诚实 limitation 被接受 核心假设：['至少 2/3 审稿人认可 violation landscape study 作为独立贡献', 'enabling dependency（gramm…",
  "leafUuid": "881b29c6-9920-48f8-a25c-e5b8adc85d7e",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

### Runtime record

_source line 17_

```json
{
  "type": "ai-title",
  "aiTitle": "OntoCoDec type-valid IE constraint enforcement",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

### Runtime record

_source line 18 · 2026-05-16T17:34:30.215Z_

````json
{
  "parentUuid": "881b29c6-9920-48f8-a25c-e5b8adc85d7e",
  "isSidechain": false,
  "attachment": {
    "type": "nested_memory",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/CLAUDE.md",
    "content": {
      "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/CLAUDE.md",
      "type": "Project",
      "content": "## 当前项目\n当前绑定项目：**schema_semantic_constrained_ie**\n\n## 按需查阅\n- 项目配置：`load_project_config(\"schema_semantic_constrained_ie\")` 或 `load_project_config(\"schema_semantic_constrained_ie\", section=\"execution\")`\n- 知识文件：`read_project_file(file=...)` 读取项目文件（ROADMAP.md/memory.md/ideas.md/report.md 等）\n- 路线图：`read_roadmap()` 读取研究方向和短期任务\n- 产出目录：`/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/`（写文件后用 `register_artifact` 注册）\n\n## Worker 操作规范\n\n### ssh-env-setup\n\n# 远程服务器环境搭建规范\n\n## 核心原则\n\n**先探测，再安装。** 不要假设服务器上什么都没有——很多包已经装好了。安装前必须走 discovery 流程。\n\n**镜像快速路径**：连接服务器后，先用 `detect_image` 检测是否为预置镜像。如果是已知镜像且版本匹配，跳过基础环境搭建（Phase 1-4），直接安装项目特有依赖。未检测到镜像时走传统流程。\n\n**aml-train 镜像使用 conda 环境**（不是 venv）。环境激活：`source /root/miniconda3/etc/profile.d/conda.sh && conda activate base`。pip/python 在 `/root/miniconda3/bin/` 下。**不要假设 .venv 存在，不要创建 venv。**\n\n## Phase 1: 环境探测（用 ssh_read_only）\n\n连接到服务器后，第一步永远是收集信息，不要直接装东西：\n\n```bash\n# 1. Python 环境\nwhich python3 && python3 --version\npip3 --version 2>/dev/null || echo \"NO_PIP\"\n\n# 2. CUDA 环境\nnvidia-smi --query-gpu=name,memory.total,driver_version --format=csv,noheader 2>/dev/null || echo \"NO_GPU\"\nnvcc --version 2>/dev/null | grep \"release\" || echo \"NO_NVCC\"\n\n# 3. 包管理器\nls -d /opt/miniconda3 ~/miniconda3 ~/.conda 2>/dev/null || echo \"NO_CONDA\"\nls -d .venv venv env 2>/dev/null || echo \"NO_VENV\"\npip3 list --format=freeze 2>/dev/null | grep -iE \"torch|transformers|flash\" || echo \"NO_ML_PKGS\"\n\n# 4. PEP 668 检查\npython3 -c \"import sysconfig; print(sysconfig.get_path('stdlib'))\" 2>/dev/null\nls /usr/lib/python*/EXTERNALLY-MANAGED 2>/dev/null && echo \"PEP668_MANAGED\" || echo \"PEP668_OK\"\n```\n\n根据探测结果决定安装策略，不要猜。\n\n## Phase 2: 环境策略选择\n\n根据 Phase 1 结果选择**一个**策略，不要混用：\n\n| 探测结果 | 策略 | 说明 |\n|----------|------|------|\n| 项目目录有 `.venv/` | 用它：`source .venv/bin/activate` | 最优先 |\n| 有 conda 且有写权限 | `conda activate base` 或创建专属 env | 次优先 |\n| PEP668_MANAGED + 无 venv | 创建 venv：`python3 -m venv .venv && source .venv/bin/activate` | 不要用 --break-system-packages |\n| PEP668_OK（无保护） | 直接 `pip install`（旧系统） | 仍建议 venv |\n\n**决不混用 conda install + pip install 到同一环境。** 选了 pip 就全用 pip。\n\n## Phase 3: PyTorch 安装\n\n### CUDA 版本映射（2025-2026 常用）\n\n先从 `nvcc --version` 或 `nvidia-smi` 获取 CUDA 版本，然后匹配：\n\n| CUDA 版本 | PyTorch pip index URL | 推荐 torch 版本 |\n|-----------|----------------------|-----------------|\n| 11.8 | `https://download.pytorch.org/whl/cu118` | ≥ 2.0 |\n| 12.1 | `https://download.pytorch.org/whl/cu121` | ≥ 2.1 |\n| 12.4 | `https://download.pytorch.org/whl/cu124` | ≥ 2.4 |\n| 12.6 | `https://download.pytorch.org/whl/cu126` | ≥ 2.6 |\n\n**不要猜版本号。** 如果不确定可用版本：\n```bash\npip index versions torch --index-url https://download.pytorch.org/whl/cu121 2>/dev/null | head -3\n```\n\n安装命令：\n```bash\npip install torch torchvision torchaudio --index-url https://download.pytorch.org/whl/cu{CUDA_SHORT}\n```\n\n### 大包超时处理\n\nPyTorch wheel 约 500MB-2GB，默认 SSH 超时可能不够。策略：\n\n```bash\n# 方法 1: nohup + 轮询（推荐）\nnohup pip install torch torchvision torchaudio --index-url https://download.pytorch.org/whl/cu121 > /tmp/pip_install.log 2>&1 &\necho $!  # 记录 PID\n\n# 后续用 ssh_read_only 轮询\ncat /tmp/pip_install.log | tail -5\nps -p &lt;PID> -o pid= 2>/dev/null && echo \"STILL_RUNNING\" || echo \"DONE\"\n```\n\n```bash\n# 方法 2: 加大 pip 超时\npip install --timeout 300 torch ...\n```\n\n## Phase 4: 验证（必须执行）\n\n安装后必须验证，不要假设成功：\n\n```bash\npython3 -c \"\nimport torch\nprint(f'torch={torch.__version__}, cuda={torch.cuda.is_available()}, gpus={torch.cuda.device_count()}')\nif torch.cuda.is_available():\n    for i in range(torch.cuda.device_count()):\n        print(f'  GPU {i}: {torch.cuda.get_device_name(i)} ({torch.cuda.get_device_properties(i).total_mem // 1024**3}GB)')\n\"\n```\n\n验证失败的常见原因：\n- `torch.cuda.is_available()` 返回 False → CUDA 版本和 torch 不匹配，重装正确版本\n- `ImportError: libcudnn` → 缺 cuDNN，装 `nvidia-cudnn-cu1x`\n- GPU 数量不对 → 检查 `CUDA_VISIBLE_DEVICES` 环境变量\n\n## Phase 5: 项目依赖\n\n基础环境就绪后，安装项目依赖：\n\n```bash\n# 优先用 requirements.txt / pyproject.toml\npip install -r requirements.txt  # 或 pip install -e .\n\n# 常用 ML 依赖补装\npip install transformers datasets einops accelerate wandb\n```\n\nflash-attention 特殊处理（编译型包）：\n```bash\n# 需要匹配的 CUDA toolkit，编译耗时 5-15 分钟\npip install flash-attn --no-build-isolation\n# 如果编译失败，试预编译版本\npip install flash-attn --no-build-isolation 2>/dev/null || pip install flash-attn-wheels\n```\n\n## ssh_read_only vs ssh_execute 使用规则\n\n| 操作 | 用哪个工具 |\n|------|-----------|\n| 检查环境（python --version, nvidia-smi, pip list） | `ssh_read_only` |\n| 读文件内容、查日志 | `ssh_read_only` |\n| 安装包（pip install, conda install） | `ssh_execute` |\n| 创建/修改文件、启动进程 | `ssh_execute` |\n| 运行实验脚本 | `ssh_execute` |\n\n**原则：能用 read_only 就用 read_only，只有要改变服务器状态时才用 execute。**\n\n## AutoDL 专项注意事项\n\nAutoDL 实例有一系列特殊约束，5 个项目反复踩坑，必须遵守：\n\n### 磁盘\n- **根分区只有 ~30GB，严禁存大文件。** 模型、数据集、HF cache 全部放数据盘 `/root/autodl-tmp/`\n- 设置 `HF_HOME=/root/autodl-tmp/.hf_cache`，否则 HF 默认缓存到根分区导致磁盘满\n- 下载模型时用 `--local-dir /root/autodl-tmp/models/&lt;name>`，不要用默认路径\n\n### 网络\n- pip install / git clone 前必须 `source /etc/network_turbo` 启用代理加速，否则 pypi.nvidia.com 504 超时、GitHub TLS 断连\n- HF 下载设 `HF_HUB_DISABLE_XET=1`，xet_get 在 AutoDL 上返回 401\n- **SSL 证书**：`network_turbo` 的代理使用自签名证书，Python 默认 SSL 验证会失败。必须设置 `REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt` 和 `SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt`，否则 HF 下载、datasets 加载等全部报 SSL 错误\n- **大模型下载优先用 ModelScope**：AutoDL 代理下载 HuggingFace 大文件极慢（~200KB/s），改用 ModelScope 国内 CDN 速度快很多。`pip install modelscope && python -c \"from modelscope import snapshot_download; snapshot_download('Qwen/Qwen2.5-7B-Instruct', cache_dir='/root/autodl-tmp/.hf_cache')\"`\n\n### SSH\n- **AutoDL 实例重启后 SSH 端口会变。** 连接失败时不要反复重试，应提示用户去控制台查新端口并更新 `~/.ssh/config`\n\n## 经验沉淀\n\n- [2026-04-05] Worker 首次连接服务器时，先用一条 ssh_read_only 组合命令完成全部探测，减少 SSH 往返次数\n- [2026-04-05] 遇到 PEP 668 时创建 venv 而非 --break-system-packages，避免污染系统 Python\n- [2026-04-05] PyTorch 大包安装用 nohup 后台执行 + 轮询方式，避免 SSH 超时导致安装中断\n- [2026-04-05] conda 环境和 pip 不要混用——如果项目用 pip，就全部用 pip\n- [2026-04-09] sync_code 前确保本地 commit 已 push 到 remote，否则服务器 git pull 拉不到最新代码\n- [2026-04-09] venv 创建后用 `which python` 验证路径指向正确的 venv python，不要假设系统 PATH 正确\n\n## 更多 Skills（按需加载）\n\n执行相关任务前，先 Read 对应 skill 获取环境配置和最佳实践。\n\n- **check-training-status** — 当用户问训练进度/实验状态/查状态时使用。用专用工具查看训练状态，禁止 ssh_execute。  →  `/home/ubuntu/agent-ml-research/skills/global/check-training-status.skill.md`\n- **rebuttal** — 撰写和优化学术 rebuttal——逐条回应审稿意见，生成 response letter。当收到审稿意见、需要写 rebuttal、回复 reviewer 评论时使用。关键词：rebuttal、审稿意见、reviewer response、author response、meta-review、AC 意见。  →  `/home/ubuntu/agent-ml-research/skills/global/rebuttal.skill.md`\n- **review-reviewer-session-start** — Review Reviewer session 启动初始化——检查论文格式、编译状态、材料清单。Review Reviewer 角色 session 启动时自动使用。  →  `/home/ubuntu/agent-ml-research/skills/global/review-reviewer-session-start.skill.md`\n- **reference-audit** — 引用验证与审计——检查 bib 条目完整性、引用真实性、格式一致性。写论文、审查论文、提交前检查引用时使用。关键词：citation verification、引用检查、bib 审计、fake citation、引用格式。  →  `/home/ubuntu/agent-ml-research/skills/global/reference-audit.skill.md`\n- **accelerate-distributed** — HuggingFace Accelerate 分布式训练指南——4行代码实现多GPU/DeepSpeed/FSDP/混合精度。多GPU训练时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/accelerate-distributed.skill.md`\n- **draw-paper-figure** — 生成学术论文级 matplotlib 图表——reliability diagrams、ECE heatmap、T* scatter plot、模型对比图，直接在 A6000 服务器上执行，输出 PDF/PNG  →  `/home/ubuntu/agent-ml-research/skills/global/draw-paper-figure.skill.md`\n- **experiment-analysis** — 实验结果分析框架——统计显著性检验、消融分析、baseline 对比、可视化建议。分析实验结果或撰写论文 Results 部分时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/experiment-analysis.skill.md`\n- **hf-hub** — HuggingFace Hub CLI (hf) — 下载/上传模型和数据集、管理缓存、搜索论文和模型。涉及 HuggingFace 资源操作时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/hf-hub.skill.md`\n- **latex-paper** — ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md`\n- **lm-eval-harness** — lm-evaluation-harness 模型评估指南——MMLU/GSM8K/HumanEval 等 60+ 学术基准测试。评估模型质量、对比实验时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/lm-eval-harness.skill.md`\n- **ml-experiment-guide** — 跨项目 ML 实验避坑指南——从多个项目沉淀的通用踩坑经验与最佳实践。当 Worker 准备写实验代码、或排查实验问题时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/ml-experiment-guide.skill.md`\n- **paper-banana** — 用 PaperBanana 生成发表级学术统计图——LLM 写 matplotlib 代码 + Critic 迭代 3 轮，输入 CSV/JSON 数据 + 意图描述即可。需要 GOOGLE_API_KEY。  →  `/home/ubuntu/agent-ml-research/skills/global/paper-banana.skill.md`\n- **paper-image-extractor** — 从论文 PDF 或 arXiv 源码包提取图表——优先 arXiv 原始图片，回退 PDF 解析。用户说\"提取图\"/\"抽图\"/\"extract figures\"时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/paper-image-extractor.skill.md`\n- **peft-lora** — PEFT/LoRA/QLoRA 参数高效微调指南——LoRA 配置选择、QLoRA 量化训练、Adapter 管理与合并。微调大模型时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/peft-lora.skill.md`\n- **research-news** — 每日论文推荐——搜索 arXiv 最新论文，按相关性/新颖性/影响力评分，生成推荐列表。Director 说\"有什么新论文\"/\"最近进展\"/\"research news\"时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/research-news.skill.md`\n- **trl-training** — TRL (Transformer Reinforcement Learning) 训练指南——SFT/DPO/GRPO/KTO 配置与最佳实践。训练或对齐语言模型时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/trl-training.skill.md`\n- **wandb-guide** — W&B 查询最佳实践——如何高效使用 fetch_wandb_metrics / compare_wandb_runs / get_best_wandb_run 分析实验结果。分析实验指标时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/wandb-guide.skill.md`\n",
      "contentDiffersFromDisk": false
    },
    "displayPath": "projects/schema_semantic_constrained_ie/.claude/CLAUDE.md"
  },
  "type": "attachment",
  "uuid": "c49c8f74-6846-46b1-9ae7-35f09685295b",
  "timestamp": "2026-05-16T17:34:30.215Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

---

### Assistant

_source line 19 · 2026-05-16T17:35:07.798Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have the full experiment plan. All 20 planned experiments are marked as complete (DONE). The user wants me to generate detailed predicted data for each experiment under the "best" tier scenario.

Let me also check if there are additional experiments that were planned beyond what's in this file - like the FT ablation experiments (w5, w6, w7, w8 series) and the Mistral experiments that appear in the registry.

Looking at the registry in the paper_framing.md, I can see there are many more completed experiments beyond P001-P020. The experiment_plan.yaml only lists P001-P020 which are the core Phase 0-2 experiments. 

Beyond those core experiments, the registry also includes fine-tuning ablations across multiple models—Qwen and Llama variants on both SciERC and DocRED datasets, a third model comparison with Mistral, grammar-only and semantic-only ablation studies, and a completion study with posthoc baselines, plus the CF experiments.

Now I'm refocusing on what the user actually wants—they're asking for detailed results across the planned experiments P001-P020 from the experiment_plan.yaml. But these are already completed experiments with recorded results. I think what they're really asking for is how these results would be perceived under a "best-case" review scenario, not generating new predictions. Let me reconsider what they mean by the "best" tier outcome. I need to check the full experiment registry to see if there are additional experiments beyond the initial twenty that should be included in this analysis. Looking at the broader matrix, there are fine-tuning experiments across multiple model variants and datasets, plus ablation studies and a post-hoc baseline that all seem relevant to the complete experimental scope.

But the user was specifically asking about the planned experiments in the YAML file—P001 through P020—so I should stick to those rather than trying to include every extension that was added later. Now I'll generate the YAML output showing the actual results and how they'd be interpreted in the best-case tier, working through each experiment systematically. Now I'm pulling together the complete output using the actual experiment data from the registry, structuring each of the 20 experiments with their reported metrics and explaining how those results support a best-tier reception narrative.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c49c8f74-6846-46b1-9ae7-35f09685295b",
  "isSidechain": false,
  "requestId": "req_011Cb6efh3ezxTgErFh5XXnm",
  "type": "assistant",
  "uuid": "bfabdbf2-41f8-4eb8-8e13-f24e74e0e593",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JqXhKeN72tXM4UQPcSK44F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7954,
      "cache_read_input_tokens": 40936,
      "output_tokens": 1610,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7954,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1610,
          "cache_read_input_tokens": 40936,
          "cache_creation_input_tokens": 7954,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7954
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

_source line 20 · 2026-05-16T17:35:07.817Z_

Now I have the full experiment plan with 20 planned experiments (P001-P020). Let me also check the lock file for any additional planned experiments beyond the base plan.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bfabdbf2-41f8-4eb8-8e13-f24e74e0e593",
  "isSidechain": false,
  "requestId": "req_011Cb6efh3ezxTgErFh5XXnm",
  "type": "assistant",
  "uuid": "d8371ca1-2451-4a41-b1d1-0a61dda19275",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JqXhKeN72tXM4UQPcSK44F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7954,
      "cache_read_input_tokens": 40936,
      "output_tokens": 1610,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7954,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1610,
          "cache_read_input_tokens": 40936,
          "cache_creation_input_tokens": 7954,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7954
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

_source line 21 · 2026-05-16T17:35:09.114Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FAr9LxkX5GcRHcXV6M87jC`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/experiment_plan.lock"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d8371ca1-2451-4a41-b1d1-0a61dda19275",
  "isSidechain": false,
  "requestId": "req_011Cb6efh3ezxTgErFh5XXnm",
  "type": "assistant",
  "uuid": "31f7061e-7e79-4a4e-adc8-e988adcc5391",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JqXhKeN72tXM4UQPcSK44F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7954,
      "cache_read_input_tokens": 40936,
      "output_tokens": 1610,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7954,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1610,
          "cache_read_input_tokens": 40936,
          "cache_creation_input_tokens": 7954,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7954
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

_source line 22 · 2026-05-16T17:35:09.119Z_

<details><summary>↩ Tool result · `toolu_01FAr9LxkX5GcRHcXV6M87jC`</summary>

```text
&lt;system-reminder>Warning: the file exists but is shorter than the provided offset (1). The file has 1 lines.&lt;/system-reminder>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "31f7061e-7e79-4a4e-adc8-e988adcc5391",
  "isSidechain": false,
  "promptId": "9892bc0f-ed9c-4ac7-ab74-05a30afa53d9",
  "type": "user",
  "uuid": "3c343451-46d8-4373-a4f0-4201ed23b9cd",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/experiment_plan.lock",
      "content": "",
      "numLines": 1,
      "startLine": 1,
      "totalLines": 1
    }
  },
  "sourceToolAssistantUUID": "31f7061e-7e79-4a4e-adc8-e988adcc5391",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-16T17:35:22.020Z_

<details><summary>Logged reasoning block</summary>

```text
The lock file is essentially empty. Let me just work with the 20 experiments from the plan. Let me now construct the comprehensive YAML output for the best tier.

I'll need to include all 20 experiments plus the additional FT/Mistral/ablation experiments that are referenced in the paper framing but not in the formal plan. Actually, looking more carefully at the plan, it only goes to P020 and says "ALL COMPLETE". The FT experiments are additional work done after the initial plan was written.

But the user's instruction says "experiment_plan 中每个 planned 实验" - so P001-P020. 

The best tier definition explicitly references "3 模型 × 2 数据集矩阵 + FT ablation 8/8" as key evidence, which corresponds to the w5-w8 experiments, so I should include those as well since they're materially relevant to the paper's core claims.

Actually, the user specifically asked for details on each planned experiment in the experiment_plan, which is P001-P020, so I'll focus on those and treat the FT experiments as supporting evidence rather than primary content.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3c343451-46d8-4373-a4f0-4201ed23b9cd",
  "isSidechain": false,
  "requestId": "req_011Cb6eiZnvdhMmkrfeRt8hk",
  "type": "assistant",
  "uuid": "f0a23cb7-d5aa-4ebb-bf6f-559058f16b14",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WXLZQSMkdczvCVaE3uVPde",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1649,
      "cache_read_input_tokens": 48890,
      "output_tokens": 13098,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1649,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13098,
          "cache_read_input_tokens": 48890,
          "cache_creation_input_tokens": 1649,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1649
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---

### Assistant

_source line 24 · 2026-05-16T17:39:39.672Z_

Now I have all the data needed. Let me construct the detailed best-tier predictions for all 20 planned experiments.

```yaml
tier: best
narrative_guidance: "原始 framing 完全成立。Title 'Type-Valid IE via Compiled Ontology Constraints' 精准定位贡献。§3 violation landscape 被引用为 empirical contribution。Claim 3 composable framework 的 enabling dependency 被视为关键设计 insight。DR↓94% (SciERC) / ↓90.2% (Llama DocRED) at zero/positive F1 cost 是干净的主结果。CF 在 limitations 和 analysis 双重出现被审稿人正面评价为 'refreshingly honest'。FT regime 下 DR 1.95%→0% + F1 neutral 补全了 'method scales to supervised setting' 的叙事。Post-hoc baseline 的多维对比构成完整的 defense。Rebuttal 只需回应小的澄清问题，不需要额外实验。"
imagined_experiments:
  - name: "SciERC violation rate (minimal prompt)"
    plan_id: "P001"
    description: "Zero-shot Qwen3-8B on SciERC with minimal task prompt, measuring baseline ontology constraint violation rates across 7 relation types"
    expected_results:
      total_triples: 1724
      total_entities: 2474
      json_parse_rate: 1.0
      entity_type_violation_rate: 0.004
      relation_vocabulary_violation_rate: 0.0139
      domain_range_violation_rate: 0.1537
      cross_field_consistency_violation_rate: 0.0008
      entity_f1: 0.3101
      relation_f1: 0.0823
      per_relation_dr_range: "[0.0076 (Used-for) — 0.4242 (Compare)]"
    result_rationale: "15.4% overall DR with massive per-relation variance (0.8%–42.4%) is the ideal setup for the paper's tightness hypothesis。审稿人看到 7-relation ontology 产生 15.4% DR（与 96-relation DocRED 的 18.7% 可比）时，'violation rate driven by tightness not size' 的 insight 立即成立。Compare (42.4%) 和 Used-for (0.8%) 的 56× 差距是极具说服力的 motivating example。在 best 档，至少 2/3 审稿人将此 landscape study 视为独立 empirical contribution——它回答了'LLM-based IE 到底在哪里、多严重地违反 ontology constraints'这一此前未系统回答的问题。"
    tables:
      - "Table 1: Per-relation violation rates (7 rows × columns: relation, |triples|, DR rate, constraint tightness τ)"
    figures_description:
      - "Figure 2: Bar chart of per-relation DR rate colored by constraint tightness; scatter overlay showing τ vs DR correlation"
    analysis: "审稿人评价：'The violation landscape study (§3) is a valuable empirical contribution in its own right — prior work assumes violations exist but never quantifies their distribution across relation types.' Novelty score 3.5+ 因为这是 first systematic measurement。Evaluate-for 24.1% 和 Compare 42.4% 的高违规率直接 motivate 了 decoding-time enforcement 的必要性。"

  - name: "SciERC violation rate (schema-informed prompt)"
    plan_id: "P002"
    description: "Zero-shot Qwen3-8B on SciERC with schema-informed prompt explicitly describing domain/range constraints"
    expected_results:
      domain_range_violation_rate: 0.0578
      relation_vocabulary_violation_rate: 0.003
      entity_type_violation_rate: 0.0
      overall_reduction_vs_minimal: -0.624
      evaluate_for_delta_pp: +5.8
      feature_of_delta_pp: -22.3
      compare_delta_pp: -14.8
    result_rationale: "62.4% overall reduction 表面看很好，但 Evaluate-for 的 regression (+5.8pp) 是关键 finding。在 best 档，审稿人将此理解为 'prompt-level intervention is fundamentally unreliable as a guarantee mechanism'——不仅 insufficient，而且 per-relation 不可预测甚至 counterproductive。Prior-constraint conflict 解释（schema prompt 干扰模型 type assignment）被视为 deeper insight 而非 post-hoc excuse。这为 Claim 2 提供了从'statistically insufficient'到'mechanistically unreliable'的升级论据。3 个 relation 仍保留 >10% violation rate 的事实让 'safety-critical IE needs guaranteed compliance' 的论点不可反驳。"
    tables:
      - "Table 2: Per-relation DR before/after schema-informed prompt (7 rows × columns: relation, DR_minimal, DR_schema, Δpp, direction)"
    figures_description:
      - "Figure 3: Paired bar chart showing per-relation DR reduction with Evaluate-for regression highlighted in red"
    analysis: "审稿人评价：'The observation that schema-informed prompting can *increase* violations for specific relations (Evaluate-for: +5.8pp) is compelling evidence that prompt-level intervention is not merely weak but unpredictable.' 这使 Claim 2 从 'obvious' 升级为 'insightful'——不仅仅是'prompt 不够'，而是'prompt 在特定 constraint configuration 下 actively harmful'。"

  - name: "DocRED violation rate (minimal prompt)"
    plan_id: "P003"
    description: "Zero-shot Qwen3-8B on DocRED (96 relations) with minimal prompt, measuring violation rates on complex ontology"
    expected_results:
      total_docs: 998
      parsed_docs: 962
      total_triples: 16540
      total_entities: 19099
      entity_type_violation_rate: 0.075
      relation_vocabulary_violation_rate: 0.289
      domain_range_violation_rate: 0.187
      cross_field_consistency_violation_rate: 0.0008
      top_dr_by_rate: "P35_head_of_state=1.0, P710_participant=0.919"
      top_dr_by_count: "P31_instance_of (322/533=60.4%)"
    result_rationale: "DocRED DR 18.7% 与 SciERC 15.4% 的 comparable rate（尽管 ontology 规模差 14×）是 tightness hypothesis 的 killer evidence。在 best 档，审稿人直接认可 'violation rate is driven by constraint tightness, not ontology size'。RV 28.9% 揭示了 LLM 生成大量 OOV relation names 的严重问题——这同时 motivates grammar 层的必要性。P31_instance_of 60.4% DR rate 说明即使最常见的 relation 也可以有极高违规率（因其 domain 限制为特定 entity types），进一步支持 tightness 论点。"
    tables:
      - "Table 1 (extended): DocRED violation summary alongside SciERC for direct comparison"
    figures_description:
      - "Figure 2 (panel b): DocRED top-10 violating relations by count, with tightness annotation"
    analysis: "审稿人评价：'The fact that a 7-relation ontology (SciERC, 15.4%) and a 96-relation ontology (DocRED, 18.7%) produce comparable violation rates is strong evidence for the tightness hypothesis. This is a non-obvious finding — one might expect more relations = more confusion = more violations.' 这成为 §3 的 headline finding。"

  - name: "DocRED violation rate (schema-informed prompt)"
    plan_id: "P004"
    description: "Zero-shot Qwen3-8B on DocRED with schema-informed prompt, testing prompt intervention scalability"
    expected_results:
      total_triples: 16782
      domain_range_violation_rate: 0.1284
      relation_vocabulary_violation_rate: 0.1841
      entity_type_violation_rate: 0.0061
      dr_reduction_vs_minimal: -0.32
      vs_scierc_reduction: "32% vs 62.4%"
    result_rationale: "DocRED schema-informed prompt 仅达到 32% DR reduction（vs SciERC 的 62.4%）——这是 'prompt-level intervention scales poorly with ontology complexity' 的直接证据。在 best 档，审稿人将 SciERC 62% vs DocRED 32% 的对比视为 prompt approach 的 fundamental scalability limit，而非实验 noise。96 relations 的 constraint descriptions 放入 prompt 后，模型无法有效利用全部信息——这是 attention/context window 的固有限制，不可能通过更好的 prompt engineering 解决。这为 decoding-time enforcement 的 motivation 提供了 scalability argument。"
    tables:
      - "Table 2 (panel b): DocRED prompt intervention summary"
    figures_description:
      - "Figure 3 (panel b): Reduction percentage comparison: SciERC 62% vs DocRED 32% with ontology size annotation"
    analysis: "审稿人评价：'The reduced effectiveness of schema-informed prompting on DocRED (32% vs 62% on SciERC) demonstrates that prompt-level intervention does not scale with ontology complexity — precisely the regime where guaranteed compliance is most needed.' 审稿人在 Claim 2 的 soundness score 给 4.0+。"

  - name: "SciERC unconstrained baseline"
    plan_id: "P005a"
    description: "Phase 2 re-run of unconstrained SciERC with v2 checker for exact apples-to-apples comparison"
    expected_results:
      total_samples: 551
      total_triples: 1724
      total_entities: 2474
      json_parse_rate: 1.0
      entity_type_violation_rate: 0.004
      relation_vocabulary_violation_rate: 0.0139
      domain_range_violation_rate: 0.1537
      cross_field_consistency_violation_rate: 0.0008
      entity_f1: 0.3101
      relation_f1: 0.0823
    result_rationale: "与 P001 完全一致的结果（同一 inference output，只是用 v2 checker 重新计算）确认了 checker 修正后 baseline 数字不变，实验可复现性无问题。在 best 档，审稿人注意到所有 ablation 用同一 checker version (v2) 计算，methodology 被视为 rigorous。json_parse_rate=100% 说明 Qwen3-8B 在 SciERC prompt 下输出格式完美——unconstrained 不需要 grammar 来保证 JSON 合法性，grammar 层的价值在于 vocabulary/type constraint。"
    tables:
      - "Table 3 row: unconstrained baseline"
    figures_description: []
    analysis: "作为 ablation table 的 baseline row，所有 Δ 值从此计算。审稿人验证了 F1 计算方法（all_set：OOV predictions 计入 denominator）是合理的——它让 grammar 层的 OOV elimination 体现为 F1 gain 而非被忽略。"

  - name: "SciERC grammar-only"
    plan_id: "P005"
    description: "SciERC with only grammar layer (XGrammar CFG): enforces JSON structure + valid relation/entity type vocabulary"
    expected_results:
      total_triples: 1725
      entity_type_violation_rate: 0.0
      relation_vocabulary_violation_rate: 0.0
      domain_range_violation_rate: 0.1484
      cross_field_consistency_violation_rate: 0.0008
      entity_f1: 0.3098
      relation_f1: 0.0823
    result_rationale: "Grammar 层完美消除 ET 和 RV（→0%），但 DR 几乎不变（14.84% vs 15.37%，Δ-0.53pp）。这是 enabling dependency 论证的关键一半：grammar 确保 relation name 合法，使 semantic 层可以查表执行 domain/range 约束——但 grammar 本身不知道什么 entity type 可以填什么 relation slot。在 best 档，审稿人将此解读为 clean ablation evidence：'Grammar provides structural prerequisite but not semantic enforcement.' SciERC RV baseline 仅 1.39%，所以 grammar 在 SciERC 上 F1 impact 可忽略（Δ-0.03pp），但 DocRED RV 29.66% 时 grammar 是 F1 gain 的唯一来源。"
    tables:
      - "Table 3 row: grammar_only"
    figures_description:
      - "Figure 4: Ablation stacked bar showing each layer's contribution to DR/RV/ET reduction"
    analysis: "审稿人评价：'The grammar-only ablation demonstrates that structural constraints (vocabulary enforcement) are necessary but insufficient — domain/range violations require the stateful semantic layer. This cleanly separates the two layers\u0027 roles.' DR 几乎不降说明 random valid relation name 被 grammar 强制分配时，type constraint 仍然被违反——grammar 不理解 semantics。"

  - name: "SciERC semantic-only"
    plan_id: "P006"
    description: "SciERC with only semantic layer (TypeConstraintProcessor): enforces domain/range via entity registry + logit masking, without grammar vocabulary constraint"
    expected_results:
      total_triples: 1726
      entity_type_violation_rate: 0.004
      relation_vocabulary_violation_rate: 0.0151
      domain_range_violation_rate: 0.1165
      cross_field_consistency_violation_rate: 0.0271
      entity_f1: 0.3101
      relation_f1: 0.0815
    result_rationale: "Semantic-only DR=11.65%（仅↓24% vs baseline 15.37%）——远低于 full_s1 的↓94%。这是 enabling dependency 的 smoking gun：当 RV≠0（semantic-only 允许 OOV relation names），semantic 层遇到未知 relation 时无法查表获得 domain/range 约束，退化为 no-op。在 best 档，审稿人将 24% vs 94% 的对比视为 'compelling evidence for the enabling dependency architecture — grammar is a prerequisite for semantic, not an independent parallel system。' 这区分了 OntoCoDec 与 naive 'apply two masks independently' 的关键 architectural insight，被审稿人视为论文的 non-trivial contribution。CF 从 0.08% 升至 2.71% 预示了 semantic enforcement 引入 CF 的 trade-off，但在 best 档 审稿人在此阶段只是 note 它。"
    tables:
      - "Table 3 row: semantic_only"
    figures_description:
      - "Figure 4: Arrow diagram showing enabling dependency (grammar→semantic) with DR reduction numbers"
    analysis: "审稿人评价：'The dramatic difference between semantic-only (↓24%) and full system (↓94%) is the strongest evidence that grammar is an enabling prerequisite, not merely an additive component. This is a genuine architectural insight distinguishing OntoCoDec from systems like SynCode that operate a single constraint layer.' Novelty perception 提升——不是简单的 'apply CFG to IE' 而是 'design a two-layer system with principled dependency structure'。"

  - name: "SciERC full S1"
    plan_id: "P007"
    description: "SciERC with both grammar + semantic layers in single-pass (S1): the primary recommended configuration"
    expected_results:
      total_triples: 1729
      entity_type_violation_rate: 0.0
      relation_vocabulary_violation_rate: 0.0
      domain_range_violation_rate: 0.0093
      cross_field_consistency_violation_rate: 0.099
      entity_f1: 0.3098
      relation_f1: 0.0836
      dr_reduction_pct: 94.0
      r_f1_delta_pp: +0.13
      r_f1_p_value: 0.58
    result_rationale: "DR 15.37%→0.93%（↓94%）at R-F1 +0.13pp (p=0.58, not significant) 是论文的 headline result。在 best 档，审稿人将此解读为：(1) near-complete DR elimination，(2) zero F1 cost（p=0.58 确认 noise），(3) 干净的方法学贡献而非 cherry-picked 数字。CF 9.9% 被正面对待因为论文主动披露 + 提供 root cause analysis (type ambiguity in SciERC) + 消融归因 (100% 由 semantic 层引入)。审稿人评论 'refreshingly honest' 关于 CF 的处理。Residual DR 0.93%（16/1729 triples）在 best 档被接受为'near-complete'——审稿人理解 forward-only decoding 的 fundamental limitation (truly non-local constraints undecidable)。"
    tables:
      - "Table 3 row: full_s1 (PRIMARY)"
      - "Table 4: Bootstrap CI results — R-F1 95% CI [-0.32, +0.58], p=0.58"
    figures_description:
      - "Figure 1 (teaser): DR reduction bar from 15.37% to 0.93% with F1-neutral annotation"
    analysis: "审稿人评价：'94% reduction in domain/range violations with statistically neutral F1 impact is a strong result. The residual 0.93% is well-explained by the decidability taxonomy (§4.3) — these are genuinely non-local constraints beyond the scope of forward-only decoding.' Soundness score 4.0+ 因为 ablation 干净、CI 提供、residual 有理论解释。"

  - name: "SciERC full S2 (ablation)"
    plan_id: "P008"
    description: "SciERC with two-pass strategy: Pass 1 grammar-only entity extraction, Pass 2 entity-conditioned relation generation"
    expected_results:
      total_triples: 1644
      entity_type_violation_rate: 0.0
      relation_vocabulary_violation_rate: 0.0
      domain_range_violation_rate: 0.0097
      cross_field_consistency_violation_rate: 0.0803
      entity_f1: 0.319
      relation_f1: 0.0803
      cf_reduction_vs_s1: -1.87
    result_rationale: "S2 DR=0.97% ≈ S1 0.93%，CF=8.03% vs S1 9.90%（Δ-1.87pp, not significant）。在 best 档，审稿人接受 S2 作为 architectural variant demonstrating framework flexibility，而非核心贡献。S2 没有解决 CF 的事实被诚实报告——审稿人评价 'The authors correctly position S2 as an architectural ablation rather than overclaiming CF mitigation.' S2 R-F1=8.03% 略低于 S1 8.36%（Δ-0.33pp）进一步支持了 S1 作为 recommended configuration 的选择。在 best 档这被视为 thorough engineering exploration 而非 weakness。"
    tables:
      - "Table 3 row: full_s2 (ABLATION)"
      - "Appendix Table: S1 vs S2 detailed comparison"
    figures_description: []
    analysis: "审稿人评价：'S2 demonstrates that the framework supports alternative decoding strategies, though S1 is correctly identified as superior. The honest reporting that S2 does not meaningfully reduce CF is appreciated.' 这作为 §5 ablation 或 Appendix B 出现。不占正文空间过多，但展示了 framework 的 composability。"

  - name: "DocRED unconstrained baseline"
    plan_id: "P009"
    description: "Qwen3-8B on DocRED (96 relations) unconstrained, establishing violation baseline for complex ontology"
    expected_results:
      documents_checked: 986
      parse_failures: 12
      total_entities: 20171
      total_triples: 17497
      entity_type_violation_rate: 0.0248
      relation_vocabulary_violation_rate: 0.2966
      domain_range_violation_rate: 0.1846
      cross_field_consistency_violation_rate: 0.001
      entity_f1: 58.15
      relation_f1: 7.74
      unrecognized_relations: 5189
    result_rationale: "RV 29.66% 是 DocRED 的 defining pathology——模型生成大量不存在于 ontology 中的 relation names（5189 instances）。在 best 档，审稿人将此视为 grammar 层在 complex ontology 下 critical importance 的明确证据。ET 2.48% 说明模型也生成非法 entity types。all_set F1 方法将这些 OOV predictions 计入 denominator（penalize them as FP），所以 grammar 消除 OOV 后 F1 提升是 methodologically correct 而非 artifact。这组 baseline 数字建立了 DocRED 作为'high-violation-rate complex ontology'的定位，与 SciERC 的'small but tight ontology'形成互补 test bed。"
    tables:
      - "Table 5 row: DocRED unconstrained"
    figures_description:
      - "Figure 5: Violation type breakdown pie chart — RV dominates at 29.66%"
    analysis: "审稿人注意到 RV 29.66% 远高于 SciERC 1.39%——这解释了为什么 grammar 层在 DocRED 上产生显著 F1 gain（消除 OOV = 消除 FP）而在 SciERC 上 F1 neutral。model-dataset interaction 被视为 insightful analysis。"

  - name: "DocRED grammar-only"
    plan_id: "P010"
    description: "DocRED with grammar layer only: enforcing valid relation vocabulary + entity type vocabulary via CFG"
    expected_results:
      documents_checked: 985
      total_triples: 17341
      entity_type_violation_rate: 0.0
      relation_vocabulary_violation_rate: 0.0003
      domain_range_violation_rate: 0.2617
      cross_field_consistency_violation_rate: 0.0007
      entity_f1: 59.38
      relation_f1: 8.31
      unrecognized_relations: 5
    result_rationale: "Grammar 层将 RV 从 29.66% 压到 0.03%，ET 从 2.48% 压到 0%——但 DR 从 18.46% 升至 26.17%（+7.71pp）。这个 DR 上升是 best 档审稿人特别欣赏的 finding：grammar 强制 OOV relation names 映射到 valid vocabulary，但随机映射的 valid relation name 往往与 entity types 不匹配 → 暴露大量 latent DR violations。在 best 档，审稿人将此解读为 'grammar reveals latent violations that were previously hidden behind OOV names — these triples were already semantically invalid but the invalidity was masked by the OOV relation name not having defined domain/range constraints。' 这是 D014 tightness × RV baseline 双因子分析的核心数据点。E-F1 59.38% 显著高于 unconstrained 58.15%（+1.23pp, p<0.001）——grammar 是 F1 gain 的唯一来源（full_s1 E-F1=59.37% ≈ grammar_only）。"
    tables:
      - "Table 5 row: grammar_only"
    figures_description:
      - "Figure 6: Sankey diagram showing how grammar redirects OOV → valid relation names, exposing latent DR"
    analysis: "审稿人评价：'The counterintuitive finding that grammar-only *increases* DR (18.46%→26.17%) is well-explained: OOV relations masked constraint violations by lacking defined domain/range rules. Grammar exposes these latent violations. This is a key insight for understanding the interaction between vocabulary and semantic constraints.' 这直接支持 enabling dependency narrative 并解释了 Qwen DocRED full_s1 DR↓45% (not ↓94%) 的原因。"

  - name: "DocRED semantic-only"
    plan_id: "P011"
    description: "DocRED with semantic layer only: TypeConstraintProcessor enforces domain/range without grammar vocabulary constraint"
    expected_results:
      documents_checked: 987
      total_triples: 17571
      entity_type_violation_rate: 0.0422
      relation_vocabulary_violation_rate: 0.2987
      domain_range_violation_rate: 0.1384
      cross_field_consistency_violation_rate: 0.0105
      entity_f1: 57.81
      relation_f1: 7.70
    result_rationale: "Semantic-only DR=13.84%（↓25% from 18.46%）——与 SciERC semantic-only ↓24% 高度一致。在 best 档，审稿人将两个数据集上 semantic-only 都只能降 ~25% 的一致性视为 enabling dependency 的 robust evidence：'Regardless of ontology complexity, semantic constraints alone achieve only modest DR reduction because ~30% of relations are OOV and cannot be constraint-checked.' RV 仍然 29.87%（几乎不变于 baseline 29.66%）——semantic 层不处理 vocabulary。ET 实际升至 4.22%（from 2.48%）可能是 semantic masking 的副作用，但在 best 档 审稿人不 flag 这个因为 full system ET=0%。"
    tables:
      - "Table 5 row: semantic_only"
    figures_description: []
    analysis: "审稿人评价：'Consistent ~25% DR reduction for semantic-only across both datasets (SciERC 24%, DocRED 25%) provides robust evidence that the enabling dependency is a general architectural property, not dataset-specific.' Semantic 层的 partial effectiveness 精确匹配了 'only enforceable on known relations' 的理论预测。"

  - name: "DocRED full S1"
    plan_id: "P012"
    description: "DocRED with full grammar+semantic S1: the primary configuration on complex ontology"
    expected_results:
      documents_checked: 987
      total_triples: 17341
      entity_type_violation_rate: 0.0
      relation_vocabulary_violation_rate: 0.0003
      domain_range_violation_rate: 0.1021
      cross_field_consistency_violation_rate: 0.0257
      entity_f1: 59.37
      relation_f1: 8.23
      r_f1_delta_pp: +0.50
      r_f1_p_value: "<0.001"
      e_f1_delta_pp: +1.23
      e_f1_p_value: "<0.001"
      dr_reduction_pct: 44.7
    result_rationale: "DR 18.46%→10.21%（↓44.7%）+ R-F1 +0.50pp (p<0.001) + E-F1 +1.23pp (p<0.001)。在 best 档，审稿人对 Qwen DocRED ↓45%（vs SciERC ↓94%）的'较弱'reduction 的理解是关键。D014 dual-factor analysis 提供了完整解释：Qwen RV baseline 29.66% → grammar 暴露大量 latent DR → residual DR 更高。审稿人将此解读为 'the method works as theoretically predicted — weaker reduction on DocRED is explained by the RV×tightness interaction, not method failure。' Cross-model validation (Llama DocRED ↓90.2%) 进一步证实方法本身有效，Qwen 的 weaker reduction 是 model-specific RV pathology。F1 gain 被归因于 OOV elimination（grammar 层功劳），如实报告不升级为 core claim。CF=2.57% 远低于 SciERC 9.9%——审稿人注意到 CF 与 ontology tightness 正相关。"
    tables:
      - "Table 5 row: full_s1 (PRIMARY)"
      - "Table 6: Bootstrap CI — R-F1 95% CI [+0.23, +0.81], E-F1 95% CI [+0.94, +1.55]"
    figures_description:
      - "Figure 7: Cross-dataset DR reduction comparison with tightness×RV explanation callout"
    analysis: "审稿人评价：'The authors provide a principled explanation for the reduced DR elimination on DocRED (45% vs 94% on SciERC) through the tightness×RV baseline interaction. This dual-factor analysis (§5.2) transforms what could be perceived as a weakness into a deeper insight about constraint enforcement dynamics. The significant F1 improvement (p<0.001) is a bonus, correctly attributed to OOV elimination rather than semantic constraint quality.' Soundness score 4.0+。"

  - name: "Llama SciERC unconstrained"
    plan_id: "P013"
    description: "Llama-3.1-8B on SciERC unconstrained, establishing cross-model baseline"
    expected_results:
      total_entities: 2451
      total_relations: 1274
      entity_type_violation_rate: 0.0
      relation_vocab_violation_rate: 0.0055
      domain_range_violation_rate: 0.1334
      cross_field_consistency_violations: 6
      entity_f1: 0.2356
      relation_f1: 0.0268
      json_parse_failures: 1
    result_rationale: "Llama DR=13.34% vs Qwen DR=15.37%——不同模型有不同的 violation profile 但 non-trivial rates are universal。Llama RV=0.55%（很低，类似 Qwen SciERC 1.39%）预示了 full_s1 将有极高 DR reduction（因为 grammar 不需要暴露 latent violations）。在 best 档，审稿人将 cross-model baseline 视为 rigorous experimental design：'Testing on a second model family (Llama vs Qwen) with zero code modification demonstrates the method is model-agnostic by design.' Llama 较低的 absolute F1（R-F1 2.68% vs Qwen 8.23%）被理解为 model capability difference 而非 constraint method issue——zero-shot R-F1 is control variable not optimization target。"
    tables:
      - "Table 7 row: Llama SciERC unconstrained"
    figures_description: []
    analysis: "审稿人评价：'The cross-model validation is commendable — testing on Llama-3.1-8B without any code modification demonstrates the framework\u0027s model-agnosticism. The different violation profiles (Llama: lower RV, lower overall DR) set up the model-interaction analysis that follows.' 零代码修改是 strong engineering claim。"

  - name: "Llama SciERC full S1"
    plan_id: "P014"
    description: "Llama-3.1-8B on SciERC with full grammar+semantic S1, zero code modification"
    expected_results:
      samples: 550
      entities_extracted: 2469
      relations_extracted: 1315
      domain_range_violation_rate: 0.0008
      relation_vocab_violation_rate: 0.0
      entity_type_violation_rate: 0.0
      cross_field_consistency_violation_rate: 0.0656
      entity_f1: 0.2349
      relation_f1: 0.0254
      dr_reduction_pct: 99.4
      r_f1_delta_pp: -0.14
      r_f1_p_value: 0.011
    result_rationale: "DR 13.34%→0.08%（↓99.4%）是全矩阵中最高的 reduction rate。在 best 档，审稿人将 99.4% 解读为'near-perfect constraint enforcement on a different model family'。R-F1 -0.14pp (p=0.011) technically significant 但 magnitude negligible（0.14pp on a ~2.7% baseline = 5% relative）。审稿人在 best 档接受这是 'statistically detectable but practically negligible' 的 F1 cost。DR 0.08%（仅 1 triple out of 1315）接近 theoretical minimum。CF 6.56% 高于 Qwen SciERC（与 paper framing 一致：'non-local constraint problem is more pronounced on Llama'），在 limitations 中提及。关键：这个实验用与 Qwen 完全相同的 grammar/semantic 配置——'zero code modification' claim 被实证验证。"
    tables:
      - "Table 7 row: Llama SciERC full_s1"
      - "Table 8: Cross-model summary — DR reduction rates"
    figures_description:
      - "Figure 8: Cross-model DR reduction bars — Qwen 94%, Llama 99.4%"
    analysis: "审稿人评价：'99.4% DR reduction on Llama-3.1-8B with zero code modification is the most compelling evidence for model-agnosticism. The near-perfect elimination (1 residual violation out of 1315 triples) approaches the theoretical limit of forward-only decoding.' 这与 Qwen 94% 形成互补——不同模型不同 reduction rate 但都 substantial，且差异被 RV baseline 理论解释。"

  - name: "Llama DocRED unconstrained"
    plan_id: "P015"
    description: "Llama-3.1-8B on DocRED unconstrained, establishing complex ontology × different model baseline"
    expected_results:
      documents: 998
      documents_checked: 930
      parse_failures: 68
      unique_entities: 11525
      total_triples: 16437
      ET_rate_pct: 0.13
      RV_rate_pct: 16.03
      DR_rate_pct: 26.07
      CF_rate_pct: 0.17
      entity_f1: 55.65
      relation_f1: 5.98
    result_rationale: "Llama DocRED DR=26.07% >> Qwen DocRED DR=18.46%——不同模型在同一 ontology 上有显著不同的 violation profile。但 Llama RV=16.03% << Qwen RV=29.66%。在 best 档，审稿人将此 RV↓DR↑ 的正交性视为 §5 cross-model 的独立 finding：'vocabulary compliance ≠ semantic compliance——a model can produce valid relation names (low RV) while still violating domain/range constraints at high rates (high DR)。' 这证明两层约束解决正交的 failure modes。Parse failures 68/998=6.8% 高于 Qwen 12/998=1.2%——bias 方向保守（fewer docs checked → constrained 有效性被 underestimated if anything）。"
    tables:
      - "Table 7 row: Llama DocRED unconstrained"
    figures_description:
      - "Figure 9: RV-DR scatter plot showing Qwen and Llama on same ontology — orthogonal failure modes"
    analysis: "审稿人评价：'The orthogonal RV-DR profiles between Qwen (high RV, moderate DR) and Llama (low RV, high DR) on the same ontology is a valuable finding — it demonstrates that the two constraint layers address genuinely independent failure modes. This justifies the two-layer architecture from an empirical, not just theoretical, perspective.' D014 insight 被 validated。"

  - name: "Llama DocRED full S1"
    plan_id: "P016"
    description: "Llama-3.1-8B on DocRED with full grammar+semantic S1, testing scalability to complex ontology × different model"
    expected_results:
      documents: 998
      documents_checked: 907
      parse_failures: 91
      unique_entities: 11296
      triples: 16368
      ET: 0.0
      RV: 0.0
      DR: 2.55
      CF: 12.02
      entity_f1: 55.01
      relation_f1: 6.27
      dr_reduction_pct: 90.2
      r_f1_delta_pp: +0.29
      r_f1_p_value: 0.013
      e_f1_delta_pp: -0.64
      e_f1_p_value: 0.022
    result_rationale: "DR 26.07%→2.55%（↓90.2%）完成了 2×2 矩阵的最后一格。在 best 档，审稿人将 4 格矩阵视为充分的 generalization evidence：Qwen SciERC ↓94%, Qwen DocRED ↓45%, Llama SciERC ↓99.4%, Llama DocRED ↓90.2%——全部 substantial reduction。Llama DocRED ↓90.2% vs Qwen DocRED ↓45% 的巨大差异被 RV baseline 理论完美解释（Llama RV=16% low → grammar 不暴露太多 latent DR → semantic 可高效执行）。R-F1 +0.29pp (p=0.013, significant) 是 'no F1 cost' 的进一步确认——实际有 small gain。E-F1 -0.64pp (p=0.022) 是唯一的 modest decline——在 best 档被接受为 'model-dependent, small magnitude, within acceptable range'。CF=12.02% 是全矩阵最高值——Llama 在 DocRED 上更容易产生 entity-vs-relation type drift。在 best 档 limitations 中如实报告，审稿人评价 'acceptable given the CF is a known limitation of per-relation enforcement'。"
    tables:
      - "Table 7 row: Llama DocRED full_s1"
      - "Table 8: Full 2×2 cross-model × cross-dataset matrix summary"
    figures_description:
      - "Figure 10: 2×2 heatmap of DR reduction rates with RV baseline annotation"
    analysis: "审稿人评价：'The complete 2-model × 2-dataset matrix with substantial DR reductions across all cells (45%–99.4%) is convincing generalization evidence. The variation in reduction rates is well-explained by the tightness×RV interaction model, demonstrating principled understanding rather than ad-hoc tuning. The framework achieves this with zero code modification across models — a strong engineering contribution.' 这满足了 '3 模型 × 2 数据集矩阵被视为充分 generalization 证据' 的 best 档条件（注：第 3 模型 Mistral 在 FT ablation 中补全）。"

  - name: "S2 pilot (50 docs)"
    plan_id: "P017"
    description: "Small-scale pilot of S2 two-pass strategy on 50 SciERC documents"
    expected_results:
      domain_range_violation_rate: 0.0205
      relation_vocabulary_violation_rate: 0.0
      relation_f1: 0.1008
      samples: 50
      predicted_relations: 146
    result_rationale: "Pilot 确认了 S2 implementation 可工作（DR 2.05%），但小样本 artifact 不可用于 claim。在 best 档，审稿人不会看到这个实验的数据——它仅作为 engineering validation 在开发过程中使用。Paper 只报告 full S2 run (P008, n=551)。如果审稿人在 appendix 看到 pilot 数据，会理解为 'standard engineering practice of pilot testing before full run'。关键：pilot DR=2.05% 与 full run DR=0.97% 的差异仅因样本量，不构成 concern。"
    tables: []
    figures_description: []
    analysis: "不出现在论文正文。如果 appendix 包含开发 timeline，可简要提及 'pilot validation confirmed implementation correctness before full evaluation'。在 best 档审稿人不会质疑这个。"

  - name: "Post-hoc filtering baseline"
    plan_id: "P018"
    description: "Post-hoc filtering comparison: remove all violated triples from unconstrained output and re-evaluate F1"
    expected_results:
      docred_f1_after: 9.61
      docred_f1_ontocoded: 8.23
      docred_rejection_rate: 0.481
      docred_tp_lost: 127
      docred_recall_delta: -1.06
      docred_et_residual: 0.0247
      scierc_f1_after: 8.63
      scierc_f1_ontocoded: 8.36
      scierc_rejection_rate: 0.168
      scierc_recall_delta: -0.72
    result_rationale: "Post-hoc F1 > OntoCoDec F1（SciERC 8.63 vs 8.36, DocRED 9.61 vs 8.23）。在 best 档，审稿人接受论文的 multi-dimensional framing 而不简单以 F1 论高低。关键论据层次：(1) Recall 维度——OntoCoDec recall 上升（probability mass redistribution 生效），post-hoc recall 下降（误删正确 triples）；(2) Information coverage——DocRED post-hoc 丢弃 48.1% triples（近半数信息丢失），无法接受 for completeness-critical applications；(3) ET residual——post-hoc 无法解决 entity type 违规（残余 ET=2.47% DocRED），OntoCoDec ET=0%；(4) 127 个 lost TP 是正确提取但 entity type 违规的 triple——OntoCoDec 通过生成时强制合法 type 保留它们。在 best 档，审稿人评价：'The comparison is fair and multi-dimensional. Post-hoc achieves higher precision through aggressive filtering, but the 48.1% rejection rate and recall loss make it unsuitable for applications requiring completeness.' 这足以 defend against C2 reviewer concern。"
    tables:
      - "Table 9: OntoCoDec vs Post-hoc multi-dimensional comparison (precision, recall, rejection rate, TP lost, ET residual)"
    figures_description:
      - "Figure 11: Stacked bar showing retained vs rejected triples with TP/FP breakdown"
    analysis: "审稿人评价：'The post-hoc baseline is well-designed and honestly reported — the authors acknowledge post-hoc achieves higher precision while correctly arguing that (1) it cannot prevent violations during generation, only detect them after, (2) the 48% rejection rate is unacceptable for many applications, and (3) it cannot address entity-type violations at all. The \u0027prevent vs detect\u0027 framing is appropriate.' 这个 baseline 的存在本身被视为 thorough experimental design——'the authors anticipated this obvious comparison and addressed it systematically'。"

  - name: "Bootstrap CI (10000 iterations)"
    plan_id: "P019"
    description: "Bootstrap confidence intervals (10000 resamples) for all F1 delta claims, providing statistical rigor"
    expected_results:
      scierc_r_f1_delta: +0.13
      scierc_r_f1_p: 0.58
      scierc_r_f1_ci: "[-0.32, +0.58]"
      scierc_r_f1_interpretation: "not significant (F1-neutral)"
      docred_r_f1_delta: +0.50
      docred_r_f1_p: "<0.001"
      docred_r_f1_ci: "[+0.23, +0.81]"
      docred_e_f1_delta: +1.23
      docred_e_f1_p: "<0.001"
      docred_e_f1_ci: "[+0.94, +1.55]"
      llama_scierc_r_f1_delta: -0.14
      llama_scierc_r_f1_p: 0.011
      llama_docred_r_f1_delta: +0.29
      llama_docred_r_f1_p: 0.013
    result_rationale: "Bootstrap CI 为每个 F1 claim 提供了统计保障。在 best 档，审稿人将 10000-iteration bootstrap 视为 gold standard statistical practice：(1) SciERC p=0.58 明确标记为 'neutral' 而非 overclaim improvement；(2) DocRED p<0.001 with CI entirely above zero 支持 'significant improvement' 声明；(3) Llama SciERC p=0.011 with magnitude 0.14pp 被正确标记为 'negligible'——作者区分了 statistical significance 和 practical significance。在 best 档，这种 calibrated statistical reporting 被视为 methodological rigor 的 evidence。审稿人不需要质疑任何 F1 claim 的 validity 因为 CI 和 p-values 全部提供。"
    tables:
      - "Table 10: Bootstrap CI summary for all F1 claims (Δ, 95% CI, p-value, interpretation)"
    figures_description: []
    analysis: "审稿人评价：'The bootstrap confidence intervals are appropriately computed and correctly interpreted — the authors distinguish between statistical significance and practical relevance (Llama SciERC: p=0.011 but Δ=0.14pp is negligible). This level of statistical rigor exceeds most NLP papers.' Soundness score 直接受益于此——无 reviewer 需要质疑 'is this improvement real?'"

  - name: "DocRED schema compilation (Phase 0 R2)"
    plan_id: "P020"
    description: "Second attempt at DocRED schema-informed prompt compilation (killed, superseded by P004)"
    expected_results:
      status: "killed"
      superseded_by: "P004"
    result_rationale: "被 P004 替代，不出现在论文中。在 best 档，审稿人完全不会看到这个实验——它是内部开发迭代的产物。killed experiments 的存在说明团队在开发过程中进行了 iterative refinement，但论文只报告 final/correct versions。在 best 档这是完全正常且 expected 的 engineering practice。"
    tables: []
    figures_description: []
    analysis: "不出现在论文中。无审稿人 visibility。"
```

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f0a23cb7-d5aa-4ebb-bf6f-559058f16b14",
  "isSidechain": false,
  "requestId": "req_011Cb6eiZnvdhMmkrfeRt8hk",
  "type": "assistant",
  "uuid": "e26275ef-5e10-400b-90b2-31c2c2b32332",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WXLZQSMkdczvCVaE3uVPde",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1649,
      "cache_read_input_tokens": 48890,
      "output_tokens": 13098,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1649,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 13098,
          "cache_read_input_tokens": 48890,
          "cache_creation_input_tokens": 1649,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1649
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---

### Runtime record

_source line 25_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：所有核心 claim 经受住审稿，novelty 被认可为 IE-specific 贡献而非简单迁移，CF 作为诚实 limitation 被接受 核心假设：['至少 2/3 审稿人认可 violation landscape study 作为独立贡献', 'enabling dependency（gramm…",
  "leafUuid": "e26275ef-5e10-400b-90b2-31c2c2b32332",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

### Runtime record

_source line 26_

```json
{
  "type": "ai-title",
  "aiTitle": "OntoCoDec type-valid IE constraint enforcement",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

### Runtime record

_source line 27_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：所有核心 claim 经受住审稿，novelty 被认可为 IE-specific 贡献而非简单迁移，CF 作为诚实 limitation 被接受 核心假设：['至少 2/3 审稿人认可 violation landscape study 作为独立贡献', 'enabling dependency（gramm…",
  "leafUuid": "e26275ef-5e10-400b-90b2-31c2c2b32332",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---

### Runtime record

_source line 28_

```json
{
  "type": "ai-title",
  "aiTitle": "OntoCoDec type-valid IE constraint enforcement",
  "sessionId": "9c4a0487-ad45-4ba9-84d2-909d5f582c6c"
}
```

---
