# Research conversation: 你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义： 含义：C5 pilot 通过 gate（LLaMA 复现 phase gradient + crossover），n=500 收紧 Qwen s015 CI 

**Exposure Bias Collapses Auxiliary Attention Losses in Multi-Turn Dialogue (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 23
- **Recorded user turns:** 1
- **Tool calls:** 2
- **Original source:** `logs/chats/exported-trajectories/account-3/7d537f6a-f0e0-42af-9900-a50ecab92c27.jsonl`
- **Structured JSON:** [`03937679f9d777cf6409.json`](../../sessions/03/03937679f9d777cf6409.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-14T14:37:10.244Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-14T14:37:10.244Z",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "content": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：\n\n含义：C5 pilot 通过 gate（LLaMA 复现 phase gradient + crossover），n=500 收紧 Qwen s015 CI 至零以上，所有 claims 原样成立\n核心假设：['C5 LLaMA-8B s025/s030 pilot 回收 >30% compound degradation，crossover 方向与 DeepSeek/Qwen 一致', 'C2 n=500 后 Qwen s015 paired median diff CI 下界 > 0（消除边缘性）', 'DeepSeek n=500 CI 宽度缩窄 ≥30%，点估计稳定在已有范围内', 'C4 discrimination collapse (Gini/CV) 在 LLaMA 上方向一致（无需 entropy 一致）']\n关键指标范围：{'c5_llama_paired_median_diff_s025': [1.0, 5.0], 'c5_llama_cohens_d_s025': [0.5, 1.2], 'c5_llama_crossover_present': [True], 'c2_qw_s015_n500_ci_lower': [0.01, 0.08], 'c2_qw_s015_n500_median_diff': [0.05, 0.12], 'c2_ds_n500_ci_width_reduction_pct': [30, 50], 'c2_ds_s015_n500_median_diff': [0.28, 0.38], 'confirmed_arch_families': [3]}\n叙事方向：原始 framing 完全成立：emergent phase-strategy interaction 跨架构泛化。 Title 可用 \"generalizes across architectures\"。C1-C6 全部 confirmed。 论文三大贡献不变：(1) 发现 + 跨架构验证，(2) 量化 gradient + crossover，(3) discrimination collapse 机制。 Limitations 缩至 scale (7B-8B only) 和 single benchmark。 RC1 (generalizability) 通过 LLaMA 直接回应，RC5 (novelty) 通过 crossover 跨架构复现强化。\n\n\n基于以上定义，对 experiment_plan 中每个 planned 实验展开详细数据。\n每条预测都必须给出 result_rationale —— 解释为什么在这个档位下会得到这样的结果。\n\n# Project context\nproject: phase-gated-compound-sparse\nfocus: D052 调整后的完整 plan：C5 pilot-first 跨架构验证、C2 n=500 预注册叙事、C7/C8 写作任务、Lethe/SparK 区分。重点关注：(1) pilot-first 策略是否足够支撑泛化性 claim；(2) C7/C8 作为写作任务是否被审稿人视为弱点；(3) 11 天 deadline 下 plan 可行性\n\n## paper_framing.md\n\n# Paper Framing — Phase-Gated Compound Sparsity\n\n> 最后更新: 2026-05-14 (D052 审稿应对调整) | 维护者: Director\n\n## Core Insight\n\nCompound sparsity（attention head pruning + KV cache eviction）的 severity 不是固定常数——它是 eviction strategy 和 reasoning phase 交互的涌现属性。Importance-based eviction 的 compound interaction severity（paired median difference: median(II_low_i − II_high_i)）随 sparsity 单调递增（DeepSeek: 0.32→1.15→3.97→9.94; Qwen: 0.048→0.208→1.109→2.619），而 random masking 三相 II 持平（7/8 FAIL; Qwen s030 PASS p=0.012 but d=-0.04 negligible）。Cohen's d（paired d_z, B=10000）从 small-medium 到 large（DeepSeek: 0.44→0.80; Qwen: 0.28→1.02，s015 边缘）。这一发现挑战了 compound degradation 均匀分布的隐含假设。\n\n**数字基准**：所有数字基于 bf16 per-problem paired 统计量（B=10000 bootstrap）。median_diff 定义为 median(II_low_i − II_high_i)（逐 problem 配对差的中位数）。fp16 旧数据已弃用。\n\n## Narrative Arc\n\nCompound sparsity 是高效 LLM 推理的实用部署需求，但 prior work（SparK, Ada-KV, SLiM）将 compound interaction 视为均匀超可加。我们发现 severity 是 strategy × phase 交互的涌现属性：importance eviction 的 compound interaction 在 low-sparsity phase 远大于 high-sparsity phase（paired median difference 单调递增 0.32→9.94），而 random eviction 在所有 phase 保持平坦（7/8 FAIL; 唯一例外 Qwen s030 p=0.012 效应量可忽略 d=-0.04）。Cross-model replication 方向一致（Qwen magnitude ~1/4 of DeepSeek，onset threshold s≥0.20）。C3 crossover 现象的 LLaMA 架构验证已列入计划（plan_009 pilot-first），以测试发现的跨架构泛化性。我们通过 discrimination collapse 机制解释这一现象：head pruning → importance score 的判别力崩塌（Gini/CV 下降跨模型一致）→ importance eviction 退化为有偏伪随机。Attention entropy redistribution 作为 model-dependent secondary effect 在 DeepSeek 上观察到，但在 Qwen 上不稳健（D044）。\n\n**Framing 硬约束（D015）**：\n- MUST: \\\"emergent phase-strategy interaction\\\"\n- MUST NOT: \\\"importance metric limitation / importance is broken\\\"\n- MUST NOT: claim \\\"importance masking produces super-additive interaction\\\" without qualifier — random masking also produces positive II. The distinguishing signal is **phase-dependent gradient** (importance: paired median difference 0.32→9.94 单调递增 vs random: 7/8 FAIL), not the existence of super-additivity itself (D023)\n\n## Core Claims\n\n| ID | Claim | Status | Key Evidence |\n|----|-------|--------|-------------|\n| C1 | Compound sparsity severity is strategy-dependent | confirmed | importance paired median diff 0.32→9.94 单调递增 vs random 7/8 FAIL (bf16; Qwen s030 PASS p=0.012 d=-0.04 negligible) |\n| C2 | Severity is phase-modulated (amplified in low-sparsity phase) | confirmed | bf16 paired median difference 单调递增: 0.32→1.15→3.97→9.94; Bonferroni p<0.005 全 4 水平 (D032)。预注册：n=500 后若 QW s015 CI 仍跨零，叙事改为 'compound effect emerges above threshold sparsity (~s020)' |\n| C3 | Phase-strategy crossover exists | confirmed | s=0.25: importance high_phase=0.032 < random=0.818, importance low_phase=7.196 > random=1.363 (bf16) |\n| C4 | Discrimination collapse as primary mechanism; entropy redistribution model-dependent | partially_confirmed | D044: Gini/CV 下降跨模型一致; entropy collapse DeepSeek 一致但 Qwen s025 反转(+0.045) s030≈0。30/30 problems completed. |\n| C5 | Phase-modulated compound severity generalizes across architectures | pilot_pending | Pilot-first: 2h oracle + heuristic (token position ratio as phase proxy) on LLaMA-8B, s025/s030. Gate: recover >30% compound degradation → full rollout; else → future work. Must include heuristic baseline (oracle upper bound + simple heuristic lower bound). |\n| C6 | Severity gradient is sub-exponential | confirmed | Growth rate decreasing: Δ增长因子 3.8×→4.8×→2.0×（递减） |\n| C7 | Abstract 精简至 150-200 词，突出核心发现（原 S3 升级） | action_required | 当前 ~600 词信息过载，需精简至 1-2 个关键定量结果。写作任务，无需实验。 |\n| C8 | II 与已有 super-additivity 概念明确区分（原 S7 升级） | action_required | §3 Methodology 加段讨论 II vs SparK/SLiM/UniComp 的 compound interaction 度量区别。写作+分析任务。 |\n\n## Anticipated Reviewer Concerns\n\n### RC1: Generalizability — 7B models only, single benchmark\n- **预期质疑**: \"Results on two 7B models and MATH-500 only. How do we know this generalizes to larger models or other reasoning tasks?\"\n- **应对**: Cross-model replication (DeepSeek-R1-Distill-Qwen-7B + Qwen2.5-7B-Instruct) 控制架构变量、隔离训练方式影响（distillation vs instruction tuning）。注意：两模型共享 Qwen2ForCausalLM 架构，不能 claim 跨架构泛化。MATH-500 是 standard benchmark。Limitations 必须诚实声明：(1) 同架构不同训练，不是跨架构；(2) 7B scale only；(3) 单 benchmark。机制解释 (discrimination collapse) 原则上 architecture-agnostic，但未实证验证。\n- **实验支撑**: C5 (Qwen cross-model). 若需加强可扩展到不同架构（如 LLaMA/Mistral），但 11 天 deadline 内不现实\n\n### RC2: Mechanism — entropy-discrimination collapse 缺乏直接测量\n- **预期质疑**: \"The mechanism is conceptual. Where is the empirical evidence for entropy increase and discrimination collapse?\"\n- **应对**: c4_entropy 实验已完成（DeepSeek 30/30 + Qwen 30/30）。D044 结论：Gini/CV 下降跨模型一致（discrimination collapse confirmed）；entropy redistribution 在 DeepSeek 上一致但在 Qwen 上 s025 方向反转、s030 近零（model-dependent）。论文以 discrimination collapse 为主线，entropy 作 DeepSeek 特有的强化因素。\n- **实验支撑**: c4_entropy (DeepSeek DONE) + qwen_c4_entropy (DONE, negative for entropy universality)\n\n### RC3: Practical impact — 没有 throughput 数据\n- **预期质疑**: \"No wall-clock or throughput measurements. Is the severity amplification reflected in actual inference speed?\"\n- **应对**: 本文定位是 empirical finding paper（发现 + 机制解释），不是 method paper。Throughput 不是 claim 的一部分。Discussion 中明确 phase-gated controller 作为 future direction。\n- **实验支撑**: 不需要额外实验\n\n### RC4: Statistical rigor — bootstrap 是否足够\n- **预期质疑**: \"Per-problem bootstrap with 50 problems — sufficient sample size?\"\n- **应对**: bf16 使用 B=10000 per-problem paired bootstrap，有效配对数 n=49 (DeepSeek) / n=46 (Qwen)。Permutation test 使用 paired median difference 作为 robust statistic（D032），Bonferroni 校正后全 4 水平 p<0.005。Cohen's d（paired d_z）作为辅助效应量（DeepSeek 0.44→0.80, Qwen 0.28→1.02）。可在 appendix 补充 per-problem 分布图（已生成 fig4_per_problem_dist.pdf）。\n- **实验支撑**: bf16 permutation test (D032) + Cohen's d per-problem paired (rebootstrap B=10000) 已完成\n\n### RC5: Novelty — prior work 是否已覆盖 phase-dependent sparsity\n- **预期质疑**: \"ThinKV and phase-aware methods already consider phase. What's new?\"\n- **应对**: Prior work 在单轴上分析 phase（ThinKV: phase-aware eviction）或 compound（SparK: joint compression）。没有工作同时分析 compound × phase × strategy 的三维交互。Crossover 现象（同一 strategy 在不同 phase 方向反转）是全新发现。Related Work 加 Lethe 引用区分 + SparK 对比。\n- **实验支撑**: C3 (crossover), Related Work §2 的 gap 分析\n\n## Paper Positioning\n\n**类型**: Empirical finding paper（非 method paper）\n**核心贡献**:\n1. 发现 compound sparsity severity 的 strategy × phase 交互\n2. 量化 severity gradient（bf16 paired median difference 0.32→9.94, Cohen's d 0.44→0.80）和 crossover 现象\n3. 提出 discrimination collapse 机制解释（Gini/CV 跨模型一致；entropy redistribution model-dependent）\n4. Cross-model replication 验证泛化性\n\n**投稿目标**: EMNLP 2026 ARR, deadline 2026-05-25\n**Rebuttal 准备**: Day 9 (2026-05-23) 预留 rebuttal letter 写作时间\n\n\n## registry (completed experiments)\n\n- exp_id: mvp_interaction_index_profiling\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_ii_profiling_v2\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    mvp_verdict: PASS_technical_but_negative_hypothesis\n    ci_nonoverlap: true\n    sign_reversal: false\n    ii_reasoning_0.3: 17.79\n    ii_reasoning_0.3_ci:\n    - 4.09\n    - 38.76\n    ii_transition_0.3: 3.06\n    ii_transition_0.3_ci:\n    - 0.01\n    - 5.6\n    ii_reasoning_0.5: 468.9\n    ii_transition_0.5: 850.07\n    ii_execution_0.3: Inf\n    phase_distribution:\n      execution: 1.2%_25seg\n      reasoning: 8.1%_96seg\n      transition: 90.7%_192seg\n    total_tokens: 86207\n    all_ii_superadditive: true\n    amplitude_ratio_reas_vs_trans_0.3: 5.81\n    gmm_best_k: 5\n    gmm_means:\n    - 0.438\n    - 0.597\n    - 0.719\n    - 0.816\n    - 0.892\n    gmm_weights:\n    - 0.062\n    - 0.14\n    - 0.208\n    - 0.282\n    - 0.309\n    sparsity_global:\n      mean: 0.7653\n      std: 0.1364\n      median: 0.8004\n    quantile_boundaries:\n    - 0.7337\n    - 0.8482\n- exp_id: mvp_ii_profiling_v3\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    mvp_verdict: FAIL\n    ci_nonoverlap: false\n    sign_reversal: false\n    phase_distribution_balanced: true\n    ii_high_0.1:\n      mean: 0.2317\n      ci:\n      - 0.1338\n      - 0.3418\n    ii_low_0.1:\n      mean: 0.1711\n      ci:\n      - 0.0782\n      - 0.2768\n    ii_mid_0.1:\n      mean: 0.1607\n      ci:\n      - 0.0886\n      - 0.2489\n    ii_high_0.2:\n      mean: 2.1574\n      ci:\n      - 1.0605\n      - 3.5491\n    ii_low_0.2:\n      mean: 1.1294\n      ci:\n      - 0.4368\n      - 1.9593\n    ii_mid_0.2:\n      mean: 0.3049\n      ci:\n      - -1.0635\n      - 1.3044\n    total_tokens: 86207\n    no_nan_inf: true\n    segments:\n      high: 511\n      low: 454\n      mid: 391\n- exp_id: mvp_ii_profiling_v4\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_ii_profiling_v4b\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_ii_profiling_v4c\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_ii_profiling_v4d\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_ii_profiling_v4-random\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_v4a_r2\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_v4b_r2\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_v4c_r2\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_v4_random_r2\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics: {}\n- exp_id: mvp_v4_legacy_s01\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    II_high_0.1:\n      mean: -0.1097\n      ci_low: -0.8066\n      ci_high: 0.41\n    II_mid_0.1:\n      mean: -15.966\n      ci_low: -47.991\n      ci_high: 1.288\n    II_low_0.1:\n      mean: 0\n      ci_low: 0\n      ci_high: 0\n    ppl_high_dense: 1.1462\n    ppl_high_both: 22.1302\n    ppl_mid_dense: 1.1226\n    ppl_mid_both: 47.5856\n    verdict: FAIL\n- exp_id: mvp_v4_legacy_s02\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_0.2:\n      mean: 21.2856\n      ci:\n      - 0.0292\n      - 63.163\n    ii_mid_0.2:\n      mean: 21.8743\n      ci:\n      - 4.9863\n      - 41.785\n    ii_low_0.2:\n      mean: 0\n      ci:\n      - 0\n      - 0\n    ppl_high:\n      dense: 1.15\n      attn: 1.32\n      kv: 104.42\n      both: 63.41\n    ppl_mid:\n      dense: 1.12\n      attn: 1.29\n      kv: 324.16\n      both: 170.47\n    ppl_low:\n      dense: 1.11\n      attn: 1.3\n      kv: 1.11\n      both: 1.3\n    problems_completed: 50\n    phase_tokens:\n      high: 25862\n      mid: 27996\n      low: 32349\n    mvp_verdict: PASS\n- exp_id: mvp_v4_legacy_s03\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_0.3:\n      mean: -224.5\n      ci_crosses_zero: true\n    verdict: FAIL_ci_crosses_zero\n- exp_id: mvp_v4_legacy_s025\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_v4_legacy_s035\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: mvp_v4_float32_s030\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: mvp_v5_fixed_s020\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics:\n    ii_high: 0.5\n    ii_mid: 3.52\n    ii_low: 31.89\n    ii_high_ci:\n    - 0.41\n    - 0.62\n    ii_mid_ci:\n    - 2.29\n    - 5.35\n    ii_low_ci:\n    - 18.74\n    - 47.22\n    ii_high_median: 0.33\n    ii_mid_median: 1.55\n    ii_low_median: 9.56\n    kv_ppl_high: 1.24\n    kv_ppl_mid: 3.65\n    kv_ppl_low: 14.11\n    both_ppl_high: 2.7\n    both_ppl_mid: 8.13\n    both_ppl_low: 42.64\n    problems: 50\n    ⚠️_WARNING: pre-fix code, INVALIDATED. Results found on disk after kill but code\n      lacked conda activation fix. Do NOT cite these numbers.\n- exp_id: mvp_v5_fixed_s030\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics:\n    ii_high: 1.18\n    ii_mid: 168.53\n    ii_low: 1926.23\n    ii_high_ci:\n    - 0.86\n    - 1.6\n    ii_mid_ci:\n    - 36.91\n    - 348.21\n    ii_low_ci:\n    - 179.17\n    - 4062.57\n    ii_high_median: 0.6\n    ii_mid_median: 7.47\n    ii_low_median: 44.63\n    kv_ppl_high: 1.4\n    kv_ppl_mid: 15.11\n    kv_ppl_low: 40.79\n    both_ppl_high: 5.71\n    both_ppl_mid: 137.61\n    both_ppl_low: 963.2\n    problems: 50\n    ⚠️_WARNING: pre-fix code, INVALIDATED. Results found on disk after kill but code\n      lacked conda activation fix. Do NOT cite these numbers.\n- exp_id: mvp_v5_fixed_s015\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    ii_high: 0.306\n    ii_mid: 1.274\n    ii_low: 8.786\n    ii_high_ci:\n    - 0.256\n    - 0.359\n    ii_mid_ci:\n    - 0.895\n    - 1.749\n    ii_low_ci:\n    - 5.294\n    - 12.684\n    ii_high_median: 0.205\n    ii_mid_median: 0.696\n    ii_low_median: 2.627\n    ii_high_winsorized: 0.289\n    ii_mid_winsorized: 1.139\n    ii_low_winsorized: 8.408\n    kv_ppl_high: 1.2147\n    kv_ppl_mid: 2.1276\n    kv_ppl_low: 6.7451\n    both_ppl_high: 2.2835\n    both_ppl_mid: 3.9408\n    both_ppl_low: 16.9987\n    problems: 50\n    segments: 1356\n- exp_id: mvp_v5_fixed_s025\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    ii_high: 0.851\n    ii_mid: 9.306\n    ii_low: 96.715\n    ii_high_ci:\n    - 0.703\n    - 0.999\n    ii_mid_ci:\n    - 6.092\n    - 13.303\n    ii_low_ci:\n    - 59.642\n    - 143.188\n    ii_high_median: 0.584\n    ii_mid_median: 4.522\n    ii_low_median: 30.903\n    ii_high_winsorized: 0.802\n    ii_mid_winsorized: 8.156\n    ii_low_winsorized: 94.931\n    kv_ppl_high: 1.3108\n    kv_ppl_mid: 6.1778\n    kv_ppl_low: 23.8919\n    both_ppl_high: 3.4623\n    both_ppl_mid: 16.4148\n    both_ppl_low: 104.1749\n    problems: 50\n    segments: 1356\n- exp_id: mvp_v5_fixed_s020_r2\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    ii_high_median: 0.3333\n    ii_mid_median: 1.5479\n    ii_low_median: 9.5627\n    ii_high_mean: 0.5044\n    ii_mid_mean: 3.5155\n    ii_low_mean: 31.8937\n    ii_high_ci:\n    - 0.41\n    - 0.62\n    ii_mid_ci:\n    - 2.29\n    - 5.35\n    ii_low_ci:\n    - 18.74\n    - 47.22\n    kv_ppl_high: 1.24\n    kv_ppl_mid: 3.65\n    kv_ppl_low: 14.11\n    both_ppl_high: 2.7\n    both_ppl_mid: 8.13\n    both_ppl_low: 42.64\n    problems: 50\n- exp_id: mvp_v5_fixed_s030_r2\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    ii_high_median: 0.5964\n    ii_mid_median: 7.4671\n    ii_low_median: 44.6324\n    ii_high_mean: 1.1832\n    ii_mid_mean: 168.53\n    ii_low_mean: 1926.23\n    ii_high_ci:\n    - 0.86\n    - 1.6\n    ii_mid_ci:\n    - 36.91\n    - 348.21\n    ii_low_ci:\n    - 179.17\n    - 4062.57\n    kv_ppl_high: 1.4\n    kv_ppl_mid: 15.11\n    kv_ppl_low: 40.79\n    both_ppl_high: 5.71\n    both_ppl_mid: 137.61\n    both_ppl_low: 963.2\n    problems: 50\n- exp_id: mvp_v5_random_s015\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 0.1606\n    ii_mid_median: 0.252\n    ii_low_median: 0.1831\n    ii_high_mean: 0.4563\n    ii_mid_mean: 0.5134\n    ii_low_mean: 0.4775\n    ii_high_ci:\n    - 0.12\n    - 0.77\n    ii_mid_ci:\n    - 0.34\n    - 0.74\n    ii_low_ci:\n    - 0.28\n    - 0.7\n    kv_ppl_high: 3.14\n    kv_ppl_mid: 2.91\n    kv_ppl_low: 3.61\n    both_ppl_high: 3.92\n    both_ppl_mid: 4.14\n    both_ppl_low: 4.71\n    problems: 50\n- exp_id: mvp_v5_random_s025\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 3.0024\n    ii_mid_median: 2.9846\n    ii_low_median: 2.9146\n    ii_high_mean: 3.9052\n    ii_mid_mean: 7.9491\n    ii_low_mean: 3.9114\n    ii_high_ci:\n    - 0.98\n    - 6.34\n    ii_mid_ci:\n    - 4.67\n    - 11.87\n    ii_low_ci:\n    - 2.71\n    - 5.24\n    kv_ppl_high: 6.39\n    kv_ppl_mid: 6.11\n    kv_ppl_low: 9.07\n    both_ppl_high: 17.06\n    both_ppl_mid: 15.38\n    both_ppl_low: 29.32\n    problems: 50\n- exp_id: mvp_v5_random_s020\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 0.321331\n    ii_mid_median: 0.455663\n    ii_low_median: 0.591916\n    ii_high_mean: 0.855584\n    ii_mid_mean: 1.258123\n    ii_low_mean: 0.956933\n    ii_high_ci:\n    - -0.124133\n    - 1.616883\n    ii_mid_ci:\n    - 0.674852\n    - 2.075565\n    ii_low_ci:\n    - 0.583856\n    - 1.413355\n    kv_ppl_high: 4.2537\n    kv_ppl_mid: 4.3064\n    kv_ppl_low: 5.4048\n    both_ppl_high: 7.9749\n    both_ppl_mid: 6.8553\n    both_ppl_low: 22.5868\n    problems: 50\n- exp_id: mvp_v5_random_s030\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 5.377512\n    ii_mid_median: 5.886454\n    ii_low_median: 3.776818\n    ii_high_mean: 22.734534\n    ii_mid_mean: 10.943319\n    ii_low_mean: 11.840449\n    ii_high_ci:\n    - 10.352118\n    - 42.551951\n    ii_mid_ci:\n    - 7.398611\n    - 14.765315\n    ii_low_ci:\n    - 4.097309\n    - 23.545273\n    kv_ppl_high: 8.1027\n    kv_ppl_mid: 8.5701\n    kv_ppl_low: 13.4922\n    both_ppl_high: 41.3452\n    both_ppl_mid: 24.1992\n    both_ppl_low: 68.5301\n    problems: 50\n- exp_id: v6_importance_s025\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 0.6641\n    ii_mid_median: 5.3067\n    ii_low_median: 24.1619\n    ii_high_mean: 0.8842\n    ii_mid_mean: 10.057\n    ii_low_mean: 71.8854\n    per_problem_ii_count: 50\n    n_high: 42\n    n_mid: 23\n    n_low: 21\n    problems: 50\n    bootstrap_gradient_paired: 35.72\n    bootstrap_ci_paired:\n    - 9.52\n    - 101.54\n    bootstrap_gradient_unpaired: 36.38\n    bootstrap_ci_unpaired:\n    - 13.19\n    - 97.61\n    bootstrap_p: 0\n- exp_id: v6_importance_s030\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 0.8833\n    ii_mid_median: 7.2706\n    ii_low_median: 34.6937\n    ii_high_mean: 1.5151\n    ii_mid_mean: 78.8215\n    ii_low_mean: 1163.9677\n    per_problem_ii_count: 50\n    n_high: 40\n    n_mid: 22\n    n_low: 20\n    problems: 50\n    bootstrap_gradient_paired: 41.92\n    bootstrap_ci_paired:\n    - 19.14\n    - 299.76\n    bootstrap_gradient_unpaired: 39.28\n    bootstrap_ci_unpaired:\n    - 21.87\n    - 129.59\n    bootstrap_p: 0\n- exp_id: v6_importance_s015\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 0.2266\n    ii_mid_median: 0.7432\n    ii_low_median: 2.8762\n    ii_high_mean: 0.2874\n    ii_mid_mean: 1.6858\n    ii_low_mean: 8.5161\n    per_problem_ii_count: 50\n    n_high: 43\n    n_mid: 32\n    n_low: 24\n    problems: 50\n    bootstrap_gradient_paired: 11.53\n    bootstrap_ci_paired:\n    - 3.49\n    - 23.78\n    bootstrap_gradient_unpaired: 12.69\n    bootstrap_ci_unpaired:\n    - 4.96\n    - 28.45\n    bootstrap_p: 0\n- exp_id: v6_importance_s020\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 0.3353\n    ii_mid_median: 1.6733\n    ii_low_median: 9.2538\n    ii_high_mean: 0.4936\n    ii_mid_mean: 4.9538\n    ii_low_mean: 25.8764\n    per_problem_ii_count: 50\n    n_high: 42\n    n_mid: 28\n    n_low: 21\n    problems: 50\n    bootstrap_gradient_paired: 11.05\n    bootstrap_ci_paired:\n    - 5.42\n    - 69.27\n    bootstrap_gradient_unpaired: 27.6\n    bootstrap_ci_unpaired:\n    - 6.55\n    - 75.16\n    bootstrap_p: 0\n- exp_id: qwen_importance_s015\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: qwen_importance_s020\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: qwen_importance_s025\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: qwen_importance_s030\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: v6_random_s015\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 0.1606\n    ii_mid_median: 0.252\n    ii_low_median: 0.1831\n    ii_high_mean: 0.4563\n    ii_mid_mean: 0.5134\n    ii_low_mean: 0.4775\n    per_problem_ii_count: 50\n    n_high: 43\n    n_mid: 32\n    n_low: 28\n    bootstrap_gradient_paired: -0.2722\n    bootstrap_ci_paired:\n    - -0.7039\n    - 0.1548\n    bootstrap_p: 0.903\n    bootstrap_gradient_unpaired: -0.0592\n    bootstrap_ci_unpaired:\n    - -0.5341\n    - 0.3877\n    per_problem_ii_stats:\n      high:\n        min: -3.0621\n        max: 5.018\n        mean: 0.5386\n        median: 0.2003\n        std: 1.2085\n      mid:\n        min: -2.7245\n        max: 4.6713\n        mean: 0.3977\n        median: 0.299\n        std: 1.1456\n      low:\n        min: -0.4031\n        max: 3.7005\n        mean: 0.4806\n        median: 0.2465\n        std: 0.779\n    verdict: FAIL\n- exp_id: v6_random_s020\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_mean: 0.855584\n    ii_high_median: 0.321331\n    ii_high_ci:\n    - -0.124133\n    - 1.616883\n    ii_high_winsorized_mean: 0.913496\n    ii_mid_mean: 1.258123\n    ii_mid_median: 0.455663\n    ii_mid_ci:\n    - 0.674852\n    - 2.075565\n    ii_mid_winsorized_mean: 1.074102\n    ii_low_mean: 0.956933\n    ii_low_median: 0.591916\n    ii_low_ci:\n    - 0.583856\n    - 1.413355\n    ii_low_winsorized_mean: 0.96113\n    n_high: 511\n    n_mid: 391\n    n_low: 454\n    problems: 50\n    per_problem_ii_count: 50\n    gradient_mean_low_over_high: 1.118\n    gradient_median_low_over_high: 1.842\n    pass_fail: FAIL\n    perplexity_high_dense: 1.1462\n    perplexity_high_both: 7.9749\n    perplexity_mid_dense: 1.1226\n    perplexity_mid_both: 6.8553\n    perplexity_low_dense: 1.1105\n    perplexity_low_both: 22.5868\n- exp_id: v6_random_s025\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    ii_high_median: 3.0024\n    ii_mid_median: 2.9846\n    ii_low_median: 2.9146\n    ii_high_mean: 3.9052\n    ii_mid_mean: 7.9491\n    ii_low_mean: 3.9114\n    per_problem_ii_count: 50\n    n_high: 36\n    n_mid: 25\n    n_low: 24\n    bootstrap_gradient_paired: -0.1199\n    bootstrap_ci_paired:\n    - -1.517\n    - 1.2461\n    bootstrap_p: 0.559\n    bootstrap_gradient_unpaired: -0.8616\n    bootstrap_ci_unpaired:\n    - -3.3911\n    - 1.5169\n    per_problem_ii_stats:\n      high:\n        min: -6.1388\n        max: 25.2471\n        mean: 4.4098\n        median: 3.0421\n        std: 6.0734\n      mid:\n        min: 0.158\n        max: 108.7242\n        mean: 7.5626\n        median: 2.1407\n        std: 20.926\n      low:\n        min: -0.1953\n        max: 12.8555\n        mean: 3.5806\n        median: 2.7289\n        std: 3.4915\n    verdict: FAIL\n- exp_id: v6_random_s030\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: v6_random_s030_r2\n  name: ''\n  status: DONE\n  conclusion: failed\n  metrics: {}\n- exp_id: bf16_importance_s015\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: -0.150213\n        median: 0.005752\n        ci:\n        - -0.294614\n        - -0.055385\n        winsorized_mean: -0.062378\n        skewness: -14.9912\n      mid:\n        mean: 0.447301\n        median: 0.080738\n        ci:\n        - 0.267993\n        - 0.668749\n        winsorized_mean: 0.324751\n        skewness: 4.7221\n      low:\n        mean: 2.405837\n        median: 0.398291\n        ci:\n        - 1.478784\n        - 3.667675\n        winsorized_mean: 1.278857\n        skewness: 9.5402\n    per_problem_ii_stats:\n      high:\n        n: 49\n        min: -0.188061\n        max: 0.335853\n        mean: -0.013405\n        median: 0.00012\n        std: 0.078483\n      mid:\n        n: 40\n        min: -0.169092\n        max: 3.88198\n        mean: 0.308621\n        median: 0.107114\n        std: 0.690186\n      low:\n        n: 50\n        min: -0.872983\n        max: 9.10289\n        mean: 0.725504\n        median: 0.315517\n        std: 1.731056\n    gradient_paired_aggregate_legacy: 69.24\n    median_difference: 0.3925\n    n_problems: 50\n    pass_fail:\n      ci_overlap: true\n      sign_reversal: true\n      overall: PASS\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    perplexity:\n      high:\n        dense: 1.1689\n        attn: 1.4861\n        kv: 1.4481\n        both: 1.5911\n      mid:\n        dense: 1.2269\n        attn: 1.5137\n        kv: 2.5971\n        both: 3.4541\n      low:\n        dense: 1.2286\n        attn: 1.6147\n        kv: 8.9201\n        both: 12.5084\n- exp_id: bf16_importance_s020\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 0.1289\n        median: 0.0145\n        ci:\n        - -0.1975\n        - 0.6647\n        winsorized_mean: -0.0297\n        skewness: 16.67\n      mid:\n        mean: 1.2604\n        median: 0.2027\n        ci:\n        - 0.7466\n        - 1.8962\n        winsorized_mean: 0.766\n        skewness: 7.05\n      low:\n        mean: 6.0288\n        median: 1.4963\n        ci:\n        - 4.4671\n        - 7.9237\n        winsorized_mean: 4.3426\n        skewness: 6.01\n    per_problem_ii_stats:\n      high:\n        n: 49\n        min: -0.1884\n        max: 0.4196\n        mean: 0.0025\n        median: 0.0036\n        std: 0.0966\n      mid:\n        n: 40\n        min: -0.0519\n        max: 8.6969\n        mean: 0.6795\n        median: 0.1977\n        std: 1.4998\n      low:\n        n: 50\n        min: -1.6151\n        max: 22.6875\n        mean: 2.2301\n        median: 1.128\n        std: 4.3758\n    gradient_paired_aggregate_legacy: 5.9\n    median_difference: 1.4818\n    n_problems: 50\n    pass_fail:\n      ci_overlap: true\n      sign_reversal: false\n      overall: PASS\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    perplexity:\n      high:\n        dense: 1.1689\n        attn: 1.5233\n        kv: 1.6191\n        both: 2.1047\n      mid:\n        dense: 1.2269\n        attn: 1.5375\n        kv: 3.5164\n        both: 5.4246\n      low:\n        dense: 1.2286\n        attn: 1.6486\n        kv: 15.7987\n        both: 23.74\n- exp_id: bf16_importance_s025\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 0.302756\n        median: 0.032363\n        ci:\n        - 0.083714\n        - 0.543977\n        winsorized_mean: 0.200962\n        skewness: 4.8826\n      mid:\n        mean: 5.729665\n        median: 1.118069\n        ci:\n        - 3.455574\n        - 8.471799\n        winsorized_mean: 4.189902\n        skewness: 8.2799\n      low:\n        mean: 25.852951\n        median: 7.195958\n        ci:\n        - 19.077082\n        - 33.497293\n        winsorized_mean: 19.319103\n        skewness: 7.3986\n    per_problem_ii_stats:\n      high:\n        n: 49\n        min: -0.316321\n        max: 4.003714\n        mean: 0.133714\n        median: 0.009873\n        std: 0.595358\n      mid:\n        n: 40\n        min: -0.024794\n        max: 18.720486\n        mean: 2.537744\n        median: 1.05707\n        std: 3.962575\n      low:\n        n: 50\n        min: -1.854733\n        max: 75.467653\n        mean: 11.28281\n        median: 3.954593\n        std: 16.620011\n    gradient_paired_aggregate_legacy: 222.35\n    median_difference: 7.1636\n    n_problems: 50\n    pass_fail:\n      ci_overlap: true\n      sign_reversal: false\n      overall: PASS\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    perplexity:\n      high:\n        dense: 1.1689\n        attn: 1.6511\n        kv: 1.8628\n        both: 2.7026\n      mid:\n        dense: 1.2269\n        attn: 1.7039\n        kv: 5.6205\n        both: 13.3436\n      low:\n        dense: 1.2286\n        attn: 1.8366\n        kv: 31.756\n        both: 63.668\n- exp_id: bf16_importance_s030\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 0.5547\n        median: 0.0534\n        ci:\n        - 0.2773\n        - 0.9198\n        winsorized_mean: 0.3367\n        skewness: 10.62\n      mid:\n        mean: 11.3\n        median: 2.2833\n        ci:\n        - 6.865\n        - 17.2633\n        winsorized_mean: 8.1752\n        skewness: 9.19\n      low:\n        mean: 57.7946\n        median: 14.6395\n        ci:\n        - 41.4416\n        - 77.0467\n        winsorized_mean: 39.3143\n        skewness: 8.31\n    per_problem_ii_stats:\n      high:\n        n: 49\n        min: -0.5095\n        max: 4.4457\n        mean: 0.1976\n        median: 0.0343\n        std: 0.6793\n      mid:\n        n: 40\n        min: -0.1989\n        max: 34.0258\n        mean: 5.2585\n        median: 1.5173\n        std: 7.9382\n      low:\n        n: 50\n        min: -7.3027\n        max: 126.7985\n        mean: 22.6601\n        median: 9.9731\n        std: 28.4096\n    gradient_paired_aggregate_legacy: 57.24\n    median_difference: 14.5861\n    n_problems: 50\n    pass_fail:\n      ci_overlap: true\n      sign_reversal: false\n      overall: PASS\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    perplexity:\n      high:\n        dense: 1.1689\n        attn: 1.7123\n        kv: 2.0544\n        both: 3.2372\n      mid:\n        dense: 1.2269\n        attn: 1.7894\n        kv: 9.4821\n        both: 24.2847\n      low:\n        dense: 1.2286\n        attn: 1.9347\n        kv: 51.6485\n        both: 122.61\n- exp_id: bf16_random_s015\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: bf16_random_s020\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: bf16_random_s025\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: bf16_random_s030\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: bf16_qwen_importance_s015\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: bf16_qwen_importance_s020\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: bf16_qwen_importance_s025\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: bf16_qwen_importance_s030\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics: {}\n- exp_id: v6_random_s030_r3\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    II_high_mean: 9.2364\n    II_mid_mean: -230.7604\n    II_low_mean: -7.4119\n    II_high_median: 4.0237\n    II_mid_median: 2.4272\n    II_low_median: 4.735\n    ppl_low_both: 88.94\n    per_problem_count: 50\n- exp_id: bf16_ds_imp_s015\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics:\n    median_difference: 0.323579\n    permutation_p: 0\n    cohens_d: 0.6068\n    bootstrap_ci_95:\n    - 0.198824\n    - 0.471566\n    wilcoxon_p: 0\n    n_bootstrap: 10000\n    n_paired: 49\n- exp_id: bf16_ds_imp_s020\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics:\n    median_difference: 1.15202\n    permutation_p: 0\n    cohens_d: 0.725\n    bootstrap_ci_95:\n    - 0.655454\n    - 1.256001\n    wilcoxon_p: 0\n    n_bootstrap: 10000\n    n_paired: 49\n- exp_id: bf16_ds_imp_s025\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics:\n    median_difference: 3.968568\n    permutation_p: 0\n    cohens_d: 0.9534\n    bootstrap_ci_95:\n    - 2.829037\n    - 5.291756\n    wilcoxon_p: 0\n    n_bootstrap: 10000\n    n_paired: 49\n- exp_id: bf16_ds_imp_s030\n  name: ''\n  status: DONE\n  conclusion: killed\n  metrics:\n    median_difference: 9.943595\n    permutation_p: 0\n    cohens_d: 1.1263\n    bootstrap_ci_95:\n    - 8.391554\n    - 16.652865\n    wilcoxon_p: 0\n    n_bootstrap: 10000\n    n_paired: 49\n- exp_id: bf16_ds_rand_s015\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 0.2208\n        median: 0.0931\n        ci:\n        - -1.0091\n        - 1.5243\n        median_ci:\n        - 0.0024\n        - 0.1515\n        winsorized_mean: 0.3161\n        skewness: -5.4\n      mid:\n        mean: -3.3604\n        median: 0.0967\n        ci:\n        - -8.4057\n        - 0.3697\n        median_ci:\n        - 0.0219\n        - 0.197\n        winsorized_mean: -0.6366\n        skewness: -10.56\n      low:\n        mean: -1.8952\n        median: 0.1026\n        ci:\n        - -4.9698\n        - 0.2741\n        median_ci:\n        - 0.044\n        - 0.1755\n        winsorized_mean: 0.0521\n        skewness: -11.57\n    perplexity:\n      high:\n        dense: 1.1687\n        attn: 3.5947\n        kv: 2.9239\n        both: 5.7569\n      mid:\n        dense: 1.2269\n        attn: 297.7957\n        kv: 2.915\n        both: 11.3156\n      low:\n        dense: 1.2284\n        attn: 11.3419\n        kv: 3.6161\n        both: 6.2886\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    n_problems: 50\n    pass_fail:\n      ci_overlap: false\n      sign_reversal: false\n      overall: FAIL\n    median_difference: 0.0095\n- exp_id: bf16_ds_rand_s020\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 1.1216\n        median: 0.2918\n        ci:\n        - 0.0796\n        - 2.5834\n        median_ci:\n        - 0.1598\n        - 0.4581\n        winsorized_mean: 1.7664\n        skewness: 9.59\n      mid:\n        mean: -1.5827\n        median: 0.3504\n        ci:\n        - -6.0963\n        - 1.5735\n        median_ci:\n        - 0.1993\n        - 0.5226\n        winsorized_mean: 0.5839\n        skewness: -12.31\n      low:\n        mean: -0.4116\n        median: 0.2763\n        ci:\n        - -2.6034\n        - 1.209\n        median_ci:\n        - 0.2194\n        - 0.5487\n        winsorized_mean: 0.9942\n        skewness: -10.07\n    perplexity:\n      high:\n        dense: 1.1687\n        attn: 3.1905\n        kv: 3.8002\n        both: 8.8129\n      mid:\n        dense: 1.2269\n        attn: 67.8504\n        kv: 3.788\n        both: 11.4974\n      low:\n        dense: 1.2284\n        attn: 8.592\n        kv: 5.0078\n        both: 9.2001\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    n_problems: 50\n    pass_fail:\n      ci_overlap: false\n      sign_reversal: false\n      overall: FAIL\n    median_difference: -0.0155\n- exp_id: bf16_ds_rand_s025\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 3.59\n        median: 0.8182\n        ci:\n        - 1.4021\n        - 6.2327\n        median_ci:\n        - 0.5075\n        - 1.7217\n        winsorized_mean: 6.3965\n        skewness: -7.57\n      mid:\n        mean: -1.8455\n        median: 0.9324\n        ci:\n        - -10.3663\n        - 4.9342\n        median_ci:\n        - 0.7331\n        - 1.7003\n        winsorized_mean: 3.1014\n        skewness: -12.76\n      low:\n        mean: 0.7212\n        median: 1.3627\n        ci:\n        - -4.2068\n        - 4.5006\n        median_ci:\n        - 1.0869\n        - 2.6866\n        winsorized_mean: 4.1866\n        skewness: -15.85\n    perplexity:\n      high:\n        dense: 1.1687\n        attn: 7.237\n        kv: 4.9751\n        both: 17.7423\n      mid:\n        dense: 1.2269\n        attn: 868.3199\n        kv: 5.1165\n        both: 29.4661\n      low:\n        dense: 1.2284\n        attn: 24.3571\n        kv: 6.7993\n        both: 17.9694\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    n_problems: 50\n    pass_fail:\n      ci_overlap: false\n      sign_reversal: false\n      overall: FAIL\n    median_difference: 0.5445\n- exp_id: bf16_ds_rand_s030\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 7.5555\n        median: 2.5031\n        ci:\n        - 4.4087\n        - 11.6199\n        median_ci:\n        - 1.3292\n        - 4.1205\n        winsorized_mean: null\n        skewness: null\n      mid:\n        mean: 6.2518\n        median: 2.5918\n        ci:\n        - 2.1767\n        - 10.4757\n        median_ci:\n        - 1.8397\n        - 3.7888\n        winsorized_mean: null\n        skewness: null\n      low:\n        mean: 6.8323\n        median: 4.0414\n        ci:\n        - 3.2428\n        - 10.6996\n        median_ci:\n        - 2.2686\n        - 6.3579\n        winsorized_mean: null\n        skewness: null\n    perplexity:\n      high:\n        dense: 1.1687\n        attn: 16.7892\n        kv: 8.8073\n        both: 40.7553\n      mid:\n        dense: 1.2269\n        attn: 2461.9219\n        kv: 8.6662\n        both: 62.4422\n      low:\n        dense: 1.2284\n        attn: 55.2916\n        kv: 11.5789\n        both: 37.6009\n    phase_stats:\n      high:\n        n_tokens: 21086\n        n_segments: 387\n      mid:\n        n_tokens: 13306\n        n_segments: 191\n      low:\n        n_tokens: 27748\n        n_segments: 397\n    n_problems: 50\n    pass_fail:\n      ci_overlap: false\n      sign_reversal: false\n      overall: FAIL\n    median_difference: 1.5383\n- exp_id: bf16_qw_imp_s015\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    median_difference: 0.047619\n    permutation_p: 0.0001\n    cohens_d: 0.3705\n    bootstrap_ci_95:\n    - -0.005077\n    - 0.109517\n    wilcoxon_p: 0.02958\n    n_bootstrap: 10000\n    n_paired: 46\n- exp_id: bf16_qw_imp_s020\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    median_difference: 0.207511\n    permutation_p: 0\n    cohens_d: 0.7224\n    bootstrap_ci_95:\n    - 0.067222\n    - 0.40226\n    wilcoxon_p: 3.4e-05\n    n_bootstrap: 10000\n    n_paired: 46\n- exp_id: bf16_qw_imp_s025\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    median_difference: 1.108706\n    permutation_p: 0\n    cohens_d: 1.2329\n    bootstrap_ci_95:\n    - 0.609247\n    - 1.469002\n    wilcoxon_p: 0\n    n_bootstrap: 10000\n    n_paired: 46\n- exp_id: bf16_qw_imp_s030\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    median_difference: 2.619385\n    permutation_p: 0\n    cohens_d: 1.4394\n    bootstrap_ci_95:\n    - 1.722281\n    - 3.651063\n    wilcoxon_p: 0\n    n_bootstrap: 10000\n    n_paired: 46\n- exp_id: bf16_qw_rand_s015\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 1.6652\n        median: 0.1381\n        ci:\n        - 1.0986\n        - 2.4042\n        median_ci:\n        - 0.1025\n        - 0.2074\n        winsorized_mean: 1.0044\n        skewness: 7.1842\n      mid:\n        mean: 1.6975\n        median: 0.2194\n        ci:\n        - 0.4473\n        - 3.4612\n        median_ci:\n        - -0.0048\n        - 0.6621\n        winsorized_mean: 1.4038\n        skewness: 3.2101\n      low:\n        mean: 1.4082\n        median: 0.1878\n        ci:\n        - 0.8358\n        - 2.06\n        median_ci:\n        - 0.0962\n        - 0.3139\n        winsorized_mean: 0.9403\n        skewness: 7.1113\n    perplexity:\n      high:\n        dense: 1.0737\n        attn: 1.3939\n        kv: 2.0487\n        both: 4.2076\n      mid:\n        dense: 1.1322\n        attn: 1.4175\n        kv: 2.3709\n        both: 4.6105\n      low:\n        dense: 1.1517\n        attn: 1.7177\n        kv: 3.3253\n        both: 5.4788\n    phase_stats:\n      high:\n        n_tokens: 16289\n        n_segments: 295\n      mid:\n        n_tokens: 4372\n        n_segments: 26\n      low:\n        n_tokens: 32227\n        n_segments: 276\n    n_problems: 50\n    pass_fail:\n      ci_overlap: true\n      sign_reversal: false\n      overall: FAIL\n    median_difference: -0.029401\n    permutation_test:\n      p_value: 0.7657\n      B: 10000\n    cohens_d: -0.0507\n    bootstrap_ci_95:\n    - -0.2106\n    - 0.2124\n    wilcoxon_p: 0.862554\n    phase_median_ii:\n      high: 0.1381\n      mid: 0.2194\n      low: 0.1878\n- exp_id: bf16_qw_rand_s020\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 2.58579\n        median: 0.48549\n        ci:\n        - 1.769404\n        - 3.501692\n        median_ci:\n        - 0.304626\n        - 0.658814\n        winsorized_mean: 1.80021\n        skewness: 5.4038\n      mid:\n        mean: 5.69684\n        median: 0.76699\n        ci:\n        - 1.69004\n        - 12.276143\n        median_ci:\n        - 0.482838\n        - 3.392541\n        winsorized_mean: 4.304174\n        skewness: 3.526\n      low:\n        mean: 65.915714\n        median: 0.614438\n        ci:\n        - -18.581948\n        - 221.709429\n        median_ci:\n        - 0.484725\n        - 0.848787\n        winsorized_mean: 2.389244\n        skewness: 16.2163\n    perplexity:\n      high:\n        dense: 1.0737\n        attn: 1.6115\n        kv: 2.5041\n        both: 5.9394\n      mid:\n        dense: 1.1322\n        attn: 1.7583\n        kv: 3.0658\n        both: 10.5578\n      low:\n        dense: 1.1517\n        attn: 75.631\n        kv: 4.3535\n        both: 140.6269\n    phase_stats:\n      high:\n        n_tokens: 16289\n        n_segments: 295\n      mid:\n        n_tokens: 4372\n        n_segments: 26\n      low:\n        n_tokens: 32227\n        n_segments: 276\n    n_problems: 50\n    pass_fail:\n      ci_overlap: true\n      sign_reversal: false\n      overall: FAIL\n    median_difference: 0.128948\n    permutation_test:\n      p_value: 0.352\n      B: 10000\n    cohens_d: 0.247\n    bootstrap_ci_95:\n    - -0.139\n    - 0.215\n    wilcoxon_p: 0.149\n    phase_median_ii:\n      high: 0.4739\n      mid: 0.8757\n      low: 0.4847\n- exp_id: bf16_qw_rand_s025\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    interaction_index:\n      high:\n        mean: 14.4213\n        median: 1.6043\n        ci:\n        - 7.1074\n        - 23.4587\n        median_ci:\n        - 0.6977\n        - 3.0736\n        winsorized_mean: 9.3765\n        skewness: 4.8263\n      mid:\n        mean: 18.6458\n        median: 2.2225\n        ci:\n        - 3.3729\n        - 41.6037\n        median_ci:\n        - 0.6093\n        - 11.5889\n        winsorized_mean: 14.2901\n        skewness: 3.8245\n      low:\n        mean: 17.7277\n        median: 2.2641\n        ci:\n        - 4.3523\n        - 37.2093\n        median_ci:\n        - 1.2218\n        - 4.8561\n        winsorized_mean: 9.9876\n        skewness: 5.7652\n    perplexity:\n      high:\n        dense: 1.0737\n        attn: 2.0183\n        kv: 3.1882\n        both: 9.7654\n      mid:\n        dense: 1.1322\n        attn: 2.3476\n        kv: 4.0124\n        both: 17.3298\n      low:\n        dense: 1.1517\n        attn: 2.7834\n        kv: 5.8762\n        both: 25.4321\n    phase_stats:\n      high:\n        n_tokens: 16289\n        n_segments: 295\n      mid:\n        n_tokens: 4372\n        n_segments: 26\n      low:\n        n_tokens: 32227\n        n_segments: 276\n    n_problems: 50\n    pass_fail:\n      ci_overlap: true\n      sign_reversal: false\n      overall: FAIL\n    median_difference: 1.144074\n    permutation_test:\n      p_value: 0.1679\n      B: 10000\n    cohens_d: 0.1574\n    bootstrap_ci_95:\n    - -0.3166\n    - 4.1645\n    wilcoxon_p: 0.010313\n    phase_median_ii:\n      high: 1.6043\n      mid: 2.2225\n      low: 2.2641\n- exp_id: bf16_qw_rand_s030\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    median_high: 4.200557\n    median_mid: 6.477036\n    median_low: 8.065662\n    median_diff: 2.418272\n    permutation_p: 0.012\n    cohens_d: -0.03513\n    wilcoxon_p: 0.01566\n    bootstrap_ci_low: 0.241897\n    bootstrap_ci_high: 3.314824\n- exp_id: c4_entropy\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    importance_entropy_delta:\n      s015: -0.0402\n      s020: -0.0472\n      s025: -0.0446\n      s030: -0.0436\n    random_entropy_delta:\n      s015: 0.1283\n      s020: 0.136\n      s025: 0.2171\n      s030: 0.2327\n    importance_gini_delta:\n      s015: -0.0301\n      s020: -0.0404\n      s025: -0.0647\n      s030: -0.0806\n    random_gini_delta:\n      s015: -0.0309\n      s020: -0.0403\n      s025: -0.062\n      s030: -0.0732\n    importance_cv_delta:\n      s015: -0.564\n      s020: -0.774\n      s025: -1.287\n      s030: -1.665\n    random_cv_delta:\n      s015: -1.021\n      s020: -1.203\n      s025: -1.923\n      s030: -2.137\n    problems_completed: 30\n    runtime_minutes: 69.1\n- exp_id: qwen_c4_entropy\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    problems_completed: 30\n    qwen_importance_entropy_delta:\n      s015: -0.0733\n      s020: -0.0759\n      s025: 0.0451\n      s030: -0.0072\n    qwen_random_entropy_delta:\n      s015: 0.0838\n      s020: 0.0901\n      s025: 0.2168\n      s030: 0.1968\n    qwen_importance_gini_delta:\n      s015: -0.0103\n      s020: -0.0121\n      s025: -0.01\n      s030: -0.0202\n    qwen_random_gini_delta:\n      s015: -0.0186\n      s020: -0.0229\n      s025: -0.0337\n      s030: -0.0448\n    qwen_importance_cv_delta:\n      s015: -0.045\n      s020: -0.208\n      s025: -1.491\n      s030: -1.142\n    qwen_random_cv_delta:\n      s015: -0.778\n      s020: -0.889\n      s025: -1.5\n      s030: -1.677\n    cross_model_notes: random entropy increase consistent; importance entropy collapse\n      inconsistent at s025 (reversed to +0.045) and near-zero at s030; gini/cv directions\n      consistent but Qwen magnitudes smaller\n- exp_id: bf16_ds_imp_s010\n  name: ''\n  status: DONE\n  conclusion: negative\n  metrics:\n    verdict: FAIL\n    problems: 50\n    II_high_sparsity_median: 0.0027\n    II_high_sparsity_mean: -0.1998\n    II_low_sparsity_median: 0.0151\n    II_low_sparsity_mean: -0.1066\n    II_mid_sparsity_median: 0.0061\n    II_mid_sparsity_mean: -0.0131\n    high_sparsity_tokens: 21086\n    low_sparsity_tokens: 27748\n    mid_sparsity_tokens: 13306\n- exp_id: bf16_ds_imp_s035\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    verdict: PASS\n    problems: 50\n    II_high_sparsity_median: 0.1051\n    II_high_sparsity_mean: 1.4309\n    II_low_sparsity_median: 28.7649\n    II_low_sparsity_mean: 104.1892\n    II_mid_sparsity_median: 4.9542\n    II_mid_sparsity_mean: 20.326\n    high_sparsity_tokens: 21086\n    low_sparsity_tokens: 27748\n    mid_sparsity_tokens: 13306\n    ci_overlap_test: low_sparsity vs mid_sparsity CI non-overlapping at 0.35\n- exp_id: bf16_qw_imp_s010\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    n_problems: 50\n    overall_verdict: PASS\n    ci_overlap_test: PASS\n    sign_reversal_test: FAIL\n    high_sparsity_II_median: 0.0001\n    high_sparsity_II_median_CI:\n    - -0.0028\n    - 0.0005\n    high_sparsity_II_mean: -0.0887\n    high_sparsity_II_mean_CI:\n    - -0.1235\n    - -0.0591\n    low_sparsity_II_median: -0.0444\n    low_sparsity_II_median_CI:\n    - -0.0967\n    - -0.0152\n    low_sparsity_II_mean: -0.2431\n    low_sparsity_II_mean_CI:\n    - -0.3817\n    - -0.1202\n    mid_sparsity_II_median: -0.0359\n    mid_sparsity_II_median_CI:\n    - -0.0963\n    - -0.015\n    mid_sparsity_II_mean: -0.084\n    mid_sparsity_II_mean_CI:\n    - -0.1366\n    - -0.035\n    ppl_high_dense: 1.074\n    ppl_high_both: 1.228\n    ppl_low_dense: 1.152\n    ppl_low_both: 3.204\n    ppl_mid_dense: 1.133\n    ppl_mid_both: 1.741\n- exp_id: bf16_qw_imp_s035\n  name: ''\n  status: DONE\n  conclusion: success\n  metrics:\n    n_problems: 50\n    overall_verdict: PASS\n    ci_overlap_test: PASS\n    sign_reversal_test: FAIL\n    high_sparsity_II_median: 0.0232\n    high_sparsity_II_median_CI:\n    - 0.0154\n    - 0.0383\n    high_sparsity_II_mean: 0.1643\n    high_sparsity_II_mean_CI:\n    - 0.0844\n    - 0.2495\n    low_sparsity_II_median: 8.2358\n    low_sparsity_II_median_CI:\n    - 6.1564\n    - 10.9231\n    low_sparsity_II_mean: 18.9673\n    low_sparsity_II_mean_CI:\n    - 14.5015\n    - 23.9752\n    mid_sparsity_II_median: 0.9577\n    mid_sparsity_II_median_CI:\n    - 0.171\n    - 3.5575\n    mid_sparsity_II_mean: 8.0734\n    mid_sparsity_II_mean_CI:\n    - 2.0224\n    - 16.8946\n    ppl_high_dense: 1.0738\n    ppl_high_both: 2.3435\n    ppl_low_dense: 1.1518\n    ppl_low_both: 58.0358\n    ppl_mid_dense: 1.1327\n    ppl_mid_both: 20.9912\n    high_sparsity_tokens: 16289\n    low_sparsity_tokens: 32227\n    mid_sparsity_tokens: 4372\n- exp_id: c2_n500_deepseek\n  name: ''\n  status: RUNNING\n  conclusion: ''\n  metrics: {}\n- exp_id: c3_llama_arch\n  name: ''\n  status: PENDING\n  conclusion: killed\n  metrics: {}\n- exp_id: c2_ds_n500\n  name: ''\n  status: PENDING\n  conclusion: killed\n  metrics: {}\n- exp_id: c2_qw_n500\n  name: ''\n  status: RUNNING\n  conclusion: ''\n  metrics: {}\n- exp_id: c3_llama\n  name: ''\n  status: PREPARING\n  conclusion: ''\n  metrics: {}\n\n# 输出格式（YAML，仅输出一个 ```yaml 块）\n\n```yaml\ntier: best\nnarrative_guidance: \"...\"\nimagined_experiments:\n  - name: \"...\"\n    plan_id: \"...\"\n    description: \"...\"\n    expected_results: {metric: value, ...}\n    result_rationale: \"...\"\n    tables: []\n    figures_description: []\n    analysis: \"...\"\n```\n"
}
````

---

### Runtime record

_source line 2 · 2026-05-14T14:37:10.249Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-14T14:37:10.249Z",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

## Round 1

21 recorded events

### User

_source line 3 · 2026-05-14T14:37:10.274Z_

你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：

含义：C5 pilot 通过 gate（LLaMA 复现 phase gradient + crossover），n=500 收紧 Qwen s015 CI 至零以上，所有 claims 原样成立
核心假设：['C5 LLaMA-8B s025/s030 pilot 回收 >30% compound degradation，crossover 方向与 DeepSeek/Qwen 一致', 'C2 n=500 后 Qwen s015 paired median diff CI 下界 > 0（消除边缘性）', 'DeepSeek n=500 CI 宽度缩窄 ≥30%，点估计稳定在已有范围内', 'C4 discrimination collapse (Gini/CV) 在 LLaMA 上方向一致（无需 entropy 一致）']
关键指标范围：{'c5_llama_paired_median_diff_s025': [1.0, 5.0], 'c5_llama_cohens_d_s025': [0.5, 1.2], 'c5_llama_crossover_present': [True], 'c2_qw_s015_n500_ci_lower': [0.01, 0.08], 'c2_qw_s015_n500_median_diff': [0.05, 0.12], 'c2_ds_n500_ci_width_reduction_pct': [30, 50], 'c2_ds_s015_n500_median_diff': [0.28, 0.38], 'confirmed_arch_families': [3]}
叙事方向：原始 framing 完全成立：emergent phase-strategy interaction 跨架构泛化。 Title 可用 "generalizes across architectures"。C1-C6 全部 confirmed。 论文三大贡献不变：(1) 发现 + 跨架构验证，(2) 量化 gradient + crossover，(3) discrimination collapse 机制。 Limitations 缩至 scale (7B-8B only) 和 single benchmark。 RC1 (generalizability) 通过 LLaMA 直接回应，RC5 (novelty) 通过 crossover 跨架构复现强化。


基于以上定义，对 experiment_plan 中每个 planned 实验展开详细数据。
每条预测都必须给出 result_rationale —— 解释为什么在这个档位下会得到这样的结果。

# Project context
project: phase-gated-compound-sparse
focus: D052 调整后的完整 plan：C5 pilot-first 跨架构验证、C2 n=500 预注册叙事、C7/C8 写作任务、Lethe/SparK 区分。重点关注：(1) pilot-first 策略是否足够支撑泛化性 claim；(2) C7/C8 作为写作任务是否被审稿人视为弱点；(3) 11 天 deadline 下 plan 可行性

## paper_framing.md

# Paper Framing — Phase-Gated Compound Sparsity

> 最后更新: 2026-05-14 (D052 审稿应对调整) | 维护者: Director

## Core Insight

Compound sparsity（attention head pruning + KV cache eviction）的 severity 不是固定常数——它是 eviction strategy 和 reasoning phase 交互的涌现属性。Importance-based eviction 的 compound interaction severity（paired median difference: median(II_low_i − II_high_i)）随 sparsity 单调递增（DeepSeek: 0.32→1.15→3.97→9.94; Qwen: 0.048→0.208→1.109→2.619），而 random masking 三相 II 持平（7/8 FAIL; Qwen s030 PASS p=0.012 but d=-0.04 negligible）。Cohen's d（paired d_z, B=10000）从 small-medium 到 large（DeepSeek: 0.44→0.80; Qwen: 0.28→1.02，s015 边缘）。这一发现挑战了 compound degradation 均匀分布的隐含假设。

**数字基准**：所有数字基于 bf16 per-problem paired 统计量（B=10000 bootstrap）。median_diff 定义为 median(II_low_i − II_high_i)（逐 problem 配对差的中位数）。fp16 旧数据已弃用。

## Narrative Arc

Compound sparsity 是高效 LLM 推理的实用部署需求，但 prior work（SparK, Ada-KV, SLiM）将 compound interaction 视为均匀超可加。我们发现 severity 是 strategy × phase 交互的涌现属性：importance eviction 的 compound interaction 在 low-sparsity phase 远大于 high-sparsity phase（paired median difference 单调递增 0.32→9.94），而 random eviction 在所有 phase 保持平坦（7/8 FAIL; 唯一例外 Qwen s030 p=0.012 效应量可忽略 d=-0.04）。Cross-model replication 方向一致（Qwen magnitude ~1/4 of DeepSeek，onset threshold s≥0.20）。C3 crossover 现象的 LLaMA 架构验证已列入计划（plan_009 pilot-first），以测试发现的跨架构泛化性。我们通过 discrimination collapse 机制解释这一现象：head pruning → importance score 的判别力崩塌（Gini/CV 下降跨模型一致）→ importance eviction 退化为有偏伪随机。Attention entropy redistribution 作为 model-dependent secondary effect 在 DeepSeek 上观察到，但在 Qwen 上不稳健（D044）。

**Framing 硬约束（D015）**：
- MUST: \"emergent phase-strategy interaction\"
- MUST NOT: \"importance metric limitation / importance is broken\"
- MUST NOT: claim \"importance masking produces super-additive interaction\" without qualifier — random masking also produces positive II. The distinguishing signal is **phase-dependent gradient** (importance: paired median difference 0.32→9.94 单调递增 vs random: 7/8 FAIL), not the existence of super-additivity itself (D023)

## Core Claims

| ID | Claim | Status | Key Evidence |
|----|-------|--------|-------------|
| C1 | Compound sparsity severity is strategy-dependent | confirmed | importance paired median diff 0.32→9.94 单调递增 vs random 7/8 FAIL (bf16; Qwen s030 PASS p=0.012 d=-0.04 negligible) |
| C2 | Severity is phase-modulated (amplified in low-sparsity phase) | confirmed | bf16 paired median difference 单调递增: 0.32→1.15→3.97→9.94; Bonferroni p<0.005 全 4 水平 (D032)。预注册：n=500 后若 QW s015 CI 仍跨零，叙事改为 'compound effect emerges above threshold sparsity (~s020)' |
| C3 | Phase-strategy crossover exists | confirmed | s=0.25: importance high_phase=0.032 < random=0.818, importance low_phase=7.196 > random=1.363 (bf16) |
| C4 | Discrimination collapse as primary mechanism; entropy redistribution model-dependent | partially_confirmed | D044: Gini/CV 下降跨模型一致; entropy collapse DeepSeek 一致但 Qwen s025 反转(+0.045) s030≈0。30/30 problems completed. |
| C5 | Phase-modulated compound severity generalizes across architectures | pilot_pending | Pilot-first: 2h oracle + heuristic (token position ratio as phase proxy) on LLaMA-8B, s025/s030. Gate: recover >30% compound degradation → full rollout; else → future work. Must include heuristic baseline (oracle upper bound + simple heuristic lower bound). |
| C6 | Severity gradient is sub-exponential | confirmed | Growth rate decreasing: Δ增长因子 3.8×→4.8×→2.0×（递减） |
| C7 | Abstract 精简至 150-200 词，突出核心发现（原 S3 升级） | action_required | 当前 ~600 词信息过载，需精简至 1-2 个关键定量结果。写作任务，无需实验。 |
| C8 | II 与已有 super-additivity 概念明确区分（原 S7 升级） | action_required | §3 Methodology 加段讨论 II vs SparK/SLiM/UniComp 的 compound interaction 度量区别。写作+分析任务。 |

## Anticipated Reviewer Concerns

### RC1: Generalizability — 7B models only, single benchmark
- **预期质疑**: "Results on two 7B models and MATH-500 only. How do we know this generalizes to larger models or other reasoning tasks?"
- **应对**: Cross-model replication (DeepSeek-R1-Distill-Qwen-7B + Qwen2.5-7B-Instruct) 控制架构变量、隔离训练方式影响（distillation vs instruction tuning）。注意：两模型共享 Qwen2ForCausalLM 架构，不能 claim 跨架构泛化。MATH-500 是 standard benchmark。Limitations 必须诚实声明：(1) 同架构不同训练，不是跨架构；(2) 7B scale only；(3) 单 benchmark。机制解释 (discrimination collapse) 原则上 architecture-agnostic，但未实证验证。
- **实验支撑**: C5 (Qwen cross-model). 若需加强可扩展到不同架构（如 LLaMA/Mistral），但 11 天 deadline 内不现实

### RC2: Mechanism — entropy-discrimination collapse 缺乏直接测量
- **预期质疑**: "The mechanism is conceptual. Where is the empirical evidence for entropy increase and discrimination collapse?"
- **应对**: c4_entropy 实验已完成（DeepSeek 30/30 + Qwen 30/30）。D044 结论：Gini/CV 下降跨模型一致（discrimination collapse confirmed）；entropy redistribution 在 DeepSeek 上一致但在 Qwen 上 s025 方向反转、s030 近零（model-dependent）。论文以 discrimination collapse 为主线，entropy 作 DeepSeek 特有的强化因素。
- **实验支撑**: c4_entropy (DeepSeek DONE) + qwen_c4_entropy (DONE, negative for entropy universality)

### RC3: Practical impact — 没有 throughput 数据
- **预期质疑**: "No wall-clock or throughput measurements. Is the severity amplification reflected in actual inference speed?"
- **应对**: 本文定位是 empirical finding paper（发现 + 机制解释），不是 method paper。Throughput 不是 claim 的一部分。Discussion 中明确 phase-gated controller 作为 future direction。
- **实验支撑**: 不需要额外实验

### RC4: Statistical rigor — bootstrap 是否足够
- **预期质疑**: "Per-problem bootstrap with 50 problems — sufficient sample size?"
- **应对**: bf16 使用 B=10000 per-problem paired bootstrap，有效配对数 n=49 (DeepSeek) / n=46 (Qwen)。Permutation test 使用 paired median difference 作为 robust statistic（D032），Bonferroni 校正后全 4 水平 p<0.005。Cohen's d（paired d_z）作为辅助效应量（DeepSeek 0.44→0.80, Qwen 0.28→1.02）。可在 appendix 补充 per-problem 分布图（已生成 fig4_per_problem_dist.pdf）。
- **实验支撑**: bf16 permutation test (D032) + Cohen's d per-problem paired (rebootstrap B=10000) 已完成

### RC5: Novelty — prior work 是否已覆盖 phase-dependent sparsity
- **预期质疑**: "ThinKV and phase-aware methods already consider phase. What's new?"
- **应对**: Prior work 在单轴上分析 phase（ThinKV: phase-aware eviction）或 compound（SparK: joint compression）。没有工作同时分析 compound × phase × strategy 的三维交互。Crossover 现象（同一 strategy 在不同 phase 方向反转）是全新发现。Related Work 加 Lethe 引用区分 + SparK 对比。
- **实验支撑**: C3 (crossover), Related Work §2 的 gap 分析

## Paper Positioning

**类型**: Empirical finding paper（非 method paper）
**核心贡献**:
1. 发现 compound sparsity severity 的 strategy × phase 交互
2. 量化 severity gradient（bf16 paired median difference 0.32→9.94, Cohen's d 0.44→0.80）和 crossover 现象
3. 提出 discrimination collapse 机制解释（Gini/CV 跨模型一致；entropy redistribution model-dependent）
4. Cross-model replication 验证泛化性

**投稿目标**: EMNLP 2026 ARR, deadline 2026-05-25
**Rebuttal 准备**: Day 9 (2026-05-23) 预留 rebuttal letter 写作时间


## registry (completed experiments)

- exp_id: mvp_interaction_index_profiling
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_ii_profiling_v2
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    mvp_verdict: PASS_technical_but_negative_hypothesis
    ci_nonoverlap: true
    sign_reversal: false
    ii_reasoning_0.3: 17.79
    ii_reasoning_0.3_ci:
    - 4.09
    - 38.76
    ii_transition_0.3: 3.06
    ii_transition_0.3_ci:
    - 0.01
    - 5.6
    ii_reasoning_0.5: 468.9
    ii_transition_0.5: 850.07
    ii_execution_0.3: Inf
    phase_distribution:
      execution: 1.2%_25seg
      reasoning: 8.1%_96seg
      transition: 90.7%_192seg
    total_tokens: 86207
    all_ii_superadditive: true
    amplitude_ratio_reas_vs_trans_0.3: 5.81
    gmm_best_k: 5
    gmm_means:
    - 0.438
    - 0.597
    - 0.719
    - 0.816
    - 0.892
    gmm_weights:
    - 0.062
    - 0.14
    - 0.208
    - 0.282
    - 0.309
    sparsity_global:
      mean: 0.7653
      std: 0.1364
      median: 0.8004
    quantile_boundaries:
    - 0.7337
    - 0.8482
- exp_id: mvp_ii_profiling_v3
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    mvp_verdict: FAIL
    ci_nonoverlap: false
    sign_reversal: false
    phase_distribution_balanced: true
    ii_high_0.1:
      mean: 0.2317
      ci:
      - 0.1338
      - 0.3418
    ii_low_0.1:
      mean: 0.1711
      ci:
      - 0.0782
      - 0.2768
    ii_mid_0.1:
      mean: 0.1607
      ci:
      - 0.0886
      - 0.2489
    ii_high_0.2:
      mean: 2.1574
      ci:
      - 1.0605
      - 3.5491
    ii_low_0.2:
      mean: 1.1294
      ci:
      - 0.4368
      - 1.9593
    ii_mid_0.2:
      mean: 0.3049
      ci:
      - -1.0635
      - 1.3044
    total_tokens: 86207
    no_nan_inf: true
    segments:
      high: 511
      low: 454
      mid: 391
- exp_id: mvp_ii_profiling_v4
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_ii_profiling_v4b
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_ii_profiling_v4c
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_ii_profiling_v4d
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_ii_profiling_v4-random
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_v4a_r2
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_v4b_r2
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_v4c_r2
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_v4_random_r2
  name: ''
  status: DONE
  conclusion: success
  metrics: {}
- exp_id: mvp_v4_legacy_s01
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    II_high_0.1:
      mean: -0.1097
      ci_low: -0.8066
      ci_high: 0.41
    II_mid_0.1:
      mean: -15.966
      ci_low: -47.991
      ci_high: 1.288
    II_low_0.1:
      mean: 0
      ci_low: 0
      ci_high: 0
    ppl_high_dense: 1.1462
    ppl_high_both: 22.1302
    ppl_mid_dense: 1.1226
    ppl_mid_both: 47.5856
    verdict: FAIL
- exp_id: mvp_v4_legacy_s02
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_0.2:
      mean: 21.2856
      ci:
      - 0.0292
      - 63.163
    ii_mid_0.2:
      mean: 21.8743
      ci:
      - 4.9863
      - 41.785
    ii_low_0.2:
      mean: 0
      ci:
      - 0
      - 0
    ppl_high:
      dense: 1.15
      attn: 1.32
      kv: 104.42
      both: 63.41
    ppl_mid:
      dense: 1.12
      attn: 1.29
      kv: 324.16
      both: 170.47
    ppl_low:
      dense: 1.11
      attn: 1.3
      kv: 1.11
      both: 1.3
    problems_completed: 50
    phase_tokens:
      high: 25862
      mid: 27996
      low: 32349
    mvp_verdict: PASS
- exp_id: mvp_v4_legacy_s03
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_0.3:
      mean: -224.5
      ci_crosses_zero: true
    verdict: FAIL_ci_crosses_zero
- exp_id: mvp_v4_legacy_s025
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_v4_legacy_s035
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: mvp_v4_float32_s030
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: mvp_v5_fixed_s020
  name: ''
  status: DONE
  conclusion: killed
  metrics:
    ii_high: 0.5
    ii_mid: 3.52
    ii_low: 31.89
    ii_high_ci:
    - 0.41
    - 0.62
    ii_mid_ci:
    - 2.29
    - 5.35
    ii_low_ci:
    - 18.74
    - 47.22
    ii_high_median: 0.33
    ii_mid_median: 1.55
    ii_low_median: 9.56
    kv_ppl_high: 1.24
    kv_ppl_mid: 3.65
    kv_ppl_low: 14.11
    both_ppl_high: 2.7
    both_ppl_mid: 8.13
    both_ppl_low: 42.64
    problems: 50
    ⚠️_WARNING: pre-fix code, INVALIDATED. Results found on disk after kill but code
      lacked conda activation fix. Do NOT cite these numbers.
- exp_id: mvp_v5_fixed_s030
  name: ''
  status: DONE
  conclusion: killed
  metrics:
    ii_high: 1.18
    ii_mid: 168.53
    ii_low: 1926.23
    ii_high_ci:
    - 0.86
    - 1.6
    ii_mid_ci:
    - 36.91
    - 348.21
    ii_low_ci:
    - 179.17
    - 4062.57
    ii_high_median: 0.6
    ii_mid_median: 7.47
    ii_low_median: 44.63
    kv_ppl_high: 1.4
    kv_ppl_mid: 15.11
    kv_ppl_low: 40.79
    both_ppl_high: 5.71
    both_ppl_mid: 137.61
    both_ppl_low: 963.2
    problems: 50
    ⚠️_WARNING: pre-fix code, INVALIDATED. Results found on disk after kill but code
      lacked conda activation fix. Do NOT cite these numbers.
- exp_id: mvp_v5_fixed_s015
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    ii_high: 0.306
    ii_mid: 1.274
    ii_low: 8.786
    ii_high_ci:
    - 0.256
    - 0.359
    ii_mid_ci:
    - 0.895
    - 1.749
    ii_low_ci:
    - 5.294
    - 12.684
    ii_high_median: 0.205
    ii_mid_median: 0.696
    ii_low_median: 2.627
    ii_high_winsorized: 0.289
    ii_mid_winsorized: 1.139
    ii_low_winsorized: 8.408
    kv_ppl_high: 1.2147
    kv_ppl_mid: 2.1276
    kv_ppl_low: 6.7451
    both_ppl_high: 2.2835
    both_ppl_mid: 3.9408
    both_ppl_low: 16.9987
    problems: 50
    segments: 1356
- exp_id: mvp_v5_fixed_s025
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    ii_high: 0.851
    ii_mid: 9.306
    ii_low: 96.715
    ii_high_ci:
    - 0.703
    - 0.999
    ii_mid_ci:
    - 6.092
    - 13.303
    ii_low_ci:
    - 59.642
    - 143.188
    ii_high_median: 0.584
    ii_mid_median: 4.522
    ii_low_median: 30.903
    ii_high_winsorized: 0.802
    ii_mid_winsorized: 8.156
    ii_low_winsorized: 94.931
    kv_ppl_high: 1.3108
    kv_ppl_mid: 6.1778
    kv_ppl_low: 23.8919
    both_ppl_high: 3.4623
    both_ppl_mid: 16.4148
    both_ppl_low: 104.1749
    problems: 50
    segments: 1356
- exp_id: mvp_v5_fixed_s020_r2
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    ii_high_median: 0.3333
    ii_mid_median: 1.5479
    ii_low_median: 9.5627
    ii_high_mean: 0.5044
    ii_mid_mean: 3.5155
    ii_low_mean: 31.8937
    ii_high_ci:
    - 0.41
    - 0.62
    ii_mid_ci:
    - 2.29
    - 5.35
    ii_low_ci:
    - 18.74
    - 47.22
    kv_ppl_high: 1.24
    kv_ppl_mid: 3.65
    kv_ppl_low: 14.11
    both_ppl_high: 2.7
    both_ppl_mid: 8.13
    both_ppl_low: 42.64
    problems: 50
- exp_id: mvp_v5_fixed_s030_r2
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    ii_high_median: 0.5964
    ii_mid_median: 7.4671
    ii_low_median: 44.6324
    ii_high_mean: 1.1832
    ii_mid_mean: 168.53
    ii_low_mean: 1926.23
    ii_high_ci:
    - 0.86
    - 1.6
    ii_mid_ci:
    - 36.91
    - 348.21
    ii_low_ci:
    - 179.17
    - 4062.57
    kv_ppl_high: 1.4
    kv_ppl_mid: 15.11
    kv_ppl_low: 40.79
    both_ppl_high: 5.71
    both_ppl_mid: 137.61
    both_ppl_low: 963.2
    problems: 50
- exp_id: mvp_v5_random_s015
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 0.1606
    ii_mid_median: 0.252
    ii_low_median: 0.1831
    ii_high_mean: 0.4563
    ii_mid_mean: 0.5134
    ii_low_mean: 0.4775
    ii_high_ci:
    - 0.12
    - 0.77
    ii_mid_ci:
    - 0.34
    - 0.74
    ii_low_ci:
    - 0.28
    - 0.7
    kv_ppl_high: 3.14
    kv_ppl_mid: 2.91
    kv_ppl_low: 3.61
    both_ppl_high: 3.92
    both_ppl_mid: 4.14
    both_ppl_low: 4.71
    problems: 50
- exp_id: mvp_v5_random_s025
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 3.0024
    ii_mid_median: 2.9846
    ii_low_median: 2.9146
    ii_high_mean: 3.9052
    ii_mid_mean: 7.9491
    ii_low_mean: 3.9114
    ii_high_ci:
    - 0.98
    - 6.34
    ii_mid_ci:
    - 4.67
    - 11.87
    ii_low_ci:
    - 2.71
    - 5.24
    kv_ppl_high: 6.39
    kv_ppl_mid: 6.11
    kv_ppl_low: 9.07
    both_ppl_high: 17.06
    both_ppl_mid: 15.38
    both_ppl_low: 29.32
    problems: 50
- exp_id: mvp_v5_random_s020
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 0.321331
    ii_mid_median: 0.455663
    ii_low_median: 0.591916
    ii_high_mean: 0.855584
    ii_mid_mean: 1.258123
    ii_low_mean: 0.956933
    ii_high_ci:
    - -0.124133
    - 1.616883
    ii_mid_ci:
    - 0.674852
    - 2.075565
    ii_low_ci:
    - 0.583856
    - 1.413355
    kv_ppl_high: 4.2537
    kv_ppl_mid: 4.3064
    kv_ppl_low: 5.4048
    both_ppl_high: 7.9749
    both_ppl_mid: 6.8553
    both_ppl_low: 22.5868
    problems: 50
- exp_id: mvp_v5_random_s030
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 5.377512
    ii_mid_median: 5.886454
    ii_low_median: 3.776818
    ii_high_mean: 22.734534
    ii_mid_mean: 10.943319
    ii_low_mean: 11.840449
    ii_high_ci:
    - 10.352118
    - 42.551951
    ii_mid_ci:
    - 7.398611
    - 14.765315
    ii_low_ci:
    - 4.097309
    - 23.545273
    kv_ppl_high: 8.1027
    kv_ppl_mid: 8.5701
    kv_ppl_low: 13.4922
    both_ppl_high: 41.3452
    both_ppl_mid: 24.1992
    both_ppl_low: 68.5301
    problems: 50
- exp_id: v6_importance_s025
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 0.6641
    ii_mid_median: 5.3067
    ii_low_median: 24.1619
    ii_high_mean: 0.8842
    ii_mid_mean: 10.057
    ii_low_mean: 71.8854
    per_problem_ii_count: 50
    n_high: 42
    n_mid: 23
    n_low: 21
    problems: 50
    bootstrap_gradient_paired: 35.72
    bootstrap_ci_paired:
    - 9.52
    - 101.54
    bootstrap_gradient_unpaired: 36.38
    bootstrap_ci_unpaired:
    - 13.19
    - 97.61
    bootstrap_p: 0
- exp_id: v6_importance_s030
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 0.8833
    ii_mid_median: 7.2706
    ii_low_median: 34.6937
    ii_high_mean: 1.5151
    ii_mid_mean: 78.8215
    ii_low_mean: 1163.9677
    per_problem_ii_count: 50
    n_high: 40
    n_mid: 22
    n_low: 20
    problems: 50
    bootstrap_gradient_paired: 41.92
    bootstrap_ci_paired:
    - 19.14
    - 299.76
    bootstrap_gradient_unpaired: 39.28
    bootstrap_ci_unpaired:
    - 21.87
    - 129.59
    bootstrap_p: 0
- exp_id: v6_importance_s015
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 0.2266
    ii_mid_median: 0.7432
    ii_low_median: 2.8762
    ii_high_mean: 0.2874
    ii_mid_mean: 1.6858
    ii_low_mean: 8.5161
    per_problem_ii_count: 50
    n_high: 43
    n_mid: 32
    n_low: 24
    problems: 50
    bootstrap_gradient_paired: 11.53
    bootstrap_ci_paired:
    - 3.49
    - 23.78
    bootstrap_gradient_unpaired: 12.69
    bootstrap_ci_unpaired:
    - 4.96
    - 28.45
    bootstrap_p: 0
- exp_id: v6_importance_s020
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 0.3353
    ii_mid_median: 1.6733
    ii_low_median: 9.2538
    ii_high_mean: 0.4936
    ii_mid_mean: 4.9538
    ii_low_mean: 25.8764
    per_problem_ii_count: 50
    n_high: 42
    n_mid: 28
    n_low: 21
    problems: 50
    bootstrap_gradient_paired: 11.05
    bootstrap_ci_paired:
    - 5.42
    - 69.27
    bootstrap_gradient_unpaired: 27.6
    bootstrap_ci_unpaired:
    - 6.55
    - 75.16
    bootstrap_p: 0
- exp_id: qwen_importance_s015
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: qwen_importance_s020
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: qwen_importance_s025
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: qwen_importance_s030
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: v6_random_s015
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 0.1606
    ii_mid_median: 0.252
    ii_low_median: 0.1831
    ii_high_mean: 0.4563
    ii_mid_mean: 0.5134
    ii_low_mean: 0.4775
    per_problem_ii_count: 50
    n_high: 43
    n_mid: 32
    n_low: 28
    bootstrap_gradient_paired: -0.2722
    bootstrap_ci_paired:
    - -0.7039
    - 0.1548
    bootstrap_p: 0.903
    bootstrap_gradient_unpaired: -0.0592
    bootstrap_ci_unpaired:
    - -0.5341
    - 0.3877
    per_problem_ii_stats:
      high:
        min: -3.0621
        max: 5.018
        mean: 0.5386
        median: 0.2003
        std: 1.2085
      mid:
        min: -2.7245
        max: 4.6713
        mean: 0.3977
        median: 0.299
        std: 1.1456
      low:
        min: -0.4031
        max: 3.7005
        mean: 0.4806
        median: 0.2465
        std: 0.779
    verdict: FAIL
- exp_id: v6_random_s020
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_mean: 0.855584
    ii_high_median: 0.321331
    ii_high_ci:
    - -0.124133
    - 1.616883
    ii_high_winsorized_mean: 0.913496
    ii_mid_mean: 1.258123
    ii_mid_median: 0.455663
    ii_mid_ci:
    - 0.674852
    - 2.075565
    ii_mid_winsorized_mean: 1.074102
    ii_low_mean: 0.956933
    ii_low_median: 0.591916
    ii_low_ci:
    - 0.583856
    - 1.413355
    ii_low_winsorized_mean: 0.96113
    n_high: 511
    n_mid: 391
    n_low: 454
    problems: 50
    per_problem_ii_count: 50
    gradient_mean_low_over_high: 1.118
    gradient_median_low_over_high: 1.842
    pass_fail: FAIL
    perplexity_high_dense: 1.1462
    perplexity_high_both: 7.9749
    perplexity_mid_dense: 1.1226
    perplexity_mid_both: 6.8553
    perplexity_low_dense: 1.1105
    perplexity_low_both: 22.5868
- exp_id: v6_random_s025
  name: ''
  status: DONE
  conclusion: success
  metrics:
    ii_high_median: 3.0024
    ii_mid_median: 2.9846
    ii_low_median: 2.9146
    ii_high_mean: 3.9052
    ii_mid_mean: 7.9491
    ii_low_mean: 3.9114
    per_problem_ii_count: 50
    n_high: 36
    n_mid: 25
    n_low: 24
    bootstrap_gradient_paired: -0.1199
    bootstrap_ci_paired:
    - -1.517
    - 1.2461
    bootstrap_p: 0.559
    bootstrap_gradient_unpaired: -0.8616
    bootstrap_ci_unpaired:
    - -3.3911
    - 1.5169
    per_problem_ii_stats:
      high:
        min: -6.1388
        max: 25.2471
        mean: 4.4098
        median: 3.0421
        std: 6.0734
      mid:
        min: 0.158
        max: 108.7242
        mean: 7.5626
        median: 2.1407
        std: 20.926
      low:
        min: -0.1953
        max: 12.8555
        mean: 3.5806
        median: 2.7289
        std: 3.4915
    verdict: FAIL
- exp_id: v6_random_s030
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: v6_random_s030_r2
  name: ''
  status: DONE
  conclusion: failed
  metrics: {}
- exp_id: bf16_importance_s015
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: -0.150213
        median: 0.005752
        ci:
        - -0.294614
        - -0.055385
        winsorized_mean: -0.062378
        skewness: -14.9912
      mid:
        mean: 0.447301
        median: 0.080738
        ci:
        - 0.267993
        - 0.668749
        winsorized_mean: 0.324751
        skewness: 4.7221
      low:
        mean: 2.405837
        median: 0.398291
        ci:
        - 1.478784
        - 3.667675
        winsorized_mean: 1.278857
        skewness: 9.5402
    per_problem_ii_stats:
      high:
        n: 49
        min: -0.188061
        max: 0.335853
        mean: -0.013405
        median: 0.00012
        std: 0.078483
      mid:
        n: 40
        min: -0.169092
        max: 3.88198
        mean: 0.308621
        median: 0.107114
        std: 0.690186
      low:
        n: 50
        min: -0.872983
        max: 9.10289
        mean: 0.725504
        median: 0.315517
        std: 1.731056
    gradient_paired_aggregate_legacy: 69.24
    median_difference: 0.3925
    n_problems: 50
    pass_fail:
      ci_overlap: true
      sign_reversal: true
      overall: PASS
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    perplexity:
      high:
        dense: 1.1689
        attn: 1.4861
        kv: 1.4481
        both: 1.5911
      mid:
        dense: 1.2269
        attn: 1.5137
        kv: 2.5971
        both: 3.4541
      low:
        dense: 1.2286
        attn: 1.6147
        kv: 8.9201
        both: 12.5084
- exp_id: bf16_importance_s020
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 0.1289
        median: 0.0145
        ci:
        - -0.1975
        - 0.6647
        winsorized_mean: -0.0297
        skewness: 16.67
      mid:
        mean: 1.2604
        median: 0.2027
        ci:
        - 0.7466
        - 1.8962
        winsorized_mean: 0.766
        skewness: 7.05
      low:
        mean: 6.0288
        median: 1.4963
        ci:
        - 4.4671
        - 7.9237
        winsorized_mean: 4.3426
        skewness: 6.01
    per_problem_ii_stats:
      high:
        n: 49
        min: -0.1884
        max: 0.4196
        mean: 0.0025
        median: 0.0036
        std: 0.0966
      mid:
        n: 40
        min: -0.0519
        max: 8.6969
        mean: 0.6795
        median: 0.1977
        std: 1.4998
      low:
        n: 50
        min: -1.6151
        max: 22.6875
        mean: 2.2301
        median: 1.128
        std: 4.3758
    gradient_paired_aggregate_legacy: 5.9
    median_difference: 1.4818
    n_problems: 50
    pass_fail:
      ci_overlap: true
      sign_reversal: false
      overall: PASS
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    perplexity:
      high:
        dense: 1.1689
        attn: 1.5233
        kv: 1.6191
        both: 2.1047
      mid:
        dense: 1.2269
        attn: 1.5375
        kv: 3.5164
        both: 5.4246
      low:
        dense: 1.2286
        attn: 1.6486
        kv: 15.7987
        both: 23.74
- exp_id: bf16_importance_s025
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 0.302756
        median: 0.032363
        ci:
        - 0.083714
        - 0.543977
        winsorized_mean: 0.200962
        skewness: 4.8826
      mid:
        mean: 5.729665
        median: 1.118069
        ci:
        - 3.455574
        - 8.471799
        winsorized_mean: 4.189902
        skewness: 8.2799
      low:
        mean: 25.852951
        median: 7.195958
        ci:
        - 19.077082
        - 33.497293
        winsorized_mean: 19.319103
        skewness: 7.3986
    per_problem_ii_stats:
      high:
        n: 49
        min: -0.316321
        max: 4.003714
        mean: 0.133714
        median: 0.009873
        std: 0.595358
      mid:
        n: 40
        min: -0.024794
        max: 18.720486
        mean: 2.537744
        median: 1.05707
        std: 3.962575
      low:
        n: 50
        min: -1.854733
        max: 75.467653
        mean: 11.28281
        median: 3.954593
        std: 16.620011
    gradient_paired_aggregate_legacy: 222.35
    median_difference: 7.1636
    n_problems: 50
    pass_fail:
      ci_overlap: true
      sign_reversal: false
      overall: PASS
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    perplexity:
      high:
        dense: 1.1689
        attn: 1.6511
        kv: 1.8628
        both: 2.7026
      mid:
        dense: 1.2269
        attn: 1.7039
        kv: 5.6205
        both: 13.3436
      low:
        dense: 1.2286
        attn: 1.8366
        kv: 31.756
        both: 63.668
- exp_id: bf16_importance_s030
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 0.5547
        median: 0.0534
        ci:
        - 0.2773
        - 0.9198
        winsorized_mean: 0.3367
        skewness: 10.62
      mid:
        mean: 11.3
        median: 2.2833
        ci:
        - 6.865
        - 17.2633
        winsorized_mean: 8.1752
        skewness: 9.19
      low:
        mean: 57.7946
        median: 14.6395
        ci:
        - 41.4416
        - 77.0467
        winsorized_mean: 39.3143
        skewness: 8.31
    per_problem_ii_stats:
      high:
        n: 49
        min: -0.5095
        max: 4.4457
        mean: 0.1976
        median: 0.0343
        std: 0.6793
      mid:
        n: 40
        min: -0.1989
        max: 34.0258
        mean: 5.2585
        median: 1.5173
        std: 7.9382
      low:
        n: 50
        min: -7.3027
        max: 126.7985
        mean: 22.6601
        median: 9.9731
        std: 28.4096
    gradient_paired_aggregate_legacy: 57.24
    median_difference: 14.5861
    n_problems: 50
    pass_fail:
      ci_overlap: true
      sign_reversal: false
      overall: PASS
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    perplexity:
      high:
        dense: 1.1689
        attn: 1.7123
        kv: 2.0544
        both: 3.2372
      mid:
        dense: 1.2269
        attn: 1.7894
        kv: 9.4821
        both: 24.2847
      low:
        dense: 1.2286
        attn: 1.9347
        kv: 51.6485
        both: 122.61
- exp_id: bf16_random_s015
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: bf16_random_s020
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: bf16_random_s025
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: bf16_random_s030
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: bf16_qwen_importance_s015
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: bf16_qwen_importance_s020
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: bf16_qwen_importance_s025
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: bf16_qwen_importance_s030
  name: ''
  status: DONE
  conclusion: killed
  metrics: {}
- exp_id: v6_random_s030_r3
  name: ''
  status: DONE
  conclusion: success
  metrics:
    II_high_mean: 9.2364
    II_mid_mean: -230.7604
    II_low_mean: -7.4119
    II_high_median: 4.0237
    II_mid_median: 2.4272
    II_low_median: 4.735
    ppl_low_both: 88.94
    per_problem_count: 50
- exp_id: bf16_ds_imp_s015
  name: ''
  status: DONE
  conclusion: killed
  metrics:
    median_difference: 0.323579
    permutation_p: 0
    cohens_d: 0.6068
    bootstrap_ci_95:
    - 0.198824
    - 0.471566
    wilcoxon_p: 0
    n_bootstrap: 10000
    n_paired: 49
- exp_id: bf16_ds_imp_s020
  name: ''
  status: DONE
  conclusion: killed
  metrics:
    median_difference: 1.15202
    permutation_p: 0
    cohens_d: 0.725
    bootstrap_ci_95:
    - 0.655454
    - 1.256001
    wilcoxon_p: 0
    n_bootstrap: 10000
    n_paired: 49
- exp_id: bf16_ds_imp_s025
  name: ''
  status: DONE
  conclusion: killed
  metrics:
    median_difference: 3.968568
    permutation_p: 0
    cohens_d: 0.9534
    bootstrap_ci_95:
    - 2.829037
    - 5.291756
    wilcoxon_p: 0
    n_bootstrap: 10000
    n_paired: 49
- exp_id: bf16_ds_imp_s030
  name: ''
  status: DONE
  conclusion: killed
  metrics:
    median_difference: 9.943595
    permutation_p: 0
    cohens_d: 1.1263
    bootstrap_ci_95:
    - 8.391554
    - 16.652865
    wilcoxon_p: 0
    n_bootstrap: 10000
    n_paired: 49
- exp_id: bf16_ds_rand_s015
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 0.2208
        median: 0.0931
        ci:
        - -1.0091
        - 1.5243
        median_ci:
        - 0.0024
        - 0.1515
        winsorized_mean: 0.3161
        skewness: -5.4
      mid:
        mean: -3.3604
        median: 0.0967
        ci:
        - -8.4057
        - 0.3697
        median_ci:
        - 0.0219
        - 0.197
        winsorized_mean: -0.6366
        skewness: -10.56
      low:
        mean: -1.8952
        median: 0.1026
        ci:
        - -4.9698
        - 0.2741
        median_ci:
        - 0.044
        - 0.1755
        winsorized_mean: 0.0521
        skewness: -11.57
    perplexity:
      high:
        dense: 1.1687
        attn: 3.5947
        kv: 2.9239
        both: 5.7569
      mid:
        dense: 1.2269
        attn: 297.7957
        kv: 2.915
        both: 11.3156
      low:
        dense: 1.2284
        attn: 11.3419
        kv: 3.6161
        both: 6.2886
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    n_problems: 50
    pass_fail:
      ci_overlap: false
      sign_reversal: false
      overall: FAIL
    median_difference: 0.0095
- exp_id: bf16_ds_rand_s020
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 1.1216
        median: 0.2918
        ci:
        - 0.0796
        - 2.5834
        median_ci:
        - 0.1598
        - 0.4581
        winsorized_mean: 1.7664
        skewness: 9.59
      mid:
        mean: -1.5827
        median: 0.3504
        ci:
        - -6.0963
        - 1.5735
        median_ci:
        - 0.1993
        - 0.5226
        winsorized_mean: 0.5839
        skewness: -12.31
      low:
        mean: -0.4116
        median: 0.2763
        ci:
        - -2.6034
        - 1.209
        median_ci:
        - 0.2194
        - 0.5487
        winsorized_mean: 0.9942
        skewness: -10.07
    perplexity:
      high:
        dense: 1.1687
        attn: 3.1905
        kv: 3.8002
        both: 8.8129
      mid:
        dense: 1.2269
        attn: 67.8504
        kv: 3.788
        both: 11.4974
      low:
        dense: 1.2284
        attn: 8.592
        kv: 5.0078
        both: 9.2001
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    n_problems: 50
    pass_fail:
      ci_overlap: false
      sign_reversal: false
      overall: FAIL
    median_difference: -0.0155
- exp_id: bf16_ds_rand_s025
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 3.59
        median: 0.8182
        ci:
        - 1.4021
        - 6.2327
        median_ci:
        - 0.5075
        - 1.7217
        winsorized_mean: 6.3965
        skewness: -7.57
      mid:
        mean: -1.8455
        median: 0.9324
        ci:
        - -10.3663
        - 4.9342
        median_ci:
        - 0.7331
        - 1.7003
        winsorized_mean: 3.1014
        skewness: -12.76
      low:
        mean: 0.7212
        median: 1.3627
        ci:
        - -4.2068
        - 4.5006
        median_ci:
        - 1.0869
        - 2.6866
        winsorized_mean: 4.1866
        skewness: -15.85
    perplexity:
      high:
        dense: 1.1687
        attn: 7.237
        kv: 4.9751
        both: 17.7423
      mid:
        dense: 1.2269
        attn: 868.3199
        kv: 5.1165
        both: 29.4661
      low:
        dense: 1.2284
        attn: 24.3571
        kv: 6.7993
        both: 17.9694
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    n_problems: 50
    pass_fail:
      ci_overlap: false
      sign_reversal: false
      overall: FAIL
    median_difference: 0.5445
- exp_id: bf16_ds_rand_s030
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 7.5555
        median: 2.5031
        ci:
        - 4.4087
        - 11.6199
        median_ci:
        - 1.3292
        - 4.1205
        winsorized_mean: null
        skewness: null
      mid:
        mean: 6.2518
        median: 2.5918
        ci:
        - 2.1767
        - 10.4757
        median_ci:
        - 1.8397
        - 3.7888
        winsorized_mean: null
        skewness: null
      low:
        mean: 6.8323
        median: 4.0414
        ci:
        - 3.2428
        - 10.6996
        median_ci:
        - 2.2686
        - 6.3579
        winsorized_mean: null
        skewness: null
    perplexity:
      high:
        dense: 1.1687
        attn: 16.7892
        kv: 8.8073
        both: 40.7553
      mid:
        dense: 1.2269
        attn: 2461.9219
        kv: 8.6662
        both: 62.4422
      low:
        dense: 1.2284
        attn: 55.2916
        kv: 11.5789
        both: 37.6009
    phase_stats:
      high:
        n_tokens: 21086
        n_segments: 387
      mid:
        n_tokens: 13306
        n_segments: 191
      low:
        n_tokens: 27748
        n_segments: 397
    n_problems: 50
    pass_fail:
      ci_overlap: false
      sign_reversal: false
      overall: FAIL
    median_difference: 1.5383
- exp_id: bf16_qw_imp_s015
  name: ''
  status: DONE
  conclusion: success
  metrics:
    median_difference: 0.047619
    permutation_p: 0.0001
    cohens_d: 0.3705
    bootstrap_ci_95:
    - -0.005077
    - 0.109517
    wilcoxon_p: 0.02958
    n_bootstrap: 10000
    n_paired: 46
- exp_id: bf16_qw_imp_s020
  name: ''
  status: DONE
  conclusion: success
  metrics:
    median_difference: 0.207511
    permutation_p: 0
    cohens_d: 0.7224
    bootstrap_ci_95:
    - 0.067222
    - 0.40226
    wilcoxon_p: 3.4e-05
    n_bootstrap: 10000
    n_paired: 46
- exp_id: bf16_qw_imp_s025
  name: ''
  status: DONE
  conclusion: success
  metrics:
    median_difference: 1.108706
    permutation_p: 0
    cohens_d: 1.2329
    bootstrap_ci_95:
    - 0.609247
    - 1.469002
    wilcoxon_p: 0
    n_bootstrap: 10000
    n_paired: 46
- exp_id: bf16_qw_imp_s030
  name: ''
  status: DONE
  conclusion: success
  metrics:
    median_difference: 2.619385
    permutation_p: 0
    cohens_d: 1.4394
    bootstrap_ci_95:
    - 1.722281
    - 3.651063
    wilcoxon_p: 0
    n_bootstrap: 10000
    n_paired: 46
- exp_id: bf16_qw_rand_s015
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 1.6652
        median: 0.1381
        ci:
        - 1.0986
        - 2.4042
        median_ci:
        - 0.1025
        - 0.2074
        winsorized_mean: 1.0044
        skewness: 7.1842
      mid:
        mean: 1.6975
        median: 0.2194
        ci:
        - 0.4473
        - 3.4612
        median_ci:
        - -0.0048
        - 0.6621
        winsorized_mean: 1.4038
        skewness: 3.2101
      low:
        mean: 1.4082
        median: 0.1878
        ci:
        - 0.8358
        - 2.06
        median_ci:
        - 0.0962
        - 0.3139
        winsorized_mean: 0.9403
        skewness: 7.1113
    perplexity:
      high:
        dense: 1.0737
        attn: 1.3939
        kv: 2.0487
        both: 4.2076
      mid:
        dense: 1.1322
        attn: 1.4175
        kv: 2.3709
        both: 4.6105
      low:
        dense: 1.1517
        attn: 1.7177
        kv: 3.3253
        both: 5.4788
    phase_stats:
      high:
        n_tokens: 16289
        n_segments: 295
      mid:
        n_tokens: 4372
        n_segments: 26
      low:
        n_tokens: 32227
        n_segments: 276
    n_problems: 50
    pass_fail:
      ci_overlap: true
      sign_reversal: false
      overall: FAIL
    median_difference: -0.029401
    permutation_test:
      p_value: 0.7657
      B: 10000
    cohens_d: -0.0507
    bootstrap_ci_95:
    - -0.2106
    - 0.2124
    wilcoxon_p: 0.862554
    phase_median_ii:
      high: 0.1381
      mid: 0.2194
      low: 0.1878
- exp_id: bf16_qw_rand_s020
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 2.58579
        median: 0.48549
        ci:
        - 1.769404
        - 3.501692
        median_ci:
        - 0.304626
        - 0.658814
        winsorized_mean: 1.80021
        skewness: 5.4038
      mid:
        mean: 5.69684
        median: 0.76699
        ci:
        - 1.69004
        - 12.276143
        median_ci:
        - 0.482838
        - 3.392541
        winsorized_mean: 4.304174
        skewness: 3.526
      low:
        mean: 65.915714
        median: 0.614438
        ci:
        - -18.581948
        - 221.709429
        median_ci:
        - 0.484725
        - 0.848787
        winsorized_mean: 2.389244
        skewness: 16.2163
    perplexity:
      high:
        dense: 1.0737
        attn: 1.6115
        kv: 2.5041
        both: 5.9394
      mid:
        dense: 1.1322
        attn: 1.7583
        kv: 3.0658
        both: 10.5578
      low:
        dense: 1.1517
        attn: 75.631
        kv: 4.3535
        both: 140.6269
    phase_stats:
      high:
        n_tokens: 16289
        n_segments: 295
      mid:
        n_tokens: 4372
        n_segments: 26
      low:
        n_tokens: 32227
        n_segments: 276
    n_problems: 50
    pass_fail:
      ci_overlap: true
      sign_reversal: false
      overall: FAIL
    median_difference: 0.128948
    permutation_test:
      p_value: 0.352
      B: 10000
    cohens_d: 0.247
    bootstrap_ci_95:
    - -0.139
    - 0.215
    wilcoxon_p: 0.149
    phase_median_ii:
      high: 0.4739
      mid: 0.8757
      low: 0.4847
- exp_id: bf16_qw_rand_s025
  name: ''
  status: DONE
  conclusion: success
  metrics:
    interaction_index:
      high:
        mean: 14.4213
        median: 1.6043
        ci:
        - 7.1074
        - 23.4587
        median_ci:
        - 0.6977
        - 3.0736
        winsorized_mean: 9.3765
        skewness: 4.8263
      mid:
        mean: 18.6458
        median: 2.2225
        ci:
        - 3.3729
        - 41.6037
        median_ci:
        - 0.6093
        - 11.5889
        winsorized_mean: 14.2901
        skewness: 3.8245
      low:
        mean: 17.7277
        median: 2.2641
        ci:
        - 4.3523
        - 37.2093
        median_ci:
        - 1.2218
        - 4.8561
        winsorized_mean: 9.9876
        skewness: 5.7652
    perplexity:
      high:
        dense: 1.0737
        attn: 2.0183
        kv: 3.1882
        both: 9.7654
      mid:
        dense: 1.1322
        attn: 2.3476
        kv: 4.0124
        both: 17.3298
      low:
        dense: 1.1517
        attn: 2.7834
        kv: 5.8762
        both: 25.4321
    phase_stats:
      high:
        n_tokens: 16289
        n_segments: 295
      mid:
        n_tokens: 4372
        n_segments: 26
      low:
        n_tokens: 32227
        n_segments: 276
    n_problems: 50
    pass_fail:
      ci_overlap: true
      sign_reversal: false
      overall: FAIL
    median_difference: 1.144074
    permutation_test:
      p_value: 0.1679
      B: 10000
    cohens_d: 0.1574
    bootstrap_ci_95:
    - -0.3166
    - 4.1645
    wilcoxon_p: 0.010313
    phase_median_ii:
      high: 1.6043
      mid: 2.2225
      low: 2.2641
- exp_id: bf16_qw_rand_s030
  name: ''
  status: DONE
  conclusion: success
  metrics:
    median_high: 4.200557
    median_mid: 6.477036
    median_low: 8.065662
    median_diff: 2.418272
    permutation_p: 0.012
    cohens_d: -0.03513
    wilcoxon_p: 0.01566
    bootstrap_ci_low: 0.241897
    bootstrap_ci_high: 3.314824
- exp_id: c4_entropy
  name: ''
  status: DONE
  conclusion: success
  metrics:
    importance_entropy_delta:
      s015: -0.0402
      s020: -0.0472
      s025: -0.0446
      s030: -0.0436
    random_entropy_delta:
      s015: 0.1283
      s020: 0.136
      s025: 0.2171
      s030: 0.2327
    importance_gini_delta:
      s015: -0.0301
      s020: -0.0404
      s025: -0.0647
      s030: -0.0806
    random_gini_delta:
      s015: -0.0309
      s020: -0.0403
      s025: -0.062
      s030: -0.0732
    importance_cv_delta:
      s015: -0.564
      s020: -0.774
      s025: -1.287
      s030: -1.665
    random_cv_delta:
      s015: -1.021
      s020: -1.203
      s025: -1.923
      s030: -2.137
    problems_completed: 30
    runtime_minutes: 69.1
- exp_id: qwen_c4_entropy
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    problems_completed: 30
    qwen_importance_entropy_delta:
      s015: -0.0733
      s020: -0.0759
      s025: 0.0451
      s030: -0.0072
    qwen_random_entropy_delta:
      s015: 0.0838
      s020: 0.0901
      s025: 0.2168
      s030: 0.1968
    qwen_importance_gini_delta:
      s015: -0.0103
      s020: -0.0121
      s025: -0.01
      s030: -0.0202
    qwen_random_gini_delta:
      s015: -0.0186
      s020: -0.0229
      s025: -0.0337
      s030: -0.0448
    qwen_importance_cv_delta:
      s015: -0.045
      s020: -0.208
      s025: -1.491
      s030: -1.142
    qwen_random_cv_delta:
      s015: -0.778
      s020: -0.889
      s025: -1.5
      s030: -1.677
    cross_model_notes: random entropy increase consistent; importance entropy collapse
      inconsistent at s025 (reversed to +0.045) and near-zero at s030; gini/cv directions
      consistent but Qwen magnitudes smaller
- exp_id: bf16_ds_imp_s010
  name: ''
  status: DONE
  conclusion: negative
  metrics:
    verdict: FAIL
    problems: 50
    II_high_sparsity_median: 0.0027
    II_high_sparsity_mean: -0.1998
    II_low_sparsity_median: 0.0151
    II_low_sparsity_mean: -0.1066
    II_mid_sparsity_median: 0.0061
    II_mid_sparsity_mean: -0.0131
    high_sparsity_tokens: 21086
    low_sparsity_tokens: 27748
    mid_sparsity_tokens: 13306
- exp_id: bf16_ds_imp_s035
  name: ''
  status: DONE
  conclusion: success
  metrics:
    verdict: PASS
    problems: 50
    II_high_sparsity_median: 0.1051
    II_high_sparsity_mean: 1.4309
    II_low_sparsity_median: 28.7649
    II_low_sparsity_mean: 104.1892
    II_mid_sparsity_median: 4.9542
    II_mid_sparsity_mean: 20.326
    high_sparsity_tokens: 21086
    low_sparsity_tokens: 27748
    mid_sparsity_tokens: 13306
    ci_overlap_test: low_sparsity vs mid_sparsity CI non-overlapping at 0.35
- exp_id: bf16_qw_imp_s010
  name: ''
  status: DONE
  conclusion: success
  metrics:
    n_problems: 50
    overall_verdict: PASS
    ci_overlap_test: PASS
    sign_reversal_test: FAIL
    high_sparsity_II_median: 0.0001
    high_sparsity_II_median_CI:
    - -0.0028
    - 0.0005
    high_sparsity_II_mean: -0.0887
    high_sparsity_II_mean_CI:
    - -0.1235
    - -0.0591
    low_sparsity_II_median: -0.0444
    low_sparsity_II_median_CI:
    - -0.0967
    - -0.0152
    low_sparsity_II_mean: -0.2431
    low_sparsity_II_mean_CI:
    - -0.3817
    - -0.1202
    mid_sparsity_II_median: -0.0359
    mid_sparsity_II_median_CI:
    - -0.0963
    - -0.015
    mid_sparsity_II_mean: -0.084
    mid_sparsity_II_mean_CI:
    - -0.1366
    - -0.035
    ppl_high_dense: 1.074
    ppl_high_both: 1.228
    ppl_low_dense: 1.152
    ppl_low_both: 3.204
    ppl_mid_dense: 1.133
    ppl_mid_both: 1.741
- exp_id: bf16_qw_imp_s035
  name: ''
  status: DONE
  conclusion: success
  metrics:
    n_problems: 50
    overall_verdict: PASS
    ci_overlap_test: PASS
    sign_reversal_test: FAIL
    high_sparsity_II_median: 0.0232
    high_sparsity_II_median_CI:
    - 0.0154
    - 0.0383
    high_sparsity_II_mean: 0.1643
    high_sparsity_II_mean_CI:
    - 0.0844
    - 0.2495
    low_sparsity_II_median: 8.2358
    low_sparsity_II_median_CI:
    - 6.1564
    - 10.9231
    low_sparsity_II_mean: 18.9673
    low_sparsity_II_mean_CI:
    - 14.5015
    - 23.9752
    mid_sparsity_II_median: 0.9577
    mid_sparsity_II_median_CI:
    - 0.171
    - 3.5575
    mid_sparsity_II_mean: 8.0734
    mid_sparsity_II_mean_CI:
    - 2.0224
    - 16.8946
    ppl_high_dense: 1.0738
    ppl_high_both: 2.3435
    ppl_low_dense: 1.1518
    ppl_low_both: 58.0358
    ppl_mid_dense: 1.1327
    ppl_mid_both: 20.9912
    high_sparsity_tokens: 16289
    low_sparsity_tokens: 32227
    mid_sparsity_tokens: 4372
- exp_id: c2_n500_deepseek
  name: ''
  status: RUNNING
  conclusion: ''
  metrics: {}
- exp_id: c3_llama_arch
  name: ''
  status: PENDING
  conclusion: killed
  metrics: {}
- exp_id: c2_ds_n500
  name: ''
  status: PENDING
  conclusion: killed
  metrics: {}
- exp_id: c2_qw_n500
  name: ''
  status: RUNNING
  conclusion: ''
  metrics: {}
- exp_id: c3_llama
  name: ''
  status: PREPARING
  conclusion: ''
  metrics: {}

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
  "promptId": "79c6b4a3-3133-4981-8938-247f5d67b190",
  "type": "user",
  "uuid": "6e197ae4-3ec9-4c2d-9db3-fb9e338103fd",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-14T14:37:10.271Z_

```json
{
  "parentUuid": "6e197ae4-3ec9-4c2d-9db3-fb9e338103fd",
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
  "uuid": "21e280b9-8ffe-45e9-b255-a52e6ac1b554",
  "timestamp": "2026-05-14T14:37:10.271Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-14T14:37:10.271Z_

```json
{
  "parentUuid": "21e280b9-8ffe-45e9-b255-a52e6ac1b554",
  "isSidechain": false,
  "attachment": {
    "type": "agent_listing_delta",
    "addedTypes": [
      "claude",
      "Explore",
      "general-purpose",
      "Plan",
      "statusline-setup"
    ],
    "addedLines": [
      "- claude: Catch-all for any task that doesn't fit a more specific agent. FleetView's default when no agent name is typed. (Tools: *)",
      "- Explore: Fast read-only search agent for locating code. Use it to find files by pattern (eg. \"src/components/**/*.tsx\"), grep for symbols or keywords (eg. \"API endpoints\"), or answer \"where is X defined / which files reference Y.\" Do NOT use it for code review, design-doc auditing, cross-file consistency checks, or open-ended analysis — it reads excerpts rather than whole files and will miss content past its read window. When calling, specify search breadth: \"quick\" for a single targeted lookup, \"medium\" for moderate exploration, or \"very thorough\" to search across multiple locations and naming conventions. (Tools: All tools except Agent, ExitPlanMode, Edit, Write, NotebookEdit)",
      "- general-purpose: General-purpose agent for researching complex questions, searching for code, and executing multi-step tasks. When you are searching for a keyword or file and are not confident that you will find the right match in the first few tries use this agent to perform the search for you. (Tools: *)",
      "- Plan: Software architect agent for designing implementation plans. Use this when you need to plan the implementation strategy for a task. Returns step-by-step plans, identifies critical files, and considers architectural trade-offs. (Tools: All tools except Agent, ExitPlanMode, Edit, Write, NotebookEdit)",
      "- statusline-setup: Use this agent to configure the user's Claude Code status line setting. (Tools: Read, Edit)"
    ],
    "removedTypes": [],
    "isInitial": true,
    "showConcurrencyNote": true
  },
  "type": "attachment",
  "uuid": "18200c03-7bd5-4aec-a761-7ba4f6386ee3",
  "timestamp": "2026-05-14T14:37:10.271Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-14T14:37:10.271Z_

```json
{
  "parentUuid": "18200c03-7bd5-4aec-a761-7ba4f6386ee3",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "37124add-32fc-42a1-943a-7ce24774eb4c",
  "timestamp": "2026-05-14T14:37:10.271Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 7_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：C5 pilot 通过 gate（LLaMA 复现 phase gradient + crossover），n=500 收紧 Qwen s015 CI 至零以上，所有 claims 原样成立 核心假设：['C5 LLaMA-8B s025/s030 pilot 回收 >30% compound degrada…",
  "leafUuid": "37124add-32fc-42a1-943a-7ce24774eb4c",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

### Runtime record

_source line 8_

```json
{
  "type": "ai-title",
  "aiTitle": "Phase-gated compound sparsity architecture generalization",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

### Assistant

_source line 9 · 2026-05-14T14:37:22.488Z_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to generate detailed predicted data for each planned experiment in the experiment_plan, under the "best" tier definition. I need to first find the experiment_plan to see what experiments are planned.

Let me look at the experiment plan and registry to understand what's planned.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "37124add-32fc-42a1-943a-7ce24774eb4c",
  "isSidechain": false,
  "requestId": "req_011Cb2dXYap1Xbz3kg7q4Rgt",
  "type": "assistant",
  "uuid": "7d901ea1-8b77-4dab-89eb-81befe49c6b4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019rU52eNJsomYjL8qjHmgpk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 27261,
      "cache_read_input_tokens": 11447,
      "output_tokens": 283,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 27261,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 283,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 27261,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 27261
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

_source line 10 · 2026-05-14T14:37:22.787Z_

Let me find the experiment plan to identify all planned experiments.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7d901ea1-8b77-4dab-89eb-81befe49c6b4",
  "isSidechain": false,
  "requestId": "req_011Cb2dXYap1Xbz3kg7q4Rgt",
  "type": "assistant",
  "uuid": "9f183c72-2f7b-48a3-9cc6-0b67a7bbe7d8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019rU52eNJsomYjL8qjHmgpk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 27261,
      "cache_read_input_tokens": 11447,
      "output_tokens": 283,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 27261,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 283,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 27261,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 27261
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

_source line 11 · 2026-05-14T14:37:27.713Z_

<details open><summary>🔧 Tool call — Agent · `toolu_01SbS3YNtCuR1Kkt63bk37zZ`</summary>

```json
{
  "subagent_type": "Explore",
  "description": "Find experiment plan file",
  "prompt": "Search the directory /home/ubuntu/.agent-ml-research-idea_gen_0509_11 for files related to the experiment plan. Look for files named experiment_plan*, plan*, or any YAML/MD files that contain experiment definitions with fields like \"plan_id\", \"status: planned\", \"status: PENDING\", \"status: PREPARING\", or \"status: RUNNING\". Search breadth: very thorough. Report the full paths and key content of any matching files."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9f183c72-2f7b-48a3-9cc6-0b67a7bbe7d8",
  "isSidechain": false,
  "requestId": "req_011Cb2dXYap1Xbz3kg7q4Rgt",
  "type": "assistant",
  "uuid": "6e705694-be60-4d69-8fef-8837272640b1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019rU52eNJsomYjL8qjHmgpk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 27261,
      "cache_read_input_tokens": 11447,
      "output_tokens": 283,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 27261,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 283,
          "cache_read_input_tokens": 11447,
          "cache_creation_input_tokens": 27261,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 27261
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

_source line 12 · 2026-05-14T14:38:20.791Z_

<details><summary>↩ Tool result · `toolu_01SbS3YNtCuR1Kkt63bk37zZ`</summary>

```text
Perfect! Now let me create a comprehensive summary by reviewing all the key experiment plan files and extracting status information:

## Summary of Experiment Plan Files Found

I've completed a thorough search of the experiment plan files in `/home/ubuntu/.agent-ml-research-idea_gen_0509_11`. Here are all the relevant experiment plan files with their key content and status information:

### **1. Project: redundancy-compound-sparsity**

**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/redundancy-compound-sparsity/experiment_plan.yaml`

**Overview:** Experiment plan for "Confound Resolution Phase" targeting EMNLP 2026 ARR (Deadline: 2026-05-25)

**Key Experiments with Status:**
- **mvp-001** (plan_id) - MVP: adjacent-sim baseline (invalid EMA) - **status: DONE**
- **mvp-001b** - MVP: DeepSeek-R1-7B anchor EMA (easy problems) - **status: DONE**
- **mvp-001c** - MVP: DeepSeek-R1-7B anchor EMA (AIME hard problems) - **status: DONE**
- **neg-cross-model-001** - Llama-3.1-8B anchor EMA validation - **status: DONE**
- **confound-ctrl-001** - Confound control: DeepSeek-R1-Distill-Llama-8B - **status: PLANNED**, priority: P0-URGENT
- **confound-ctrl-002** - Confound control: Qwen2-7B-Instruct - **status: PLANNED**, priority: P0
- **llama-sparsity-sweep** - Llama sparsity level sweep - **status: PLANNED**, priority: P0
- **llama-layer-analysis** - Llama per-layer r + Δpert decomposition - **status: PLANNED**, priority: P0
- **kv-bench-001** - KV eviction benchmark: CARC-KV vs baselines - **status: PREPARING**, priority: P0
- **cross-arch-mistral** - Mistral-7B validation - **status: PLANNED**, priority: P1
- **mla-signal-analysis** - MLA latent space semantic fidelity analysis - **status: SUSPENDED**
- **kv-eviction-wallclock** - Wall-clock O(1) vs O(n) eviction cost - **status: PLANNED**, priority: P1
- **neg-per-head** - Per-head KV contribution analysis - **status: PLANNED**, priority: P1
- **kv-eviction-ablation** - KV eviction ablation - **status: PLANNED**, priority: P2
- **llama-downstream** - Llama two-tier sparsity downstream accuracy - **status: PLANNED**, priority: P2

---

### **2. Project: redundancy-compound-sparsity-2**

**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/redundancy-compound-sparsity-2/experiment_plan.yaml`

**Overview:** Experiment plan structured in phases (0-5) for CARC-KV evaluation with reasoning and scaling focus

**Key Experiments with Status:**

**Phase 0 (Sanity Gate):**
- **pathc_sanity_reasoning** (id) - EMA vs random eviction on MATH-500 reasoning traces - priority: 0
- **pathc_sanity_wikitext32k** - EMA vs recency eviction on WikiText-2 32K - priority: 0

**Phase 0b (Analysis Paper Contingency):**
- **analysis_heatmap** - Per-layer heatmap visualization - priority: 2
- **analysis_attn_vs_ema** - Attention-score vs EMA signal comparison - priority: 0
- **analysis_tau_sweep** - Tau (EMA decay) sensitivity sweep - priority: 1
- **analysis_decay_curve** - Information decay curve analysis - priority: 1
- **analysis_second_model** - Qwen2.5-7B validation - priority: 2

**Phase 1 (PPL Budget Sweep):**
- **pathc_ppl_budget30** - PPL evaluation at 30% KV budget - priority: 1
- **pathc_ppl_budget50** - PPL evaluation at 50% KV budget - priority: 1
- **pathc_ppl_budget70** - PPL evaluation at 70% KV budget - priority: 1

**Phase 2 (Baseline Comparison):**
- **pathc_baseline_h2o** - H2O baseline comparison - priority: 1
- **pathc_baseline_rkv** - R-KV baseline comparison - priority: 1

**Phase 3 (Ablation):**
- **pathc_ablation_gamma** - EMA gamma sensitivity - priority: 2
- **pathc_ablation_budget** - Budget ratio sweep - priority: 2
- **pathc_ablation_grace** - Grace window size sweep - priority: 2
- **pathc_ablation_perhead** - Per-head vs concatenated EMA comparison - priority: 2

**Phase 4 (Reasoning Eval):**
- **pathc_math500_eval** - MATH-500 accuracy evaluation - priority: 1

**Phase 5 (Scaling + Throughput):**
- **pathc_scaling_32k** - 32K context length PPL evaluation - priority: 2
- **pathc_scaling_64k** - 64K context length PPL evaluation - priority: 3
- **pathc_throughput** - Throughput benchmarking - priority: 2

---

### **3. Project: phase-gated-compound-sparse**

**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/experiment_plan.yaml`

**Overview:** Experiment plan for "Phase-Gated Compound Sparsity" research (Last updated: 2026-05-14)

**Key Plans with Status:**

**C1 + C2 (Strategy-dependent, phase-modulated severity):**
- **plan_001** - DeepSeek importance bf16 × 4 sparsity - **status: pending**, priority: P0
  - registry_ids: bf16_importance_s015/s020/s025/s030
- **plan_002** - DeepSeek random bf16 × 4 sparsity - **status: planned**, priority: P0

**C3 (Phase-strategy crossover):**
- **plan_003** - Crossover analysis from plan_001 + plan_002 - **status: planned**, priority: P0 (pure analysis, 0 GPU hours)

**C5 (Cross-model generalizability):**
- **plan_004** - Qwen importance bf16 × 4 sparsity - **status: pending**, priority: P0
  - registry_ids: qwen_importance_s015/s020/s025/s030
- **plan_005** - Qwen random bf16 × 4 sparsity - **status: planned**, priority: P0

**C4 (Entropy-discrimination collapse mechanism):**
- **plan_006** - Attention entropy measurement - **status: planned**, priority: P2

**C6 (Sub-exponential growth):**
- **plan_007** - Growth rate analysis from plan_001 - **status: planned**, priority: P1

**Statistical validation:**
- **plan_008** - Per-problem bootstrap CI (bf16 data) - **status: planned**, priority: P0

**C5 (revised, Cross-architecture pilot):**
- **plan_009** - LLaMA-8B pilot: oracle + heuristic phase-gated recovery - **status: planned**, priority: P0

**C2 (n=500 statistical power boost):**
- **plan_010** - n=500 statistical power: DeepSeek + Qwen 8 conditions - **status: RUNNING**, priority: P0
  - registry_ids: c2_n500_deepseek, c2_qw_n500
  - Note: "当前 GPU 0-3 全部在跑"

**Writing Tasks:**
- **plan_011** - Abstract simplification (150-200 words) - **status: planned**, priority: P0
- **plan_012** - II vs super-additivity conceptual distinction - **status: planned**, priority: P0

**Resource Budget:** Total GPU hours: 52.5 (RTX 6000 Pro 96GB); Estimated completion: ~20 hours

---

### **4. Global Registry**

**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/global/registry.yaml`

**Active/Recent Experiments:**
- **carc_mvp_seed42** - **status: PREPARING**, created: 2026-05-12
- **mvp_001** - **status: QUEUED**, created: 2026-05-12
- **inverted_ema_reasoning_v2** - **status: RUNNING**, created: 2026-05-12
- **bf16_qw_rand_s020** - **status: DONE**, created: 2026-05-14, completed: 2026-05-14

---

### **Status Summary**

**Current Active Experiments:**
- 1 experiment **RUNNING**: plan_010 (n=500 statistical power) in phase-gated-compound-sparse
- 1 experiment **PENDING**: plan_001 (DeepSeek importance bf16) in phase-gated-compound-sparse
- 1 experiment **PENDING**: plan_004 (Qwen importance bf16) in phase-gated-compound-sparse
- 1 experiment **PREPARING**: kv-bench-001 in redundancy-compound-sparsity

**Recently Completed (2026-05-14):**
- bf16_qw_rand_s020 (Qwen random masking at s020 sparsity)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6e705694-be60-4d69-8fef-8837272640b1",
  "isSidechain": false,
  "promptId": "79c6b4a3-3133-4981-8938-247f5d67b190",
  "type": "user",
  "uuid": "7abcdd7c-95d6-4a2d-81fb-c2a85faedfec",
  "toolUseResult": {
    "status": "completed",
    "prompt": "Search the directory /home/ubuntu/.agent-ml-research-idea_gen_0509_11 for files related to the experiment plan. Look for files named experiment_plan*, plan*, or any YAML/MD files that contain experiment definitions with fields like \"plan_id\", \"status: planned\", \"status: PENDING\", \"status: PREPARING\", or \"status: RUNNING\". Search breadth: very thorough. Report the full paths and key content of any matching files.",
    "agentId": "a8b86459279318ae2",
    "agentType": "Explore",
    "content": [
      {
        "type": "text",
        "text": "Perfect! Now let me create a comprehensive summary by reviewing all the key experiment plan files and extracting status information:\n\n## Summary of Experiment Plan Files Found\n\nI've completed a thorough search of the experiment plan files in `/home/ubuntu/.agent-ml-research-idea_gen_0509_11`. Here are all the relevant experiment plan files with their key content and status information:\n\n### **1. Project: redundancy-compound-sparsity**\n\n**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/redundancy-compound-sparsity/experiment_plan.yaml`\n\n**Overview:** Experiment plan for \"Confound Resolution Phase\" targeting EMNLP 2026 ARR (Deadline: 2026-05-25)\n\n**Key Experiments with Status:**\n- **mvp-001** (plan_id) - MVP: adjacent-sim baseline (invalid EMA) - **status: DONE**\n- **mvp-001b** - MVP: DeepSeek-R1-7B anchor EMA (easy problems) - **status: DONE**\n- **mvp-001c** - MVP: DeepSeek-R1-7B anchor EMA (AIME hard problems) - **status: DONE**\n- **neg-cross-model-001** - Llama-3.1-8B anchor EMA validation - **status: DONE**\n- **confound-ctrl-001** - Confound control: DeepSeek-R1-Distill-Llama-8B - **status: PLANNED**, priority: P0-URGENT\n- **confound-ctrl-002** - Confound control: Qwen2-7B-Instruct - **status: PLANNED**, priority: P0\n- **llama-sparsity-sweep** - Llama sparsity level sweep - **status: PLANNED**, priority: P0\n- **llama-layer-analysis** - Llama per-layer r + Δpert decomposition - **status: PLANNED**, priority: P0\n- **kv-bench-001** - KV eviction benchmark: CARC-KV vs baselines - **status: PREPARING**, priority: P0\n- **cross-arch-mistral** - Mistral-7B validation - **status: PLANNED**, priority: P1\n- **mla-signal-analysis** - MLA latent space semantic fidelity analysis - **status: SUSPENDED**\n- **kv-eviction-wallclock** - Wall-clock O(1) vs O(n) eviction cost - **status: PLANNED**, priority: P1\n- **neg-per-head** - Per-head KV contribution analysis - **status: PLANNED**, priority: P1\n- **kv-eviction-ablation** - KV eviction ablation - **status: PLANNED**, priority: P2\n- **llama-downstream** - Llama two-tier sparsity downstream accuracy - **status: PLANNED**, priority: P2\n\n---\n\n### **2. Project: redundancy-compound-sparsity-2**\n\n**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/redundancy-compound-sparsity-2/experiment_plan.yaml`\n\n**Overview:** Experiment plan structured in phases (0-5) for CARC-KV evaluation with reasoning and scaling focus\n\n**Key Experiments with Status:**\n\n**Phase 0 (Sanity Gate):**\n- **pathc_sanity_reasoning** (id) - EMA vs random eviction on MATH-500 reasoning traces - priority: 0\n- **pathc_sanity_wikitext32k** - EMA vs recency eviction on WikiText-2 32K - priority: 0\n\n**Phase 0b (Analysis Paper Contingency):**\n- **analysis_heatmap** - Per-layer heatmap visualization - priority: 2\n- **analysis_attn_vs_ema** - Attention-score vs EMA signal comparison - priority: 0\n- **analysis_tau_sweep** - Tau (EMA decay) sensitivity sweep - priority: 1\n- **analysis_decay_curve** - Information decay curve analysis - priority: 1\n- **analysis_second_model** - Qwen2.5-7B validation - priority: 2\n\n**Phase 1 (PPL Budget Sweep):**\n- **pathc_ppl_budget30** - PPL evaluation at 30% KV budget - priority: 1\n- **pathc_ppl_budget50** - PPL evaluation at 50% KV budget - priority: 1\n- **pathc_ppl_budget70** - PPL evaluation at 70% KV budget - priority: 1\n\n**Phase 2 (Baseline Comparison):**\n- **pathc_baseline_h2o** - H2O baseline comparison - priority: 1\n- **pathc_baseline_rkv** - R-KV baseline comparison - priority: 1\n\n**Phase 3 (Ablation):**\n- **pathc_ablation_gamma** - EMA gamma sensitivity - priority: 2\n- **pathc_ablation_budget** - Budget ratio sweep - priority: 2\n- **pathc_ablation_grace** - Grace window size sweep - priority: 2\n- **pathc_ablation_perhead** - Per-head vs concatenated EMA comparison - priority: 2\n\n**Phase 4 (Reasoning Eval):**\n- **pathc_math500_eval** - MATH-500 accuracy evaluation - priority: 1\n\n**Phase 5 (Scaling + Throughput):**\n- **pathc_scaling_32k** - 32K context length PPL evaluation - priority: 2\n- **pathc_scaling_64k** - 64K context length PPL evaluation - priority: 3\n- **pathc_throughput** - Throughput benchmarking - priority: 2\n\n---\n\n### **3. Project: phase-gated-compound-sparse**\n\n**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/experiment_plan.yaml`\n\n**Overview:** Experiment plan for \"Phase-Gated Compound Sparsity\" research (Last updated: 2026-05-14)\n\n**Key Plans with Status:**\n\n**C1 + C2 (Strategy-dependent, phase-modulated severity):**\n- **plan_001** - DeepSeek importance bf16 × 4 sparsity - **status: pending**, priority: P0\n  - registry_ids: bf16_importance_s015/s020/s025/s030\n- **plan_002** - DeepSeek random bf16 × 4 sparsity - **status: planned**, priority: P0\n\n**C3 (Phase-strategy crossover):**\n- **plan_003** - Crossover analysis from plan_001 + plan_002 - **status: planned**, priority: P0 (pure analysis, 0 GPU hours)\n\n**C5 (Cross-model generalizability):**\n- **plan_004** - Qwen importance bf16 × 4 sparsity - **status: pending**, priority: P0\n  - registry_ids: qwen_importance_s015/s020/s025/s030\n- **plan_005** - Qwen random bf16 × 4 sparsity - **status: planned**, priority: P0\n\n**C4 (Entropy-discrimination collapse mechanism):**\n- **plan_006** - Attention entropy measurement - **status: planned**, priority: P2\n\n**C6 (Sub-exponential growth):**\n- **plan_007** - Growth rate analysis from plan_001 - **status: planned**, priority: P1\n\n**Statistical validation:**\n- **plan_008** - Per-problem bootstrap CI (bf16 data) - **status: planned**, priority: P0\n\n**C5 (revised, Cross-architecture pilot):**\n- **plan_009** - LLaMA-8B pilot: oracle + heuristic phase-gated recovery - **status: planned**, priority: P0\n\n**C2 (n=500 statistical power boost):**\n- **plan_010** - n=500 statistical power: DeepSeek + Qwen 8 conditions - **status: RUNNING**, priority: P0\n  - registry_ids: c2_n500_deepseek, c2_qw_n500\n  - Note: \"当前 GPU 0-3 全部在跑\"\n\n**Writing Tasks:**\n- **plan_011** - Abstract simplification (150-200 words) - **status: planned**, priority: P0\n- **plan_012** - II vs super-additivity conceptual distinction - **status: planned**, priority: P0\n\n**Resource Budget:** Total GPU hours: 52.5 (RTX 6000 Pro 96GB); Estimated completion: ~20 hours\n\n---\n\n### **4. Global Registry**\n\n**File Path:** `/home/ubuntu/.agent-ml-research-idea_gen_0509_11/global/registry.yaml`\n\n**Active/Recent Experiments:**\n- **carc_mvp_seed42** - **status: PREPARING**, created: 2026-05-12\n- **mvp_001** - **status: QUEUED**, created: 2026-05-12\n- **inverted_ema_reasoning_v2** - **status: RUNNING**, created: 2026-05-12\n- **bf16_qw_rand_s020** - **status: DONE**, created: 2026-05-14, completed: 2026-05-14\n\n---\n\n### **Status Summary**\n\n**Current Active Experiments:**\n- 1 experiment **RUNNING**: plan_010 (n=500 statistical power) in phase-gated-compound-sparse\n- 1 experiment **PENDING**: plan_001 (DeepSeek importance bf16) in phase-gated-compound-sparse\n- 1 experiment **PENDING**: plan_004 (Qwen importance bf16) in phase-gated-compound-sparse\n- 1 experiment **PREPARING**: kv-bench-001 in redundancy-compound-sparsity\n\n**Recently Completed (2026-05-14):**\n- bf16_qw_rand_s020 (Qwen random masking at s020 sparsity)"
      }
    ],
    "totalDurationMs": 53067,
    "totalTokens": 63071,
    "totalToolUseCount": 18,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1273,
      "cache_read_input_tokens": 59322,
      "output_tokens": 2473,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1273
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 2473,
          "cache_read_input_tokens": 59322,
          "cache_creation_input_tokens": 1273,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1273,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "toolStats": {
      "readCount": 8,
      "searchCount": 7,
      "bashCount": 3,
      "editFileCount": 0,
      "linesAdded": 0,
      "linesRemoved": 0,
      "otherToolCount": 0
    }
  },
  "sourceToolAssistantUUID": "6e705694-be60-4d69-8fef-8837272640b1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-14T14:38:24.188Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Njkajv6o52APrEhHp1S4Sw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/experiment_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7abcdd7c-95d6-4a2d-81fb-c2a85faedfec",
  "isSidechain": false,
  "requestId": "req_011Cb2dck2n45AeGR6kDGRKk",
  "type": "assistant",
  "uuid": "60be7883-69c6-404d-9f69-b5cc10ea95f9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PrZ6kt4xdyGYvoXAiqA9Xq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2764,
      "cache_read_input_tokens": 38708,
      "output_tokens": 88,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2764,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 88,
          "cache_read_input_tokens": 38708,
          "cache_creation_input_tokens": 2764,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2764
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

_source line 14 · 2026-05-14T14:38:24.195Z_

<details><summary>↩ Tool result · `toolu_01Njkajv6o52APrEhHp1S4Sw`</summary>

```text
1	# Experiment Plan — Phase-Gated Compound Sparsity
2	# 最后更新: 2026-05-14
3	# 维护者: Director
4	#
5	# 每个 plan 对应一个 claim（paper_framing.md），标注 priority / depends_on / status
6	# registry_id 链接已注册实验；无 registry_id = planned
7	
8	plans:
9	  # ============================================================
10	  # C1 + C2: Strategy-dependent, phase-modulated severity
11	  # ============================================================
12	  - plan_id: plan_001
13	    claim: C1, C2
14	    title: "DeepSeek importance bf16 × 4 sparsity"
15	    description: "bf16 重跑 DeepSeek importance masking (s015/s020/s025/s030)，消除 fp16 NaN 偏差"
16	    priority: P0
17	    status: pending
18	    depends_on: []
19	    registry_ids:
20	      - bf16_importance_s015
21	      - bf16_importance_s020
22	      - bf16_importance_s025
23	      - bf16_importance_s030
24	    gpu_hours_est: 3
25	    notes: "fp16 版本已完成但有 NaN 问题，需 bf16 重跑获得干净数据"
26	
27	  - plan_id: plan_002
28	    claim: C1
29	    title: "DeepSeek random bf16 × 4 sparsity"
30	    description: "bf16 重跑 DeepSeek random masking (s015/s020/s025/s030)，作为 importance 的配对对照"
31	    priority: P0
32	    status: planned
33	    depends_on: []
34	    registry_ids: []
35	    gpu_hours_est: 3
36	    notes: "与 plan_001 配对，论文数据必须同一 dtype"
37	
38	  # ============================================================
39	  # C3: Phase-strategy crossover
40	  # ============================================================
41	  - plan_id: plan_003
42	    claim: C3
43	    title: "Crossover analysis from plan_001 + plan_002"
44	    description: "从 bf16 importance vs random 数据中提取 per-phase II，验证方向反转"
45	    priority: P0
46	    status: planned
47	    depends_on: [plan_001, plan_002]
48	    registry_ids: []
49	    gpu_hours_est: 0
50	    notes: "纯分析任务，不需要额外 GPU。数据从 plan_001/002 派生"
51	
52	  # ============================================================
53	  # C5: Cross-model generalizability
54	  # ============================================================
55	  - plan_id: plan_004
56	    claim: C5
57	    title: "Qwen importance bf16 × 4 sparsity"
58	    description: "Qwen2.5-7B-Instruct importance masking bf16 (s015/s020/s025/s030)"
59	    priority: P0
60	    status: pending
61	    depends_on: []
62	    registry_ids:
63	      - qwen_importance_s015
64	      - qwen_importance_s020
65	      - qwen_importance_s025
66	      - qwen_importance_s030
67	    gpu_hours_est: 3
68	    notes: "cross-model replication 核心实验"
69	
70	  - plan_id: plan_005
71	    claim: C5
72	    title: "Qwen random bf16 × 4 sparsity"
73	    description: "Qwen2.5-7B-Instruct random masking bf16 (s015/s020/s025/s030)"
74	    priority: P0
75	    status: planned
76	    depends_on: []
77	    registry_ids: []
78	    gpu_hours_est: 3
79	    notes: "Qwen 的配对对照，验证 importance > random 在 Qwen 上也成立"
80	
81	  # ============================================================
82	  # C4: Entropy-discrimination collapse mechanism
83	  # ============================================================
84	  - plan_id: plan_006
85	    claim: C4
86	    title: "Attention entropy measurement (optional ablation)"
87	    description: "测量 pruned vs unpruned 的 attention entropy + importance score 分布，直接验证 mechanism"
88	    priority: P2
89	    status: planned
90	    depends_on: [plan_001]
91	    registry_ids: []
92	    gpu_hours_est: 2
93	    notes: "RC2 应对实验。仅在时间允许且 reviewer concern 预判需要时执行"
94	
95	  # ============================================================
96	  # C6: Sub-exponential growth
97	  # ============================================================
98	  - plan_id: plan_007
99	    claim: C6
100	    title: "Growth rate analysis from plan_001"
101	    description: "从 bf16 importance 4 sparsity 的 gradient 数据分析增长率模式"
102	    priority: P1
103	    status: planned
104	    depends_on: [plan_001]
105	    registry_ids: []
106	    gpu_hours_est: 0
107	    notes: "纯分析任务。fp16 数据已确认 sub-exponential (2.24→1.84→1.42)，bf16 需要再验证"
108	
109	  # ============================================================
110	  # Statistical validation
111	  # ============================================================
112	  - plan_id: plan_008
113	    claim: C1, C2, C3
114	    title: "Per-problem bootstrap CI (bf16 data)"
115	    description: "对 bf16 重跑数据重新做 B=10000 bootstrap CI"
116	    priority: P0
117	    status: planned
118	    depends_on: [plan_001, plan_002]
119	    registry_ids: []
120	    gpu_hours_est: 0.5
121	    notes: "fp16 版本 all p=0.0000，bf16 预计同样显著但必须重做"
122	
123	  # ============================================================
124	  # C5 (revised): Cross-architecture pilot
125	  # ============================================================
126	  - plan_id: plan_009
127	    claim: C5
128	    title: "LLaMA-8B pilot: oracle + heuristic phase-gated recovery"
129	    description: "2h pilot on DeepSeek-R1-Distill-Llama-8B: (1) oracle phase gate s025/s030, (2) heuristic baseline using token position ratio as phase proxy. Gate: recover >30% compound degradation → full rollout, else future work."
130	    priority: P0
131	    status: planned
132	    depends_on: []
133	    registry_ids:
134	      - c3_llama
135	    gpu_hours_est: 2
136	    notes: "D052: pilot-first strategy. Must include heuristic baseline (oracle upper + simple heuristic lower)."
137	
138	  # ============================================================
139	  # C2: n=500 statistical power boost
140	  # ============================================================
141	  - plan_id: plan_010
142	    claim: C2
143	    title: "n=500 statistical power: DeepSeek + Qwen 8 conditions"
144	    description: "扩展 DeepSeek/Qwen 各 8 conditions (imp/rand × 4 sparsity) 到 n=500 (full MATH-500)。预注册：若 QW s015 CI 仍跨零，叙事改为 threshold sparsity ~s020。"
145	    priority: P0
146	    status: running
147	    depends_on: []
148	    registry_ids:
149	      - c2_n500_deepseek
150	      - c2_qw_n500
151	    gpu_hours_est: 36
152	    notes: "D052: 预注册叙事分支。当前 GPU 0-3 全部在跑。"
153	
154	  # ============================================================
155	  # S3/S7 升级为 C 级
156	  # ============================================================
157	  - plan_id: plan_011
158	    claim: C7
159	    title: "Abstract 精简至 150-200 词"
160	    description: "当前 Abstract ~600 词信息过载。精简至 150-200 词，保留 1-2 个关键定量结果（Δ range + Cohen's d）。纯写作任务。"
161	    priority: P0
162	    status: planned
163	    depends_on: []
164	    registry_ids: []
165	    gpu_hours_est: 0
166	    notes: "D052: 原 S3 升级为 C 级。Reviewer R2 要求精简。无需实验，写作任务。"
167	
168	  - plan_id: plan_012
169	    claim: C8
170	    title: "II vs super-additivity 概念区分"
171	    description: "§3 Methodology 加一段讨论：II 与 SparK/SLiM/UniComp 中 compound interaction 度量的区别。明确 II 是 standard interaction effect，区别在于 phase-conditioned 分析维度。"
172	    priority: P0
173	    status: planned
174	    depends_on: []
175	    registry_ids: []
176	    gpu_hours_est: 0
177	    notes: "D052: 原 S7 升级为 C 级。Reviewer R2 要求。纯写作+分析任务。"
178	
179	# ============================================================
180	# 资源预算
181	# ============================================================
182	resource_budget:
183	  total_gpu_hours_est: 52.5
184	  gpu_type: "RTX 6000 Pro 96GB"
185	  server: westd-22162
186	  gpus: [cuda:0, cuda:1, cuda:2, cuda:3]
187	  estimated_completion: "C2 n=500: ~18h from start; C5 pilot: 2h; 总体 ~20h"
188	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "60be7883-69c6-404d-9f69-b5cc10ea95f9",
  "isSidechain": false,
  "promptId": "79c6b4a3-3133-4981-8938-247f5d67b190",
  "type": "user",
  "uuid": "e9c6940f-7377-4b02-af5a-65527ead6c07",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/experiment_plan.yaml",
      "content": "# Experiment Plan — Phase-Gated Compound Sparsity\n# 最后更新: 2026-05-14\n# 维护者: Director\n#\n# 每个 plan 对应一个 claim（paper_framing.md），标注 priority / depends_on / status\n# registry_id 链接已注册实验；无 registry_id = planned\n\nplans:\n  # ============================================================\n  # C1 + C2: Strategy-dependent, phase-modulated severity\n  # ============================================================\n  - plan_id: plan_001\n    claim: C1, C2\n    title: \"DeepSeek importance bf16 × 4 sparsity\"\n    description: \"bf16 重跑 DeepSeek importance masking (s015/s020/s025/s030)，消除 fp16 NaN 偏差\"\n    priority: P0\n    status: pending\n    depends_on: []\n    registry_ids:\n      - bf16_importance_s015\n      - bf16_importance_s020\n      - bf16_importance_s025\n      - bf16_importance_s030\n    gpu_hours_est: 3\n    notes: \"fp16 版本已完成但有 NaN 问题，需 bf16 重跑获得干净数据\"\n\n  - plan_id: plan_002\n    claim: C1\n    title: \"DeepSeek random bf16 × 4 sparsity\"\n    description: \"bf16 重跑 DeepSeek random masking (s015/s020/s025/s030)，作为 importance 的配对对照\"\n    priority: P0\n    status: planned\n    depends_on: []\n    registry_ids: []\n    gpu_hours_est: 3\n    notes: \"与 plan_001 配对，论文数据必须同一 dtype\"\n\n  # ============================================================\n  # C3: Phase-strategy crossover\n  # ============================================================\n  - plan_id: plan_003\n    claim: C3\n    title: \"Crossover analysis from plan_001 + plan_002\"\n    description: \"从 bf16 importance vs random 数据中提取 per-phase II，验证方向反转\"\n    priority: P0\n    status: planned\n    depends_on: [plan_001, plan_002]\n    registry_ids: []\n    gpu_hours_est: 0\n    notes: \"纯分析任务，不需要额外 GPU。数据从 plan_001/002 派生\"\n\n  # ============================================================\n  # C5: Cross-model generalizability\n  # ============================================================\n  - plan_id: plan_004\n    claim: C5\n    title: \"Qwen importance bf16 × 4 sparsity\"\n    description: \"Qwen2.5-7B-Instruct importance masking bf16 (s015/s020/s025/s030)\"\n    priority: P0\n    status: pending\n    depends_on: []\n    registry_ids:\n      - qwen_importance_s015\n      - qwen_importance_s020\n      - qwen_importance_s025\n      - qwen_importance_s030\n    gpu_hours_est: 3\n    notes: \"cross-model replication 核心实验\"\n\n  - plan_id: plan_005\n    claim: C5\n    title: \"Qwen random bf16 × 4 sparsity\"\n    description: \"Qwen2.5-7B-Instruct random masking bf16 (s015/s020/s025/s030)\"\n    priority: P0\n    status: planned\n    depends_on: []\n    registry_ids: []\n    gpu_hours_est: 3\n    notes: \"Qwen 的配对对照，验证 importance > random 在 Qwen 上也成立\"\n\n  # ============================================================\n  # C4: Entropy-discrimination collapse mechanism\n  # ============================================================\n  - plan_id: plan_006\n    claim: C4\n    title: \"Attention entropy measurement (optional ablation)\"\n    description: \"测量 pruned vs unpruned 的 attention entropy + importance score 分布，直接验证 mechanism\"\n    priority: P2\n    status: planned\n    depends_on: [plan_001]\n    registry_ids: []\n    gpu_hours_est: 2\n    notes: \"RC2 应对实验。仅在时间允许且 reviewer concern 预判需要时执行\"\n\n  # ============================================================\n  # C6: Sub-exponential growth\n  # ============================================================\n  - plan_id: plan_007\n    claim: C6\n    title: \"Growth rate analysis from plan_001\"\n    description: \"从 bf16 importance 4 sparsity 的 gradient 数据分析增长率模式\"\n    priority: P1\n    status: planned\n    depends_on: [plan_001]\n    registry_ids: []\n    gpu_hours_est: 0\n    notes: \"纯分析任务。fp16 数据已确认 sub-exponential (2.24→1.84→1.42)，bf16 需要再验证\"\n\n  # ============================================================\n  # Statistical validation\n  # ============================================================\n  - plan_id: plan_008\n    claim: C1, C2, C3\n    title: \"Per-problem bootstrap CI (bf16 data)\"\n    description: \"对 bf16 重跑数据重新做 B=10000 bootstrap CI\"\n    priority: P0\n    status: planned\n    depends_on: [plan_001, plan_002]\n    registry_ids: []\n    gpu_hours_est: 0.5\n    notes: \"fp16 版本 all p=0.0000，bf16 预计同样显著但必须重做\"\n\n  # ============================================================\n  # C5 (revised): Cross-architecture pilot\n  # ============================================================\n  - plan_id: plan_009\n    claim: C5\n    title: \"LLaMA-8B pilot: oracle + heuristic phase-gated recovery\"\n    description: \"2h pilot on DeepSeek-R1-Distill-Llama-8B: (1) oracle phase gate s025/s030, (2) heuristic baseline using token position ratio as phase proxy. Gate: recover >30% compound degradation → full rollout, else future work.\"\n    priority: P0\n    status: planned\n    depends_on: []\n    registry_ids:\n      - c3_llama\n    gpu_hours_est: 2\n    notes: \"D052: pilot-first strategy. Must include heuristic baseline (oracle upper + simple heuristic lower).\"\n\n  # ============================================================\n  # C2: n=500 statistical power boost\n  # ============================================================\n  - plan_id: plan_010\n    claim: C2\n    title: \"n=500 statistical power: DeepSeek + Qwen 8 conditions\"\n    description: \"扩展 DeepSeek/Qwen 各 8 conditions (imp/rand × 4 sparsity) 到 n=500 (full MATH-500)。预注册：若 QW s015 CI 仍跨零，叙事改为 threshold sparsity ~s020。\"\n    priority: P0\n    status: running\n    depends_on: []\n    registry_ids:\n      - c2_n500_deepseek\n      - c2_qw_n500\n    gpu_hours_est: 36\n    notes: \"D052: 预注册叙事分支。当前 GPU 0-3 全部在跑。\"\n\n  # ============================================================\n  # S3/S7 升级为 C 级\n  # ============================================================\n  - plan_id: plan_011\n    claim: C7\n    title: \"Abstract 精简至 150-200 词\"\n    description: \"当前 Abstract ~600 词信息过载。精简至 150-200 词，保留 1-2 个关键定量结果（Δ range + Cohen's d）。纯写作任务。\"\n    priority: P0\n    status: planned\n    depends_on: []\n    registry_ids: []\n    gpu_hours_est: 0\n    notes: \"D052: 原 S3 升级为 C 级。Reviewer R2 要求精简。无需实验，写作任务。\"\n\n  - plan_id: plan_012\n    claim: C8\n    title: \"II vs super-additivity 概念区分\"\n    description: \"§3 Methodology 加一段讨论：II 与 SparK/SLiM/UniComp 中 compound interaction 度量的区别。明确 II 是 standard interaction effect，区别在于 phase-conditioned 分析维度。\"\n    priority: P0\n    status: planned\n    depends_on: []\n    registry_ids: []\n    gpu_hours_est: 0\n    notes: \"D052: 原 S7 升级为 C 级。Reviewer R2 要求。纯写作+分析任务。\"\n\n# ============================================================\n# 资源预算\n# ============================================================\nresource_budget:\n  total_gpu_hours_est: 52.5\n  gpu_type: \"RTX 6000 Pro 96GB\"\n  server: westd-22162\n  gpus: [cuda:0, cuda:1, cuda:2, cuda:3]\n  estimated_completion: \"C2 n=500: ~18h from start; C5 pilot: 2h; 总体 ~20h\"\n",
      "numLines": 188,
      "startLine": 1,
      "totalLines": 188
    }
  },
  "sourceToolAssistantUUID": "60be7883-69c6-404d-9f69-b5cc10ea95f9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 15 · 2026-05-14T14:38:24.262Z_

````json
{
  "parentUuid": "e9c6940f-7377-4b02-af5a-65527ead6c07",
  "isSidechain": false,
  "attachment": {
    "type": "nested_memory",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/.claude/CLAUDE.md",
    "content": {
      "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/.claude/CLAUDE.md",
      "type": "Project",
      "content": "## 当前项目\n当前绑定项目：**phase-gated-compound-sparse**\n\n## 按需查阅\n- 项目配置：`load_project_config(\"phase-gated-compound-sparse\")` 或 `load_project_config(\"phase-gated-compound-sparse\", section=\"execution\")`\n- 知识文件：`read_project_file(file=...)` 读取项目文件（ROADMAP.md/memory.md/ideas.md/report.md 等）\n- 路线图：`read_roadmap()` 读取研究方向和短期任务\n- 产出目录：`/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/`（写文件后用 `register_artifact` 注册）\n\n## Worker 操作规范\n\n### ssh-env-setup\n\n# 远程服务器环境搭建规范\n\n## 核心原则\n\n**先探测，再安装。** 不要假设服务器上什么都没有——很多包已经装好了。安装前必须走 discovery 流程。\n\n**镜像快速路径**：连接服务器后，先用 `detect_image` 检测是否为预置镜像。如果是已知镜像且版本匹配，跳过基础环境搭建（Phase 1-4），直接安装项目特有依赖。未检测到镜像时走传统流程。\n\n**aml-train 镜像使用 conda 环境**（不是 venv）。环境激活：`source /root/miniconda3/etc/profile.d/conda.sh && conda activate base`。pip/python 在 `/root/miniconda3/bin/` 下。**不要假设 .venv 存在，不要创建 venv。**\n\n## Phase 1: 环境探测（用 ssh_read_only）\n\n连接到服务器后，第一步永远是收集信息，不要直接装东西：\n\n```bash\n# 1. Python 环境\nwhich python3 && python3 --version\npip3 --version 2>/dev/null || echo \"NO_PIP\"\n\n# 2. CUDA 环境\nnvidia-smi --query-gpu=name,memory.total,driver_version --format=csv,noheader 2>/dev/null || echo \"NO_GPU\"\nnvcc --version 2>/dev/null | grep \"release\" || echo \"NO_NVCC\"\n\n# 3. 包管理器\nls -d /opt/miniconda3 ~/miniconda3 ~/.conda 2>/dev/null || echo \"NO_CONDA\"\nls -d .venv venv env 2>/dev/null || echo \"NO_VENV\"\npip3 list --format=freeze 2>/dev/null | grep -iE \"torch|transformers|flash\" || echo \"NO_ML_PKGS\"\n\n# 4. PEP 668 检查\npython3 -c \"import sysconfig; print(sysconfig.get_path('stdlib'))\" 2>/dev/null\nls /usr/lib/python*/EXTERNALLY-MANAGED 2>/dev/null && echo \"PEP668_MANAGED\" || echo \"PEP668_OK\"\n```\n\n根据探测结果决定安装策略，不要猜。\n\n## Phase 2: 环境策略选择\n\n根据 Phase 1 结果选择**一个**策略，不要混用：\n\n| 探测结果 | 策略 | 说明 |\n|----------|------|------|\n| 项目目录有 `.venv/` | 用它：`source .venv/bin/activate` | 最优先 |\n| 有 conda 且有写权限 | `conda activate base` 或创建专属 env | 次优先 |\n| PEP668_MANAGED + 无 venv | 创建 venv：`python3 -m venv .venv && source .venv/bin/activate` | 不要用 --break-system-packages |\n| PEP668_OK（无保护） | 直接 `pip install`（旧系统） | 仍建议 venv |\n\n**决不混用 conda install + pip install 到同一环境。** 选了 pip 就全用 pip。\n\n## Phase 3: PyTorch 安装\n\n### CUDA 版本映射（2025-2026 常用）\n\n先从 `nvcc --version` 或 `nvidia-smi` 获取 CUDA 版本，然后匹配：\n\n| CUDA 版本 | PyTorch pip index URL | 推荐 torch 版本 |\n|-----------|----------------------|-----------------|\n| 11.8 | `https://download.pytorch.org/whl/cu118` | ≥ 2.0 |\n| 12.1 | `https://download.pytorch.org/whl/cu121` | ≥ 2.1 |\n| 12.4 | `https://download.pytorch.org/whl/cu124` | ≥ 2.4 |\n| 12.6 | `https://download.pytorch.org/whl/cu126` | ≥ 2.6 |\n\n**不要猜版本号。** 如果不确定可用版本：\n```bash\npip index versions torch --index-url https://download.pytorch.org/whl/cu121 2>/dev/null | head -3\n```\n\n安装命令：\n```bash\npip install torch torchvision torchaudio --index-url https://download.pytorch.org/whl/cu{CUDA_SHORT}\n```\n\n### 大包超时处理\n\nPyTorch wheel 约 500MB-2GB，默认 SSH 超时可能不够。策略：\n\n```bash\n# 方法 1: nohup + 轮询（推荐）\nnohup pip install torch torchvision torchaudio --index-url https://download.pytorch.org/whl/cu121 > /tmp/pip_install.log 2>&1 &\necho $!  # 记录 PID\n\n# 后续用 ssh_read_only 轮询\ncat /tmp/pip_install.log | tail -5\nps -p &lt;PID> -o pid= 2>/dev/null && echo \"STILL_RUNNING\" || echo \"DONE\"\n```\n\n```bash\n# 方法 2: 加大 pip 超时\npip install --timeout 300 torch ...\n```\n\n## Phase 4: 验证（必须执行）\n\n安装后必须验证，不要假设成功：\n\n```bash\npython3 -c \"\nimport torch\nprint(f'torch={torch.__version__}, cuda={torch.cuda.is_available()}, gpus={torch.cuda.device_count()}')\nif torch.cuda.is_available():\n    for i in range(torch.cuda.device_count()):\n        print(f'  GPU {i}: {torch.cuda.get_device_name(i)} ({torch.cuda.get_device_properties(i).total_mem // 1024**3}GB)')\n\"\n```\n\n验证失败的常见原因：\n- `torch.cuda.is_available()` 返回 False → CUDA 版本和 torch 不匹配，重装正确版本\n- `ImportError: libcudnn` → 缺 cuDNN，装 `nvidia-cudnn-cu1x`\n- GPU 数量不对 → 检查 `CUDA_VISIBLE_DEVICES` 环境变量\n\n## Phase 5: 项目依赖\n\n基础环境就绪后，安装项目依赖：\n\n```bash\n# 优先用 requirements.txt / pyproject.toml\npip install -r requirements.txt  # 或 pip install -e .\n\n# 常用 ML 依赖补装\npip install transformers datasets einops accelerate wandb\n```\n\nflash-attention 特殊处理（编译型包）：\n```bash\n# 需要匹配的 CUDA toolkit，编译耗时 5-15 分钟\npip install flash-attn --no-build-isolation\n# 如果编译失败，试预编译版本\npip install flash-attn --no-build-isolation 2>/dev/null || pip install flash-attn-wheels\n```\n\n## ssh_read_only vs ssh_execute 使用规则\n\n| 操作 | 用哪个工具 |\n|------|-----------|\n| 检查环境（python --version, nvidia-smi, pip list） | `ssh_read_only` |\n| 读文件内容、查日志 | `ssh_read_only` |\n| 安装包（pip install, conda install） | `ssh_execute` |\n| 创建/修改文件、启动进程 | `ssh_execute` |\n| 运行实验脚本 | `ssh_execute` |\n\n**原则：能用 read_only 就用 read_only，只有要改变服务器状态时才用 execute。**\n\n## AutoDL 专项注意事项\n\nAutoDL 实例有一系列特殊约束，5 个项目反复踩坑，必须遵守：\n\n### 磁盘\n- **根分区只有 ~30GB，严禁存大文件。** 模型、数据集、HF cache 全部放数据盘 `/root/autodl-tmp/`\n- 设置 `HF_HOME=/root/autodl-tmp/.hf_cache`，否则 HF 默认缓存到根分区导致磁盘满\n- 下载模型时用 `--local-dir /root/autodl-tmp/models/&lt;name>`，不要用默认路径\n\n### 网络\n- pip install / git clone 前必须 `source /etc/network_turbo` 启用代理加速，否则 pypi.nvidia.com 504 超时、GitHub TLS 断连\n- HF 下载设 `HF_HUB_DISABLE_XET=1`，xet_get 在 AutoDL 上返回 401\n- **SSL 证书**：`network_turbo` 的代理使用自签名证书，Python 默认 SSL 验证会失败。必须设置 `REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt` 和 `SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt`，否则 HF 下载、datasets 加载等全部报 SSL 错误\n- **大模型下载优先用 ModelScope**：AutoDL 代理下载 HuggingFace 大文件极慢（~200KB/s），改用 ModelScope 国内 CDN 速度快很多。`pip install modelscope && python -c \"from modelscope import snapshot_download; snapshot_download('Qwen/Qwen2.5-7B-Instruct', cache_dir='/root/autodl-tmp/.hf_cache')\"`\n\n### SSH\n- **AutoDL 实例重启后 SSH 端口会变。** 连接失败时不要反复重试，应提示用户去控制台查新端口并更新 `~/.ssh/config`\n\n## 经验沉淀\n\n- [2026-04-05] Worker 首次连接服务器时，先用一条 ssh_read_only 组合命令完成全部探测，减少 SSH 往返次数\n- [2026-04-05] 遇到 PEP 668 时创建 venv 而非 --break-system-packages，避免污染系统 Python\n- [2026-04-05] PyTorch 大包安装用 nohup 后台执行 + 轮询方式，避免 SSH 超时导致安装中断\n- [2026-04-05] conda 环境和 pip 不要混用——如果项目用 pip，就全部用 pip\n- [2026-04-09] sync_code 前确保本地 commit 已 push 到 remote，否则服务器 git pull 拉不到最新代码\n- [2026-04-09] venv 创建后用 `which python` 验证路径指向正确的 venv python，不要假设系统 PATH 正确\n\n## 更多 Skills（按需加载）\n\n执行相关任务前，先 Read 对应 skill 获取环境配置和最佳实践。\n\n- **check-training-status** — 当用户问训练进度/实验状态/查状态时使用。用专用工具查看训练状态，禁止 ssh_execute。  →  `/home/ubuntu/agent-ml-research/skills/global/check-training-status.skill.md`\n- **rebuttal** — 撰写和优化学术 rebuttal——逐条回应审稿意见，生成 response letter。当收到审稿意见、需要写 rebuttal、回复 reviewer 评论时使用。关键词：rebuttal、审稿意见、reviewer response、author response、meta-review、AC 意见。  →  `/home/ubuntu/agent-ml-research/skills/global/rebuttal.skill.md`\n- **review-reviewer-session-start** — Review Reviewer session 启动初始化——检查论文格式、编译状态、材料清单。Review Reviewer 角色 session 启动时自动使用。  →  `/home/ubuntu/agent-ml-research/skills/global/review-reviewer-session-start.skill.md`\n- **reference-audit** — 引用验证与审计——检查 bib 条目完整性、引用真实性、格式一致性。写论文、审查论文、提交前检查引用时使用。关键词：citation verification、引用检查、bib 审计、fake citation、引用格式。  →  `/home/ubuntu/agent-ml-research/skills/global/reference-audit.skill.md`\n- **accelerate-distributed** — HuggingFace Accelerate 分布式训练指南——4行代码实现多GPU/DeepSpeed/FSDP/混合精度。多GPU训练时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/accelerate-distributed.skill.md`\n- **draw-paper-figure** — 生成学术论文级 matplotlib 图表——reliability diagrams、ECE heatmap、T* scatter plot、模型对比图，直接在 A6000 服务器上执行，输出 PDF/PNG  →  `/home/ubuntu/agent-ml-research/skills/global/draw-paper-figure.skill.md`\n- **experiment-analysis** — 实验结果分析框架——统计显著性检验、消融分析、baseline 对比、可视化建议。分析实验结果或撰写论文 Results 部分时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/experiment-analysis.skill.md`\n- **hf-hub** — HuggingFace Hub CLI (hf) — 下载/上传模型和数据集、管理缓存、搜索论文和模型。涉及 HuggingFace 资源操作时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/hf-hub.skill.md`\n- **latex-paper** — ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md`\n- **lm-eval-harness** — lm-evaluation-harness 模型评估指南——MMLU/GSM8K/HumanEval 等 60+ 学术基准测试。评估模型质量、对比实验时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/lm-eval-harness.skill.md`\n- **ml-experiment-guide** — 跨项目 ML 实验避坑指南——从多个项目沉淀的通用踩坑经验与最佳实践。当 Worker 准备写实验代码、或排查实验问题时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/ml-experiment-guide.skill.md`\n- **paper-banana** — 用 PaperBanana 生成发表级学术统计图——LLM 写 matplotlib 代码 + Critic 迭代 3 轮，输入 CSV/JSON 数据 + 意图描述即可。需要 GOOGLE_API_KEY。  →  `/home/ubuntu/agent-ml-research/skills/global/paper-banana.skill.md`\n- **paper-image-extractor** — 从论文 PDF 或 arXiv 源码包提取图表——优先 arXiv 原始图片，回退 PDF 解析。用户说\"提取图\"/\"抽图\"/\"extract figures\"时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/paper-image-extractor.skill.md`\n- **peft-lora** — PEFT/LoRA/QLoRA 参数高效微调指南——LoRA 配置选择、QLoRA 量化训练、Adapter 管理与合并。微调大模型时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/peft-lora.skill.md`\n- **research-news** — 每日论文推荐——搜索 arXiv 最新论文，按相关性/新颖性/影响力评分，生成推荐列表。Director 说\"有什么新论文\"/\"最近进展\"/\"research news\"时使用。  →  `/home/ubuntu/agent-ml-research/skills/global/research-news.skill.md`\n- **trl-training** — TRL (Transformer Reinforcement Learning) 训练指南——SFT/DPO/GRPO/KTO 配置与最佳实践。训练或对齐语言模型时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/trl-training.skill.md`\n- **wandb-guide** — W&B 查询最佳实践——如何高效使用 fetch_wandb_metrics / compare_wandb_runs / get_best_wandb_run 分析实验结果。分析实验指标时参考。  →  `/home/ubuntu/agent-ml-research/skills/global/wandb-guide.skill.md`\n",
      "contentDiffersFromDisk": false
    },
    "displayPath": "projects/phase-gated-compound-sparse/.claude/CLAUDE.md"
  },
  "type": "attachment",
  "uuid": "b0138e56-d1aa-484f-86b1-69d9086ee3db",
  "timestamp": "2026-05-14T14:38:24.262Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

---

### Runtime record

_source line 16_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：C5 pilot 通过 gate（LLaMA 复现 phase gradient + crossover），n=500 收紧 Qwen s015 CI 至零以上，所有 claims 原样成立 核心假设：['C5 LLaMA-8B s025/s030 pilot 回收 >30% compound degrada…",
  "leafUuid": "b0138e56-d1aa-484f-86b1-69d9086ee3db",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

### Runtime record

_source line 17_

```json
{
  "type": "ai-title",
  "aiTitle": "Phase-gated compound sparsity architecture generalization",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

### Assistant

_source line 18 · 2026-05-14T14:39:43.465Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have the full experiment plan. Let me identify all experiments that need predictions under the "best" tier. The plans are:

1. **plan_001**: DeepSeek importance bf16 × 4 sparsity — already DONE (bf16_importance_s015/s020/s025/s030 and bf16_ds_imp_s015/s020/s025/s030)
2. **plan_002**: DeepSeek random bf16 × 4 sparsity — already DONE (bf16_ds_rand_s015/s020/s025/s030)


3. **plan_003**: Crossover analysis — pure analysis, already confirmed
4. **plan_004**: Qwen importance bf16 × 4 sparsity — already DONE (bf16_qw_imp_s015/s020/s025/s030)
5. **plan_005**: Qwen random bf16 × 4 sparsity — already DONE (bf16_qw_rand_s015/s020/s025/s030)
6. **plan_006**: Attention entropy measurement — already DONE (c4_entropy, qwen_c4_entropy)
7. **plan_007**: Growth rate analysis — pure analysis
8. **plan_008**: Per-problem bootstrap CI — already done as part of the bf16 experiments
9. **plan_009**: LLaMA-8B pilot — PREPARING (c3_llama)
10. **plan_010**: n=500 statistical power — RUNNING (c2_n500_deepseek, c2_qw_n500)
11. **plan_011**: Abstract writing — no experiment
12. **plan_012**: II vs super-additivity distinction — no experiment

Now I'm checking the user's request about expanding detailed data for each planned experiment in the plan. Looking at the registry, many of these are already completed, but I need to verify the status field to identify which ones are actually still pending versus already done. The first one shows bf16_importance is complete in the registry.

Checking through the statuses: most of the "planned" experiments actually have results already recorded — bf16_ds_rand, bf16_qw_imp, bf16_qw_rand, c4_entropy experiments are all done. The user wants me to generate predicted results for the "best" tier, which assumes C5 pilot passes the gate with LLaMA re-

replication of phase gradient and crossover, plus n=500 tightens Qwen s015 CI above zero. I need to predict what the remaining experiments will show under this best-case scenario, focusing on the ones still running or pending like plan_009 (C5 LLaMA pilot), plan_010 (C2 n=500), and the analysis tasks that are derivable from existing data.

Actually, looking back at the request more carefully—it's asking for predicted data across all planned experiments in the registry, not just the ones currently running. Since many already have actual results, I should focus on the ones still pending or in progress: c2_n500_deepseek and c2_qw_n500 are running, and c3_llama is preparing.

For the YAML output, I need to forecast what the "best" tier would look like for each experiment. For plan_009 with the C5 LLaMA pilot, the best case would show LLaMA-8B achieving meaningful paired median differences in the 1.0-5.0 range with Cohen's d between 0.5-1.2, plus evidence of crossover effects and recovery patterns.

Plan_010 (C2 with n=500) in the best scenario would have Qwen s015's confidence interval lower bound exceeding zero, with median differences around 0.05-0.12 and DeepSeek showing at least 30% CI width reduction while maintaining stable point estimates around 0.28-0.38.

For the remaining plans—C3 crossover analysis, C6 sub-exponential, and statistical validation—those are already confirmed from existing data, while the writing task plans don't require experimental metrics. Now I need to check what the C4 expectations would be.

The C4 discrimination collapse on LLaMA should show consistent directional behavior in the Gini/CV metrics without requiring entropy alignment. With that confirmed, I'm ready to construct the comprehensive YAML output mapping each plan against the best tier predictions—most of the core plans (001-006) are already complete with actual data, and I can derive the remaining analyses from what's already been collected.

For the plans still in progress or pending, I'll generate detailed predicted metrics that align with the best tier definition. For plan_009 on the LLaMA pilot, I'm estimating the paired median difference around 2.8 with a Cohen's d near 0.75, and checking whether the crossover effect is present in the predictions.

The recovery percentage should exceed the 30% threshold at roughly 45%, with s030 showing a stronger effect than s025. Since LLaMA-8B uses the same distillation approach as the Qwen variant but on a different architecture, the phase-strategy interaction mechanism—driven by attention head pruning and importance score distribution collapse—should produce similar directional effects across architectures, though the magnitude will likely fall somewhere between what we've already observed.

For the n=500 sample in plan_010, I'm expecting the confidence interval for Qwen s015 to tighten substantially, shrinking by roughly 3.3 times from its current width. The new interval should land around [0.01, 0.08] with a median difference near 0.05-0.06, and DeepSeek should see at least a 30% reduction in CI width while maintaining stable point estimates.

Now I need to write out the full YAML configuration, focusing on the experiment plans that still show "planned" status.  Looking at the registry, I can see which plans have actual data already collected versus which ones need synthetic predictions. The critical ones requiring predictions are plan_009 and plan_010, while the others that are complete should report the best interpretation of their existing data. The user's request seems to be asking for detailed data across all planned experiments, so I should generate predictions for everything systematically. So the LLaMA pilot needs to include C4 discrimination collapse measurements alongside the other components. Now I'm structuring the full YAML output with predictions for all experiments — the completed ones will use actual results as predictions, while the running and planned ones will reflect what the best tier expects to find. I'm looking at the performance metrics for the DeepSeek importance masking experiment across all sparsity levels, and the results show a clear monotonic increase in effect sizes as sparsity increases—from a median difference of 0.32 at 15% sparsity up to 9.94 at 30% sparsity, with Cohen's d values ranging from medium to large effect sizes, and all four sparsity levels achieving statistical significance with p<0.0001 across 49 paired samples.

Now I'm confirming that the phase-modulated severity pattern holds consistently across the DeepSeek model as well, and I'm ready to consolidate all 12 experimental plans into a complete YAML structure, keeping the rationales concise while capturing the key findings and predictions for each experiment.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b0138e56-d1aa-484f-86b1-69d9086ee3db",
  "isSidechain": false,
  "requestId": "req_011Cb2dczszkqhce9qBsMebZ",
  "type": "assistant",
  "uuid": "7de3591b-f531-4f9d-a022-23300f12710b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BLPdtaXFQy35TeQQXDs5WM",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7874,
      "cache_read_input_tokens": 41472,
      "output_tokens": 12931,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7874,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 12931,
          "cache_read_input_tokens": 41472,
          "cache_creation_input_tokens": 7874,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7874
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

_source line 19 · 2026-05-14T14:42:30.690Z_

Now I have the full experiment plan. Let me cross-reference the registry data for running/planned experiments to construct the best-tier predictions.

```yaml
tier: best
narrative_guidance: >
  原始 framing 完全成立：emergent phase-strategy interaction 跨三个架构族泛化。
  Title 升级为 "generalizes across architectures"。C1-C6 全部 confirmed，C7/C8 写作完成。
  三大贡献不变：(1) 发现 + 跨架构验证 (Qwen2 + LLaMA)，(2) 量化 gradient + crossover，
  (3) discrimination collapse 机制。Limitations 缩至 scale (7B-8B) 和 single benchmark。
  RC1 通过 LLaMA-8B 第三架构直接回应；RC5 通过 crossover 跨架构复现强化。
  n=500 消除 Qwen s015 边缘性，所有 CI 下界 > 0，无需预注册叙事降级。

imagined_experiments:
  # ============================================================
  # plan_001: DeepSeek importance bf16 (DONE — 报告实际数据)
  # ============================================================
  - name: "DeepSeek importance bf16 × 4 sparsity"
    plan_id: "plan_001"
    description: "bf16 重跑 DeepSeek importance masking s015/s020/s025/s030，消除 fp16 NaN 偏差"
    expected_results:
      s015_median_diff: 0.3236
      s015_cohens_d: 0.6068
      s015_ci_95: [0.1988, 0.4716]
      s020_median_diff: 1.1520
      s020_cohens_d: 0.7250
      s020_ci_95: [0.6555, 1.2560]
      s025_median_diff: 3.9686
      s025_cohens_d: 0.9534
      s025_ci_95: [2.8290, 5.2918]
      s030_median_diff: 9.9436
      s030_cohens_d: 1.1263
      s030_ci_95: [8.3916, 16.6529]
      all_permutation_p: "<0.0001"
      n_paired: 49
      monotonic_gradient: true
    result_rationale: >
      已完成实验。bf16 消除 fp16 NaN 偏差后 median_diff 单调递增 0.32→1.15→3.97→9.94，
      Cohen's d 从 medium (0.61) 到 large (1.13)。全 4 水平 Bonferroni 校正后 p<0.005。
      phase-modulated severity 在 DeepSeek 上完全确认，作为论文主数据表的 anchor。
    tables:
      - "Table 1: DeepSeek-R1-Distill-Qwen-7B paired median difference & Cohen's d across 4 sparsity levels"
    figures_description:
      - "Fig 2a: severity gradient 折线图 (median_diff vs sparsity)，含 95% CI shading"
    analysis: >
      增长因子 3.57×→3.45×→2.50×（递减）确认 C6 sub-exponential。
      CI 均不跨零，效应量从 medium 到 large，统计结论稳固。

  # ============================================================
  # plan_002: DeepSeek random bf16 (DONE)
  # ============================================================
  - name: "DeepSeek random bf16 × 4 sparsity"
    plan_id: "plan_002"
    description: "bf16 DeepSeek random masking s015/s020/s025/s030 作为 importance 配对对照"
    expected_results:
      s015_median_diff: 0.0095
      s015_permutation_p: 0.7657
      s015_verdict: FAIL
      s020_median_diff: -0.0155
      s020_permutation_p: 0.352
      s020_verdict: FAIL
      s025_median_diff: 0.5445
      s025_permutation_p: 0.1679
      s025_verdict: FAIL
      s030_median_diff: 1.5383
      s030_permutation_p: 0.012
      s030_cohens_d: -0.035
      s030_verdict: FAIL
      overall_gradient: "flat (7/8 phase-level FAIL)"
    result_rationale: >
      已完成实验。Random masking 在 4 个 sparsity 水平中 7/8 phase-level 对比 FAIL（p>0.05 或 d≈0）。
      唯一例外 s030 permutation p=0.012 但 Cohen's d=-0.035 效应量可忽略。
      与 importance 的单调递增形成鲜明对比——phase gradient 是 strategy-dependent 现象，
      非 sparsity 本身的固有属性。这直接支撑 C1 的 strategy-dependent claim。
    tables:
      - "Table 1 (续): random masking 列，与 importance 并列对比"
    figures_description:
      - "Fig 2b: random masking severity gradient 折线图，平坦 vs importance 单调递增"
    analysis: >
      s030 的微弱统计显著性(p=0.012)在 d=-0.035 下无实质意义，
      论文报告时强调 effect size 而非 p-value 避免误导。

  # ============================================================
  # plan_003: Crossover analysis (DONE — 纯分析)
  # ============================================================
  - name: "Phase-strategy crossover analysis"
    plan_id: "plan_003"
    description: "从 bf16 importance vs random 数据提取 per-phase II，验证方向反转 (C3)"
    expected_results:
      crossover_sparsity: "s025"
      importance_high_phase_ii_s025: 0.0324
      importance_low_phase_ii_s025: 7.1960
      random_high_phase_ii_s025: 0.8182
      random_low_phase_ii_s025: 1.3627
      crossover_present: true
      crossover_direction: "importance low > random low; importance high < random high"
    result_rationale: >
      已从 plan_001/002 数据直接派生。在 s025 处 crossover 清晰可见：
      importance 的 low-sparsity phase II (7.20) 远大于 random (1.36)，
      而 importance 的 high-sparsity phase II (0.032) 远小于 random (0.818)。
      同一 strategy 在不同 phase 方向反转，这是本文最独特的发现——
      prior work 未报告过 compound × phase × strategy 三维交互中的 crossover。
    tables:
      - "Table 2: per-phase II comparison at s025 crossover point"
    figures_description:
      - "Fig 3: crossover 交叉图 (importance vs random per-phase II)"
    analysis: >
      Crossover 为论文提供最强 novelty signal。在 best tier 下 LLaMA 复现同一现象，
      将 crossover 升级为跨架构普遍现象。

  # ============================================================
  # plan_004: Qwen importance bf16 (DONE)
  # ============================================================
  - name: "Qwen importance bf16 × 4 sparsity"
    plan_id: "plan_004"
    description: "Qwen2.5-7B-Instruct importance masking bf16 s015/s020/s025/s030"
    expected_results:
      s015_median_diff: 0.0476
      s015_cohens_d: 0.3705
      s015_ci_95: [-0.0051, 0.1095]
      s015_ci_crosses_zero: true
      s020_median_diff: 0.2075
      s020_cohens_d: 0.7224
      s020_ci_95: [0.0672, 0.4023]
      s025_median_diff: 1.1087
      s025_cohens_d: 1.2329
      s025_ci_95: [0.6092, 1.4690]
      s030_median_diff: 2.6194
      s030_cohens_d: 1.4394
      s030_ci_95: [1.7223, 3.6511]
      n_paired: 46
      monotonic_gradient: true
      magnitude_vs_deepseek: "~1/4"
    result_rationale: >
      已完成实验。Qwen 同样呈单调递增 0.048→0.208→1.109→2.619，
      magnitude 约为 DeepSeek 的 1/4（consistent with instruction tuning vs distillation 差异）。
      Cohen's d 从 small (0.37) 到 very large (1.44)。
      唯一边缘点：s015 CI 下界 -0.005 跨零。这是 n=500 实验 (plan_010) 的核心目标。
    tables:
      - "Table 1 (续): Qwen importance 行"
    figures_description:
      - "Fig 2c: Qwen severity gradient 折线图，与 DeepSeek 同一坐标系但 y 轴缩放"
    analysis: >
      Cross-model replication 方向一致但 magnitude 差异大——
      论文解释为训练方式差异（distillation 继承了 R1 的 reasoning pattern 强化了 phase 差异）。
      s015 边缘性在 best tier 下由 n=500 解决。

  # ============================================================
  # plan_005: Qwen random bf16 (DONE)
  # ============================================================
  - name: "Qwen random bf16 × 4 sparsity"
    plan_id: "plan_005"
    description: "Qwen2.5-7B-Instruct random masking bf16 s015/s020/s025/s030"
    expected_results:
      s015_median_diff: -0.0294
      s015_cohens_d: -0.0507
      s015_verdict: FAIL
      s020_median_diff: 0.1290
      s020_cohens_d: 0.247
      s020_verdict: FAIL
      s025_median_diff: 1.1441
      s025_cohens_d: 0.1574
      s025_verdict: FAIL
      s030_median_diff: 2.4183
      s030_permutation_p: 0.012
      s030_cohens_d: -0.035
      s030_verdict: "PASS but negligible effect"
    result_rationale: >
      已完成实验。Qwen random 与 DeepSeek random 一致：gradient 平坦，
      7/8 phase-level FAIL。Qwen s030 与 DeepSeek s030 均为唯一 PASS 但 d≈0。
      跨模型 random masking 行为一致性进一步强化 C1 claim——
      phase gradient 是 importance strategy 的独有属性。
    tables:
      - "Table 1 (续): Qwen random 行"
    figures_description:
      - "Fig 2d: Qwen random gradient (flat) vs importance (monotonic)"
    analysis: >
      Qwen s030 random 的 p=0.012 需在论文中谨慎处理。
      报告 effect size d=-0.035 而非强调 p-value，避免被审稿人抓住。

  # ============================================================
  # plan_006: C4 entropy-discrimination collapse (DONE)
  # ============================================================
  - name: "Attention entropy & discrimination collapse measurement"
    plan_id: "plan_006"
    description: "DeepSeek + Qwen pruned vs unpruned attention entropy + importance Gini/CV"
    expected_results:
      deepseek_gini_delta: [-0.0301, -0.0404, -0.0647, -0.0806]
      deepseek_cv_delta: [-0.564, -0.774, -1.287, -1.665]
      deepseek_entropy_delta: [-0.0402, -0.0472, -0.0446, -0.0436]
      qwen_gini_delta: [-0.0103, -0.0121, -0.0100, -0.0202]
      qwen_cv_delta: [-0.045, -0.208, -1.491, -1.142]
      qwen_entropy_delta_inconsistent: true
      qwen_entropy_s025_reversed: 0.0451
      gini_cv_cross_model_consistent: true
      entropy_cross_model_consistent: false
    result_rationale: >
      已完成 (c4_entropy + qwen_c4_entropy，各 30 problems)。
      Gini/CV 下降跨模型方向一致：pruning 后 importance score 判别力崩塌，
      importance eviction 退化为有偏伪随机——这是 primary mechanism。
      Entropy redistribution 在 DeepSeek 一致（全 4 水平负 delta）
      但 Qwen s025 反转 (+0.045)、s030 近零——model-dependent secondary effect。
      论文以 discrimination collapse 为主线，entropy 仅作 DeepSeek-specific 补充。
    tables:
      - "Table 3: Gini/CV/entropy deltas across models and sparsity levels"
    figures_description:
      - "Fig 5: Gini coefficient before/after pruning (DeepSeek + Qwen)"
    analysis: >
      Gini/CV 跨模型一致性是 best tier 的关键——
      证明 mechanism 在 architecture level 是 universal 的，
      即使 entropy response 因模型而异。

  # ============================================================
  # plan_007: C6 sub-exponential growth (纯分析)
  # ============================================================
  - name: "Sub-exponential growth rate analysis"
    plan_id: "plan_007"
    description: "从 bf16 importance 4 sparsity median_diff 分析增长率递减模式"
    expected_results:
      growth_factors: [3.57, 3.45, 2.50]
      growth_factor_sequence: "s015→s020: 3.57×, s020→s025: 3.45×, s025→s030: 2.50×"
      growth_decreasing: true
      sub_exponential_confirmed: true
    result_rationale: >
      从 plan_001 实际数据直接计算：1.152/0.324=3.57, 3.969/1.152=3.45, 9.944/3.969=2.50。
      增长因子单调递减 3.57→3.45→2.50 确认 sub-exponential。
      这意味着 severity 不会在更高 sparsity 处无界爆炸——
      对部署场景的实际意义是：存在一个 practical ceiling。
    tables: []
    figures_description:
      - "Fig 2 inset: growth factor 柱状图 showing deceleration"
    analysis: >
      Sub-exponential 是 C6 claim 的全部支撑。
      增长因子递减从 3.57 到 2.50 说明曲线在弯向 plateau 而非指数爆炸。

  # ============================================================
  # plan_008: Statistical validation bootstrap CI (DONE)
  # ============================================================
  - name: "Per-problem bootstrap CI (bf16)"
    plan_id: "plan_008"
    description: "bf16 数据 B=10000 bootstrap CI + permutation test + Cohen's d"
    expected_results:
      deepseek_all_p_below_bonferroni: true
      deepseek_bonferroni_threshold: 0.005
      qwen_s020_s025_s030_p_below_bonferroni: true
      qwen_s015_p: 0.0001
      qwen_s015_ci_crosses_zero: true
      all_cohens_d_positive: true
    result_rationale: >
      已完成。DeepSeek 4 水平 + Qwen s020/s025/s030 全部 Bonferroni p<0.005。
      Qwen s015 permutation p=0.0001 显著但 bootstrap CI [-0.005, 0.110] 跨零，
      这是 n=46 的 power limitation。best tier 下 plan_010 (n=500) 解决此边缘性。
    tables:
      - "Table 1 footnote: statistical test details"
    figures_description:
      - "Appendix Fig: per-problem II distribution violin plots"
    analysis: >
      统计框架充分回应 RC4：paired design + permutation test + bootstrap CI + Cohen's d
      四重验证。唯一弱点 Qwen s015 由 n=500 补强。

  # ============================================================
  # plan_009: C5 LLaMA-8B pilot (PREPARING — 核心预测)
  # ============================================================
  - name: "LLaMA-8B pilot: oracle + heuristic phase-gated recovery"
    plan_id: "plan_009"
    description: >
      DeepSeek-R1-Distill-Llama-8B 上 s025/s030 的 oracle phase gate + heuristic baseline。
      Gate: recover >30% compound degradation → full rollout; else → future work。
    expected_results:
      # --- Oracle phase gate results ---
      llama_oracle_s025_paired_median_diff: 2.8
      llama_oracle_s025_cohens_d: 0.78
      llama_oracle_s025_ci_95: [1.4, 4.6]
      llama_oracle_s025_permutation_p: "<0.0001"
      llama_oracle_s030_paired_median_diff: 6.5
      llama_oracle_s030_cohens_d: 0.92
      llama_oracle_s030_ci_95: [4.1, 10.2]
      llama_oracle_s030_permutation_p: "<0.0001"
      # --- Crossover replication ---
      llama_crossover_s025_present: true
      llama_importance_high_phase_ii_s025: 0.045
      llama_importance_low_phase_ii_s025: 5.8
      llama_random_high_phase_ii_s025: 0.72
      llama_random_low_phase_ii_s025: 1.15
      # --- Recovery gate ---
      llama_compound_degradation_s025_baseline_ppl: 3.8
      llama_oracle_gated_ppl_s025: 2.2
      llama_recovery_pct_s025: 42
      llama_compound_degradation_s030_baseline_ppl: 12.5
      llama_oracle_gated_ppl_s030: 6.8
      llama_recovery_pct_s030: 46
      gate_passed: true
      # --- Heuristic baseline (token position ratio) ---
      heuristic_recovery_pct_s025: 28
      heuristic_recovery_pct_s030: 33
      heuristic_vs_oracle_gap: "oracle 上界 42-46%, heuristic 下界 28-33%"
      # --- C4 discrimination collapse on LLaMA ---
      llama_gini_delta_s025: -0.038
      llama_gini_delta_s030: -0.055
      llama_cv_delta_s025: -0.92
      llama_cv_delta_s030: -1.35
      gini_cv_direction_consistent_with_deepseek_qwen: true
      # --- Architecture count ---
      confirmed_arch_families: 3
    result_rationale: >
      LLaMA-8B 是 DeepSeek-R1-Distill-Llama-8B——与 DeepSeek-R1-Distill-Qwen-7B 使用
      相同的 R1 distillation pipeline 但基于完全不同的 backbone 架构（LLaMA 3.1 vs Qwen2）。
      Best tier 预测依据：
      (1) Phase gradient: distillation 训练赋予强 reasoning phase 结构（与 DeepSeek-R1-Distill-Qwen 一致），
      LLaMA 的 GQA（Grouped Query Attention）结构下 head pruning 对 importance score distribution
      的影响应与 MHA/GQA 变体方向一致——pruning 后 Gini/CV 下降，importance eviction 判别力崩塌。
      预测 s025 median_diff=2.8 介于 DeepSeek (3.97) 和 Qwen (1.11) 之间，因为 LLaMA 架构的
      attention head 数量和 KV head 共享模式（GQA 8 KV heads）不同于 Qwen2 的完整 MHA，
      pruning 效果的 magnitude 预期居中。
      (2) Crossover: 同一 discrimination collapse mechanism 驱动，方向应一致。
      LLaMA 的 RoPE 实现与 Qwen 不同但不影响 importance score 的 distributional collapse，
      因此 crossover（importance low > random low; importance high < random high）应复现。
      (3) Recovery >30%: oracle gate 已知 exact phase boundary，42-46% recovery
      基于 DeepSeek/Qwen 观察到的 phase-conditioned II 差异比例外推。
      Heuristic（token position ratio）略低于 oracle 因为 heuristic 的 phase 边界估计有噪声，
      但 s030 仍 >30% 通过 gate。
      (4) C4 Gini/CV 方向一致：discrimination collapse 是统计现象（pruning reduces score spread），
      与具体 attention implementation 无关，只要有 importance-based eviction 就会发生。
    tables:
      - "Table 4: LLaMA-8B pilot results — oracle vs heuristic recovery"
      - "Table 5: Cross-architecture severity gradient comparison (DeepSeek / Qwen / LLaMA)"
    figures_description:
      - "Fig 6: 三架构 severity gradient overlay (DeepSeek/Qwen/LLaMA) 含 CI shading"
      - "Fig 7: LLaMA crossover 图 与 DeepSeek/Qwen crossover 并列"
      - "Fig 8: Oracle vs heuristic recovery bar chart"
    analysis: >
      LLaMA pilot 通过 gate 是 best tier 的 defining feature。
      三架构 gradient 方向一致（Qwen2 + LLaMA + DeepSeek-R1 distilled variants）
      直接回应 RC1 "how do we know this generalizes"。
      Crossover 跨架构复现强化 RC5 novelty claim。
      Heuristic baseline（即使 <30% at s025）提供 practical lower bound，
      论文可 claim "even simple heuristics capture partial benefit"。
      C4 Gini/CV 方向一致性使 discrimination collapse 升级为
      architecture-agnostic mechanism，而非 model-specific artifact。

  # ============================================================
  # plan_010: C2 n=500 statistical power boost (RUNNING — 核心预测)
  # ============================================================
  - name: "n=500 statistical power: DeepSeek + Qwen 8 conditions"
    plan_id: "plan_010"
    description: >
      扩展 DeepSeek/Qwen importance+random × 4 sparsity 到 n=500 (full MATH-500)。
      核心目标：收紧 Qwen s015 CI 至零以上，消除边缘性。
    expected_results:
      # --- Qwen importance n=500 ---
      qw_s015_n500_median_diff: 0.062
      qw_s015_n500_cohens_d: 0.38
      qw_s015_n500_ci_95: [0.018, 0.098]
      qw_s015_n500_ci_lower_above_zero: true
      qw_s015_n500_permutation_p: 0.0001
      qw_s020_n500_median_diff: 0.215
      qw_s020_n500_ci_95: [0.12, 0.33]
      qw_s025_n500_median_diff: 1.12
      qw_s025_n500_ci_95: [0.78, 1.42]
      qw_s030_n500_median_diff: 2.65
      qw_s030_n500_ci_95: [1.95, 3.45]
      # --- Qwen random n=500 ---
      qw_rand_s015_n500_median_diff: -0.018
      qw_rand_s015_n500_verdict: FAIL
      qw_rand_s020_n500_verdict: FAIL
      qw_rand_s025_n500_verdict: FAIL
      qw_rand_s030_n500_median_diff: 2.30
      qw_rand_s030_n500_cohens_d: -0.03
      qw_rand_s030_n500_verdict: "PASS but d≈0"
      # --- DeepSeek importance n=500 ---
      ds_s015_n500_median_diff: 0.33
      ds_s015_n500_ci_95: [0.24, 0.42]
      ds_s015_n500_ci_width: 0.18
      ds_s015_n50_ci_width: 0.273
      ds_s015_ci_width_reduction_pct: 34
      ds_s020_n500_median_diff: 1.16
      ds_s020_n500_ci_95: [0.88, 1.38]
      ds_s020_ci_width_reduction_pct: 37
      ds_s025_n500_median_diff: 4.02
      ds_s025_n500_ci_95: [3.18, 4.92]
      ds_s025_ci_width_reduction_pct: 41
      ds_s030_n500_median_diff: 9.98
      ds_s030_n500_ci_95: [8.55, 12.10]
      ds_s030_ci_width_reduction_pct: 43
      # --- DeepSeek random n=500 ---
      ds_rand_all_verdict: "FAIL (all 4 levels)"
      ds_rand_s030_n500_median_diff: 1.48
      ds_rand_s030_n500_cohens_d: -0.03
      # --- Summary ---
      qw_s015_marginal_resolved: true
      ds_point_estimates_stable: true
      ds_ci_width_reduction_range: [34, 43]
      narrative_downgrade_needed: false
    result_rationale: >
      n=500 (full MATH-500) 相比 n=46-49 提供 ~3.3× 有效样本量增长 (√(500/46)≈3.3)。
      (1) Qwen s015 CI 收紧：当前 n=46 的 CI [-0.005, 0.110] 宽度 0.115。
      n=500 下 CI 宽度缩至 ~0.115/3.3 ≈ 0.035，叠加 point estimate 上移（更多 problem 覆盖
      增加 low-sparsity phase 的统计 power），预测 CI [0.018, 0.098]，下界明确 > 0。
      Cohen's d 保持 ~0.38 不变（是效应量不依赖样本量）。
      (2) DeepSeek CI 宽度缩窄 34-43%：n=49→n=500 的 sqrt 缩窄因子约 3.2×。
      原 s015 CI 宽度 0.273，预测收至 0.18（reduction 34%）。
      高 sparsity 水平缩窄更多（43%），因为 effect size 大使得 bootstrap 分布更集中。
      Point estimate 稳定在 n=49 已有范围内（median_diff ±5% 波动，因 MATH-500 problem
      分布与前 50 题高度重叠）。
      (3) Random masking 结果不变：更多 problem 不会让平坦 gradient 变显著。
      Qwen s030 random 可能维持 p≈0.012 但 d 仍 ≈0。
      (4) 无需预注册叙事降级：Qwen s015 CI 下界 > 0 意味着
      "compound effect emerges at all measured sparsity levels"
      而非降级为 "emerges above threshold sparsity ~s020"。
    tables:
      - "Table 1 (updated): n=500 CI 替换 n=50 CI，所有水平"
      - "Appendix Table: n=50 vs n=500 CI width comparison"
    figures_description:
      - "Fig 4: CI shrinkage visualization (n=50 vs n=500 forest plot)"
    analysis: >
      n=500 的核心作用是消除 Qwen s015 边缘性。在 best tier 下这一目标达成，
      论文可 claim phase gradient 在 Qwen 的全部 4 个 sparsity 水平均显著（all CI > 0）。
      DeepSeek 的 CI 收紧提供更精确的 point estimate，增强审稿人对效应量稳定性的信心。
      无 narrative downgrade = 论文 framing 保持最强形式。

  # ============================================================
  # plan_011: C7 Abstract 精简 (写作任务)
  # ============================================================
  - name: "Abstract 精简至 150-200 词"
    plan_id: "plan_011"
    description: "当前 ~600 词 Abstract 精简至 150-200 词，保留关键定量结果"
    expected_results:
      word_count: 180
      key_numbers_retained: 2
      number_1: "paired median difference 0.32→9.94 (DeepSeek)"
      number_2: "Cohen's d 0.61→1.13"
      architecture_claim: "三架构泛化 (Qwen2, LLaMA, DeepSeek variants)"
    result_rationale: >
      Best tier 下 Abstract 包含三架构泛化 claim（因 C5 LLaMA pilot 通过 gate），
      保留 DeepSeek severity gradient 和 Cohen's d 作为核心定量 hook。
      180 词在 EMNLP 200 词上限内留有余量。精简策略：砍掉方法论细节和
      全部中间结果，只保留 "what we found" + "why it matters"。
    tables: []
    figures_description: []
    analysis: >
      写作任务无实验数据。Best tier 下 Abstract 可以更强——
      "generalizes across architectures" 比 "cross-model replication" 更有力。

  # ============================================================
  # plan_012: C8 II vs super-additivity 概念区分 (写作+分析)
  # ============================================================
  - name: "II vs super-additivity 概念区分"
    plan_id: "plan_012"
    description: "§3 加段讨论 II 与 SparK/SLiM/UniComp compound interaction 度量的区别"
    expected_results:
      section: "§3.2 Relationship to Prior Compound Interaction Measures"
      word_count: 300
      key_distinctions:
        - "II = standard factorial interaction effect (II = ppl_both - ppl_attn - ppl_kv + ppl_dense)"
        - "SparK: compound ratio = ppl_both / (ppl_attn × ppl_kv / ppl_dense), 假定 multiplicative baseline"
        - "SLiM/UniComp: aggregate accuracy drop, 不分解 interaction component"
        - "本文创新: phase-conditioned II 分析，揭示 interaction 的 heterogeneity"
      lethe_distinction: "Lethe 做 phase-aware eviction 但不分析 compound interaction; 我们分析 compound × phase 交互但不提出 eviction method"
      spark_distinction: "SparK 的 multiplicative assumption 在 high-sparsity phase 下失效——我们的 additive II 更 robust"
    result_rationale: >
      概念区分是回应 RC5 novelty concern 的必要条件。
      先验 compound sparsity 文献用不同度量（ratio vs drop vs interaction），
      均未做 phase-conditioned 分析。明确 II 是 standard factorial design
      中的 interaction term 消除 "你们发明了新指标" 的疑虑。
      Lethe 区分避免审稿人误以为我们与 Lethe 重叠——
      Lethe 是 method (phase-aware eviction)，我们是 finding (phase-modulated compound severity)。
    tables:
      - "Table in §3.2: side-by-side comparison of compound interaction measures"
    figures_description: []
    analysis: >
      写作+分析任务。Best tier 下这段文字更从容——
      有三架构验证在手，不需要过度解释度量选择的合理性，
      只需清晰定义和对比即可。
```

核心结论：best tier 的两个 deciding factor 是 plan_009（LLaMA pilot 通过 gate，median_diff ~2.8-6.5，crossover 复现，recovery >30%）和 plan_010（Qwen s015 n=500 CI [0.018, 0.098] 下界 > 0）。两者同时达成 → 论文以最强形式提交：三架构泛化 + 全 sparsity 水平显著 + 无 claim 降级。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7de3591b-f531-4f9d-a022-23300f12710b",
  "isSidechain": false,
  "requestId": "req_011Cb2dczszkqhce9qBsMebZ",
  "type": "assistant",
  "uuid": "1c42782a-d826-4f42-a43f-2f3b4eb9f8b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BLPdtaXFQy35TeQQXDs5WM",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7874,
      "cache_read_input_tokens": 41472,
      "output_tokens": 12931,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7874,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 12931,
          "cache_read_input_tokens": 41472,
          "cache_creation_input_tokens": 7874,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7874
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

_source line 20_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：C5 pilot 通过 gate（LLaMA 复现 phase gradient + crossover），n=500 收紧 Qwen s015 CI 至零以上，所有 claims 原样成立 核心假设：['C5 LLaMA-8B s025/s030 pilot 回收 >30% compound degrada…",
  "leafUuid": "1c42782a-d826-4f42-a43f-2f3b4eb9f8b3",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "Phase-gated compound sparsity architecture generalization",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

### Runtime record

_source line 22_

```json
{
  "type": "last-prompt",
  "lastPrompt": "你是一位经验丰富的 ML 研究者。Phase 1 已定义了 best 档的含义：  含义：C5 pilot 通过 gate（LLaMA 复现 phase gradient + crossover），n=500 收紧 Qwen s015 CI 至零以上，所有 claims 原样成立 核心假设：['C5 LLaMA-8B s025/s030 pilot 回收 >30% compound degrada…",
  "leafUuid": "1c42782a-d826-4f42-a43f-2f3b4eb9f8b3",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---

### Runtime record

_source line 23_

```json
{
  "type": "ai-title",
  "aiTitle": "Phase-gated compound sparsity architecture generalization",
  "sessionId": "7d537f6a-f0e0-42af-9900-a50ecab92c27"
}
```

---
