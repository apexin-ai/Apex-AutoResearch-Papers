# check paper pre submission audit 20260521T163758 retry2 — Part 2 of 3

**Knowing When Not to Correct: Adaptive Test-Time Refinement for Vision-Language-Action Models** · Worker execution logs

[← Part 1](part-001.md) · [Transcript overview](../check-paper-pre-submission-audit-20260521t163758-retry2.md) · [Part 3 →](part-003.md) · [Structured JSON](../../../sessions/1e/1eb5ecdb19664a139477.json)

## Before a recorded user message

### Large event (continued)

```text
rics\": {\"success_rate\": 0.14, \"n_episodes\": 100, \"per_task\": {\"KITCHEN_SCENE3_turn_on_stove_put_moka_pot\": 0.8, \"LIVING_ROOM_SCENE5_white_mug_left_yellow_right\": 0.3, \"STUDY_SCENE1_book_in_back_compartment\": 0.1, \"LIVING_ROOM_SCENE6_white_mug_pudding\": 0.1, \"KITCHEN_SCENE6_mug_in_microwave_close\": 0.1, \"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter\": 0, \"KITCHEN_SCENE4_black_bowl_in_drawer\": 0, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese\": 0, \"KITCHEN_SCENE8_both_moka_pots\": 0}}, \"completed_at\": \"2026-05-20T00:16:50.121Z\"}, \"eval-crm-long-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:24:13.996Z\", \"updated_at\": \"2026-05-20T00:13:08.430Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-Long seed46. OOD 泛化测试：CRM 仅在 Object+Spatial 训练，Long 是未见过的 suite。补齐 CRM-Long 第 5 个 seed。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark long --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_long_obs_only_norm02_seed46.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"160883\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-crm-long-seed46.log\", \"submitted_at\": \"2026-05-19T21:24:28.772Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Long (OOD)\", \"data_count\": \"100 (10 tasks x 10 rollouts)\", \"model_name\": \"CRM obs_only + SmolVLA\", \"seed\": 46, \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 10119.7, \"gpu_hours\": 2.81}, \"reproduce\": {\"finished_at\": \"2026-05-19T23:11:28.326Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T23:11:42.503998+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.18, \"n_episodes\": 100, \"per_task\": {\"KITCHEN_SCENE3_turn_on_stove_put_moka_pot\": 0.9, \"KITCHEN_SCENE6_mug_in_microwave_close\": 0.5, \"LIVING_ROOM_SCENE5_white_mug_left_yellow_right\": 0.2, \"STUDY_SCENE1_book_in_back_compartment\": 0.2, \"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter\": 0, \"KITCHEN_SCENE4_black_bowl_in_drawer\": 0, \"LIVING_ROOM_SCENE6_white_mug_pudding\": 0, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese\": 0, \"KITCHEN_SCENE8_both_moka_pots\": 0}}, \"completed_at\": \"2026-05-20T00:13:08.430Z\"}, \"eval-crm-goal-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:49:33.318Z\", \"updated_at\": \"2026-05-20T00:11:46.069Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-Goal seed45. OOD 泛化测试：CRM 仅在 Object+Spatial 训练，Goal 是未见过的 suite。重跑（前次 crash）。\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark goal --seed 45 --K 10 --max_correction_norm 0.2 --checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --n_rollouts 10\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:2\", \"pid\": \"24959\", \"data_path\": \"LIBERO-Goal\", \"data_count\": \"100 (10 tasks x 10 rollouts)\", \"model_name\": \"SmolVLA + CRM obs_only\", \"seed\": 45}, \"reproduce\": {\"finished_at\": \"2026-05-19T23:22:53.612Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T23:22:58.214Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T23:23:10.738919+00:00\"}]}, \"metrics\": {\"success_rate\": 0.65, \"n_episodes\": 100, \"per_task\": {\"turn_on_the_stove\": 1, \"put_the_bowl_on_the_plate\": 1, \"push_the_plate_to_the_front_of_the_stove\": 0.9, \"put_the_bowl_on_the_stove\": 0.9, \"put_the_bowl_on_top_of_the_cabinet\": 0.8, \"open_the_middle_drawer_of_the_cabinet\": 0.7, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.4, \"put_the_wine_bottle_on_the_rack\": 0.4, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.2, \"put_the_cream_cheese_in_the_bowl\": 0.2}}}, \"eval-crm-goal-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:49:31.838Z\", \"updated_at\": \"2026-05-20T00:11:07.345Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-Goal seed44. OOD 泛化测试：CRM 仅在 Object+Spatial 训练，Goal 是未见过的 suite。重跑（前次 crash）。\", \"parent\": \"eval-crm-goal-seed44\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark goal --seed 44 --K 10 --max_correction_norm 0.2 --checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --n_rollouts 10\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:0\", \"pid\": \"24694\", \"data_path\": \"LIBERO-Goal\", \"data_count\": \"100 (10 tasks x 10 rollouts)\", \"model_name\": \"SmolVLA + CRM obs_only\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Goal (10 tasks x 10 rollouts)\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T23:17:53.707Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T23:18:01.172Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T23:18:12.623102+00:00\"}]}, \"metrics\": {\"success_rate\": 0.64, \"n_episodes\": 100, \"per_task\": {\"turn_on_the_stove\": 1, \"put_the_bowl_on_the_plate\": 1, \"put_the_bowl_on_the_stove\": 0.9, \"push_the_plate_to_the_front_of_the_stove\": 0.8, \"put_the_bowl_on_top_of_the_cabinet\": 0.7, \"open_the_middle_drawer_of_the_cabinet\": 0.6, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.5, \"put_the_wine_bottle_on_the_rack\": 0.4, \"put_the_cream_cheese_in_the_bowl\": 0.3, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.2}}}, \"eval-obs-only-spatial-norm02-seed43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:06:58.021Z\", \"updated_at\": \"2026-05-19T23:20:20.286Z\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_seed43_r2.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"29960\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-spatial-norm02-seed43-r2.log\", \"submitted_at\": \"2026-05-19T18:06:57.251Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 18803.0, \"gpu_hours\": 5.22}, \"hypothesis\": \"obs_only CRM (ε=0.2, K=10) on LIBERO-Spatial seed43. 重跑：bjb2-40593 上 7/10 tasks 后进程终止无 JSON。补齐 Spatial K=10 n=5。\", \"parent\": \"eval-obs-only-spatial-norm02-seed43\", \"reproduce\": {\"finished_at\": \"2026-05-19T19:45:27.333Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T19:45:35.483915+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.34, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"between_plate_and_ramekin\": 0.9, \"next_to_ramekin\": 1, \"from_table_center\": 0, \"on_cookie_box\": 0.3, \"in_top_drawer\": 0, \"on_ramekin\": 0, \"next_to_cookie_box\": 1, \"on_stove\": 0, \"next_to_plate\": 0.2, \"on_wooden_cabinet\": 0}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-spatial-norm02-seed43-r2.log\", \"completed_at\": \"2026-05-19T23:20:20.286Z\"}, \"eval-openvla-object-baseline-seed42-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T23:07:05.761Z\", \"updated_at\": \"2026-05-19T23:07:36.717Z\", \"hypothesis\": \"OpenVLA-7B fine-tuned on LIBERO-Object baseline eval (seed42). 复现官方 88.4% SR，获取 per-task breakdown 与 SmolVLA 对比。如果 SR 符合预期，验证 CRM 路线的 base policy 基线可用性。重试：前次 timeout (6h不够，需~10h)。\", \"parent\": \"eval-openvla-object-baseline-seed42\", \"spec\": \"placeholder\"}, \"k2-l2-calibration-phase1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:32:52.408Z\", \"updated_at\": \"2026-05-19T22:38:04.117Z\", \"hypothesis\": \"K=2 L2 divergence (mean pairwise L2 from K=10 samples) as uncertainty proxy for Adaptive K. Measures action-space disagreement directly. Go/no-go: Spearman ρ(mean_pair_l2, k10_variance) > 0.3.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u src/calibrate_fmvd.py --benchmark object --n_episodes 5 --seed 42 --output logs/k2_l2_calibration.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO object benchmark (10 tasks x 5 episodes)\", \"data_count\": 50, \"model_name\": \"smolvla_libero\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-19T20:57:30.913Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T20:57:36.071Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T20:57:50.152755+00:00\"}]}, \"metrics\": {\"k2l2_vs_k10var_rho\": 0.9979, \"k2l2_vs_k10var_pvalue\": 0, \"k2l2_vs_fmvd_rho\": 0.0925, \"k2l2_vs_fmvd_pvalue\": 6.03e-29, \"k10var_vs_fmvd_rho\": 0.0825, \"k10var_vs_fmvd_pvalue\": 2.33e-23, \"n_samples\": 14512, \"k2l2_mean\": 0.0807, \"k2l2_std\": 0.0361, \"go_nogo_k2_proxy\": \"GO (rho=0.9979)\", \"go_nogo_fmvd_signal\": \"NO-GO (rho=0.09)\"}}, \"eval-crm-long-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:10:29.495Z\", \"updated_at\": \"2026-05-19T22:15:17.800Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-10 seed45. OOD 泛化测试：CRM 仅在 Object+Spatial 训练，LIBERO-10 是 OOD long-horizon 任务。补充 seed42/43/44 增加 n。\", \"spec\": {\"command\": \"python evaluate.py --benchmark long --mode crm_obs_only --seed 45 --K 10 --max_correction_norm 0.2 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Long\", \"data_count\": 100, \"model_name\": \"crm_obs_only_norm02_K10\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Long (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_crm_long_seed45.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T22:05:21.880Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T22:05:26.458Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T22:05:33.603900+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.18, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"total_successes\": 18}}, \"eval-vla-only-spatial-seed49-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T22:12:47.550Z\", \"updated_at\": \"2026-05-19T22:12:58.379Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode acr_vla --benchmark spatial --seed 49 --K 1 --n_rollouts 10 --output_file logs/eval_vla_only_spatial_seed49_r2.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:5\"], \"pid\": \"37308\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-spatial-seed49-r2.log\", \"submitted_at\": \"2026-05-19T22:12:46.685Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"VLA-only baseline on LIBERO-Spatial seed49. 补齐 Spatial VLA-only 样本量 (n→7)。重跑（前次进程死亡）。\"}, \"eval-vla-only-spatial-seed49\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:15:11.071Z\", \"updated_at\": \"2026-05-19T22:12:05.406Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Spatial seed49. 补齐 Spatial VLA-only 样本量 (n→7)，增强 baseline 统计可靠性。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode acr_vla --benchmark spatial --seed 49 --K 1 --n_rollouts 10 --output_file logs/eval_vla_only_spatial_seed49.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:5\"], \"pid\": \"21588\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-spatial-seed49.log\", \"submitted_at\": \"2026-05-19T21:40:46.664Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": \"100 (10 tasks x 10 rollouts)\", \"model_name\": \"SmolVLA\", \"seed\": 49, \"checkpoint_path\": \"N/A (process died)\", \"wall_clock_seconds\": 1878.7, \"gpu_hours\": 0.52}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T22:12:05.406Z\"}, \"eval-vla-only-goal-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:32:25.931Z\", \"updated_at\": \"2026-05-19T22:08:08.414Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Goal seed48. 补齐 Goal VLA-only 样本量 (n→7)，与 CRM-Goal 配对统计检验。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode acr_vla --benchmark goal --seed 48 --K 1 --n_rollouts 10 --output_file logs/eval_vla_only_goal_seed48.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"20720\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-19T21:40:40.338Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Goal\", \"data_count\": \"100 (10 tasks x 10 rollouts)\", \"model_name\": \"SmolVLA\", \"seed\": 48, \"checkpoint_path\": \"N/A (killed before completion)\", \"wall_clock_seconds\": 1648.1, \"gpu_hours\": 0.46}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T22:08:08.414Z\"}, \"eval-vla-only-goal-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:40:01.140Z\", \"updated_at\": \"2026-05-19T21:32:22.969Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Goal seed43. 补齐 Goal VLA-only 样本量 (n→7)，与 CRM-Goal 配对统计检验。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark goal --n_rollouts 10 --seed 43 --K 1 --output_file logs/eval_goal_vla_only_seed43.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"988708\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_goal_vla_only_seed43.json\", \"submitted_at\": \"2026-05-19T16:40:29.456Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Goal\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 43, \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 5016.1, \"gpu_hours\": 1.39}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.69, \"per_task\": {\"open_the_middle_drawer_of_the_cabinet\": 0.9, \"put_the_bowl_on_the_stove\": 0.9, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.4, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.5, \"put_the_bowl_on_top_of_the_cabinet\": 0.5, \"push_the_plate_to_the_front_of_the_stove\": 0.8, \"put_the_cream_cheese_in_the_bowl\": 0.4, \"turn_on_the_stove\": 0.9, \"put_the_bowl_on_the_plate\": 1, \"put_the_wine_bottle_on_the_rack\": 0.6}}, \"completed_at\": \"2026-05-19T18:04:05.564Z\"}, \"eval-vla-only-goal-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:39:58.936Z\", \"updated_at\": \"2026-05-19T21:32:21.219Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Goal seed42. 补齐 Goal VLA-only 样本量 (n→7)，与 CRM-Goal 配对统计检验。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark goal --n_rollouts 10 --seed 42 --K 1 --output_file logs/eval_goal_vla_only_seed42.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": \"988117\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_goal_vla_only_seed42.json\", \"submitted_at\": \"2026-05-19T16:40:26.140Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Goal\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 42, \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 5014.3, \"gpu_hours\": 1.39}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.71, \"per_task\": {\"open_the_middle_drawer_of_the_cabinet\": 0.9, \"put_the_bowl_on_the_stove\": 0.9, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.6, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.4, \"put_the_bowl_on_top_of_the_cabinet\": 0.7, \"push_the_plate_to_the_front_of_the_stove\": 0.9, \"put_the_cream_cheese_in_the_bowl\": 0.2, \"turn_on_the_stove\": 0.9, \"put_the_bowl_on_the_plate\": 0.9, \"put_the_wine_bottle_on_the_rack\": 0.7}}, \"completed_at\": \"2026-05-19T18:04:00.409Z\"}, \"eval-vla-only-object-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T19:10:43.834Z\", \"updated_at\": \"2026-05-19T21:32:10.689Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Object seed47. 补齐 Object VLA-only n=5，与 CRM K=10 配对统计检验。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark object --n_rollouts 10 --seed 47 --K 1 --output_file logs/eval_object_vla_only_seed47.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:0\"], \"pid\": \"959564\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-object-seed47.log\", \"submitted_at\": \"2026-05-19T19:09:57Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 47, \"checkpoint_source\": \"/root/autodl-tmp/models/smolvla_libero\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 8533.7, \"gpu_hours\": 2.37}, \"metrics\": {\"overall_success_rate\": 0.1, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"salad_dressing\": 0.2, \"bbq_sauce\": 0.2, \"milk\": 0.2, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.2, \"alphabet_soup\": 0, \"cream_cheese\": 0, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T21:32:10.689Z\"}, \"eval-crm-long-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T19:10:50.501Z\", \"updated_at\": \"2026-05-19T21:32:07.617Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-10 seed44. 跨 suite 泛化性测试：CRM 仅在 Object+Spatial 训练，LIBERO-10 是 OOD。Long baseline=12%，若 CRM 显著提升则证明泛化；若无效则定位 CRM 边界。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=5 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark long --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_long_obs_only_norm02_seed44.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:5\"], \"pid\": \"960107\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-crm-long-seed44.log\", \"submitted_at\": \"2026-05-19T19:10:00Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-10\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-10 (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 8527.6, \"gpu_hours\": 2.37}, \"metrics\": {\"overall_success_rate\": 0.2, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"KITCHEN_SCENE3_stove_moka_pot\": 0.8, \"KITCHEN_SCENE6_mug_microwave\": 0.6, \"LIVING_ROOM_SCENE5_mugs_plates\": 0.3, \"STUDY_SCENE1_book_caddy\": 0.2, \"LIVING_ROOM_SCENE6_mug_plate_pudding\": 0.1, \"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter\": 0, \"KITCHEN_SCENE4_black_bowl_drawer\": 0, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese\": 0, \"KITCHEN_SCENE8_both_moka_pots\": 0}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T21:32:07.617Z\"}, \"eval-crm-long-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T19:10:49.078Z\", \"updated_at\": \"2026-05-19T21:32:03.390Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-10 seed43. 跨 suite 泛化性测试：CRM 仅在 Object+Spatial 训练，LIBERO-10 是 OOD。Long baseline=12%，若 CRM 显著提升则证明泛化；若无效则定位 CRM 边界。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark long --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_long_obs_only_norm02_seed43.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": \"959901\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-crm-long-seed43.log\", \"submitted_at\": \"2026-05-19T19:09:59Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-10\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-10 (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 8524.4, \"gpu_hours\": 2.37}, \"metrics\": {\"overall_success_rate\": 0.15, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"KITCHEN_SCENE3_stove_moka_pot\": 0.8, \"KITCHEN_SCENE6_mug_microwave\": 0.3, \"LIVING_ROOM_SCENE5_mugs_plates\": 0.2, \"STUDY_SCENE1_book_caddy\": 0.2, \"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter\": 0, \"KITCHEN_SCENE4_black_bowl_drawer\": 0, \"LIVING_ROOM_SCENE6_mug_plate_pudding\": 0, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese\": 0, \"KITCHEN_SCENE8_both_moka_pots\": 0}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T21:32:03.390Z\"}, \"eval-crm-long-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T19:10:47.244Z\", \"updated_at\": \"2026-05-19T21:31:58.213Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-10 seed42. 跨 suite 泛化性测试：CRM 仅在 Object+Spatial 训练，LIBERO-10 是 OOD。Long baseline=12%，若 CRM 显著提升则证明泛化；若无效则定位 CRM 边界。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark long --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_long_obs_only_norm02_seed42.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"959637\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-crm-long-seed42.log\", \"submitted_at\": \"2026-05-19T19:09:58Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-10\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-10 (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 8520.2, \"gpu_hours\": 2.37}, \"metrics\": {\"overall_success_rate\": 0.17, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"KITCHEN_SCENE3_stove_moka_pot\": 0.8, \"KITCHEN_SCENE6_mug_microwave\": 0.4, \"LIVING_ROOM_SCENE5_mugs_plates\": 0.2, \"STUDY_SCENE1_book_caddy\": 0.2, \"LIVING_ROOM_SCENE6_mug_plate_pudding\": 0.1, \"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter\": 0, \"KITCHEN_SCENE4_black_bowl_drawer\": 0, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese\": 0, \"KITCHEN_SCENE8_both_moka_pots\": 0}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T21:31:58.213Z\"}, \"eval-crm-goal-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:10:24.873Z\", \"updated_at\": \"2026-05-19T21:22:37.560Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-Goal seed42. OOD 泛化测试：CRM 仅在 Object+Spatial 训练，Goal 是未见过的 suite。若 CRM 提升 Goal SR，证明跨 suite 泛化；若无效则定位 CRM 边界。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_obs_only --benchmark goal --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_goal_obs_only_norm02_seed42.json\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Goal (10 tasks)\", \"data_count\": 100, \"model_name\": \"SmolVLA + CRM_v3_norm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"crm_v3_norm/obs_only/crm_best.pt (trained on Object+Spatial)\", \"eval_data\": \"LIBERO-Goal (OOD, 10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"logs/eval_goal_obs_only_norm02_seed42.json\"}, \"metrics\": {\"overall_success_rate\": 0.67, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"open_the_middle_drawer_of_the_cabinet\": 0.8, \"put_the_bowl_on_the_stove\": 0.9, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.4, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.2, \"put_the_bowl_on_top_of_the_cabinet\": 1, \"push_the_plate_to_the_front_of_the_stove\": 0.9, \"put_the_cream_cheese_in_the_bowl\": 0.2, \"turn_on_the_stove\": 1, \"put_the_bowl_on_the_plate\": 0.9, \"put_the_wine_bottle_on_the_rack\": 0.4}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T21:22:37.560Z\"}, \"eval-crm-goal-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:10:26.786Z\", \"updated_at\": \"2026-05-19T21:19:08.468Z\", \"hypothesis\": \"CRM obs_only (ε=0.2, K=10) on LIBERO-Goal seed43. OOD 泛化测试：CRM 仅在 Object+Spatial 训练，Goal 是未见过的 suite。与 seed42 配对增加统计稳健性。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u src/evaluate.py --mode crm_obs_only --benchmark goal --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_goal_obs_only_norm02_seed43.json\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Goal (10 tasks)\", \"data_count\": 100, \"model_name\": \"SmolVLA + CRM_v3_norm_obs_only\", \"seed\": 43, \"checkpoint_source\": \"crm_v3_norm/obs_only/crm_best.pt (trained on Object+Spatial)\", \"eval_data\": \"LIBERO-Goal (OOD, 10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"logs/eval_goal_obs_only_norm02_seed43.log\"}, \"metrics\": {\"overall_success_rate\": 0.72, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"open_the_middle_drawer_of_the_cabinet\": 0.8, \"put_the_bowl_on_the_stove\": 0.9, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.6, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.5, \"put_the_bowl_on_top_of_the_cabinet\": 0.9, \"push_the_plate_to_the_front_of_the_stove\": 0.8, \"put_the_cream_cheese_in_the_bowl\": 0.3, \"turn_on_the_stove\": 1, \"put_the_bowl_on_the_plate\": 1, \"put_the_wine_bottle_on_the_rack\": 0.4}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T21:19:08.468Z\"}, \"eval-vla-only-spatial-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:51:37.036Z\", \"updated_at\": \"2026-05-19T21:15:20.345Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Spatial seed46. 补齐 Spatial VLA-only n=5，与 seed42/43/44/45 配套。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 46 --K 1 --output_file logs/eval_spatial_vla_only_seed46.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:0\"], \"pid\": \"47637\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-spatial-seed46.log\", \"submitted_at\": \"2026-05-19T18:50:42Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 46, \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 8678.3, \"gpu_hours\": 2.41}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.3, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"successful_rollouts\": 30}, \"completed_at\": \"2026-05-19T21:15:20.345Z\"}, \"eval-vla-only-long-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:51:41.106Z\", \"updated_at\": \"2026-05-19T21:14:38.930Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-10 (Long) with seed47 establishes additional statistical sample (n→6) for baseline success rate estimation.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=4 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark long --n_rollouts 10 --seed 47 --K 1 --output_file logs/eval_long_vla_only_seed47.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-10 (Long)\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA (vla_only)\", \"seed\": 47, \"log_path\": \"logs/eval_long_vla_only_seed47.log\", \"checkpoint_path\": \"N/A (eval only)\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T20:57:59.764Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T20:58:07.132Z\", \"metrics\": {\"overall_success_rate\": 0.14, \"n_tasks\": 10, \"n_rollouts\": 100, \"successful_rollouts\": 14, \"per_task\": {\"put_both_alphabet_soup_and_tomato_sauce_in_basket\": 0, \"put_both_cream_cheese_box_and_butter_in_basket\": 0, \"turn_on_stove_put_moka_pot\": 0.8, \"put_black_bowl_in_bottom_drawer\": 0, \"put_white_mug_left_plate_yellow_mug_right_plate\": 0.4, \"pick_up_book_place_in_caddy\": 0.1, \"put_white_mug_on_plate_chocolate_pudding_right\": 0.1, \"put_both_alphabet_soup_and_cream_cheese_in_basket\": 0, \"put_both_moka_pots_on_stove\": 0, \"put_yellow_white_mug_in_microwave\": 0}}, \"notes\": \"Cron false positive: eval 脚本无 W&B/sentinel，进程正常退出被误判 failed。实际已完成全部 10 tasks。SR=14.0%，与已有 seeds 一致 (mean~14.2%)。手动修正 conclusion=success。\"}, \"eval-crm-goal-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:32:44.897Z\", \"updated_at\": \"2026-05-19T20:53:05.054Z\", \"hypothesis\": \"CRM obs_only (trained on Object+Spatial) generalizes to LIBERO-Goal OOD benchmark with ε=0.2 norm constraint, providing meaningful action refinement despite distribution shift.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark goal --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_goal_obs_only_norm02_seed45.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-Goal\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"CRM_obs_only_v3_norm\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Goal (OOD)\", \"log_path\": \"logs/eval_goal_obs_only_norm02_seed45.log\", \"checkpoint_path\": \"N/A (eval only)\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T20:52:59.523Z\", \"failure_reason\": \"Process killed after 3/10 tasks (SIGKILL, no OOM in dmesg). Completed: open_middle_drawer 70%, bowl_on_stove 90%, wine_bottle_on_cabinet 40%. No JSON output.\"}, \"eval-crm-goal-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:32:43.382Z\", \"updated_at\": \"2026-05-19T20:52:09.464Z\", \"hypothesis\": \"CRM obs_only (trained on Object+Spatial) generalizes to LIBERO-Goal OOD benchmark with ε=0.2 norm constraint, providing meaningful action refinement despite distribution shift.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark goal --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_goal_obs_only_norm02_seed44.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-Goal\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"CRM_obs_only_v3_norm\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Goal (OOD)\", \"log_path\": \"logs/eval_goal_obs_only_norm02_seed44.log\", \"checkpoint_path\": \"N/A (eval only)\"}, \"conclusion\": \"failed\", \"failure_reason\": \"Process silently exited after completing 3/10 tasks (no OOM, no error in log). Only open_the_middle_drawer(60%), put_the_bowl_on_the_stove(90%), put_the_wine_bottle(50%) completed. No JSON output generated.\", \"completed_at\": \"2026-05-19T20:52:09.464Z\"}, \"eval-vla-only-goal-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:31:14.902Z\", \"updated_at\": \"2026-05-19T20:10:50.847Z\", \"spec\": {\"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-goal-seed45.log\", \"command\": \"python -u src/evaluate.py --mode vla_only --benchmark goal --n_rollouts 10 --seed 45 --K 1 --output_file logs/eval_goal_vla_only_seed45.json\", \"server\": \"bjb2-28827\"}, \"hypothesis\": \"VLA-only baseline on LIBERO-Goal seed45. 补齐 Goal suite 第 4 个 seed (n=4)，与 seed42/43/44-r2 配套。LIBERO-Goal 目标条件泛化 baseline。\", \"reproduce\": {\"finished_at\": \"2026-05-19T18:55:39.155Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:55:47.453692+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.63, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"open_the_middle_drawer_of_the_cabinet\": 0.9, \"put_the_bowl_on_the_stove\": 0.9, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.3, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.4, \"put_the_bowl_on_top_of_the_cabinet\": 0.3, \"push_the_plate_to_the_front_of_the_stove\": 0.9, \"put_the_cream_cheese_in_the_bowl\": 0.1, \"turn_on_the_stove\": 0.8, \"put_the_bowl_on_the_plate\": 0.9, \"put_the_wine_bottle_on_the_rack\": 0.8}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:58:07.307Z\"}, \"eval-vla-only-goal-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:05:08.765Z\", \"updated_at\": \"2026-05-19T20:08:19.990Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Goal seed46. 补齐 Goal suite n=5 数据，与 seed42/43/44/45 配套。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=4 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark goal --n_rollouts 10 --seed 46 --K 1 --output_file logs/eval_goal_vla_only_seed46.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": \"26499\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-goal-seed46.log\", \"submitted_at\": \"2026-05-19T18:04:00Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Goal\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 46, \"wall_clock_seconds\": 4527.5, \"gpu_hours\": 1.26}, \"reproduce\": {\"finished_at\": \"2026-05-19T19:19:23.200Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T19:19:27.480Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T19:19:37.813983+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.71, \"n_tasks\": 10, \"n_rollouts_per_task\": 10, \"total_rollouts\": 100, \"total_successes\": 71, \"per_task\": {\"open_the_middle_drawer_of_the_cabinet\": 0.9, \"put_the_bowl_on_the_stove\": 0.9, \"put_the_wine_bottle_on_top_of_the_cabinet\": 0.5, \"open_the_top_drawer_and_put_the_bowl_inside\": 0.4, \"put_the_bowl_on_top_of_the_cabinet\": 0.6, \"push_the_plate_to_the_front_of_the_stove\": 0.8, \"put_the_cream_cheese_in_the_bowl\": 0.5, \"turn_on_the_stove\": 0.9, \"put_the_bowl_on_the_plate\": 0.9, \"put_the_wine_bottle_on_the_rack\": 0.7}}, \"notes\": \"Cron false positive: eval completed normally (71.0%), but no W&B/sentinel → auto-resolved as failed. Manually corrected to success.\"}, \"eval-vla-only-long-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:05:07.011Z\", \"updated_at\": \"2026-05-19T20:08:18.540Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-10 seed46. 补齐 Long suite n=5 数据，与 seed42/43/44/45 配套。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark long --n_rollouts 10 --seed 46 --K 1 --output_file logs/eval_long_vla_only_seed46.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": \"26430\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-long-seed46.log\", \"submitted_at\": \"2026-05-19T18:04:00Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-10\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 46, \"wall_clock_seconds\": 7296.8, \"gpu_hours\": 2.03}, \"reproduce\": {\"finished_at\": \"2026-05-19T20:05:32.504Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T20:05:36.751Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T20:05:43.463636+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.18, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"LIVING_ROOM_SCENE2_put_both_the_alphabet_soup_and_the_tomato_sauce_in_the_basket\": 0, \"LIVING_ROOM_SCENE2_put_both_the_cream_cheese_box_and_the_butter_in_the_basket\": 0, \"KITCHEN_SCENE3_turn_on_the_stove_and_put_the_moka_pot_on_it\": 0.9, \"KITCHEN_SCENE4_put_the_black_bowl_in_the_bottom_drawer_of_the_cabinet_and_close_it\": 0, \"LIVING_ROOM_SCENE5_put_the_white_mug_on_the_left_plate_and_put_the_yellow_and_white_mug_on_the_right_plate\": 0.5, \"STUDY_SCENE1_pick_up_the_book_and_place_it_in_the_back_compartment_of_the_caddy\": 0.1, \"LIVING_ROOM_SCENE6_put_the_white_mug_on_the_plate_and_put_the_chocolate_pudding_to_the_right_of_the_plate\": 0.1, \"LIVING_ROOM_SCENE1_put_both_the_alphabet_soup_and_the_cream_cheese_box_in_the_basket\": 0, \"KITCHEN_SCENE8_put_both_moka_pots_on_the_stove\": 0, \"KITCHEN_SCENE6_put_the_yellow_and_white_mug_in_the_microwave_and_close_it\": 0.2}}, \"notes\": \"Cron false positive: eval completed normally (18.0%), but no W&B/sentinel → auto-resolved as failed. Manually corrected to success.\"}, \"fmvd-calibration-phase1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:57:05.859Z\", \"updated_at\": \"2026-05-19T20:07:21.125Z\", \"hypothesis\": \"FMVD (Flow Velocity Dispersion) signal validation: verify correlation between ODE velocity dispersion during K=1 denoising and K=10 action variance. Go/no-go gate for Adaptive K mechanism (Spearman ρ > 0.3).\", \"spec\": {\"command\": \"python -u src/calibrate_fmvd.py --benchmark object --n_episodes 5 --seed 42 --output logs/fmvd_calibration.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:5\"], \"pid\": \"901435\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/fmvd_calibration.json\", \"submitted_at\": \"2026-05-19T17:05:13.349Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/libero_object/\", \"data_count\": 50, \"model_name\": \"smolvla_libero\", \"seed\": 42, \"wall_clock_seconds\": 7170.2, \"gpu_hours\": 1.99, \"checkpoint_path\": \"N/A\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T19:01:21.318Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T19:01:39.128507+00:00\"}]}, \"metrics\": {\"spearman_rho\": 0.082528, \"spearman_pvalue\": 2.33e-23, \"n_samples\": 14512, \"go_nogo\": \"NO-GO\", \"threshold\": 0.3, \"fmvd_mean\": 0.054867, \"fmvd_std\": 0.040291, \"fmvd_P25\": 0.027738, \"fmvd_P50\": 0.046693, \"fmvd_P75\": 0.070899, \"fmvd_P90\": 0.093805, \"k10_variance_mean\": 0.004888, \"k10_variance_std\": 0.005635, \"task_success_rate\": 0.06, \"n_tasks\": 10, \"n_episodes\": 50, \"n_successes\": 3}, \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/logs/fmvd_calibration.json\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T19:04:43.573Z\"}, \"eval-vla-only-long-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:31:11.716Z\", \"updated_at\": \"2026-05-19T19:21:47.544Z\", \"spec\": {\"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-long-seed45.log\"}, \"hypothesis\": \"VLA-only baseline on LIBERO-10 seed45. 补齐 Long suite 第 4 个 seed (n=4)，与 seed42/43/44 配套。LIBERO-10 长 horizon 任务 baseline。\", \"reproduce\": {\"finished_at\": \"2026-05-19T19:18:41.602Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T19:18:52.082488+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.17, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_episodes\": 100, \"per_task\": {\"LIVING_ROOM_SCENE2_put_both_the_alphabet_soup_and_the_tomato_sauce_in_the_basket\": 0, \"LIVING_ROOM_SCENE2_put_both_the_cream_cheese_box_and_the_butter_in_the_basket\": 0, \"KITCHEN_SCENE3_turn_on_the_stove_and_put_the_moka_pot_on_it\": 1, \"KITCHEN_SCENE4_put_the_black_bowl_in_the_bottom_drawer_of_the_cabinet_and_close_it\": 0, \"LIVING_ROOM_SCENE5_put_the_white_mug_on_the_left_plate_and_put_the_yellow_and_white_mug_on_the_right_plate\": 0.2, \"STUDY_SCENE1_pick_up_the_book_and_place_it_in_the_back_compartment_of_the_caddy\": 0.2, \"LIVING_ROOM_SCENE6_put_the_white_mug_on_the_plate_and_put_the_chocolate_pudding_to_the_right_of_the_plate\": 0.1, \"LIVING_ROOM_SCENE1_put_both_the_alphabet_soup_and_the_cream_cheese_box_in_the_basket\": 0, \"KITCHEN_SCENE8_put_both_moka_pots_on_the_stove\": 0, \"KITCHEN_SCENE6_put_the_yellow_and_white_mug_in_the_microwave_and_close_it\": 0.2}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T19:21:47.544Z\"}, \"eval-perdof-object-norm003-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:56:24.175Z\", \"updated_at\": \"2026-05-19T19:05:12.052Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed47.log\", \"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed47.json\\\"\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 47}, \"hypothesis\": \"perdof CRM with ε=0.03 (max_correction_norm) on LIBERO-Object seed47 tests whether a smaller correction magnitude improves or degrades task success rate compared to ε=0.05\", \"reproduce\": {\"finished_at\": \"2026-05-19T18:45:55.645Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:46:06.068016+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.15, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.2, \"milk\": 0.1, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.3}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T19:05:12.052Z\"}, \"eval-perdof-object-norm005-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:56:21.800Z\", \"updated_at\": \"2026-05-19T19:05:09.001Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm005-seed47.log\", \"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005_seed47.json\\\"\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 47}, \"hypothesis\": \"perdof CRM with ε=0.05 (max_correction_norm) on LIBERO-Object seed47 provides per-DOF conformal refinement; this run supplements the magnitude curve at ε=0.05 (currently n=4)\", \"reproduce\": {\"finished_at\": \"2026-05-19T19:01:18.825Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T19:01:34.362696+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.1, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.2, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0.1, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T19:05:09.001Z\"}, \"eval-vla-only-long-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:39:55.593Z\", \"updated_at\": \"2026-05-19T18:38:52.937Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-10 seed44. 扩展到新 benchmark suite 验证 CRM 泛化性的前提——先建立 baseline。\", \"spec\": {\"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-long-seed44.log\", \"wall_clock_seconds\": 6848.4, \"gpu_hours\": 1.9}, \"reproduce\": {\"finished_at\": \"2026-05-19T18:34:31.522Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:34:43.640067+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.12, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce_basket\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter_basket\": 0, \"KITCHEN_SCENE3_stove_moka_pot\": 0.8, \"KITCHEN_SCENE4_black_bowl_drawer\": 0, \"LIVING_ROOM_SCENE5_white_mug_left_yellow_mug_right\": 0.2, \"STUDY_SCENE1_book_caddy\": 0.1, \"LIVING_ROOM_SCENE6_white_mug_plate_chocolate_pudding\": 0, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese_basket\": 0, \"KITCHEN_SCENE8_both_moka_pots_stove\": 0, \"KITCHEN_SCENE6_yellow_white_mug_microwave\": 0.1}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:38:52.937Z\"}, \"eval-vla-only-long-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:39:49.327Z\", \"updated_at\": \"2026-05-19T18:38:48.009Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-10 seed42. 扩展到新 benchmark suite 验证 CRM 泛化性的前提——先建立 baseline。\", \"spec\": {\"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-long-seed42.log\", \"wall_clock_seconds\": 6839.3, \"gpu_hours\": 1.9}, \"reproduce\": {\"finished_at\": \"2026-05-19T18:34:16.744Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:34:25.767118+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.11, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce_basket\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter_basket\": 0, \"KITCHEN_SCENE3_stove_moka_pot\": 0.8, \"KITCHEN_SCENE4_black_bowl_drawer\": 0, \"LIVING_ROOM_SCENE5_white_mug_left_yellow_mug_right\": 0.1, \"STUDY_SCENE1_book_caddy\": 0.1, \"LIVING_ROOM_SCENE6_white_mug_plate_chocolate_pudding\": 0, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese_basket\": 0, \"KITCHEN_SCENE8_both_moka_pots_stove\": 0, \"KITCHEN_SCENE6_yellow_white_mug_microwave\": 0.1}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:38:48.009Z\"}, \"eval-vla-only-long-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:39:52.159Z\", \"updated_at\": \"2026-05-19T18:33:56.305Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-10 seed43. 扩展到新 benchmark suite 验证 CRM 泛化性的前提——先建立 baseline。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark long --n_rollouts 10 --seed 43 --K 1 --output_file logs/eval_long_vla_only_seed43.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:2\"], \"pid\": \"987573\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_long_vla_only_seed43.json\", \"submitted_at\": \"2026-05-19T16:40:20.361Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-10\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 43, \"checkpoint_path\": \"N/A (eval-only)\", \"wall_clock_seconds\": 6815.9, \"gpu_hours\": 1.89}, \"reproduce\": {\"finished_at\": \"2026-05-19T18:30:41.776Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:30:49.971343+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.13, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"LIVING_ROOM_SCENE2_alphabet_soup_tomato_sauce_basket\": 0, \"LIVING_ROOM_SCENE2_cream_cheese_butter_basket\": 0, \"KITCHEN_SCENE3_stove_moka_pot\": 0.7, \"KITCHEN_SCENE4_black_bowl_drawer\": 0, \"LIVING_ROOM_SCENE5_white_mug_left_yellow_mug_right\": 0.3, \"STUDY_SCENE1_book_caddy\": 0, \"LIVING_ROOM_SCENE6_white_mug_plate_chocolate_pudding\": 0.1, \"LIVING_ROOM_SCENE1_alphabet_soup_cream_cheese_basket\": 0, \"KITCHEN_SCENE8_both_moka_pots_stove\": 0, \"KITCHEN_SCENE6_yellow_white_mug_microwave\": 0.2}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:33:56.305Z\"}, \"eval-obs-only-spatial-norm02-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:49:53.389Z\", \"updated_at\": \"2026-05-19T18:07:05.998Z\", \"hypothesis\": \"obs_only CRM (ε=0.2) on LIBERO-Spatial seed43. 审稿 M2: 验证 CRM 在 Spatial benchmark 上的跨 seed 一致性。CRM 已覆盖 Spatial 训练数据（all 20 LIBERO tasks）。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_seed43.json\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"tmux_session\": \"eval-spatial-obs-only-norm02-seq\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T18:07:05.998Z\"}, \"eval-obs-only-spatial-norm02-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:27:35.615Z\", \"updated_at\": \"2026-05-19T18:04:19.943Z\", \"hypothesis\": \"obs_only CRM (ε=0.2, K=10) on LIBERO-Spatial seed47. 补充 Spatial cross-seed 一致性数据。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_seed47.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": \"972439\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_spatial_obs_only_norm02_seed47.json\", \"submitted_at\": \"2026-05-19T15:27:46.376Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 47, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 9393.6, \"gpu_hours\": 2.61}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:59:36.860Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T16:59:45.213677+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.32, \"per_task\": {\"pick_up_the_black_bowl_between_the_plate_and_the_ramekin_and_place_it_on_the_plate\": 0.8, \"pick_up_the_black_bowl_next_to_the_ramekin_and_place_it_on_the_plate\": 0.9, \"pick_up_the_black_bowl_from_table_center_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_on_the_cookie_box_and_place_it_on_the_plate\": 0.3, \"pick_up_the_black_bowl_in_the_top_drawer_of_the_wooden_cabinet_and_place_it_on_the_plate\": 0.1, \"pick_up_the_black_bowl_on_the_ramekin_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_next_to_the_cookie_box_and_place_it_on_the_plate\": 0.9, \"pick_up_the_black_bowl_on_the_stove_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_next_to_the_plate_and_place_it_on_the_plate\": 0.2, \"pick_up_the_black_bowl_on_the_wooden_cabinet_and_place_it_on_the_plate\": 0}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:04:19.943Z\"}, \"eval-obs-only-spatial-norm02-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:27:33.151Z\", \"updated_at\": \"2026-05-19T17:24:14.391Z\", \"hypothesis\": \"obs_only CRM (ε=0.2, K=10) on LIBERO-Spatial seed46. 补充 Spatial K=10 cross-benchmark 数据，当前 n=3 (seed42=35%, seed44=36%, seed45=34%)，扩展到 n=5 增强统计稳健性。\", \"spec\": {\"kill_cause\": \"AutoDL platform-level SIGKILL (not OOM). 2 processes killed simultaneously. Memory 840GB free. Progress: 80% (8/10 tasks done). Output file not written.\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:50:40.827Z\"}, \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill) on bjb2-28827\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T16:50:45.374Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T16:50:55.167859+00:00\"}]}}, \"eval-argmin-object-k5-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T08:21:11.529Z\", \"updated_at\": \"2026-05-19T17:24:12.993Z\", \"spec\": {\"kill_cause\": \"AutoDL platform-level SIGKILL (not OOM). 2 processes killed simultaneously. Memory 840GB free. Progress: 98% (task 10/10, rollout 8/10). Output file not written (evaluate.py writes only on completion).\"}, \"hypothesis\": \"K=5 argmin-only baseline (reconvla mode) seed44 on LIBERO-Object. D066 K=5 decomposition: isolate selection-only benefit from CRM correction.\", \"reproduce\": {\"finished_at\": \"2026-05-19T16:49:50.337Z\"}, \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T16:49:54.738Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T16:50:03.858693+00:00\"}]}}, \"eval-vla-only-goal-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:40:03.921Z\", \"updated_at\": \"2026-05-19T17:08:52.675Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Goal seed44. LIBERO-Goal 使用相同初始状态不同目标，测试 VLA 对 goal-conditioned 任务的 baseline 表现。\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark goal --n_rollouts 10 --seed 44 --K 1 --output_file logs/eval_goal_vla_only_seed44.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:0\"], \"pid\": \"887053\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-goal-seed44.log\", \"submitted_at\": \"2026-05-19T16:40:33.136Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Goal\", \"data_count\": 100, \"model_name\": \"SmolVLA\", \"seed\": 44, \"wall_clock_seconds\": 1699.5, \"gpu_hours\": 0.47}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T17:08:52.675Z\"}, \"eval-random-selection-object-k5-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:30:30.944Z\", \"updated_at\": \"2026-05-19T16:31:13.969Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed45. K=5 decomposition 对照第四个 seed，与 argmin K=5 seed45 (13%) 配对，增强 selection effect 统计可靠性。\", \"parent\": \"eval-random-selection-object-k5-seed45\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 45 --K 5 --output_file logs/eval_object_random_selection_k5_seed45.json\", \"server\": \"bjb1-32546\", \"data_path\": \"/root/acr-vla-conformal-refinement\", \"data_count\": 10, \"model_name\": \"SmolVLA\", \"seed\": 45, \"gpu\": \"cuda:3\", \"pid\": 942099, \"checkpoint_source\": \"N/A (random selection baseline)\", \"eval_data\": \"LIBERO-Object\", \"tmux_session\": \"eval-random-selection-object-k5-seed45\", \"output_file\": \"logs/eval_object_random_selection_k5_seed45.json\", \"log_file\": \"logs/eval_object_random_selection_k5_seed45.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:23:32.014Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T16:23:25.240Z\", \"metrics\": {\"success_rate\": 0.07, \"successes\": 7, \"total\": 100, \"n_tasks\": 10, \"n_rollouts\": 10}}, \"eval-random-selection-object-k5-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:30:29.373Z\", \"updated_at\": \"2026-05-19T16:31:10.982Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed44. K=5 decomposition 对照第三个 seed，与 argmin K=5 seed44 配对验证 selection effect 统计显著性。\", \"parent\": \"eval-random-selection-object-k5-seed44\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 44 --K 5 --output_file logs/eval_object_random_selection_k5_seed44.json\", \"server\": \"bjb1-32546\", \"data_path\": \"/root/acr-vla-conformal-refinement\", \"data_count\": 10, \"model_name\": \"SmolVLA\", \"seed\": 44, \"gpu\": \"cuda:2\", \"pid\": 942029, \"checkpoint_source\": \"N/A (random selection baseline)\", \"eval_data\": \"LIBERO-Object\", \"tmux_session\": \"eval-random-selection-object-k5-seed44\", \"output_file\": \"logs/eval_object_random_selection_k5_seed44.json\", \"log_file\": \"logs/eval_object_random_selection_k5_seed44.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:22:40.807Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T16:22:38.525Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T16:22:54.719277+00:00\"}]}, \"metrics\": {\"success_rate\": 0.1, \"successes\": 10, \"total\": 100, \"n_tasks\": 10, \"n_rollouts\": 10}}, \"eval-random-selection-object-k5-seed43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:30:27.994Z\", \"updated_at\": \"2026-05-19T16:31:08.997Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed43. 第二个 seed 的 K=5 random selection，与 argmin K=5 seed43 (13%) 配对，增强 selection effect 统计可靠性。\", \"parent\": \"eval-random-selection-object-k5-seed43\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 43 --K 5 --output_file logs/eval_object_random_selection_k5_seed43.json\", \"server\": \"bjb2-28827\", \"data_path\": \"/root/acr-vla-conformal-refinement\", \"data_count\": 10, \"model_name\": \"SmolVLA\", \"seed\": 43, \"gpu\": \"cuda:0\", \"pid\": 841426, \"checkpoint_source\": \"N/A (random selection baseline)\", \"eval_data\": \"LIBERO-Object\", \"tmux_session\": \"eval-random-selection-object-k5-seed43\", \"output_file\": \"logs/eval_object_random_selection_k5_seed43.json\", \"log_file\": \"logs/eval_object_random_selection_k5_seed43.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:22:14.014Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T16:22:19.121Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T16:22:25.948147+00:00\"}]}, \"metrics\": {\"success_rate\": 0.11, \"successes\": 11, \"total\": 100, \"n_tasks\": 10, \"n_rollouts\": 10}}, \"eval-random-selection-object-k5-seed42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:30:26.607Z\", \"updated_at\": \"2026-05-19T16:31:06.453Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed42. 从 K=5 VLA samples 中随机选 1 个执行（不用 argmin/CRM）。验证 K=5 decomposition 中 selection effect 是否真实：如果 random ≈ argmin (13.7%)，则 selection effect 不显著；如果 random < argmin，则 argmin 的选择能力在小候选池中有真实价值。\", \"parent\": \"eval-random-selection-object-k5-seed42\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 42 --K 5 --output_file logs/eval_object_random_selection_k5_seed42.json\", \"server\": \"bjb1-32546\", \"data_path\": \"/root/acr-vla-conformal-refinement\", \"data_count\": 10, \"model_name\": \"SmolVLA\", \"seed\": 42, \"gpu\": \"cuda:5\", \"pid\": 939548, \"checkpoint_source\": \"N/A (random selection baseline)\", \"eval_data\": \"LIBERO-Object\", \"tmux_session\": \"eval-random-selection-object-k5-seed42\", \"output_file\": \"logs/eval_object_random_selection_k5_seed42.json\", \"log_file\": \"logs/eval_object_random_selection_k5_seed42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:18:49.960Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T16:18:51.282Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T16:19:03.242474+00:00\"}]}, \"metrics\": {\"success_rate\": 0.14, \"successes\": 14, \"total\": 100, \"n_tasks\": 10, \"n_rollouts\": 10}}, \"eval-obs-only-spatial-norm02-k5-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:30:32.306Z\", \"updated_at\": \"2026-05-19T16:30:37.908Z\", \"hypothesis\": \"CRM obs-only with K=5 conformal refinement steps and max_correction_norm=0.2 will improve SmolVLA spatial task success rate compared to baseline, though potentially less than K=10 due to fewer correction iterations.\", \"parent\": \"eval-obs-only-spatial-norm02-k5-seed44\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 44 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_k5_seed44.json\", \"server\": \"bjb2-28827\", \"data_path\": \"/root/acr-vla-conformal-refinement\", \"data_count\": 10, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 44, \"gpu\": \"cuda:2\", \"pid\": 843594, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-spatial\", \"output_file\": \"logs/eval_spatial_obs_only_norm02_k5_seed44.json\", \"log_file\": \"logs/eval_spatial_obs_only_norm02_k5_seed44.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:24:46.925Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T16:24:38.292Z\", \"metrics\": {\"success_rate\": 0.37, \"successes\": 37, \"total\": 100, \"n_tasks\": 10, \"n_rollouts\": 10}}, \"eval-obs-only-spatial-norm02-k5-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:30:33.621Z\", \"updated_at\": \"2026-05-19T16:30:18.549Z\", \"hypothesis\": \"CRM obs-only with K=5 conformal refinement steps and max_correction_norm=0.2 will improve SmolVLA spatial task success rate compared to baseline, though potentially less than K=10 due to fewer correction iterations.\", \"parent\": \"eval-obs-only-spatial-norm02-k5-seed45\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 45 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_k5_seed45.json\", \"server\": \"bjb2-28827\", \"data_path\": \"/root/acr-vla-conformal-refinement\", \"data_count\": 10, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 45, \"gpu\": \"cuda:5\", \"pid\": 845019, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-spatial\", \"output_file\": \"logs/eval_spatial_obs_only_norm02_k5_seed45.json\", \"log_file\": \"logs/eval_spatial_obs_only_norm02_k5_seed45.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T16:25:51.927Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T16:25:54.177Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T16:26:43.837743+00:00\"}]}, \"metrics\": {\"success_rate\": 0.34, \"successes\": 34, \"total\": 100, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"pick_up_bowl_between_plate_ramekin\": 0.9, \"pick_up_bowl_next_to_ramekin\": 1, \"pick_up_bowl_from_table_center\": 0, \"pick_up_bowl_on_cookie_box\": 0.3, \"pick_up_bowl_in_top_drawer\": 0.1, \"pick_up_bowl_on_ramekin\": 0, \"pick_up_bowl_next_to_cookie_box\": 0.9, \"pick_up_bowl_on_stove\": 0, \"pick_up_bowl_next_to_plate\": 0.2, \"pick_up_bowl_on_wooden_cabinet\": 0}}}, \"plan_602-latency-profiling\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T16:13:57.251Z\", \"updated_at\": \"2026-05-19T16:17:38.007Z\", \"hypothesis\": \"Latency profiling: 正式测量 VLA+CRM pipeline 各组件 wall-clock time，覆盖 K=1/5/10/20 batched vs sequential，生成论文 Table 级结果。预期 CRM overhead < 1ms，pipeline 主要 bottleneck 在 VLA flow-matching sampling。\", \"spec\": {\"command\": \"python profile_latency.py\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"107232\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/latency_profile.json\", \"submitted_at\": \"2026-05-19T16:14:41.817Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/libero_object/\", \"data_count\": 1, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 171.9, \"gpu_hours\": 0.05}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T16:17:33.738Z\", \"metrics\": {\"vla_encode_ms\": 28.4, \"crm_forward_ms\": 0.246, \"preprocess_ms\": 0.96, \"batched_K1_ms\": 180, \"batched_K5_ms\": 182.3, \"batched_K10_ms\": 162.3, \"batched_K20_ms\": 167.4, \"sequential_K1_ms\": 177, \"sequential_K5_ms\": 891.7, \"sequential_K10_ms\": 1638.9, \"sequential_K20_ms\": 3245.8, \"cgs_K10_ms\": 6.3, \"full_pipe_K10_ms\": 200.7, \"full_pipe_K20_ms\": 199.7, \"vla_model_mb\": 884.1, \"crm_model_mb\": 1.8, \"peak_K20_mb\": 1085.1}}, \"eval-vla-only-spatial-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T13:24:47.682Z\", \"updated_at\": \"2026-05-19T16:06:09.222Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Spatial seed45. Spatial benchmark 第四个 VLA-only seed，配合 obs_only spatial seeds 报告 CRM 改进幅度。\", \"spec\": {\"checkpoint_path\": \"N/A (vla_only baseline)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_spatial_vla_only_seed45.json\"}, \"server\": \"bjb1-32546\", \"gpu\": \"cuda:0\", \"pid\": \"932535\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_spatial_vla_only_seed45.json\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 45 --output_file logs/eval_spatial_vla_only_seed45.json\", \"finished_at\": \"2026-05-19T15:17:27.081Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T15:17:34.738444+00:00\"}]}, \"metrics\": {\"success_rate\": 0.27, \"per_task\": {\"pick_up_the_black_bowl_between_the_plate_and_the_ramekin_and_place_it_on_the_plate\": 0.7, \"pick_up_the_black_bowl_next_to_the_ramekin_and_place_it_on_the_plate\": 0.9, \"pick_up_the_black_bowl_from_table_center_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_on_the_cookie_box_and_place_it_on_the_plate\": 0.2, \"pick_up_the_black_bowl_in_the_top_drawer_of_the_wooden_cabinet_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_on_the_ramekin_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_next_to_the_cookie_box_and_place_it_on_the_plate\": 0.9, \"pick_up_the_black_bowl_on_the_stove_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_next_to_the_plate_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_on_the_wooden_cabinet_and_place_it_on_the_plate\": 0}, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (vla_only baseline)\", \"completed_at\": \"2026-05-19T15:47:20.192Z\"}, \"eval-perdof-object-norm005-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:50:49.193Z\", \"updated_at\": \"2026-05-19T16:06:07.907Z\", \"hypothesis\": \"perdof CRM (ε=0.05) seed45 on LIBERO-Object. 补 magnitude curve perdof ε=0.05 (当前 n=2)。timeout=16h。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=4 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005_seed45.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"tmux_session\": \"eval-perdof-norm005-seed45-t16\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"conclusion\": \"success\", \"log_path\": \"logs/eval_object_perdof_norm005_seed45.json\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"completed_at\": \"2026-05-19T15:29:57.924Z\", \"metrics\": {\"success_rate\": 0.1, \"successes\": 10, \"total\": 100, \"n_tasks\": 10, \"n_rollouts\": 10, \"sr_pct\": \"10%\"}}, \"eval-vla-only-spatial-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T13:24:44.727Z\", \"updated_at\": \"2026-05-19T15:30:01.540Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Spatial seed44. Spatial benchmark 第三个 VLA-only seed，配合 obs_only spatial seeds 报告 CRM 改进幅度。\", \"spec\": {\"server\": \"bjb2-28827\", \"gpu\": [\"cuda:4\"], \"account\": \"root\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA_vla_only\", \"seed\": 44, \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\", \"command\": \"cd /root/acr-vla-conformal-refinement && timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 44 --output_file logs/eval_spatial_vla_only_seed44.json\"}, \"server\": \"bjb2-28827\", \"gpu\": \"cuda:4\", \"pid\": \"835806\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-spatial-seed44.log\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 44 --output_file logs/eval_spatial_vla_only_seed44.json\", \"finished_at\": \"2026-05-19T15:27:05.121Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T15:27:13.496164+00:00\"}]}, \"metrics\": {\"success_rate\": 0.31, \"successes\": 31, \"total\": 100, \"per_task\": {\"pick_up_the_black_bowl_between_the_plate_and_the_ramekin_and_place_it_on_the_plate\": 0.6, \"pick_up_the_black_bowl_next_to_the_ramekin_and_place_it_on_the_plate\": 1, \"pick_up_the_black_bowl_from_table_center_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_on_the_cookie_box_and_place_it_on_the_plate\": 0.3, \"pick_up_the_black_bowl_in_the_top_drawer_of_the_wooden_cabinet_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_on_the_ramekin_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_next_to_the_cookie_box_and_place_it_on_the_plate\": 0.9, \"pick_up_the_black_bowl_on_the_stove_and_place_it_on_the_plate\": 0, \"pick_up_the_black_bowl_next_to_the_plate_and_place_it_on_the_plate\": 0.3, \"pick_up_the_black_bowl_on_the_wooden_cabinet_and_place_it_on_the_plate\": 0}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only, no checkpoint produced)\", \"completed_at\": \"2026-05-19T15:30:01.540Z\"}, \"eval-obs-only-object-default-seed48-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:50:51.880Z\", \"updated_at\": \"2026-05-19T14:58:17.531Z\", \"hypothesis\": \"obs_only CRM (ε=default/unlimited) seed48 on LIBERO-Object. 补 obs_only default (当前 n=3)。timeout=16h。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=4 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 48 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed48.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"tmux_session\": \"eval-obs-only-default-seed48-t16\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 48, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_default_seed48.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T14:55:24.359Z\"}, \"failure_reason\": \"Process gone (cron miss 4/5), no sentinel, no W&B output detected\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T14:55:30.658Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:55:41.674404+00:00\"}]}, \"metrics\": {\"success_rate\": 0.17, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.4, \"ketchup\": 0.1, \"tomato_sauce\": 0.2, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.3}}, \"notes\": \"误判 failed: cron 检测到 tmux session 死亡，但实验已正常完成并写入完整 JSON。手动验证 output JSON 完整（59 行，10 tasks × 10 rollouts）。success_rate=0.17，与原 seed48 (bjb2-28827) 一致。\"}, \"eval-vla-only-spatial-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T13:01:28.636Z\", \"updated_at\": \"2026-05-19T14:43:19.646Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Spatial seed43. P1 缺口：与 Spatial K=5 CRM seed43=32% 配对，计算 per-seed improvement。没有此 baseline 无法报告 Spatial 改进幅度。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 43 --output_file logs/eval_spatial_vla_only_seed43.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"80076\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-spatial-seed43.log\", \"submitted_at\": \"2026-05-19T13:01:37.336Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA_vla_only\", \"seed\": 43, \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 6102.3, \"gpu_hours\": 1.7}, \"reproduce\": {\"finished_at\": \"2026-05-19T14:40:35.939Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:40:44.096497+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.29, \"successes\": 29, \"total\": 100, \"per_task\": {\"between_plate_and_ramekin\": 0.7, \"next_to_ramekin\": 0.8, \"from_table_center\": 0.1, \"on_cookie_box\": 0.3, \"in_top_drawer\": 0, \"on_ramekin\": 0, \"next_to_cookie_box\": 0.9, \"on_stove\": 0, \"next_to_plate\": 0.1, \"on_wooden_cabinet\": 0}}, \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/logs/eval_spatial_vla_only_seed43.json\", \"completed_at\": \"2026-05-19T14:43:19.646Z\"}, \"eval-vla-only-spatial-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T12:55:51.909Z\", \"updated_at\": \"2026-05-19T14:38:29.599Z\", \"hypothesis\": \"VLA-only baseline on LIBERO-Spatial seed42. P1 缺口：Spatial benchmark 需要 VLA-only baseline 才能报告 CRM 的改进幅度。对标 obs_only spatial K=10 seed42=35%。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 42 --output_file logs/eval_spatial_vla_only_seed42.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": \"917724\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-spatial-seed42.log\", \"submitted_at\": \"2026-05-19T12:57:06.478Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA_vla_only\", \"seed\": 42, \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 6083.1, \"gpu_hours\": 1.69}, \"reproduce\": {\"finished_at\": \"2026-05-19T14:36:03.209Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:36:10.920946+00:00\"}]}, \"metrics\": {\"success_rate\": 0.3, \"per_task\": {\"between_plate_and_ramekin\": 0.6, \"next_to_ramekin\": 1, \"from_table_center\": 0, \"on_cookie_box\": 0.2, \"in_top_drawer\": 0, \"on_ramekin\": 0, \"next_to_cookie_box\": 0.9, \"on_stove\": 0, \"next_to_plate\": 0.3, \"on_wooden_cabinet\": 0}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-spatial-seed42.log\", \"completed_at\": \"2026-05-19T14:38:29.600Z\"}, \"eval-obs-only-spatial-norm02-k5-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:00:40.507Z\", \"updated_at\": \"2026-05-19T14:32:21.490Z\", \"hypothesis\": \"CRM obs-only with K=5 conformal refinement steps and max_correction_norm=0.2 will improve SmolVLA spatial task success rate compared to baseline, though potentially less than K=10 due to fewer correction iterations.\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=5 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 45 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_k5_seed45.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\", \"K\": 5, \"max_correction_norm\": 0.2}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T14:32:21.490Z\"}, \"eval-obs-only-spatial-norm02-k5-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:00:39.233Z\", \"updated_at\": \"2026-05-19T14:32:16.468Z\", \"hypothesis\": \"CRM obs-only with K=5 conformal refinement steps and max_correction_norm=0.2 will improve SmolVLA spatial task success rate compared to baseline, though potentially less than K=10 due to fewer correction iterations.\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 44 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_k5_seed44.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\", \"K\": 5, \"max_correction_norm\": 0.2}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T14:32:16.468Z\"}, \"eval-random-selection-object-k5-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:00:37.093Z\", \"updated_at\": \"2026-05-19T14:32:11.343Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed45. K=5 decomposition 对照第四个 seed，与 argmin K=5 seed45 (13%) 配对，增强 selection effect 统计可靠性。\", \"parent\": \"eval-argmin-object-k5-seed45\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 45 --K 5 --output_file logs/eval_object_random_selection_k5_seed45.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA_random_selection_K5\", \"seed\": 45, \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_source\": \"HuggingFaceM4/SmolVLA-base\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T14:32:11.343Z\"}, \"eval-random-selection-object-k5-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:00:34.934Z\", \"updated_at\": \"2026-05-19T14:32:06.313Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed44. K=5 decomposition 对照第三个 seed，与 argmin K=5 seed44 配对验证 selection effect 统计显著性。\", \"parent\": \"eval-argmin-object-k5-seed44\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 44 --K 5 --output_file logs/eval_object_random_selection_k5_seed44.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA_random_selection_K5\", \"seed\": 44, \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_source\": \"HuggingFaceM4/SmolVLA-base\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T14:32:06.313Z\"}, \"eval-random-selection-object-k5-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T13:57:11.028Z\", \"updated_at\": \"2026-05-19T14:32:01.561Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed43. 第二个 seed 的 K=5 random selection，与 argmin K=5 seed43 (13%) 配对，增强 selection effect 统计可靠性。\", \"parent\": \"eval-argmin-object-k5-seed43\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 43 --K 5 --output_file logs/eval_object_random_selection_k5_seed43.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA_random_selection_K5\", \"seed\": 43, \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_source\": \"SmolVLA pretrained (random K=5 selection baseline, no fine-tuning)\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T14:32:01.561Z\"}, \"eval-random-selection-object-k5-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T13:43:11.414Z\", \"updated_at\": \"2026-05-19T14:31:56.882Z\", \"hypothesis\": \"Random selection baseline with K=5 on LIBERO-Object seed42. 从 K=5 VLA samples 中随机选 1 个执行（不用 argmin/CRM）。验证 K=5 decomposition 中 selection effect 是否真实：如果 random ≈ argmin (13.7%)，则 selection effect 不显著；如果 random < argmin，则 argmin 的选择能力在小候选池中有真实价值。\", \"parent\": \"eval-argmin-object-k5-seed42\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=5 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode random_selection --benchmark object --n_rollouts 10 --seed 42 --K 5 --output_file logs/eval_object_random_selection_k5_seed42.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA_random_selection_K5\", \"seed\": 42, \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_source\": \"smolvla_libero (pretrained, no finetuning)\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-19T14:31:56.882Z\"}, \"eval-obs-only-spatial-norm02-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:49:54.536Z\", \"updated_at\": \"2026-05-19T14:26:11.536Z\", \"hypothesis\": \"obs_only CRM (ε=0.2) on LIBERO-Spatial seed44. 审稿 M2: 验证 CRM 在 Spatial benchmark 上的跨 seed 一致性。CRM 已覆盖 Spatial 训练数据（all 20 LIBERO tasks）。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_seed44.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"tmux_session\": \"eval-spatial-obs-only-norm02-seed44\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T14:12:36.942Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T14:12:33.705Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:12:43.426190+00:00\"}]}, \"metrics\": {\"success_rate\": 0.36, \"successes\": 36, \"total\": 100}, \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_spatial_obs_only_norm02_seed44.json\"}, \"eval-perdof-object-norm01-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T01:29:55.249Z\", \"updated_at\": \"2026-05-19T13:39:15.552Z\", \"spec\": {\"command\": \"crm_perdof --seed 43 --K 10 --max_correction_norm 0.1\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"571010\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm01-seed43.log\", \"submitted_at\": \"2026-05-18T01:29:54.691Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"wall_clock_seconds\": 130160.9, \"gpu_hours\": 36.16}, \"reproduce\": {\"finished_at\": \"2026-05-18T16:26:03.341Z\"}, \"metrics\": {\"sr\": 0.12, \"sr_pct\": \"12%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.3}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm01-seed43.log\", \"hypothesis\": \"per-DoF CRM with max_correction_norm=0.1 on LIBERO-Object (seed43, K=10, n_rollouts=10) should achieve comparable SR to obs_only default, as tighter norm constraint limits correction magnitude per joint.\", \"completed_at\": \"2026-05-19T13:39:15.552Z\"}, \"eval-obs-only-object-default-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:05:53.834Z\", \"updated_at\": \"2026-05-19T13:35:23.895Z\", \"hypothesis\": \"obs_only CRM uncapped (default norm ~1.42) seed45 重跑 n_rollouts=10。原始 seed45 用 n_rollouts=20 (SR=12%)，需标准化。obs_only default 当前 n=3 (seed42/43/44)。\", \"parent\": \"eval-obs-only-object-default-seed45\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed45_r2.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": \"579212\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-default-seed45-r2.log\", \"submitted_at\": \"2026-05-18T13:24:59.115Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 87024.8, \"gpu_hours\": 24.17}, \"server\": \"bjb2-28827\", \"gpu\": \"cuda:3\", \"pid\": \"579212\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-default-seed45-r2.log\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed45_r2.json\", \"finished_at\": \"2026-05-19T04:22:06.623Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T04:22:13.278219+00:00\"}]}, \"metrics\": {\"sr\": 0.18, \"sr_pct\": \"18%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.3, \"bbq_sauce\": 0.3, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.2, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.3}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only)\", \"completed_at\": \"2026-05-19T13:35:23.895Z\"}, \"eval-argmin-object-k5-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:08:30.602Z\", \"updated_at\": \"2026-05-19T13:30:16.050Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 42 --K 5 --output_file logs/eval_object_argmin_k5_seed42.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:0\"], \"pid\": \"883706\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-k5-seed42.log\", \"submitted_at\": \"2026-05-19T11:36:06.499Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 42, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA_reconvla_argmin\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 6679.2, \"gpu_hours\": 1.86}, \"hypothesis\": \"K=5 argmin-only baseline (reconvla mode) seed42 on LIBERO-Object. D066 K=5 decomposition: isolate selection-only benefit from CRM correction.\", \"reproduce\": {\"finished_at\": \"2026-05-19T13:26:43.546Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:26:53.401549+00:00\"}]}, \"metrics\": {\"sr\": 0.15, \"sr_pct\": \"15%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.4, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0, \"milk\": 0.2, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}, \"conclusion\": \"success\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_argmin_k5_seed42.json\", \"checkpoint_path\": \"N/A (eval-only)\", \"completed_at\": \"2026-05-19T13:27:25.720Z\"}, \"eval-argmin-object-k5-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:36:13.145Z\", \"updated_at\": \"2026-05-19T13:26:50.930Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=5 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 45 --K 5 --output_file logs/eval_object_argmin_k5_seed45.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"884249\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-k5-seed45.log\", \"submitted_at\": \"2026-05-19T11:36:12.365Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 45, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA_reconvla_argmin\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 6638.6, \"gpu_hours\": 1.84}, \"hypothesis\": \"K=5 argmin-only baseline (reconvla mode) seed45 on LIBERO-Object. D066 K=5 decomposition: isolate selection-only benefit from CRM correction.\", \"metrics\": {\"sr\": 0.13, \"sr_pct\": \"13%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.4, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.1, \"orange_juice\": 0.3}}, \"conclusion\": \"success\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_argmin_k5_seed45.json\", \"checkpoint_path\": \"N/A (eval-only)\", \"completed_at\": \"2026-05-19T13:26:50.930Z\"}, \"eval-argmin-object-k5-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:08:15.812Z\", \"updated_at\": \"2026-05-19T13:26:46.918Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 43 --K 5 --output_file logs/eval_object_argmin_k5_seed43.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:2\"], \"pid\": \"883975\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-k5-seed43.log\", \"submitted_at\": \"2026-05-19T11:36:09.461Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 43, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA_reconvla_argmin\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 6637.5, \"gpu_hours\": 1.84}, \"hypothesis\": \"K=5 argmin-only baseline (reconvla mode) seed43 on LIBERO-Object. D066 K=5 decomposition: isolate selection-only benefit from CRM correction.\", \"metrics\": {\"sr\": 0.13, \"sr_pct\": \"13%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.3, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.2}}, \"conclusion\": \"success\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_argmin_k5_seed43.json\", \"checkpoint_path\": \"N/A (eval-only)\", \"completed_at\": \"2026-05-19T13:26:46.918Z\"}, \"eval-perdof-object-norm03-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:18:03.763Z\", \"updated_at\": \"2026-05-19T13:24:40.192Z\", \"hypothesis\": \"perdof CRM (ε=0.3) seed43 on LIBERO-Object. 补 magnitude curve：perdof ε=0.3 当前 n=3 (seed42:4%, seed44:4%, seed45:6%)，mean=4.67%。增加第 4 个 seed 强化 error bars。\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:5\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb2-28827\", \"gpu\": \"cuda:5\", \"started_at\": \"2026-05-18T15:18:23.972Z\", \"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed43.json\", \"finished_at\": \"2026-05-18T21:19:30.796Z\", \"training_hours\": 6.02}, \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed43.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:5\"], \"pid\": \"594147\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm03-seed43.log\", \"submitted_at\": \"2026-05-18T15:18:27.012Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21673.4, \"gpu_hours\": 6.02}, \"pid\": \"594147\", \"log_path\": \"/root/logs/eval_object_perdof_norm03_seed43.json\", \"failure_reason\": \"EXIT_CODE=124 (timeout — exceeded timeout_hours)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T21:19:40.460Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T21:20:00.703434+00:00\"}]}, \"metrics\": {\"sr\": 5, \"sr_pct\": \"5%\", \"n_tasks\": 10, \"n_rollouts\": 10}}, \"eval-obs-only-spatial-norm02-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:49:55.654Z\", \"updated_at\": \"2026-05-19T13:12:13.645Z\", \"hypothesis\": \"obs_only CRM (ε=0.2) on LIBERO-Spatial seed45. 审稿 M2: 验证 CRM 在 Spatial benchmark 上的跨 seed 一致性。CRM 已覆盖 Spatial 训练数据（all 20 LIBERO tasks）。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_spatial_obs_only_norm02_seed45.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"tmux_session\": \"eval-spatial-obs-only-norm02-seed45\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Spatial (10 tasks x 10 rollouts)\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T12:50:07.643Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T12:50:11.303Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T12:50:17.204819+00:00\"}]}, \"metrics\": {\"success_rate\": 0.34, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"successes\": 34}}, \"train-crm-k1-accg-object-seed42-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T15:40:51.279Z\", \"updated_at\": \"2026-05-19T12:48:29.290Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=0 python -u train_crm_k1.py --benchmark object --epochs 50 --batch_size 512 --lr 1e-3 --seed 42 --loss_mode multi --lambda_dir 0.1 --lambda_tri 0.05 --lambda_mag 0.01 --max_correction_norm 0.2 --wandb_project acr-vla-conformal-refinement --wandb_run_name crm-k1-v2-accg-multistage-object --auto 2>&1 | tee /root/acr-vla-conformal-refinement/logs/train_crm_k1_full.log\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:0\"], \"pid\": \"434871\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/train-crm-k1-accg-object-seed42-full.log\", \"submitted_at\": \"2026-05-17T15:40:50.814Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 162458.5, \"gpu_hours\": 45.13}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1_accg_full/crm_best.pt\", \"hypothesis\": \"K=1 CRM full training with multi-stage VLA feature fusion + composite loss (L2 + contrastive + uncertainty-weighted) on full object benchmark dataset. Scaled-up version of train-crm-k1-accg-object-seed42-v2 with complete training data.\", \"completed_at\": \"2026-05-19T12:48:29.290Z\"}, \"plan_701-precompute-k1-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:11:43.484Z\", \"updated_at\": \"2026-05-19T12:48:27.021Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 python -u src/precompute_k1.py --benchmark spatial --batch_size 4 --cache_dir /root/autodl-tmp/crm_cache_k1/ 2>&1 | tee logs/precompute_k1.log\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"649967\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/plan_701-precompute-k1-spatial.log\", \"submitted_at\": \"2026-05-17T14:11:42.695Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 167804.3, \"gpu_hours\": 46.61}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/precomputed/k1_spatial/\", \"hypothesis\": \"K=1 spatial benchmark precomputation: generate single-sample VLA action predictions and features for CRM K=1 training. Required preprocessing step before K=1 CRM can be trained on spatial tasks.\", \"completed_at\": \"2026-05-19T12:48:27.021Z\"}, \"plan_701-crm-k1-train\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:04:14.203Z\", \"updated_at\": \"2026-05-19T12:48:10.176Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && mkdir -p /root/autodl-tmp/checkpoints/crm_k1 && CUDA_VISIBLE_DEVICES=1 python -u src/train_crm_k1.py --auto --benchmark spatial --epochs 50 --batch_size 512 --lr 1e-3 --wandb_project acr-vla-conformal-refinement --wandb_run_name crm-k1-train-spatial --precompute_batch_size 4 --output_dir /root/autodl-tmp/checkpoints/crm_k1/ 2>&1 | tee logs/train_crm_k1.log\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:1\"], \"pid\": \"422526\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/plan_701-crm-k1-train.log\", \"submitted_at\": \"2026-05-17T14:04:13.752Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 168236.4, \"gpu_hours\": 46.73}, \"hypothesis\": \"K=1 CRM 训练：使用多阶段 VLA 特征融合 + 组合损失函数（L2 + contrastive + uncertainty-weighted），训练专门用于 K=1 单采样纠正的 CRM 模型。目标是超越 K=1 VLA-only baseline (10.8%)。\", \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_best.pt\", \"completed_at\": \"2026-05-19T12:48:10.176Z\"}, \"eval_obs_only_norm03_seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T22:59:53.216Z\", \"updated_at\": \"2026-05-19T12:48:06.312Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 48 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03_seed48.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"774538\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm03_seed48.json\", \"submitted_at\": \"2026-05-17T22:59:52.629Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 48, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 136093.7, \"gpu_hours\": 37.8}, \"conclusion\": \"success\", \"hypothesis\": \"obs_only CRM (ε=0.3) seed48 on LIBERO-Object. 补 magnitude curve obs_only ε=0.3 至 n=7。\", \"reproduce\": {\"finished_at\": \"2026-05-19T12:44:29.475Z\"}, \"metrics\": {\"success_rate\": 0.16, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"successes\": 16}, \"completed_at\": \"2026-05-19T12:48:06.312Z\"}, \"eval_obs_only_norm01_seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T22:59:51.090Z\", \"updated_at\": \"2026-05-19T12:48:03.869Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 48 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_obs_only_norm01_seed48.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"774337\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm01_seed48.json\", \"submitted_at\": \"2026-05-17T22:59:50.463Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 48, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 136093.4, \"gpu_hours\": 37.8}, \"conclusion\": \"success\", \"hypothesis\": \"obs_only CRM (ε=0.1) seed48 on LIBERO-Object. 补 magnitude curve obs_only ε=0.1 至 n=7。\", \"reproduce\": {\"finished_at\": \"2026-05-19T12:44:25.580Z\"}, \"metrics\": {\"success_rate\": 0.18, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"successes\": 18}, \"completed_at\": \"2026-05-19T12:48:03.869Z\"}, \"eval-lto-splitA-vla-only-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:56:16.472Z\", \"updated_at\": \"2026-05-19T12:48:01.446Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=1 timeout 57600 python -u evaluate.py --benchmark object --mode vla_only --task_names 'ketchup,milk,orange_juice,salad_dressing,tomato_sauce' --n_rollouts 10 --seed 42 --output_file /root/acr-vla-conformal-refinement/logs/eval_lto_splitA_vla_only_r3.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"989694\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-lto-splitA-vla-only-r3.log\", \"submitted_at\": \"2026-05-19T05:56:15.822Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 24705.6, \"gpu_hours\": 6.86}, \"hypothesis\": \"VLA-only baseline on LTO held-out 5 tasks r3 rerun. Second reproduction of LTO baseline SR=14%. Confirms v2 result consistency.\", \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"success_rate\": 0.14, \"n_tasks\": 5, \"n_rollouts\": 10, \"total_rollouts\": 50, \"successes\": 7}, \"completed_at\": \"2026-05-19T12:48:01.446Z\"}, \"eval-lto-splitA-vla-only-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:55:29.003Z\", \"updated_at\": \"2026-05-19T12:47:58.882Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=2 timeout 57600 python -u evaluate.py --benchmark object --mode vla_only --task_names 'ketchup,milk,orange_juice,salad_dressing,tomato_sauce' --n_rollouts 10 --seed 42 --output_file logs/eval_lto_splitA_vla_only_r2.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"976974\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-lto-splitA-vla-only-r2.log\", \"submitted_at\": \"2026-05-19T04:55:28.251Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 28350.6, \"gpu_hours\": 7.88}, \"hypothesis\": \"VLA-only baseline on 5 held-out tasks (ketchup, milk, orange_juice, salad_dressing, tomato_sauce). Bugfix r2: removed .replace(\\\"_\\\",\\\" \\\") that caused 3/5 task matching failures.\", \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"success_rate\": 0.14, \"n_tasks\": 5, \"n_rollouts\": 10, \"total_rollouts\": 50, \"successes\": 7}, \"completed_at\": \"2026-05-19T12:47:58.882Z\"}, \"eval-lto-splitA-heldout-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:55:26.507Z\", \"updated_at\": \"2026-05-19T12:47:56.312Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=1 timeout 57600 python -u evaluate.py --benchmark object --mode crm_obs_only --checkpoint /root/autodl-tmp/checkpoints/crm_lto_splitA_fixed/crm_best.pt --task_names 'ketchup,milk,orange_juice,salad_dressing,tomato_sauce' --n_rollouts 10 --seed 42 --K 5 --max_correction_norm 0.2 --output_file logs/eval_lto_splitA_heldout_r2.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"976768\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-lto-splitA-heldout-r2.log\", \"submitted_at\": \"2026-05-19T04:55:25.815Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 28350.5, \"gpu_hours\": 7.88}, \"hypothesis\": \"LTO split-A CRM (K=5, ε=0.2, obs_only) on 5 held-out tasks (ketchup, milk, orange_juice, salad_dressing, tomato_sauce). Bugfix r2: removed .replace(\\\"_\\\",\\\" \\\") that caused 3/5 task matching failures.\", \"conclusion\": \"negative\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"success_rate\": 0.02, \"n_tasks\": 5, \"n_rollouts\": 10, \"total_rollouts\": 50, \"successes\": 1}, \"completed_at\": \"2026-05-19T12:47:56.312Z\"}, \"crm-lto-splitA-train\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:13:30.382Z\", \"updated_at\": \"2026-05-19T12:47:52.436Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=2 python train_crm.py --benchmark object --cache_dir /root/autodl-tmp/crm_cache_v3 --input_mode obs_only --task_indices 0,1,2,3,4 --epochs 50 --batch_size 256 --lr 0.008 --seed 42 --output_dir /root/autodl-tmp/checkpoints/crm_lto_splitA/obs_only/ --hidden_dim 256 --val_split 0.1 --log_every 20 2>&1 | tee /root/runs/acr-vla-conformal-refinement/crm-lto-splitA-train.log\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"953358\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-lto-splitA-train.log\", \"submitted_at\": \"2026-05-19T03:13:29.745Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 34462.7, \"gpu_hours\": 9.57}, \"conclusion\": \"success\", \"hypothesis\": \"LTO Split A CRM training (obs_only, 5 tasks, task_indices 0-4). Predecessor to eval-lto-splitA-heldout experiments. Superseded by crm-lto-splitA-train-fixed (task_names matching).\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_lto_splitA/crm_best.pt\", \"completed_at\": \"2026-05-19T12:47:52.436Z\"}, \"eval-perdof-object-norm003-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:31:15.780Z\", \"updated_at\": \"2026-05-19T12:23:18.801Z\", \"hypothesis\": \"Per-DoF CRM (ε=0.03) seed48 on LIBERO-Object. 补 magnitude curve 最薄点 perdof ε=0.03 (当前 n=1)。timeout=16h。\", \"spec\": {\"command\": \"crm_perdof --benchmark object --seed 48 --K 10 --max_correction_norm 0.03 --n_rollouts 10 --timeout 57600\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"crm_perdof\", \"seed\": 48, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm003_seed48.json\", \"submitted_at\": \"2026-05-18T21:31:00Z\"}, \"metrics\": {\"success_rate\": 0.13, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:59:18.061Z\"}, \"eval-scalar-object-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:22:25.439Z\", \"updated_at\": \"2026-05-19T11:45:28.182Z\", \"hypothesis\": \"Scalar CRM seed45 rerun with n_rollouts=10 for consistency. Original seed45 used n_rollouts=20. Current scalar: [9,10,6,9] mean=8.5%\", \"parent\": \"eval-scalar-object-seed45\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_scalar_seed45_r2.json\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"464950\", \"log_path\": \"logs/eval_object_scalar_seed45_r2.json\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_scalar_unc\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"eval_data\": \"LIBERO object\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\"}, \"metrics\": {\"overall_success_rate\": 0.07, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T11:45:28.182Z\"}, \"eval-obs-only-spatial-norm02-k5-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:08:33.036Z\", \"updated_at\": \"2026-05-19T11:34:16.077Z\", \"spec\": {\"command\": \"K=5 obs_only spatial ε=0.2 seed43\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": \"786306\", \"log_path\": \"logs/eval_spatial_obs_only_norm02_k5_seed43.json\", \"submitted_at\": \"2026-05-19T04:08:32.396Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 43, \"wall_clock_seconds\": 26743.7, \"gpu_hours\": 7.43}, \"hypothesis\": \"K=5 obs_only CRM (ε=0.2) on LIBERO-Spatial seed43. D066 K=5 Spatial multi-benchmark evidence for cross-benchmark generalization claim.\", \"metrics\": {\"success_rate\": 0.32, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:34:16.077Z\"}, \"eval-obs-only-object-norm02-k5-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:04:44.384Z\", \"updated_at\": \"2026-05-19T11:34:12.397Z\", \"spec\": {\"command\": \"K=5 obs_only ε=0.2 seed48\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:2\"], \"pid\": \"784377\", \"log_path\": \"logs/eval_object_obs_only_norm02_k5_seed48.json\", \"submitted_at\": \"2026-05-19T04:04:42.324Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 48, \"wall_clock_seconds\": 26970.1, \"gpu_hours\": 7.49}, \"hypothesis\": \"K=5 obs_only CRM (ε=0.2) seed48 on LIBERO-Object. D066 K=5 primary configuration 补种到 n=7 统计力度增强。\", \"metrics\": {\"success_rate\": 0.18, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:34:12.398Z\"}, \"eval-obs-only-spatial-norm02-k5-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:08:18.656Z\", \"updated_at\": \"2026-05-19T11:31:39.191Z\", \"spec\": {\"command\": \"K=5 obs_only spatial seed42\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:5\"], \"pid\": \"717974\", \"log_path\": \"logs/eval_spatial_obs_only_norm02_k5_seed42.json\", \"submitted_at\": \"2026-05-19T04:08:17.987Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"data_path\": \"LIBERO-Spatial\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 42, \"wall_clock_seconds\": 26601.2, \"gpu_hours\": 7.39}, \"metrics\": {\"success_rate\": 0.35, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"hypothesis\": \"K=5 obs_only CRM (ε=0.2) on LIBERO-Spatial seed42. D066 K=5 Spatial multi-benchmark evidence for cross-benchmark generalization claim.\", \"completed_at\": \"2026-05-19T11:31:39.191Z\"}, \"eval-obs-only-object-norm02-k5-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:29:24.718Z\", \"updated_at\": \"2026-05-19T11:30:55.300Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 46 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_k5_seed46.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"956475\", \"log_path\": \"logs/eval_object_obs_only_norm02_k5_seed46.json\", \"submitted_at\": \"2026-05-19T03:31:41.175Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"tmux_session\": \"eval-obs-only-object-norm02-k5-seed46\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 46, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 28569.4, \"gpu_hours\": 7.94}, \"hypothesis\": \"K=5 obs_only CRM (ε=0.2) seed46 on LIBERO-Object. 补 K=5 primary configuration 到 n≥5。D066 统计力度增强。\", \"metrics\": {\"success_rate\": 0.16, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:27:50.610Z\"}, \"eval-lto-splitA-vla-only-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:19:21.005Z\", \"updated_at\": \"2026-05-19T11:30:43.198Z\", \"hypothesis\": \"VLA-only baseline on LTO held-out 5 tasks (ketchup, milk, orange_juice, salad_dressing, tomato_sauce). Control group for Leave-Task-Out Split A eval. Retry after .replace task matching bug fix.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=2 timeout 57600 python -u evaluate.py --benchmark object --mode vla_only --task_names 'ketchup,milk,orange_juice,salad_dressing,tomato_sauce' --n_rollouts 10 --seed 42 --output_file logs/eval_lto_splitA_vla_only_r2.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"log_path\": \"/root/acr-vla-conformal-refinement/src/logs/eval_lto_splitA_vla_only_r2.json\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"tmux_session\": \"eval-lto-splitA-vla-only-r2\", \"data_path\": \"LIBERO-Object\", \"data_count\": 50, \"model_name\": \"SmolVLA_vla_only\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"LIBERO-Object held-out (5 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A\"}, \"metrics\": {\"success_rate\": 0.14, \"n_tasks\": 5, \"n_rollouts\": 10, \"total_rollouts\": 50, \"successes\": 7}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:27:47.248Z\"}, \"eval-lto-splitA-heldout-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:19:18.968Z\", \"updated_at\": \"2026-05-19T11:30:33.951Z\", \"hypothesis\": \"Leave-Task-Out generalization: CRM trained on Split A (5 tasks) evaluated on held-out 5 tasks (ketchup, milk, orange_juice, salad_dressing, tomato_sauce). K=5 ε=0.2. Retry after .replace task matching bug fix.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=1 timeout 57600 python -u evaluate.py --benchmark object --mode crm_obs_only --checkpoint /root/autodl-tmp/checkpoints/crm_lto_splitA_fixed/crm_best.pt --task_names 'ketchup,milk,orange_juice,salad_dressing,tomato_sauce' --n_rollouts 10 --seed 42 --K 5 --max_correction_norm 0.2 --output_file logs/eval_lto_splitA_heldout_r2.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"log_path\": \"/root/acr-vla-conformal-refinement/src/logs/eval_lto_splitA_heldout_r2.json\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"tmux_session\": \"eval-lto-splitA-heldout-r2\", \"data_path\": \"LIBERO-Object\", \"data_count\": 50, \"model_name\": \"SmolVLA+CRM_lto_splitA\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_lto_splitA_fixed/crm_best.pt\", \"eval_data\": \"LIBERO-Object held-out (5 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_lto_splitA_fixed/crm_best.pt\"}, \"metrics\": {\"success_rate\": 0.02, \"n_tasks\": 5, \"n_rollouts\": 10, \"total_rollouts\": 50, \"successes\": 1}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T11:27:43.439Z\"}, \"eval-perdof-object-default-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:44.467Z\", \"updated_at\": \"2026-05-19T11:30:18.282Z\", \"hypothesis\": \"Per-DoF CRM (ε=default/unlimited) seed47 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=4 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_object_perdof_default_seed47.json\", \"server\": \"bjb2-28827\", \"seed\": 47, \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"openvla-7b+crm_perdof\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"logs/eval_object_perdof_default_seed47.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T11:24:52.163Z\", \"metrics\": {\"success_rate\": 0, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束, success_rate=0%\"}, \"eval-perdof-object-norm03-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:47.310Z\", \"updated_at\": \"2026-05-19T11:30:17.012Z\", \"hypothesis\": \"Per-DoF CRM (ε=0.3) seed47 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=5 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed47.json\", \"server\": \"bjb2-28827\", \"seed\": 47, \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"openvla-7b+crm_perdof\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"logs/eval_object_perdof_norm03_seed47.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:24:49.647Z\", \"metrics\": {\"success_rate\": 0.05, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\"}, \"eval-obs-only-object-default-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:41.596Z\", \"updated_at\": \"2026-05-19T11:30:15.785Z\", \"hypothesis\": \"Obs-only CRM (ε=default/unlimited) seed48 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 48 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed48.json\", \"server\": \"bjb2-28827\", \"seed\": 48, \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"openvla-7b+crm_obs_only\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"logs/eval_object_obs_only_default_seed48.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:24:56.050Z\", \"metrics\": {\"success_rate\": 0.17, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\"}, \"eval-perdof-object-norm003-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:35.770Z\", \"updated_at\": \"2026-05-19T11:30:14.493Z\", \"hypothesis\": \"Per-DoF CRM (ε=0.03) seed46 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed46.json\", \"server\": \"bjb2-28827\", \"seed\": 46, \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"openvla-7b+crm_perdof\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"logs/eval_object_perdof_norm003_seed46.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:24:58.897Z\", \"metrics\": {\"success_rate\": 0.09, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\"}, \"eval-perdof-object-norm005-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:34.428Z\", \"updated_at\": \"2026-05-19T11:29:18.036Z\", \"hypothesis\": \"Per-DoF CRM (ε=0.05) seed46 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005_seed46.json\", \"server\": \"bjb1-32546\", \"seed\": 46, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\", \"notes\": \"bjb1-32546 GPU process dead, no JSON output\"}, \"metrics\": {\"success_rate\": 0.11, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:25:23.296Z\"}, \"eval-perdof-object-norm003-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:15:14.634Z\", \"updated_at\": \"2026-05-19T11:28:09.358Z\", \"hypothesis\": \"perdof CRM (ε=0.03) seed45 on LIBERO-Object. 补 magnitude curve 薄数据点：perdof ε=0.03 当前 n=1 (seed42=14%)，seed43/44 已在跑。验证 per-DOF correction 在极低 norm 下表现。\", \"server\": \"bjb1-32546\", \"gpu\": \"cuda:5\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb1-32546\", \"gpu\": \"cuda:5\", \"started_at\": \"2026-05-18T15:16:48.731Z\", \"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed45.json\"}, \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed45.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"652406\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-18T15:16:51.497Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A\", \"notes\": \"bjb1-32546 GPU process dead, no JSON output\", \"wall_clock_seconds\": 72677.9, \"gpu_hours\": 20.19}, \"pid\": \"652406\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed45.log\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T11:28:09.358Z\"}, \"eval-obs-only-object-norm02-k5-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:29:27.251Z\", \"updated_at\": \"2026-05-19T11:27:53.132Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 47 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_k5_seed47.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"956741\", \"log_path\": \"logs/eval_object_obs_only_norm02_k5_seed47.json\", \"submitted_at\": \"2026-05-19T03:31:43.769Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"tmux_session\": \"eval-obs-only-object-norm02-k5-seed47\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 47, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 28569.4, \"gpu_hours\": 7.94}, \"hypothesis\": \"K=5 obs_only CRM (ε=0.2) seed47 on LIBERO-Object. 补 K=5 primary configuration 到 n≥6。D066 统计力度增强。\", \"metrics\": {\"success_rate\": 0.13, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:27:53.132Z\"}, \"eval-perdof-object-norm01-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:57:04.076Z\", \"updated_at\": \"2026-05-19T11:25:28.189Z\", \"hypothesis\": \"Per-DoF CRM (ε=0.1) seed48 on LIBERO-Object. 补 perdof ε=0.1 至 n=7，替代被 kill 的 obs_only_norm03_seed46 重复实验的 GPU slot。\", \"spec\": {\"command\": \"crm_perdof --benchmark object --seed 48 --K 10 --max_correction_norm 0.1 --n_rollouts 10\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"crm_perdof\", \"seed\": 48, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"/root/logs/eval_object_perdof_norm01_seed48.json\"}, \"metrics\": {\"success_rate\": 0.12, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束. JSON 位于 /root/logs/ 而非项目 logs/ 目录\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:25:28.189Z\"}, \"eval-obs-only-object-default-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:37.333Z\", \"updated_at\": \"2026-05-19T11:25:18.480Z\", \"hypothesis\": \"Obs-only CRM (ε=default) seed47 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed47.json\", \"server\": \"bjb1-32546\", \"seed\": 47, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"logs/eval_object_obs_only_default_seed47.log\"}, \"metrics\": {\"success_rate\": 0.16, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:25:18.480Z\"}, \"eval-perdof-object-norm03-seed46\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T11:21:58.288Z\", \"updated_at\": \"2026-05-19T11:25:13.541Z\", \"hypothesis\": \"Per-DoF CRM (ε=0.3) seed46 on LIBERO-Object. GPU 双跑补 seed。\", \"completed_at\": \"2026-05-17T11:26:50.317Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"metrics\": {\"failure_reason\": \"Process exited after ~2 min during env loading, no evaluation results produced. No JSON output. Likely OOM or SIGHUP kill (exit code 129).\", \"n_rollouts\": 0}}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed46.json\", \"server\": \"bjb1-32546\", \"seed\": 46, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"logs/eval_object_perdof_norm03_seed46.log\"}, \"metrics\": {\"success_rate\": 0.04, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\", \"conclusion\": \"success\"}, \"eval-obs-only-object-norm03-seed46\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T10:28:22.831Z\", \"updated_at\": \"2026-05-19T11:25:11.008Z\", \"hypothesis\": \"Obs-only CRM (ε=0.3) seed46 on LIBERO-Object. GPU 双跑补 seed。\", \"completed_at\": \"2026-05-17T23:30:58.329Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.17, \"successes\": 17, \"total\": 100}}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03_seed46.json\", \"server\": \"bjb1-32546\", \"seed\": 46, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"logs/eval_object_obs_only_norm03_seed46.log\"}, \"metrics\": {\"success_rate\": 0.17, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\", \"conclusion\": \"success\"}, \"eval-scalar-object-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:46.008Z\", \"updated_at\": \"2026-05-19T11:25:07.860Z\", \"hypothesis\": \"Scalar CRM (ε=0.1) seed46 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=4 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_scalar_seed46.json\", \"server\": \"bjb1-32546\", \"seed\": 46, \"model_name\": \"SmolVLA+CRM_scalar\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"log_path\": \"logs/eval_object_scalar_seed46.log\"}, \"metrics\": {\"success_rate\": 0.09, \"total_rollouts\": 100}, \"notes\": \"采集时间 2026-05-19, 进程已自然结束\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:25:07.860Z\"}, \"eval-obs-only-object-norm003-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:44:44.161Z\", \"updated_at\": \"2026-05-19T05:16:02.877Z\", \"hypothesis\": \"obs_only CRM (ε=0.03) seed45 on LIBERO-Object. Retry with timeout=16h after r1 timed out. 补 magnitude curve 最薄点 ε=0.03。\", \"spec\": {\"command\": \"timeout 57600 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_obs_only_norm003_seed45.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"tmux_session\": \"eval-obs-only-norm003-seed45-t16\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T04:44:28.725Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T04:44:32.021Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T04:44:37.585122+00:00\"}]}, \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"/root/logs/eval_object_obs_only_norm003_seed45.log\", \"metrics\": {\"partial\": true, \"tasks_completed\": \"5/10\", \"task6_partial\": \"5/10 rollouts\", \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0}, \"partial_avg_sr\": 0.1, \"failure_mode\": \"process killed silently mid-eval, no error in log, no JSON output\"}}, \"eval-lto-splitA-vla-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:35:02.089Z\", \"updated_at\": \"2026-05-19T05:13:20.212Z\", \"spec\": {\"command\": \"killed (buggy .replace task matching)\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"970894\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-19T04:35:01.423Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 50, \"model_name\": \"SmolVLA_vla_only\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"LIBERO-Object held-out (5 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval-only, killed due to task matching bug)\", \"wall_clock_seconds\": 1469.7, \"gpu_hours\": 0.41}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T04:59:31.167Z\", \"hypothesis\": \"VLA-only baseline on LTO held-out 5 tasks (ketchup, milk, orange_juice, salad_dressing, tomato_sauce). Control group for Leave-Task-Out Split A eval.\"}, \"eval-lto-splitA-heldout\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T04:34:59.607Z\", \"updated_at\": \"2026-05-19T05:13:18.481Z\", \"spec\": {\"command\": \"killed (buggy .replace task matching)\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"970686\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-19T04:34:58.943Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 50, \"model_name\": \"SmolVLA+CRM_lto_splitA\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_lto_splitA_fixed/crm_best.pt\", \"eval_data\": \"LIBERO-Object held-out (5 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A (eval-only, killed due to task matching bug)\", \"wall_clock_seconds\": 1469.4, \"gpu_hours\": 0.41}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T04:59:28.321Z\", \"hypothesis\": \"Leave-Task-Out generalization: CRM trained on Split A (5 tasks) evaluated on held-out 5 tasks (ketchup, milk, orange_juice, salad_dressing, tomato_sauce). K=5 ε=0.2. If SR > VLA-only on held-out tasks, CRM generalizes beyond training distribution.\"}, \"eval-obs-only-object-norm005-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:53:33.612Z\", \"updated_at\": \"2026-05-19T04:58:44.483Z\", \"hypothesis\": \"obs_only CRM (ε=0.05) seed46 on LIBERO-Object. GPU 双跑补 obs_only ε=0.05 seed (n=4→5)。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_obs_only_norm005_seed46.json 2>&1 | tee logs/eval_object_obs_only_norm005_seed46.log\", \"server\": \"bjb1-18228\", \"seed\": 46, \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"crm_v3_norm/obs_only/crm_best.pt\", \"checkpoint_path\": \"N/A (eval-only, killed)\", \"log_path\": \"N/A\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T04:58:44.483Z\"}, \"eval-perdof-object-norm03-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:15:14.835Z\", \"updated_at\": \"2026-05-19T04:58:40.993Z\", \"hypothesis\": \"perdof CRM (ε=0.3) seed48 on LIBERO-Object. 补 perdof ε=0.3 至 n=7。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 48 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed48.json\", \"server\": \"bjb1-18228\", \"seed\": 48, \"model_name\": \"crm_v3_norm_perdof\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"N/A (eval-only, killed)\", \"log_path\": \"N/A\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T04:58:40.993Z\"}, \"eval-obs-only-object-norm003-seed49\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:09:03.172Z\", \"updated_at\": \"2026-05-19T04:58:36.864Z\", \"hypothesis\": \"obs_only CRM (ε=0.03) seed49 on LIBERO-Object. 补 magnitude curve 最薄点 ε=0.03 (当前 n=1)，第 6 个 seed 确保极低 norm 端统计可靠。\", \"spec\": {\"command\": \"crm_obs_only --benchmark object --seed 49 --K 10 --max_correction_norm 0.03 --n_rollouts 10\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"crm_obs_only\", \"seed\": 49, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"checkpoint_path\": \"N/A (eval-only, killed)\", \"log_path\": \"N/A\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T04:58:36.864Z\"}, \"crm-lto-splitA-train-fixed\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:27:23.594Z\", \"updated_at\": \"2026-05-19T04:32:49.103Z\", \"spec\": {\"command\": \"python train_crm.py --benchmark object --task_names alphabet_soup,bbq_sauce,butter,chocolate_pudding,cream_cheese --input_mode obs_only --epochs 50 --output_dir /root/autodl-tmp/checkpoints/crm_lto_splitA_fixed --seed 42\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"955547\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-lto-splitA-train-fixed.log\", \"submitted_at\": \"2026-05-19T03:27:22.886Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Leave-Task-Out Split A: CRM (obs_only) trained on 5 tasks (alphabet_soup, bbq_sauce, butter, chocolate_pudding, cream_cheese, 7499 samples) can generalize to held-out 5 tasks (ketchup, milk, orange_juice, salad_dressing, tomato_sauce). Uses --task_names string matching (bug-fixed, no numeric index).\", \"data_path\": \"/root/autodl-tmp/crm_cache_v3/object/\", \"data_count\": 7499, \"model_name\": \"crm_obs_only_lto_splitA\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_lto_splitA_fixed/crm_best.pt\", \"metrics\": {\"best_val_loss\": 0.091861}, \"wall_clock_seconds\": 3926.2, \"gpu_hours\": 1.09}, \"conclusion\": \"success\", \"hypothesis\": \"Leave-Task-Out Split A: CRM (obs_only) trained on 5 tasks (alphabet_soup, bbq_sauce, butter, chocolate_pudding, cream_cheese, 7499 samples) can generalize to held-out 5 tasks. Uses task_names string matching.\", \"completed_at\": \"2026-05-19T04:32:49.103Z\"}, \"eval-obs-only-object-norm003-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:15:10.585Z\", \"updated_at\": \"2026-05-19T04:32:33.294Z\", \"hypothesis\": \"obs_only CRM (ε=0.03) seed47 on LIBERO-Object. 补 magnitude curve ε=0.03 至 n=6。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_obs_only_norm003_seed47.json\", \"server\": \"bjb1-18228\", \"seed\": 47, \"model_name\": \"crm_v3_norm_obs_only\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"N/A (eval-only, killed)\", \"log_path\": \"N/A (killed before completion)\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T04:32:33.295Z\"}, \"eval-perdof-object-norm003-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:05:55.304Z\", \"updated_at\": \"2026-05-19T03:28:52.476Z\", \"hypothesis\": \"perdof CRM ε=0.03 seed43 on LIBERO-Object。magnitude curve 低 ε 端当前只有 seed42 (14%, n=1)，第二个 seed 增强统计。\", \"parent\": \"eval-mag-perdof-norm003-object\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed43.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:2\"], \"pid\": \"640615\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed43.log\", \"submitted_at\": \"2026-05-18T13:25:05.368Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A-eval\", \"wall_clock_seconds\": 50627.1, \"gpu_hours\": 14.06}, \"server\": \"bjb1-32546\", \"gpu\": \"cuda:2\", \"pid\": \"640615\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed43.log\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed43.json\", \"finished_at\": \"2026-05-19T03:25:56.586Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T03:26:06.809444+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.13, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T03:28:52.476Z\"}, \"eval-perdof-object-norm005-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:27:51.549Z\", \"updated_at\": \"2026-05-19T02:56:00.676Z\", \"hypothesis\": \"perdof CRM ε=0.05 seed43 on LIBERO-Object。magnitude curve 低 ε 端 perdof ε=0.05 当前只有 seed42 (14%, n=1)，第二个 seed 增强统计可靠性。\", \"parent\": \"eval-mag-perdof-norm005-object\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005_seed43.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": \"642296\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm005-seed43.log\", \"submitted_at\": \"2026-05-18T13:28:51.027Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"max_correction_norm\": 0.05, \"seed\": 43, \"benchmark\": \"object\", \"mode\": \"crm_perdof\", \"wall_clock_seconds\": 48429.6, \"gpu_hours\": 13.45}, \"server\": \"bjb1-32546\", \"gpu\": \"cuda:1\", \"pid\": \"642296\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm005-seed43.log\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005_seed43.json\", \"finished_at\": \"2026-05-19T02:35:05.529Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T02:35:13.418956+00:00\"}]}, \"metrics\": {\"success_rate\": 0.13, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.3, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T02:56:00.676Z\"}, \"eval-perdof-object-default-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:17:50.362Z\", \"updated_at\": \"2026-05-19T01:44:05.704Z\", \"hypothesis\": \"Perdof CRM without norm clipping (uncapped, actual norm ~1.42) causes catastrophic collapse on LIBERO-Object. seed42=0%, seed46=0%, seed44=0% (partial). seed43 confirms cross-seed consistency of collapse.\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_object_perdof_default_seed43.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"832702\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-default-seed43.log\", \"submitted_at\": \"2026-05-18T10:31:01.993Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 54783.7, \"gpu_hours\": 15.22}, \"metrics\": {\"success_rate\": 0, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only, no checkpoint)\", \"log_path\": \"bjb1-18228:/root/acr-vla-conformal-refinement/logs/eval_object_perdof_default_seed43.json\", \"completed_at\": \"2026-05-19T01:44:05.704Z\"}, \"eval-perdof-object-default-seed45\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T20:21:08.043Z\", \"updated_at\": \"2026-05-19T01:38:34.712Z\", \"completed_at\": \"2026-05-17T02:54:38.157Z\", \"hypothesis\": \"Perdof CRM without norm clipping (uncapped, actual norm ~1.42) causes catastrophic collapse on LIBERO-Object. seed42=0%, seed46=0%, seed44=0% (partial). seed45 confirms cross-seed consistency of collapse.\", \"parent\": \"crm-train-v2-perdof\", \"extra\": {\"previous_failure\": {\"conclusion\": \"killed\", \"metrics\": {\"kill_reason\": \"Sacrificed for P0 direct-correction experiment (no free GPU). Was at task 5/10 after 6h. Expected result: 0% (confirmed by seed42=0%, seed44 running on autodl-4090).\", \"partial_progress\": \"5/10 tasks, bbq_sauce 0% success\"}}}, \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_object_perdof_default_seed45.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": \"626277\", \"tmux_session\": \"eval_perdof_default_seed45\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof_uncapped\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"metrics\": {\"success_rate\": 0, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"log_path\": \"bjb1-32546:/root/acr-vla-conformal-refinement/logs/eval_object_perdof_default_seed45.log\", \"checkpoint_path\": \"N/A (eval-only, no checkpoint)\"}, \"eval-obs-only-object-norm02-k5-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:38.704Z\", \"updated_at\": \"2026-05-19T01:33:59.345Z\", \"hypothesis\": \"Obs-only CRM (ε=0.2, K=5) seed45 on LIBERO-Object. GPU 双跑补 seed。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 45 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_k5_seed45.json\", \"server\": \"bjb2-28827\", \"seed\": 45, \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"openvla-7b+crm_obs_only\"}, \"metrics\": {\"success_rate\": 0.15, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only, no checkpoint)\", \"log_path\": \"bjb2-28827:/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm02_k5_seed45.log\", \"completed_at\": \"2026-05-19T01:33:59.345Z\"}, \"eval-perdof-object-norm005-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:50:46.149Z\", \"updated_at\": \"2026-05-18T21:55:07.741Z\", \"hypothesis\": \"perdof CRM (ε=0.05) seed45 on LIBERO-Object. 补 magnitude curve：perdof ε=0.05 当前 n=2 (seed42=14%, seed44=9%), seed43 在跑。第 4 个 seed 强化低 ε 端 error bars。\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb2-28827\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-18T15:51:08.830Z\", \"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005_seed45.json\", \"finished_at\": \"2026-05-18T21:53:11.259Z\", \"training_hours\": 6.03}, \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005_seed45.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:0\"], \"pid\": \"598900\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm005-seed45.log\", \"submitted_at\": \"2026-05-18T15:51:11.483Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21723.3, \"gpu_hours\": 6.03}, \"pid\": \"598900\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm005-seed45.log\", \"failure_reason\": \"EXIT_CODE=124 (timeout — exceeded timeout_hours)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T21:53:14.790Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T21:53:20.362616+00:00\"}]}, \"notes\": \"失败原因: EXIT_CODE=124 timeout (wall_clock=6.03h, timeout_hours 过低) | 已知失败模式: LIBERO-Object 全量 eval 需 12-14h，6h timeout 不够 | 建议: 重提交 timeout_hours=16\"}, \"eval-obs-only-object-norm02-k5-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T10:27:12.596Z\", \"updated_at\": \"2026-05-18T21:05:50.448Z\", \"hypothesis\": \"obs_only CRM K=5 ε=0.2 seed44. Third seed for K-value curve (seed42=14%, seed43=19%, mean=16.5%). Variance 大 (5pp gap), 第三个 seed 对 K-value scaling narrative 至关重要。\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 44 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_k5_seed44.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"575334\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm02-k5-seed44.log\", \"submitted_at\": \"2026-05-18T13:02:07.891Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 29022.6, \"gpu_hours\": 8.06}, \"server\": \"bjb2-28827\", \"gpu\": \"cuda:2\", \"pid\": \"575334\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm02-k5-seed44.log\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 44 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_k5_seed44.json\", \"finished_at\": \"2026-05-18T20:50:04.112Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T20:50:11.696653+00:00\"}]}, \"metrics\": {\"success_rate\": 0.17, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only, no checkpoint)\", \"completed_at\": \"2026-05-18T21:05:50.448Z\"}, \"eval-perdof-object-norm003-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:31:41.748Z\", \"updated_at\": \"2026-05-18T19:14:55.968Z\", \"hypothesis\": \"perdof CRM ε=0.03 seed44 on LIBERO-Object。magnitude curve 低 ε 端 perdof ε=0.03 当前 seed42=14% (n=1)，seed43 已在跑。重试 r2 修正 python 路径。\", \"parent\": \"eval-perdof-object-norm003-seed44\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed44.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"855046\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed44-r2.log\", \"submitted_at\": \"2026-05-18T13:32:24.693Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 20543.8, \"gpu_hours\": 5.71}, \"server\": \"bjb1-18228\", \"gpu\": \"cuda:2\", \"pid\": \"855046\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed44-r2.log\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed44.json\", \"finished_at\": \"2026-05-18T19:14:49.922Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T19:14:48.505Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:14:58.108020+00:00\"}]}}, \"eval-perdof-object-norm01-seed42\": {\"status\": \"DEPLOYED\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:53:01.705Z\", \"updated_at\": \"2026-05-18T18:53:10.563Z\", \"hypothesis\": \"perdof CRM with ε=0.1 on LIBERO-Object seed42. Magnitude curve comparison point for perdof variant.\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_perdof_norm01_seed42.json\", \"server\": \"bjb2-28827\", \"data_path\": \"/root/acr-vla-conformal-refinement/src/evaluate.py\", \"data_count\": \"10 rollouts x 10 tasks\", \"model_name\": \"crm_perdof\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T02:11:22.573Z\", \"metrics\": {\"success_rate\": 0.11, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}}, \"eval-obs-only-object-norm01-seed42\": {\"status\": \"DEPLOYED\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:53:00.645Z\", \"updated_at\": \"2026-05-18T18:53:09.494Z\", \"hypothesis\": \"obs_only CRM with ε=0.1 on LIBERO-Object seed42. Intermediate norm point for magnitude curve.\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_obs_only_norm01_seed42.json\", \"server\": \"bjb2-28827\", \"data_path\": \"/root/acr-vla-conformal-refinement/src/evaluate.py\", \"data_count\": \"10 rollouts x 10 tasks\", \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T02:11:19.115Z\", \"metrics\": {\"success_rate\": 0.19, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}}, \"eval-obs-only-object-norm01-seed46-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T10:33:39.698Z\", \"updated_at\": \"2026-05-18T16:48:10.654Z\", \"hypothesis\": \"obs_only CRM (ε=0.1) seed46 on LIBERO-Object. Retry r3. Supplements magnitude curve ε=0.1 data. seed42=19%, seed43=12%, seed44=16%, seed45=14%.\", \"spec\": {\"command\": \"crm_obs_only --seed 46 --K 10 --max_correction_norm 0.1\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:3\"], \"pid\": \"562396\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 46, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"failure_reason\": \"startup recovery: process dead, no active cron monitor\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T16:26:17.222Z\", \"metrics\": {\"success_rate\": 0.18, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}}, \"eval-perdof-object-norm005-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:31:56.813Z\", \"updated_at\": \"2026-05-18T15:18:13.193Z\", \"spec\": {\"command\": \"crm_perdof --seed 44 --K 10 --max_correction_norm 0.05\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:2\"], \"pid\": \"553052\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm005-seed44.log\", \"submitted_at\": \"2026-05-17T23:31:56.266Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"wall_clock_seconds\": 56776.9, \"gpu_hours\": 15.77}, \"hypothesis\": \"perdof CRM (ε=0.05) seed44 on LIBERO-Object. 补充 Figure 2 低 norm 段 perdof 数据。与 obs_only norm005 seed44 配对对比。\", \"reproduce\": {\"finished_at\": \"2026-05-18T12:34:49.939Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T12:34:56.300941+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.09, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"per_task\": {\"pick_up_the_alphabet_soup_and_place_it_in_the_basket\": 0, \"pick_up_the_cream_cheese_and_place_it_in_the_basket\": 0, \"pick_up_the_salad_dressing_and_place_it_in_the_basket\": 0.2, \"pick_up_the_bbq_sauce_and_place_it_in_the_basket\": 0.2, \"pick_up_the_ketchup_and_place_it_in_the_basket\": 0, \"pick_up_the_tomato_sauce_and_place_it_in_the_basket\": 0, \"pick_up_the_butter_and_place_it_in_the_basket\": 0, \"pick_up_the_milk_and_place_it_in_the_basket\": 0, \"pick_up_the_chocolate_pudding_and_place_it_in_the_basket\": 0.3, \"pick_up_the_orange_juice_and_place_it_in_the_basket\": 0.2}}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"completed_at\": \"2026-05-18T15:18:13.193Z\"}, \"eval-vla-only-object-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T11:44:42.438Z\", \"updated_at\": \"2026-05-18T14:17:30.462Z\", \"hypothesis\": \"VLA-only baseline seed45 rerun with n_rollouts=10 for consistency. Original seed45 used n_rollouts=20. Current VLA-only: [12,12,10,9,13] mean=11.2%\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python -u src/evaluate.py --mode vla_only --benchmark object --n_rollouts 10 --seed 45 --K 1 --output_file logs/eval_object_vla_only_seed45_r2.json\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:1\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA (VLA-only)\", \"seed\": 45, \"pid\": 839546, \"tmux_session\": \"eval_vla_only_seed45_r2\"}, \"metrics\": {\"overall_success_rate\": 0.11, \"n_tasks\": 10, \"n_rollouts_per_task\": 10, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.3, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.2, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.1, \"orange_juice\": 0.2}}, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_vla_only_seed45_r2.log\", \"checkpoint_path\": \"N/A (eval only)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T14:17:30.462Z\"}, \"eval-perdof-object-norm003-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:27:53.154Z\", \"updated_at\": \"2026-05-18T13:31:57.990Z\", \"hypothesis\": \"perdof CRM ε=0.03 seed44 on LIBERO-Object。magnitude curve 低 ε 端 perdof ε=0.03 当前 seed42=14% (n=1)，seed43 已在跑。第三个 seed 进一步增强统计。\", \"parent\": \"eval-mag-perdof-norm003-object\", \"spec\": {\"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed44.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"853859\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed44.log\", \"submitted_at\": \"2026-05-18T13:31:56.791Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"bjb1-18228\", \"gpu\": \"cuda:2\", \"pid\": \"unknown\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm003-seed44.log\", \"reproduce\": {\"command\": \"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_perdof_norm003_seed44.json\", \"finished_at\": \"2026-05-18T13:29:15.735Z\"}, \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T13:29:19.018Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T13:29:24.215222+00:00\"}]}, \"notes\": \"EXIT_CODE=127, python not found. bjb1-18228 需用 /root/miniconda3/bin/python 而非 bare python.\"}, \"eval-obs-only-object-norm03-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:02:40.444Z\", \"updated_at\": \"2026-05-18T13:27:03.418Z\", \"hypothesis\": \"obs_only CRM (ε=0.3) seed48 on LIBERO-Object. 补充 magnitude curve high-norm 段 seed48 数据。扩展 error bars。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 48 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03_seed48.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": 774538, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only_v3_norm\", \"seed\": 48, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T13:20:28.460Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T13:20:31.564Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T13:20:37.041564+00:00\"}]}, \"metrics\": {\"success_rate\": 0.16, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100}, \"checkpoint_path\": \"N/A (eval only)\"}, \"eval-obs-only-object-norm02-k5-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T04:37:18.401Z\", \"updated_at\": \"2026-05-18T12:39:30.555Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 43 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_k5_seed43.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"527465\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm02-k5-seed43.log\", \"submitted_at\": \"2026-05-18T04:37:17.870Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"SmolVLA+CRM_obs_only\", \"seed\": 43, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"wall_clock_seconds\": 28932.7, \"gpu_hours\": 8.04}, \"hypothesis\": \"obs_only CRM K=5 ε=0.2 seed43. Second seed for K-value curve (seed42=14%). Director highest priority.\", \"reproduce\": {\"finished_at\": \"2026-05-18T12:33:47.520Z\"}, \"metrics\": {\"success_rate\": 0.19, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.1, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0.1, \"tomato_sauce\": 0.2, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.5, \"orange_juice\": 0.3}}, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm02_k5_seed43.json\", \"checkpoint_path\": \"N/A (eval only)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T12:39:30.555Z\"}, \"eval-perdof-object-norm01-seed42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T02:32:26.297Z\", \"updated_at\": \"2026-05-18T12:33:45.335Z\", \"hypothesis\": \"perdof CRM with max_correction_norm=0.1 on LIBERO-Object seed42. Rerun of failed eval-perdof-object-norm01-seed42. PID 497642 on cuda:3, started 07:52 UTC.\", \"parent\": \"eval-perdof-object-norm01-seed42\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_perdof_norm01_seed42.json\", \"server\": \"bjb2-28827\", \"data_path\": \"/root/acr-vla-conformal-refinement/src/evaluate.py\", \"data_count\": \"10 rollouts x 10 tasks\", \"model_name\": \"crm_perdof\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T12:33:45.336Z\"}, \"eval-obs-only-object-norm01-seed42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T02:32:25.342Z\", \"updated_at\": \"2026-05-18T12:33:41.666Z\", \"hypothesis\": \"obs_only CRM with max_correction_norm=0.1 on LIBERO-Object seed42. Rerun of failed eval-obs-only-object-norm01-seed42. PID 497445 on cuda:1, started 07:52 UTC.\", \"parent\": \"eval-obs-only-object-norm01-seed42\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_obs_only_norm01_seed42.json\", \"server\": \"bjb2-28827\", \"data_path\": \"/root/acr-vla-conformal-refinement/src/evaluate.py\", \"data_count\": \"10 rollouts x 10 tasks\", \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T12:33:41.666Z\"}, \"eval-perdof-object-norm02-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:36:46.839Z\", \"updated_at\": \"2026-05-18T10:56:45.558Z\", \"hypothesis\": \"Perdof CRM with norm clipping ε=0.2 provides controlled corrections that preserve baseline policy behavior on LIBERO-Object. Expected SR ~10% (similar to other seeds 42/44/45/46/47 at 9-12%).\", \"spec\": {\"command\": \"crm_perdof --seed 43 --K 10 --max_correction_norm 0.2\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": \"535595\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\"}, \"metrics\": {\"success_rate\": 0.09, \"n_tasks\": 10, \"n_rollouts\": 10}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm02_seed43_bjb1-32546.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T10:56:45.558Z\"}, \"eval-perdof-object-norm01-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:51:19.181Z\", \"updated_at\": \"2026-05-18T07:05:38.605Z\", \"hypothesis\": \"perdof CRM (ε=0.1) seed=46 on LIBERO Object. Extends perdof low-norm data (seed42=11%, seed44/45 running). At ε=0.1 perdof is in its \\\"safe zone\\\" (tight bound masks noisy corrections). Paired with obs_only seed46 for direct comparison at same seed.\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_perdof_norm01_seed46.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": \"393633\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm01_seed46.json\", \"submitted_at\": \"2026-05-17T06:51:36.171Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_perdof_v3_norm\", \"seed\": 46, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 87240.0, \"gpu_hours\": 24.23}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T07:05:36.145Z\", \"metrics\": {\"overall_success_rate\": 0.1}}, \"eval-obs-only-object-norm01-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:01:52.970Z\", \"updated_at\": \"2026-05-18T07:05:03.603Z\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 python src/evaluate.py --mode crm_obs_only --max_correction_norm 0.1 --k 10 --seed 45 --benchmark object --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_norm01_seed45.json > logs/eval_object_obs_only_norm01_seed45.log 2>&1\", \"server\": \"bjb1-18228\", \"gpu_id\": \"cuda:0\", \"model_name\": \"crm_obs_only\", \"seed\": 45, \"data_path\": \"LIBERO object benchmark\", \"data_count\": -1, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object\", \"hypothesis\": \"obs_only CRM norm=0.1 seed=45 on LIBERO object. Multi-seed magnitude curve data point. seed42=19%.\"}, \"pid\": 474319, \"hypothesis\": \"obs_only CRM (ε=0.1) seed=45 on LIBERO Object. 验证 obs_only 在低 norm (0.1) 的稳定性。seed42 在 0.1 为 19%，如果一致则确认 obs_only 全 norm 范围鲁棒。\", \"conclusion\": \"success\", \"notes\": \"PID 474319 died, GPU idle 28h+. Ghost experiment — process dead but registry not updated.\", \"completed_at\": \"2026-05-17T13:31:33.316Z\", \"metrics\": {\"overall_success_rate\": 0.14}}, \"eval-obs-only-object-norm02-k5-seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T13:34:40.971Z\", \"updated_at\": \"2026-05-18T07:05:02.646Z\", \"hypothesis\": \"obs_only CRM (ε=0.2, K=5) seed42 on LIBERO-Object. K sweep 实验：K=5 vs K=10 (22%) 比较，验证 sample count 对 selection quality 的影响。若 K=5 显著低于 K=10，说明足够的 candidate 多样性对 CRM selection 关键。\", \"reproduce\": {\"finished_at\": \"2026-05-17T18:32:21.424Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"completed_at\": \"2026-05-17T18:32:28.770Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T18:32:40.928533+00:00\"}], \"previous_failure\": {\"conclusion\": \"killed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_k5_seed42.json\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"SmolVLA+CRM_obs_only_v3_norm\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.14}}, \"eval-perdof-object-default-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:21:54.338Z\", \"updated_at\": \"2026-05-18T07:05:01.672Z\", \"hypothesis\": \"perdof CRM (default norm, 无裁剪) seed46 on LIBERO-Object. 验证 perdof 在 uncapped norm 下的灾难性崩溃（seed42=0%）是否跨 seed 一致。支撑 obs_only > perdof claim。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=5 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_object_perdof_default_seed46.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": 423767, \"seed\": 46, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_default_seed46.json\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"overall_sr\": 0, \"per_task_sr\": {\"pick_up_the_alphabet_soup_and_place_it_in_the_basket\": 0, \"pick_up_the_cream_cheese_and_place_it_in_the_basket\": 0, \"pick_up_the_salad_dressing_and_place_it_in_the_basket\": 0, \"pick_up_the_bbq_sauce_and_place_it_in_the_basket\": 0, \"pick_up_the_ketchup_and_place_it_in_the_basket\": 0, \"pick_up_the_tomato_sauce_and_place_it_in_the_basket\": 0, \"pick_up_the_butter_and_place_it_in_the_basket\": 0, \"pick_up_the_milk_and_place_it_in_the_basket\": 0, \"pick_up_the_chocolate_pudding_and_place_it_in_the_basket\": 0, \"pick_up_the_orange_juice_and_place_it_in_the_basket\": 0}}}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T01:27:04.768Z\", \"metrics\": {\"overall_success_rate\": 0}}, \"eval-perdof-object-default-seed44\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T07:18:01.200Z\", \"updated_at\": \"2026-05-18T06:19:59.229Z\", \"hypothesis\": \"perdof CRM (default norm ~1.42) seed=44 on LIBERO Object. 验证 perdof 在 uncapped norm 下的 catastrophic collapse（seed42=0%）。为 magnitude curve 提供第二个 seed 的 default 数据点。\", \"reproduce\": {\"finished_at\": \"2026-05-17T07:20:12.857Z\"}, \"failure_reason\": \"EXIT_CODE=124 (timeout — exceeded timeout_hours)\", \"completed_at\": \"2026-05-17T07:20:15.008Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T07:20:19.307187+00:00\"}], \"previous_failure\": {\"conclusion\": \"negative\", \"metrics\": {\"overall_sr\": 0, \"total_successes\": 0, \"total_rollouts\": 90, \"tasks_completed\": 9, \"note\": \"Task 10 not started due to 24h timeout. 0/90 rollouts succeeded. Catastrophic collapse at unclipped norm.\", \"seed\": 44, \"mode\": \"crm_perdof\", \"benchmark\": \"object\", \"max_correction_norm\": \"default (~1.42)\"}, \"notes\": \"Timeout (EXIT_CODE=124, 24h) but partial results conclusive: 0/90 rollouts = 0% SR across 9/10 tasks. Task 10 not started. Confirms catastrophic collapse at unclipped norm, consistent with seed42=0%. Every rollout hit max_steps=300 (agent unable to complete any task), causing the timeout.\"}}, \"notes\": \"Timeout (EXIT_CODE=124, 24h) but partial results conclusive: 0/90 rollouts = 0% SR across 9/10 tasks. Task 10 not started. Confirms catastrophic collapse at unclipped norm, consistent with seed42=0%. Every rollout hit max_steps=300 (agent unable to complete any task), causing the timeout.\", \"conclusion\": \"negative\", \"metrics\": {\"overall_sr\": 0, \"total_successes\": 0, \"total_rollouts\": 90, \"tasks_completed\": 9, \"note\": \"Partial 9/10 tasks, 0/90 rollouts. Accepted as collapse evidence per Director decision 2026-05-18.\"}, \"spec\": {\"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"partial results from previous run, 0/90 rollouts across 9/10 tasks\", \"server\": \"autodl-4090 (previous run)\", \"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"model_name\": \"crm_perdof\", \"seed\": 44, \"data_path\": \"LIBERO-Object\", \"data_count\": 90}}, \"eval-mag-perdof-norm02\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:16:13.281Z\", \"updated_at\": \"2026-05-18T05:54:22.364Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --benchmark spatial --mode acr_vla --max_correction_norm 0.2 --n_rollouts 10 --K 10 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_mag_perdof_norm02.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA + CRM-v3-norm-perdof\", \"seed\": 42, \"checkpoint_source\": \"crm-train-v3-norm-perdof\", \"eval_data\": \"LIBERO spatial\"}, \"gpu\": \"bjb2-28827:cuda:2\", \"pid\": 13728, \"metrics\": {\"tasks_done\": \"6/10\", \"partial_results\": {\"T0_between_plate_ramekin\": \"60%\", \"T1_next_to_ramekin\": \"90%\", \"T2_table_center\": \"0%\", \"T3_on_cookie_box\": \"20%\", \"T4_top_drawer\": \"0%\", \"T5_on_ramekin\": \"0%\"}, \"running_avg_6task\": \"28.3%\", \"snapshot_time\": \"2026-05-15T09:00:00Z\", \"server\": \"bjb2-28827\", \"process_status\": \"alive\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:30:14.331Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T17:30:15.807Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:30:23.476790+00:00\"}]}, \"hypothesis\": \"Per-DoF CRM with max_correction_norm=0.2 on LIBERO-Spatial achieves optimal balance between correction magnitude and stability — norm=0.2 is hypothesized sweet spot from obs-only results\", \"parent\": \"eval-acr-spatial-v3\"}, \"eval-acr-spatial-v4-scalar\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:15:49.209Z\", \"updated_at\": \"2026-05-18T05:54:21.341Z\", \"hypothesis\": \"D020: scalar_unc CRM (val_loss 0.0374) with max_correction_norm=0.1. Three-way ablation: perdof vs scalar_unc vs obs_only under identical correction magnitude.\", \"spec\": {\"hypothesis\": \"D020 三路消融：scalar_unc CRM v3-norm (val_loss 0.0374) with max_correction_norm=0.1. 与 perdof (cuda:3) 和 obs_only (cuda:0) 同条件对比，判断 per-DOF vs scalar conformal features 的增益\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v3-norm scalar_unc, max_correction_norm=0.1)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"command\": \"python -u src/evaluate.py --mode crm_scalar --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": 288939, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-scalar.log\", \"gpu_ids\": [\"cuda:2\"]}, \"metrics\": {\"tasks_done\": \"3/10\", \"partial_results\": {\"between_plate_and_ramekin\": \"60.0% (6/10)\", \"next_to_ramekin\": \"100.0% (10/10)\", \"from_table_center\": \"10.0% (1/10)\"}, \"running_avg_3tasks\": \"56.7% (17/30)\", \"snapshot_time\": \"2026-05-15T12:00:00Z\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:2\", \"pid\": 288939}, \"notes\": \"[2026-05-15] HUNG: 3/10 tasks done (56.7%, 17/30), stuck on task 4 env init for 8+ hours. Process alive (pid 288939, GPU 1450 MiB) but zero log progress. Needs kill+restart.\", \"reproduce\": {\"finished_at\": \"2026-05-15T04:57:54.647Z\"}, \"failure_reason\": \"Kill-restart Worker 在 Director 撤销 kill 指令前已执行 SIGTERM (EXIT_CODE=143)。D026 kill 指令已被撤销但来不及阻止。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T04:57:55.887Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:57:57.857060+00:00\"}]}}, \"eval-acr-spatial-v4-small\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:09:00.358Z\", \"updated_at\": \"2026-05-18T05:54:20.300Z\", \"hypothesis\": \"D018: Normalization + moderate correction scaling (max_correction_norm=0.1, 14x smaller than default). If v4-small > v4-default → magnitude control needed on top of normalization.\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1\", \"server\": \"bjb1-18228\", \"gpu_ids\": [\"cuda:3\"], \"pid\": 253085, \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v3-norm per-DOF, max_correction_norm=0.1)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"log_path\": \"/root/autodl-tmp/logs/eval_acr_spatial_v4_small.log\"}, \"metrics\": {\"tasks_done\": \"7/10\", \"partial_results\": {\"between_plate_and_ramekin\": \"60.0% (6/10)\", \"next_to_ramekin\": \"100.0% (10/10)\", \"from_table_center\": \"10.0% (1/10)\", \"on_cookie_box\": \"40.0% (4/10)\", \"in_top_drawer\": \"0.0% (0/10)\", \"on_ramekin\": \"0.0% (0/10)\", \"next_to_cookie_box\": \"90.0% (9/10)\"}, \"running_avg_7tasks\": \"42.9% (30/70)\", \"snapshot_time\": \"2026-05-15T12:00:00Z\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:3\", \"pid\": 253085}, \"notes\": \"[2026-05-15 corrected] 之前误判为 env init hang，实际是被 kill-restart Worker SIGTERM kill。日志无 error/traceback，符合 SIGTERM 特征。7/10 tasks 完成，42.9% SR (30/70)。需重跑 tasks 8-10（或全部重跑）。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T05:04:16.712Z\", \"failure_reason\": \"被 kill-restart Worker SIGTERM（Director 撤销 kill 指令前已执行）。完成 7/10 tasks 后在 task 8 启动前被 kill。\"}, \"eval-acr-spatial-v4-obs-only-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:06.636Z\", \"updated_at\": \"2026-05-18T05:54:19.300Z\", \"hypothesis\": \"D020: obs_only CRM v3-norm (val_loss 0.0165) with max_correction_norm=0.1. If obs_only >= v4-small (perdof) → Claim 1 needs restructuring. If obs_only < v4-small → conformal features have unique value under distribution shift.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"270097\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-obs-only-r2.log\", \"submitted_at\": \"2026-05-14T22:21:35.775Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"gpu_ids\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v3-norm obs_only, max_correction_norm=0.1)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 24161.7, \"gpu_hours\": 6.71}, \"metrics\": {\"tasks_done\": \"6/10\", \"partial_results\": {\"between_plate_and_ramekin\": \"90.0% (9/10)\", \"next_to_ramekin\": \"100.0% (10/10)\", \"from_table_center\": \"0.0% (0/10)\", \"on_cookie_box\": \"40.0% (4/10)\", \"in_top_drawer\": \"10.0% (1/10)\", \"on_ramekin\": \"0.0% (0/10)\"}, \"running_avg_6tasks\": \"40.0% (24/60)\", \"snapshot_time\": \"2026-05-15T12:00:00Z\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:0\", \"pid\": 270097}, \"notes\": \"[2026-05-15 corrected] 之前误判为 env hang，实际是被 kill-restart Worker SIGTERM kill。日志无 error/traceback，符合 SIGTERM 特征。6/10 tasks 完成 + task 7 部分（5/10 rollouts），40.0% SR (24/60)。需重跑。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T05:04:17.448Z\", \"failure_reason\": \"被 kill-restart Worker SIGTERM（Director 撤销 kill 指令前已执行）。完成 6/10 tasks，第 7 个 task (next_to_cookie_box) rollout 5/10 时被 kill。\"}, \"eval-argmin-only-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:47:58.683Z\", \"updated_at\": \"2026-05-18T05:54:18.227Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark spatial --n_rollouts 10 --seed 42 --K 10\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"231421\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-only-spatial.log\", \"submitted_at\": \"2026-05-14T17:47:58.583Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"gpu_ids\": [\"cuda:1\"], \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"SmolVLA K=10 argmin selection (no CRM correction)\", \"seed\": 42, \"hypothesis\": \"Isolate argmin base action selection from CRM correction. If argmin-only ≈ VLA mean (40%), CRM delta is the sole culprit. If argmin-only << VLA mean, argmin selection itself is problematic.\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 40187.5, \"gpu_hours\": 11.16}, \"metrics\": {\"tasks_done\": \"9/10\", \"partial_results\": {\"between_plate_and_ramekin\": \"60.0% (6/10)\", \"next_to_ramekin\": \"100.0% (10/10)\", \"from_table_center\": \"0.0% (0/10)\", \"on_cookie_box\": \"30.0% (3/10)\", \"in_top_drawer\": \"10.0% (1/10)\", \"on_ramekin\": \"10.0% (1/10)\", \"next_to_cookie_box\": \"90.0% (9/10)\", \"on_stove\": \"0.0% (0/10)\", \"next_to_plate\": \"30.0% (3/10)\"}, \"running_avg_9tasks\": \"36.7% (33/90)\", \"snapshot_time\": \"2026-05-15T12:00:00Z\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:1\", \"pid\": 231421}, \"notes\": \"[2026-05-15] HUNG: 9/10 tasks done (36.7%, 33/90), stuck on task 10 env init for 8+ hours. Process alive (pid 231426, GPU 1414 MiB) but zero log progress. Needs kill+restart.\", \"reproduce\": {\"finished_at\": \"2026-05-15T04:57:45.148Z\"}, \"failure_reason\": \"Kill-restart Worker 在 Director 撤销 kill 指令前已执行 SIGTERM (EXIT_CODE=143)。D026 kill 指令已被撤销但来不及阻止。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T04:57:46.099Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:57:50.175181+00:00\"}]}, \"hypothesis\": \"Argmin-only selection (K=10, pick lowest CRM score without correction) on LIBERO-Spatial tests whether selection alone provides benefit — isolating the selection mechanism from the correction mechanism\", \"parent\": \"eval-reconvla-spatial-v3\"}, \"eval-acr-spatial-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:17:06.073Z\", \"updated_at\": \"2026-05-18T05:54:17.209Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v2/perdof/crm_best.pt\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"197057\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v3.log\", \"submitted_at\": \"2026-05-14T12:17:05.974Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial benchmark)\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v2 per-DOF + SmolVLA K=10)\", \"seed\": 42, \"hypothesis\": \"Per-DOF conformal correction (ACR-VLA with D016 4-bug fix) outperforms VLA K=1 (30%) and SampleConsensus (34%) on LIBERO spatial. CORE CLAIM experiment.\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v2/perdof/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 28899.4, \"gpu_hours\": 8.03}, \"metrics\": {\"tasks_done\": \"4/10\", \"overall_success_rate\": 0.025, \"total_successes\": 1, \"total_rollouts\": 40, \"per_task_partial\": {\"pick_up_black_bowl_between_plate_and_ramekin\": 0.1, \"pick_up_black_bowl_next_to_ramekin\": 0, \"pick_up_black_bowl_from_table_center\": 0, \"pick_up_black_bowl_on_cookie_box\": 0}, \"snapshot_time\": \"2026-05-14T18:15Z\"}, \"conclusion\": \"success\", \"reproduce\": {\"finished_at\": \"2026-05-14T20:18:44.725Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-14T20:18:45.380Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:18:46.631294+00:00\"}]}, \"hypothesis\": \"ACR pipeline v3 (K=10 conformal selection) on LIBERO-Spatial improves over VLA-only baseline, validating that conformal selection generalizes across spatial reasoning tasks\", \"parent\": \"crm-train-v2-perdof\"}, \"eval-acr-object-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:17:13.095Z\", \"updated_at\": \"2026-05-18T05:54:16.171Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode acr_vla --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v2/perdof/crm_best.pt\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"197803\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v3.log\", \"submitted_at\": \"2026-05-14T12:17:13.006Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (object benchmark)\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v2 per-DOF + SmolVLA K=10)\", \"seed\": 42, \"hypothesis\": \"Per-DOF conformal correction generalizes from spatial to object benchmark — cross-benchmark validation of ACR-VLA.\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v2/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 28901.2, \"gpu_hours\": 8.03}, \"metrics\": {\"tasks_done\": \"4/10\", \"overall_success_rate\": 0, \"total_successes\": 0, \"total_rollouts\": 40, \"per_task_partial\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0, \"bbq_sauce\": 0}, \"snapshot_time\": \"2026-05-14T18:15Z\"}, \"conclusion\": \"negative\", \"reproduce\": {\"finished_at\": \"2026-05-14T20:18:53.408Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-14T20:18:54.185Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:18:55.466058+00:00\"}]}, \"hypothesis\": \"ACR pipeline v3 (K=10 conformal selection with scalar uncertainty) on LIBERO-Object improves over VLA-only baseline by selecting highest-confidence action from candidate set\", \"parent\": \"crm-train-v2-perdof\"}, \"eval-openvla-object-vla-only-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T15:56:51.046Z\", \"updated_at\": \"2026-05-18T05:54:15.084Z\", \"spec\": {\"command\": \"python -u src/openvla_eval.py --mode vla_only --benchmark object --n_rollouts 10 --seed 42 --K 1 --gpu 0 --model_path /root/autodl-tmp/models/openvla-libero-object\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"667642\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-openvla-object-vla-only-seed42.log\", \"submitted_at\": \"2026-05-17T15:57:37.232Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"OpenVLA-7B-libero-object\", \"seed\": 42, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_source\": \"/root/autodl-tmp/models/openvla-libero-object\", \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 7512.0, \"gpu_hours\": 2.09}, \"hypothesis\": \"OpenVLA 7B VLA-only baseline on LIBERO-Object. 0% SR due to transformers 5.8 DynamicCache bug. Fix: use official repo eval code with transformers 4.40.1 in isolated conda env. Dry-run verified 80% SR on libero_spatial. Awaiting GPU for full LIBERO-Object eval.\", \"reproduce\": {\"finished_at\": \"2026-05-17T18:01:16.139Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T18:01:26.464150+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"overall_success_rate\": 0, \"total_successes\": 0, \"total_rollouts\": 100, \"avg_inference_time_ms\": 178, \"per_task\": {\"pick_up_the_alphabet_soup_and_place_it_in_the_basket\": 0, \"pick_up_the_cream_cheese_and_place_it_in_the_basket\": 0, \"pick_up_the_salad_dressing_and_place_it_in_the_basket\": 0, \"pick_up_the_bbq_sauce_and_place_it_in_the_basket\": 0, \"pick_up_the_ketchup_and_place_it_in_the_basket\": 0, \"pick_up_the_tomato_sauce_and_place_it_in_the_basket\": 0, \"pick_up_the_butter_and_place_it_in_the_basket\": 0, \"pick_up_the_milk_and_place_it_in_the_basket\": 0, \"pick_up_the_chocolate_pudding_and_place_it_in_the_basket\": 0, \"pick_up_the_orange_juice_and_place_it_in_the_basket\": 0}}, \"completed_at\": \"2026-05-17T18:02:49.250Z\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-openvla-object-vla-only-seed42.log\", \"notes\": \"NEEDS INVESTIGATION: 0% success rate vs OpenVLA paper 88.4% (LIBERO-Object). 100% confirmed code bug. Suspected action tokenization/detokenization or unnormalize issue. Do NOT treat as valid baseline.\"}, \"eval-perdof-object-norm02-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:32:28.585Z\", \"updated_at\": \"2026-05-18T04:37:10.886Z\", \"hypothesis\": \"perdof CRM with ε=0.2 on LIBERO-Object seed47. Magnitude curve data point for perdof at primary comparison norm.\", \"spec\": {\"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"404983\", \"command\": \"/root/miniconda3/bin/python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed47.json\", \"model_name\": \"SmolVLA+CRM_perdof\", \"seed\": 47, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm02_seed47.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T04:37:04.589Z\", \"metrics\": {\"overall_sr\": 0.11, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.1, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0.1, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}}, \"eval-obs-only-object-norm02-seed48\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:05:21.870Z\", \"updated_at\": \"2026-05-18T03:04:35.124Z\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 48 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_seed48.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"796895\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm02-seed48.log\", \"submitted_at\": \"2026-05-18T03:04:34.555Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"obs_only CRM ε=0.2 seed48. Key data point at primary comparison norm.\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T23:12:19.723Z\"}, \"eval-obs-only-object-default-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:21:52.326Z\", \"updated_at\": \"2026-05-18T03:03:50.286Z\", \"hypothesis\": \"obs_only CRM without norm constraint (uncapped correction magnitude) on LIBERO-Object seed46. Tests whether obs_only maintains performance without explicit correction capping.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed46.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:3\"], \"pid\": 422357, \"seed\": 46, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_default_seed46.json\", \"checkpoint_path\": \"N/A\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T00:20:44.089Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T00:20:46.904Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:20:52.370655+00:00\"}]}, \"metrics\": {\"overall_sr\": 0.15, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.4, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}}, \"eval-perdof-object-norm02-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:54:38.275Z\", \"updated_at\": \"2026-05-18T02:24:22.787Z\", \"hypothesis\": \"perdof CRM with ε=0.2 on LIBERO-Object seed46. Magnitude curve data point for perdof variant at primary comparison norm.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=4 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed46.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:4\"], \"pid\": 389051, \"seed\": 46, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm02_seed46.json\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T02:24:14.354Z\", \"metrics\": {\"overall_sr\": 0.09, \"successes\": 9, \"rollouts\": 100, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}}, \"eval-obs-only-object-norm01-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:51:13.356Z\", \"updated_at\": \"2026-05-18T01:01:03.202Z\", \"hypothesis\": \"obs_only CRM (ε=0.1) seed=46 on LIBERO Object. Extends magnitude curve low-norm segment to 3+ seeds. If consistent with seed42=19% and seed45 (running), strengthens robustness claim that obs_only maintains stable performance across all ε values.\", \"spec\": {\"command\": \"python evaluate.py --benchmark object --mode crm_obs_only --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --seed 46 --output_file logs/eval_object_obs_only_norm01_seed46.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"590833\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm01_seed46.log\", \"submitted_at\": \"2026-05-17T06:54:14.775Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A\", \"seed\": 46, \"wall_clock_seconds\": 65208.4, \"gpu_hours\": 18.11}, \"conclusion\": \"failed\", \"reproduce\": {\"finished_at\": \"2026-05-18T01:00:59.710Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-18T01:01:03.202Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T01:01:13.372128+00:00\"}]}}, \"eval-obs-only-object-norm01-seed46-r2\": {\"status\": \"DEPLOYED\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:05:18.047Z\", \"updated_at\": \"2026-05-18T00:33:26.447Z\", \"hypothesis\": \"obs_only CRM with ε=0.1 on LIBERO-Object seed46. Retry after previous run was killed at task 5/10.\", \"spec\": {\"command\": \"cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_obs_only_norm01_seed46.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:3\"], \"pid\": 562396, \"seed\": 46, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T13:31:53.068Z\", \"notes\": \"Retry #2: relaunched on bjb1-32546 cuda:3, PID 562396, tmux session eval-obs-only-object-norm01-seed46-r2. Previous run killed at task 5/10 on bjb1-18228.\"}, \"mag_obs_only_norm01_seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:04:31.864Z\", \"updated_at\": \"2026-05-17T23:47:05.521Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_obs_only_norm01_seed47.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:1\"], \"pid\": \"448773\", \"log_path\": \"N/A (killed as orphan)\", \"submitted_at\": \"2026-05-17T18:04:30.652Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 100, \"data_path\": \"LIBERO-Object 10tasks×10rollouts\", \"model_name\": \"crm_obs_only + SmolVLA\", \"seed\": 47, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 20554.9, \"gpu_hours\": 5.71}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T23:47:05.521Z\"}, \"mag_obs_only_norm01_seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:04:34.999Z\", \"updated_at\": \"2026-05-17T23:47:03.765Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_obs_only_norm01_seed46.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": \"449059\", \"log_path\": \"N/A (killed as orphan)\", \"submitted_at\": \"2026-05-17T18:04:34.274Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 100, \"data_path\": \"LIBERO-Object 10tasks×10rollouts\", \"model_name\": \"crm_obs_only + SmolVLA\", \"seed\": 46, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 20549.5, \"gpu_hours\": 5.71}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T23:47:03.765Z\"}, \"eval-perdof-object-norm02-seed43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T12:04:16.681Z\", \"updated_at\": \"2026-05-17T23:17:06.378Z\", \"hypothesis\": \"perdof CRM ε=0.2 seed43 on LIBERO-Object. 第 3 次尝试。补充 perdof magnitude curve ε=0.2 数据（seed42=11%）。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=4 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed43_bjb1-32546.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"crm_v3_norm_perdof\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"log_path\": \"N/A (killed as duplicate)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T23:02:21.019Z\", \"metrics\": {\"overall_sr\": 0.09, \"successes\": 9, \"total\": 100}}, \"mag_perdof_norm02_seed43_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:04:37.024Z\", \"updated_at\": \"2026-05-17T23:10:07.386Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=5 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed43_r3.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:5\"], \"pid\": \"449330\", \"log_path\": \"N/A (killed)\", \"submitted_at\": \"2026-05-17T18:04:36.487Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 100, \"data_path\": \"LIBERO-Object 10tasks×10rollouts\", \"model_name\": \"crm_perdof + SmolVLA\", \"seed\": 43, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"wall_clock_seconds\": 18330.9, \"gpu_hours\": 5.09}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T23:10:07.386Z\"}, \"eval-perdof-object-norm01-seed47-bjb1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:27:16.189Z\", \"updated_at\": \"2026-05-17T23:00:33.671Z\", \"hypothesis\": \"Duplicate of perdof norm=0.1 seed47 on bjb1-32546 (deployed by orphan Worker). Also running on bjb2-40593.\", \"spec\": {\"command\": \"cd /root/autodl-tmp/acr-vla && python evaluate.py --model smolvla --mode crm_perdof --benchmark object --seed 47 --n_rollouts 10 --norm_limit 0.1 --checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": 414817, \"data_path\": \"/root/autodl-tmp/acr-vla/libero/data\", \"data_count\": 100, \"model_name\": \"SmolVLA-450M + CRM-perdof\", \"seed\": 47, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks × 10 rollouts)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm01_seed47_r2.json\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\"}, \"metrics\": {\"overall_sr\": 0.14, \"successes\": 14, \"total\": 100}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T23:00:33.671Z\"}, \"eval-openvla-object-vla-only-seed42-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T20:06:55.243Z\", \"updated_at\": \"2026-05-17T22:39:25.302Z\", \"hypothesis\": \"OpenVLA 7B finetuned VLA-only baseline on LIBERO-Object using official eval code (transformers 4.40.1, isolated conda env). v1 failed due to transformers 5.8 DynamicCache bug. Dry-run on libero_spatial confirmed 80% SR. This run uses openvla-libero-object finetuned model with 10 trials/task.\", \"spec\": {\"command\": \"bash -c \\\"source /root/autodl-tmp/conda_envs/openvla/bin/activate && cd /root/autodl-tmp/openvla && MUJOCO_GL=egl python experiments/robot/libero/run_libero_eval.py --model_family openvla --pretrained_checkpoint /root/autodl-tmp/models/openvla-libero-object --task_suite_name libero_object --center_crop True --num_trials_per_task 10 --seed 42 --local_log_dir /root/acr-vla-conformal-refinement/results/eval-openvla-object-vla-only-seed42-v2\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": 747644, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"model_name\": \"openvla-7b-libero-object\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/openvla-libero-object\", \"eval_data\": \"libero_object (10 tasks x 10 trials = 100 rollouts)\", \"log_path\": \"/root/acr-vla-conformal-refinement/results/eval-openvla-object-vla-only-seed42-v2\", \"checkpoint_path\": \"/root/autodl-tmp/models/openvla-libero-object\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.69, \"n_tasks\": 10, \"n_trials_per_task\": 10, \"total_rollouts\": 100}, \"completed_at\": \"2026-05-17T22:39:25.302Z\"}, \"eval-k1-crm-multiscale-object-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:40:32.365Z\", \"updated_at\": \"2026-05-17T21:14:35.625Z\", \"hypothesis\": \"K=1 CRM with ACCG (multi-scale 4×960D) on LIBERO-Object seed44. Parallel deployment on bjb1-18228. Parent: train-crm-k1-accg-object-seed42-v2\", \"parent\": \"train-crm-k1-accg-object-seed42-v2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 44 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt --max_correction_norm 0.2 --output_file logs/eval_k1_crm_multiscale_object_seed44_bjb1-18228.json\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"crm_k1_multiscale\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"eval_data\": \"LIBERO-Object\", \"gpu_id\": \"cuda:3\", \"tmux_session\": \"eval-k1-seed44\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"log_path\": \"logs/eval_k1_crm_multiscale_object_seed44_bjb1-18228.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"overall_sr\": 0.1, \"successes\": 10, \"total\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}, \"completed_at\": \"2026-05-17T21:14:35.625Z\"}, \"eval-k1-crm-multiscale-object-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:34:14.132Z\", \"updated_at\": \"2026-05-17T21:02:09.738Z\", \"hypothesis\": \"K=1 CRM with ACCG (multi-scale 4x960D from layers [3,7,11,15]) on LIBERO-Object seed44. Compare with fallback (single-stage) and VLA-only baseline (10.8%). Multi-scale features enable layer-wise importance weighting for more informative correction signals.\", \"parent\": \"train-crm-k1-accg-object-seed42-v2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=4 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 44 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best_multiscale.pt --max_correction_norm 0.2\", \"server\": \"bjb1-32546\", \"gpu\": \"cuda:4\", \"pid\": 504682, \"model_name\": \"crm_k1_accg_multiscale\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best_multiscale.pt\", \"eval_data\": \"LIBERO-Object\", \"data_path\": \"LIBERO-Object benchmark (10 tasks)\", \"data_count\": 100, \"seed\": 44, \"log_path\": \"logs/eval_k1_crm_multiscale_object_seed44.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best_multiscale.pt\"}, \"conclusion\": \"negative\", \"metrics\": {\"overall_sr\": 0.1, \"successes\": 10, \"total\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}, \"completed_at\": \"2026-05-17T21:02:09.738Z\"}, \"eval-k1-crm-multiscale-object-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:34:11.800Z\", \"updated_at\": \"2026-05-17T21:02:08.069Z\", \"hypothesis\": \"K=1 CRM with ACCG (multi-scale 4x960D from layers [3,7,11,15]) on LIBERO-Object seed43. Compare with fallback (single-stage) and VLA-only baseline (10.8%). Multi-scale features enable layer-wise importance weighting for more informative correction signals.\", \"parent\": \"train-crm-k1-accg-object-seed42-v2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 43 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best_multiscale.pt --max_correction_norm 0.2\", \"server\": \"bjb1-32546\", \"gpu\": \"cuda:1\", \"pid\": 503178, \"model_name\": \"crm_k1_accg_multiscale\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best_multiscale.pt\", \"eval_data\": \"LIBERO-Object\", \"data_path\": \"LIBERO-Object benchmark (10 tasks)\", \"data_count\": 100, \"seed\": 43, \"log_path\": \"logs/eval_k1_crm_multiscale_object_seed43.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best_multiscale.pt\"}, \"conclusion\": \"negative\", \"metrics\": {\"overall_sr\": 0.09, \"successes\": 9, \"total\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.2, \"ketchup\": 0, \"tomato_sauce\": 0.2, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.2}}, \"completed_at\": \"2026-05-17T21:02:08.069Z\"}, \"eval-k1-crm-multiscale-object-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:34:09.846Z\", \"updated_at\": \"2026-05-17T21:02:06.052Z\", \"hypothesis\": \"K=1 CRM with ACCG (multi-scale 4x960D from layers [3,7,11,15]) on LIBERO-Object seed42. Compare with fallback (single-stage) and VLA-only baseline (10.8%). Multi-scale features enable layer-wise importance weighting for more informative correction signals.\", \"parent\": \"train-crm-k1-accg-object-seed42-v2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 42 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt --max_correction_norm 0.2\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:0\", \"pid\": 455518, \"model_name\": \"crm_k1_accg_multiscale\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"eval_data\": \"LIBERO-Object\", \"data_path\": \"LIBERO-Object benchmark (10 tasks)\", \"data_count\": 100, \"seed\": 42, \"log_path\": \"logs/eval_k1_crm_multiscale_object_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\"}, \"conclusion\": \"negative\", \"metrics\": {\"overall_sr\": 0.12, \"successes\": 12, \"total\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.2, \"ketchup\": 0, \"tomato_sauce\": 0.3, \"butter\": 0.1, \"milk\": 0, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.2}}, \"completed_at\": \"2026-05-17T21:02:06.052Z\"}, \"eval-perdof-object-norm01-seed46-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:05:32.383Z\", \"updated_at\": \"2026-05-17T21:01:12.153Z\", \"hypothesis\": \"perdof CRM at eps=0.1 on seed46 will show magnitude sensitivity collapse pattern similar to seed42, confirming obs_only robustness advantage\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_perdof --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --seed 46 --benchmark object\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": 393646, \"seed\": 46, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.1, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}, \"log_path\": \"logs/eval_object_perdof_norm01_seed46.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"completed_at\": \"2026-05-17T21:01:12.153Z\"}, \"eval-k1-crm-multiscale-object-seed43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:40:31.417Z\", \"updated_at\": \"2026-05-17T20:55:55.430Z\", \"hypothesis\": \"K=1 CRM with ACCG (multi-scale 4×960D) on LIBERO-Object seed43. Parallel deployment on bjb1-18228. Parent: train-crm-k1-accg-object-seed42-v2\", \"parent\": \"train-crm-k1-accg-object-seed42-v2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 43 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt --max_correction_norm 0.2 --output_file logs/eval_k1_crm_multiscale_object_seed43_bjb1-18228.json\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"crm_k1_multiscale\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"eval_data\": \"LIBERO-Object\", \"gpu_id\": \"cuda:1\", \"tmux_session\": \"eval-k1-seed43\"}, \"conclusion\": \"negative\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k1_crm_multiscale_object_seed43_bjb1-18228.json\", \"metrics\": {\"overall_sr\": 0.09, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.2, \"ketchup\": 0, \"tomato_sauce\": 0.2, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.2}}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"completed_at\": \"2026-05-17T20:55:55.430Z\"}, \"eval-perdof-object-norm02-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:32:18.289Z\", \"updated_at\": \"2026-05-17T18:37:21.561Z\", \"hypothesis\": \"perdof CRM (ε=0.2) seed45 on LIBERO-Object. 补充 Figure 2 perdof magnitude curve ε=0.2 数据（seed42=11%, seed43=9%, seed44 running）。\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed45.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"634427\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm02-seed45-r2.log\", \"submitted_at\": \"2026-05-17T13:35:38.103Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"crm_perdof\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"wall_clock_seconds\": 17779.9, \"gpu_hours\": 4.94}, \"reproduce\": {\"finished_at\": \"2026-05-17T18:31:54.940Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T18:31:57.991Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T18:32:03.172248+00:00\"}]}}, \"eval-obs-only-object-norm005-seed43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:34:38.488Z\", \"updated_at\": \"2026-05-17T18:37:20.319Z\", \"hypothesis\": \"obs_only CRM (ε=0.05) seed43 on LIBERO-Object. M006 补救重跑。seed42 ε=0.05=13%。\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_obs_only_norm005_seed43_r2.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"633631\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm005-seed43-r3.log\", \"submitted_at\": \"2026-05-17T13:35:14.715Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO-Object\", \"data_count\": 10, \"model_name\": \"crm_obs_only\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object\", \"wall_clock_seconds\": 17815.3, \"gpu_hours\": 4.95}, \"reproduce\": {\"finished_at\": \"2026-05-17T18:32:06.590Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T18:32:10.053Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T18:32:15.088162+00:00\"}]}}, \"plan_602-latency-profile\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:34:20.097Z\", \"updated_at\": \"2026-05-17T18:35:42.842Z\", \"hypothesis\": \"Measure wall-clock latency of ACR-VLA pipeline components: VLA encode, VLA K-sampling (K=1/5/10/20), CGS scoring, CRM forward pass, and full pipeline. Quantify overhead of conformal refinement relative to VLA sampling cost.\", \"spec\": {\"command\": \"python -u src/latency_profile.py\", \"server\": \"bjb2-28827\", \"seed\": 42, \"data_path\": \"/root/acr-vla-conformal-refinement/logs/latency_profile.json\", \"data_count\": 20, \"model_name\": \"SmolVLA+CRM\"}, \"conclusion\": \"success\", \"metrics\": {\"vla_encode_prefix_ms\": 33.5, \"vla_sample_K1_ms\": 192.6, \"vla_sample_K5_ms\": 965.3, \"vla_sample_K10_ms\": 1913.7, \"vla_sample_K20_ms\": 3858.2, \"cgs_ms\": 6.2, \"crm_forward_ms\": 0.3, \"full_pipeline_K10_ms\": 1908.2, \"acr_overhead_pct\": 0.34}, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/latency_profile.log\", \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/logs/latency_profile.json\", \"completed_at\": \"2026-05-17T18:35:42.842Z\"}, \"train-crm-k1-accg-object-seed42-v2\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T15:51:14.367Z\", \"updated_at\": \"2026-05-17T18:31:23.291Z\", \"hypothesis\": \"K=1 CRM with ACCG using full multi-scale features (4×960D from SmolVLA layers [3,7,11,15]). Multi-scale should capture richer correction signals than single-stage 960D fallback (val_loss=0.006505). Parent: train-crm-k1-accg-object-seed42-fallback\", \"parent\": \"train-crm-k1-accg-object-seed42-fallback\", \"notes\": \"Retry after W&B API key crash. Added --no_wandb. Precompute cache reused (65,223 samples). Training restarted from scratch (epoch 1/50). PID 447923 on cuda:0, tmux session: train-crm-k1-v2.\", \"reproduce\": {\"finished_at\": \"2026-05-17T18:01:06.354Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T18:01:12.607135+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"HDF5 corruption report was false alarm - all 10 files verified intact (md5 match, h5py OK). Training continued past crash point. Precompute running: 7500/72507, ~75 min remaining. conclusion=failed was set prematurely; training is actually running.\"}}, \"completed_at\": \"2026-05-17T18:01:40.220Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/train-crm-k1-accg-object-seed42-v2.log\"}, \"metrics\": {\"best_val_loss\": 0.007199, \"total_epochs\": 50, \"train_samples\": 65223, \"obs_dim\": \"4x960D\", \"multi_scale\": true}, \"conclusion\": \"success\"}, \"eval-k1-crm-accg-object-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T15:28:01.165Z\", \"updated_at\": \"2026-05-17T18:22:02.272Z\", \"hypothesis\": \"K=1 CRM with ACCG (fallback 960D) on LIBERO-Object seed44. 验证 ACCG correction 是否优于 K=1 VLA-only baseline (mean 10.8%). Parent: train-crm-k1-accg-object-seed42-fallback\", \"parent\": \"train-crm-k1-accg-object-seed42-fallback\", \"spec\": {\"pid\": 460733, \"gpu\": [\"cuda:5\"], \"server\": \"bjb1-32546\", \"command\": \"CUDA_VISIBLE_DEVICES=5 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 44 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt --max_correction_norm 0.2 --output_file logs/eval_k1_crm_accg_object_seed44.json\", \"model_name\": \"crm_k1_accg\", \"seed\": 44, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k1_crm_accg_object_seed44.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"overall_success_rate\": 0.07, \"n_rollouts\": 100, \"tasks\": {\"salad_dressing\": 0.1, \"bbq_sauce\": 0.1, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.1}}, \"completed_at\": \"2026-05-17T18:02:47.296Z\"}, \"eval-k1-crm-accg-object-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T15:27:59.825Z\", \"updated_at\": \"2026-05-17T18:22:01.354Z\", \"hypothesis\": \"K=1 CRM with ACCG (fallback 960D) on LIBERO-Object seed43. 验证 ACCG correction 是否优于 K=1 VLA-only baseline (mean 10.8%). Parent: train-crm-k1-accg-object-seed42-fallback\", \"parent\": \"train-crm-k1-accg-object-seed42-fallback\", \"spec\": {\"pid\": 460729, \"gpu\": [\"cuda:4\"], \"server\": \"bjb1-32546\", \"command\": \"CUDA_VISIBLE_DEVICES=4 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 43 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt --max_correction_norm 0.2 --output_file logs/eval_k1_crm_accg_object_seed43.json\", \"model_name\": \"crm_k1_accg\", \"seed\": 43, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k1_crm_accg_object_seed43.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"overall_success_rate\": 0.12, \"n_rollouts\": 100, \"tasks\": {\"salad_dressing\": 0.2, \"bbq_sauce\": 0.2, \"ketchup\": 0.1, \"tomato_sauce\": 0.2, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.1}}, \"completed_at\": \"2026-05-17T18:02:45.640Z\"}, \"eval-k1-crm-accg-object-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T15:27:58.213Z\", \"updated_at\": \"2026-05-17T18:22:00.464Z\", \"hypothesis\": \"K=1 CRM with ACCG (fallback 960D) on LIBERO-Object seed42. 验证 ACCG correction 是否优于 K=1 VLA-only baseline (mean 10.8%). Parent: train-crm-k1-accg-object-seed42-fallback\", \"parent\": \"train-crm-k1-accg-object-seed42-fallback\", \"spec\": {\"pid\": 460724, \"gpu\": [\"cuda:1\"], \"server\": \"bjb1-32546\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python -u src/evaluate.py --mode crm_k1_accg --benchmark object --n_rollouts 10 --seed 42 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt --max_correction_norm 0.2 --output_file logs/eval_k1_crm_accg_object_seed42.json\", \"model_name\": \"crm_k1_accg\", \"seed\": 42, \"data_path\": \"LIBERO-Object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_k1/crm_k1_best.pt\", \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k1_crm_accg_object_seed42.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"overall_success_rate\": 0.11, \"n_rollouts\": 100, \"tasks\": {\"salad_dressing\": 0.2, \"bbq_sauce\": 0.2, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.2}}, \"completed_at\": \"2026-05-17T18:02:43.637Z\"}, \"eval-obs-only-object-default-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:15:05.583Z\", \"updated_at\": \"2026-05-17T17:32:15.936Z\", \"spec\": {\"command\": \"python src/evaluate.py --mode crm_obs_only --K 10 --seed 45 --benchmark object --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed45.json\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:3\", \"pid\": 242264, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 10, \"model_name\": \"crm_obs_only\", \"seed\": 45}, \"hypothesis\": \"obs_only CRM (default norm ~1.42, 无裁剪) seed=45 on LIBERO Object. 验证 obs_only 在 uncapped 大 norm 下仍优于 VLA-only（seed42 在 default 为 17%）。极端 magnitude 鲁棒性测试。\", \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.12, \"tasks\": 10, \"rollouts_per_task\": 20, \"total_successes\": 24, \"total_rollouts\": 200}, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_default_seed45.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"completed_at\": \"2026-05-17T17:32:15.936Z\"}, \"eval-scalar-object-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T08:38:01.206Z\", \"updated_at\": \"2026-05-17T17:29:34.723Z\", \"spec\": {\"command\": \"python src/evaluate.py --mode crm_scalar --max_correction_norm 0.1 --K 10 --seed 45 --benchmark object --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --output_file logs/eval_object_scalar_seed45.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:0\"], \"pid\": 224623, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_scalar_unc\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"eval_data\": \"LIBERO object\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"log_path\": \"logs/eval_object_scalar_seed45.log\"}, \"hypothesis\": \"Scalar uncertainty CRM seed=45 on LIBERO Object. 测试 scalar conditioning（单一 std 而非 per-DOF）是否比 obs_only 或 perdof 更优。如果表现介于两者之间，说明 conditioning 信息量与性能正相关。\", \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.09, \"successes\": 18, \"total\": 200, \"best_task\": \"chocolate_pudding_0.25\", \"worst_task\": \"alphabet_soup_0.0\"}, \"completed_at\": \"2026-05-17T17:29:34.723Z\"}, \"eval-perdof-object-norm02-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T08:34:55.059Z\", \"updated_at\": \"2026-05-17T17:03:14.729Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python src/evaluate.py --benchmark object --mode crm_perdof --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --K 10 --seed 45 --output_file logs/eval_object_perdof_norm02_seed45.json\", \"server\": \"bjb2-28827\", \"gpu_id\": \"cuda:1\", \"pid\": 222824, \"seed\": 45, \"model_name\": \"crm_perdof\", \"data_path\": \"LIBERO object\", \"data_count\": 10, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object\", \"hypothesis\": \"Perdof CRM norm=0.2 seed=45 on LIBERO object. Additional perdof data point for cross-seed comparison. Expected ~11% based on seed42 data.\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm02_seed45.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\"}, \"hypothesis\": \"perdof CRM (ε=0.2) seed=45 on LIBERO Object. 验证 perdof 在中间 norm (0.2) 的表现（seed42=11%, seed43=9%）。为 magnitude curve 误差估计提供第三个 seed。\", \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.09, \"successes\": 18, \"total\": 200, \"n_tasks\": 10, \"n_rollouts_per_task\": 20}, \"notes\": \"perdof ε=0.2 seed45: 9% (18/200). Cross-seed: seed42=11%, seed43=9%, seed44=10%, seed45=9%. Mean ~9.75%.\", \"completed_at\": \"2026-05-17T17:03:14.729Z\"}, \"eval-perdof-object-norm02-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T00:37:24.278Z\", \"updated_at\": \"2026-05-17T16:52:17.419Z\", \"hypothesis\": \"perdof CRM (ε=0.2) seed=44 on LIBERO Object benchmark. Adds second seed to perdof norm=0.2 (seed42=11%, seed43=9%). Enables error bar on magnitude curve figure at this norm point.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=5 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed44.json\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:5\", \"pid\": \"326081\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm02-seed44.log\", \"submitted_at\": \"2026-05-17T08:36:00Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 44, \"model_name\": \"crm_perdof\", \"data_path\": \"LIBERO object benchmark (10 tasks)\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 29777.4, \"gpu_hours\": 8.27}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.1, \"successes\": 10, \"total\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.3}}, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm02-seed44.log\", \"checkpoint_path\": \"logs/eval_object_perdof_norm02_seed44.json\", \"completed_at\": \"2026-05-17T16:52:17.419Z\"}, \"train-crm-k1-accg-object-seed42-fallback\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T15:02:35.790Z\", \"updated_at\": \"2026-05-17T15:19:16.626Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=4 python -u train_crm_k1.py --benchmark object --epochs 50 --batch_size 512 --lr 1e-3 --seed 42 --loss_mode multi --lambda_dir 0.1 --lambda_tri 0.05 --lambda_mag 0.01 --max_correction_norm 0.2 --reuse_k10_cache --k10_cache_dir /root/autodl-tmp/crm_cache_v5/ --auto --no_wandb\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": 456622, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/train_crm_k1_fallback.log\", \"submitted_at\": \"2026-05-17T15:02:35.104Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"gpu_id\": \"cuda:4\", \"data_path\": \"/root/autodl-tmp/crm_cache_v5/\", \"data_count\": 4857, \"model_name\": \"crm_k1_accg_fallback\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_k1/\", \"wall_clock_seconds\": 914.9, \"gpu_hours\": 0.25}, \"hypothesis\": \"CRM K=1 with ACCG architecture trained on K=10 single-stage cache (960D fallback) can learn effective corrections for object benchmark, achieving low val_loss comparable to multi-scale approach\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T15:17:49.965Z\", \"metrics\": {\"best_val_loss\": 0.006505, \"best_epoch\": 43, \"total_epochs\": 50, \"train_samples\": 4857, \"obs_dim\": 960, \"multi_scale\": false, \"wall_clock_seconds\": 914.9}}, \"train-crm-k1-accg-object-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:48:22.459Z\", \"updated_at\": \"2026-05-17T14:53:10.162Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement/src && CUDA_VISIBLE_DEVICES=0 python -u train_crm_k1.py --benchmark object --epochs 50 --batch_size 512 --lr 1e-3 --seed 42 --loss_mode multi --lambda_dir 0.1 --lambda_tri 0.05 --lambda_mag 0.01 --max_correction_norm 0.2 --wandb_project acr-vla-conformal-refinement --wandb_run_name crm-k1-v2-accg-object --auto\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:1\"], \"pid\": \"427856\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/train-crm-k1-accg-object-seed42.log\", \"submitted_at\": \"2026-05-17T14:48:21.711Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 42, \"model_name\": \"CRM_K1_ACCG_v2\", \"data_path\": \"LIBERO-Object precomputed K=1 features\", \"data_count\": -1, \"wall_clock_seconds\": 174.4, \"gpu_hours\": 0.05}, \"hypothesis\": \"K=1 CRM 训练（ACCG 架构）：使用 Action-Conditioned Correction Gating 替代 FiLM，多阶段 VLA 特征融合 + 组合损失函数（L2 + directional + triplet + magnitude），训练专用于 K=1 单采样纠正的 CRM。目标超越 K=1 VLA-only baseline (10.8%)。ACCG 用 action 本身计算动态 gate 选择 correction 维度。\", \"reproduce\": {\"finished_at\": \"2026-05-17T14:49:15.593Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T14:49:21.444858+00:00\"}]}, \"conclusion\": \"failed\", \"failure_reason\": \"LIBERO HDF5 demo data missing on bjb2-28827. Precompute requires raw demo trajectories but only K=10 cache exists.\", \"completed_at\": \"2026-05-17T14:51:16.090Z\"}, \"eval-perdof-object-norm02-seed45-deploy\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:34:09.564Z\", \"updated_at\": \"2026-05-17T13:52:58.983Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed45.json 2>&1 | tee logs/eval_object_perdof_norm02_seed45.log\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"632156\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm02-seed45-deploy.log\", \"submitted_at\": \"2026-05-17T13:34:09.103Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1025.8, \"gpu_hours\": 0.28}, \"hypothesis\": \"perdof CRM (ε=0.2) seed45 on LIBERO-Object. 补充 Figure 2 perdof magnitude curve ε=0.2 数据（seed42=11%, seed43=9%, seed44 running）。\", \"reproduce\": {\"finished_at\": \"2026-05-17T13:47:18.573Z\"}, \"failure_reason\": \"**根因**: MuJoCo EGL 渲染初始化 segfault（native crash）。\\n\\n**证据**:\\n- tmux 日志和应用日志均在 `[eval] 10 tasks loaded.` 后中断，无 Python traceback、无 segfault handler 输出\\n- 代码中有 SIGSEGV handler 但未被触发，说明崩溃发生在 native code（MuJoCo/EGL）且 handler 未能执行\\n- 同服务器多个实验表现相同模式（eval_object_obs_only_norm03_seed47、eval_object_perdof_norm01_seed47 等均在 \\\"10 tasks loaded\\\" 后死亡）\\n- 非 OOM：系统 RAM 454GB 空闲，GPU VRAM 仅用 5.6GB/24GB\\n- 崩溃点：第一个 rollout_single() → env.reset() 触发 MuJoCo EGL context 创建\\n\\n**关键日志（最后一行有效输出）**:\\n`[eval] 10 tasks loaded.`\\n（之后无任何输出，进程静默死亡）\\n\\n**可能触发因素**: 4 张 GPU 同时运行 4 个 eval 进程，并发 EGL context 初始化存在 driver 层竞争。较早的单卡实验（seed44/45/46）正常完成。\\n\\n**建议**: PID 634438 已在 GPU 0 上重启并处于 Running 状态，等待其完成。若再次失败，考虑串行执行（不并发跑 4 个 EGL 进程）或降低并发数。\", \"conclusion\": \"killed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T13:47:28.347997+00:00\"}]}, \"completed_at\": \"2026-05-17T13:51:14.936Z\"}, \"eval-obs-only-object-norm01-seed47-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:05:28.139Z\", \"updated_at\": \"2026-05-17T13:31:57.433Z\", \"hypothesis\": \"obs_only CRM at eps=0.1 on seed47 will achieve similar improvement over VLA-only as seen in seed42 (19%), testing seed robustness of the magnitude curve\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --seed 47 --benchmark object\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": 588037, \"seed\": 47, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T13:31:55.004Z\", \"notes\": \"Worker batch7 误杀, 4/10 tasks 完成\"}, \"eval-perdof-object-norm03-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T21:32:42.117Z\", \"updated_at\": \"2026-05-17T12:04:17.540Z\", \"hypothesis\": \"perdof CRM (ε=0.3) seed=45 on LIBERO object benchmark. Retry after unregistered process conflict. Expected to confirm perdof collapse at high norm (seed42=4%, seed44 running). Supports magnitude curve narrative.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl CUDA_VISIBLE_DEVICES=5 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed45_r2.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"319463\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm03-seed45-r2.log\", \"submitted_at\": \"2026-05-16T21:33:52.055Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark (10 tasks)\", \"data_count\": 100, \"model_name\": \"crm_v3_norm_perdof\", \"seed\": 45, \"wall_clock_seconds\": 48204.7, \"gpu_hours\": 13.39}, \"reproduce\": {\"finished_at\": \"2026-05-17T10:54:49.175Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T10:54:55.730176+00:00\"}]}, \"checkpoint_path\": \"N/A - eval only\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm03-seed45-r2.log\", \"metrics\": {\"overall_sr\": 0.06, \"successes\": 6, \"total\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.2, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0.1, \"milk\": 0, \"chocolate_pudding\": 0.1, \"orange_juice\": 0.1}}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T10:57:16.754Z\"}, \"eval-perdof-object-norm03-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:22:10.412Z\", \"updated_at\": \"2026-05-17T12:00:58.173Z\", \"hypothesis\": \"perdof CRM ε=0.3 seed44 re-run on LIBERO-Object. 原 seed44 已完成(conclusion=negative, SR=4%). 重跑验证跨 seed 一致性。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed44_r2.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:0\"], \"pid\": 421086, \"seed\": 44, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\"}, \"conclusion\": \"negative\", \"reproduce\": {\"finished_at\": \"2026-05-17T11:50:26.264Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-17T11:50:20.975Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:50:33.595081+00:00\"}]}, \"metrics\": {\"success_rate\": 0.04, \"n_rollouts\": 10, \"total_rollouts\": 100, \"note\": \"JSON result found by diagnostic worker. Matches original seed44=4%. False positive failure due to no sentinel/W&B in evaluate.py.\"}}, \"eval-obs-only-object-norm03-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:21:56.645Z\", \"updated_at\": \"2026-05-17T11:50:09.879Z\", \"hypothesis\": \"obs_only CRM ε=0.3 seed47 on LIBERO-Object. 5th seed at high norm (seed42=19%, seed44=18%, seed45=14%, seed46 running). 补全 magnitude curve 高 norm 段 error bar。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 47 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03_seed47.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": 612853, \"seed\": 47, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\"}, \"conclusion\": \"failed\", \"reproduce\": {\"finished_at\": \"2026-05-17T11:50:06.763Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-17T11:50:09.879Z\"}, \"eval-perdof-object-norm03-seed46-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:28:13.840Z\", \"updated_at\": \"2026-05-17T11:36:55.536Z\", \"hypothesis\": \"perdof CRM ε=0.3 seed46 retry on LIBERO-Object. 原 PID 394433 退出，PID 392856 在 bjb2-28827 cuda:2 继续运行。seed42=4%, seed44=4%, seed45=6%。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 46 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed46.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": 392856, \"seed\": 46, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO-Object (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T11:36:55.536Z\"}, \"eval-perdof-object-norm01-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T20:21:04.937Z\", \"updated_at\": \"2026-05-17T10:59:11.317Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_perdof_norm01_seed44.json\", \"server\": \"bjb1-18228\", \"gpu_id\": 1, \"model_name\": \"crm_perdof_norm01\", \"seed\": 44, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark\", \"hypothesis\": \"perdof CRM norm=0.1 seed=44 on LIBERO object. Multi-seed magnitude curve: seed42=11%, expecting similar. Fills the biggest gap in perdof magnitude data (norm=0.1 only has 1 seed).\", \"pid\": 531963}, \"hypothesis\": \"perdof CRM (ε=0.1) seed=44 on LIBERO Object. 验证 perdof 在低 norm 的安全区域（seed42=11%，seed45 running）。多 seed 支撑 magnitude curve 低 norm 段。\", \"reproduce\": {\"finished_at\": \"2026-05-17T10:48:36.650Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T10:48:39.951Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T10:48:45.826946+00:00\"}]}, \"notes\": \"失败原因: process dead 5× with no sentinel/W&B — auto-resolved as failed | 诊断中: Worker worker_diagnose_eval-perdof-object-norm01-seed44_20260517T105221 已派发到 bjb1-18228 检查是否为 cron 误判（同配置 seed45 成功，SR=11%）\", \"metrics\": {\"overall_sr\": 0.08, \"total_successes\": 8, \"total_rollouts\": 100, \"seed\": 44, \"mode\": \"crm_perdof\", \"max_correction_norm\": 0.1}}, \"eval-obs-only-object-norm01-seed47-bjb2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:07:14.242Z\", \"updated_at\": \"2026-05-17T10:56:41.892Z\", \"hypothesis\": \"Duplicate of seed47 obs_only norm=0.1 on bjb2 (survived GPU conflict cleanup), provides extra seed47 data point\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --seed 47 --benchmark object\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": 363223, \"seed\": 47, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"checkpoint_path\": \"N/A (killed duplicate)\", \"log_path\": \"N/A (killed duplicate)\"}, \"conclusion\": \"killed\", \"reproduce\": {\"finished_at\": \"2026-05-17T10:42:47.471Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-17T10:42:49.632Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T10:42:53.924730+00:00\"}]}}, \"eval-obs-only-object-norm01-seed46-bjb2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:17:00.494Z\", \"updated_at\": \"2026-05-17T10:54:24.948Z\", \"hypothesis\": \"Duplicate of obs_only norm=0.1 seed46 on bjb2 (deployed by batch5 Worker). Extra data point for magnitude curve.\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --seed 46 --benchmark object\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:4\"], \"pid\": 365893, \"seed\": 46, \"model_name\": \"SmolVLA+CRM_obs_only\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T10:43:36.147Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T10:43:38.311Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T10:43:46.527772+00:00\"}]}}, \"eval-argmin-object-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T21:38:21.922Z\", \"updated_at\": \"2026-05-17T10:54:02.629Z\", \"hypothesis\": \"Argmin baseline (reconvla K=10) seed=47 on LIBERO object benchmark. Paired with obs_only seed47 on cuda:0 for direct comparison. Extends argmin multi-seed data for pooled Fisher test.\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --seed 47 --benchmark object --n_rollouts 10 --output_file logs/eval_object_reconvla_seed47.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:3\"], \"pid\": 322337, \"seed\": 47, \"model_name\": \"SmolVLA_argmin_K10\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-seed47.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T10:51:45.356Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T10:51:50.389646+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.1, \"total_successes\": 10, \"total_rollouts\": 100, \"n_rollouts_per_task\": 10, \"seed\": 47, \"benchmark\": \"object\", \"K\": 10, \"mode\": \"reconvla\", \"baseline_mode\": \"single\", \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.1, \"orange_juice\": 0.2}}, \"completed_at\": \"2026-05-17T10:54:02.630Z\"}, \"eval-perdof-object-norm01-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T20:21:06.341Z\", \"updated_at\": \"2026-05-17T10:22:14.183Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_perdof_norm01_seed45.json\", \"server\": \"bjb1-32546\", \"gpu_id\": 2, \"model_name\": \"crm_perdof_norm01\", \"seed\": 45, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark\", \"hypothesis\": \"perdof CRM norm=0.1 seed=45 on LIBERO object. Multi-seed magnitude curve: seed42=11%, seed44=deploying. 3rd seed for perdof low-norm baseline.\", \"pid\": 309151}, \"hypothesis\": \"perdof CRM (ε=0.1) seed=45 on LIBERO Object. 验证 perdof 在低 norm (0.1) 的安全区域（seed42=11%）。如果与 obs_only 接近，支持\\\"低 norm 两者等效\\\"叙事。\", \"metrics\": {\"overall_sr\": 0.11, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}, \"seed\": 45, \"benchmark\": \"object\", \"mode\": \"crm_perdof\", \"max_correction_norm\": 0.1}, \"conclusion\": \"success\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm01_seed45.json\", \"checkpoint_path\": \"N/A (eval only)\", \"completed_at\": \"2026-05-17T10:22:14.184Z\"}, \"eval-perdof-object-norm01-seed47\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:51:20.872Z\", \"updated_at\": \"2026-05-17T10:19:28.338Z\", \"hypothesis\": \"perdof CRM at eps=0.1 on seed47, completes magnitude curve low-norm data for perdof\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/evaluate.py --mode crm_perdof --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --seed 47 --benchmark object --n_rollouts 10 --output_file logs/eval_object_perdof_norm01_seed47.json\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"388460\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm01-seed47.log\", \"submitted_at\": \"2026-05-17T06:54:11.992Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 47, \"model_name\": \"SmolVLA+CRM_perdof\", \"data_path\": \"LIBERO-Object 10 tasks\", \"data_count\": 100, \"eval_data\": \"LIBERO-Object\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"checkpoint_path\": \"N/A (killed before completion)\", \"wall_clock_seconds\": 12316.3, \"gpu_hours\": 3.42}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T10:19:28.338Z\"}, \"eval-argmin-object-seed46\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T18:39:23.017Z\", \"updated_at\": \"2026-05-17T10:19:26.819Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 46 --K 10 --output_file logs/eval_object_reconvla_seed46.json\", \"server\": \"bjb1-32546\", \"gpu\": \"cuda:1\", \"seed\": 46, \"model_name\": \"reconvla\", \"hypothesis\": \"argmin baseline K=10 seed=46 on LIBERO object. 5th seed for Fisher test. Pairs with eval-obs-only-object-norm02-seed46 (bjb1-18228:cuda:3).\", \"data_path\": \"\", \"data_count\": 0, \"checkpoint_source\": \"\", \"eval_data\": \"object\", \"pid\": 295478, \"log_path\": \"logs/eval_argmin_object_seed46.log\", \"checkpoint_path\": \"N/A (eval-only, reconvla baseline)\"}, \"hypothesis\": \"Argmin baseline (conformal selection K=10, 无 learned correction) seed=46 on LIBERO Object. 与 obs_only seed=46 配对，扩展 pooled Fisher test 到 6 seeds。预期 12-17% SR。\", \"metrics\": {\"overall_sr\": 0.1, \"total_successes\": 10, \"total_rollouts\": 100, \"n_rollouts_per_task\": 10, \"seed\": 46, \"benchmark\": \"object\", \"K\": 10, \"mode\": \"reconvla\", \"baseline_mode\": \"single\", \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.4, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.1, \"orange_juice\": 0.1}}, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_argmin_object_seed46.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T10:19:26.819Z\"}, \"eval-obs-only-object-norm03-seed45-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T15:24:08.486Z\", \"updated_at\": \"2026-05-17T07:02:49.285Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl CUDA_VISIBLE_DEVICES=4 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03_seed45_r2.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:4\"], \"pid\": \"272762\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm03-seed45-r2.log\", \"submitted_at\": \"2026-05-16T15:24:08.144Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"gpu_id\": \"cuda:3\", \"model_name\": \"crm_obs_only_norm03\", \"seed\": 45, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"wall_clock_seconds\": 56321.1, \"gpu_hours\": 15.64}, \"hypothesis\": \"obs_only CRM with max_correction_norm=0.3 on LIBERO Object (seed=45) should show graceful degradation similar to seed42 (19%), providing multi-seed error estimates for the magnitude curve\", \"reproduce\": {\"finished_at\": \"2026-05-17T07:00:25.758Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T07:00:32.829645+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 14, \"total_successes\": 14, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 10, \"bbq_sauce\": 30, \"ketchup\": 10, \"tomato_sauce\": 10, \"butter\": 10, \"milk\": 10, \"chocolate_pudding\": 30, \"orange_juice\": 30}, \"max_correction_norm\": 0.3, \"seed\": 45, \"mode\": \"crm_obs_only\", \"benchmark\": \"object\"}, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm03-seed45-r2.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T07:02:49.285Z\"}, \"eval-vla-mean-object-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:14:45.495Z\", \"updated_at\": \"2026-05-17T06:54:28.933Z\", \"spec\": {\"model_name\": \"smolvla_libero_vla_mean\", \"seed\": 45, \"data_path\": \"LIBERO object benchmark (10 tasks)\", \"data_count\": 100, \"checkpoint_source\": \"N/A\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --benchmark object --mode vla_only --baseline_mode mean --n_rollouts 10 --K 10 --seed 45 --output_file logs/eval_object_vla_mean_seed45.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"248652\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-mean-object-seed45.log\", \"submitted_at\": \"2026-05-16T11:14:45Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 70783.9, \"gpu_hours\": 19.66}, \"hypothesis\": \"VLA-mean baseline (K=10, mean aggregation) seed=45 on LIBERO object benchmark. Completes seed=45 six-way comparison. seed42=12%, seed43=15%, seed44=running.\", \"reproduce\": {\"finished_at\": \"2026-05-17T03:29:41.019Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T03:29:45.978517+00:00\"}]}, \"metrics\": {\"overall_sr\": 0.13, \"total_success\": 13, \"total_rollouts\": 100, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.4, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0, \"milk\": 0.1, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.3}, \"multi_seed_summary\": \"seed42=12%, seed43=15%, seed44=10%, seed45=13%, mean=12.5%\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T06:54:28.933Z\"}, \"eval-argmin-object-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:44:23.744Z\", \"updated_at\": \"2026-05-17T06:53:28.467Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 45 --K 10 --output_file logs/eval_object_argmin_seed45.json\", \"server\": \"bjb2-28827\", \"gpu\": \"cuda:5\", \"pid\": \"215932\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-seed45.log\", \"submitted_at\": \"2026-05-16T07:45:06.846Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 45, \"model_name\": \"reconvla_argmin_baseline\", \"hypothesis\": \"argmin baseline K=10 seed=45 on LIBERO object. 4th seed baseline for Fisher test. Paired with eval-obs-only-object-norm02-seed45.\", \"data_path\": \"LIBERO object benchmark (10 tasks)\", \"data_count\": 100, \"wall_clock_seconds\": 60530.4, \"gpu_hours\": 16.81}, \"reproduce\": {\"finished_at\": \"2026-05-17T00:31:27.579Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T00:31:32.330885+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.12, \"successes\": 12, \"total_rollouts\": 100, \"tasks_completed\": \"10/10\"}, \"checkpoint_path\": \"N/A (eval-only)\", \"hypothesis\": \"Argmin baseline (conformal selection K=10, no correction) seed=45 on LIBERO Object. Highest priority: expands argmin multi-seed data from 3 to 4 seeds, balancing against obs_only 5 seeds for symmetric Fisher test. Expected 12-17% SR.\", \"completed_at\": \"2026-05-17T00:33:57.260Z\"}, \"eval-direct-correction-object-seed42-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:01:50.937Z\", \"updated_at\": \"2026-05-17T04:48:50.296Z\", \"hypothesis\": \"obs_only CRM 直接纠正单次 VLA 输出（K=1, 跳过 argmin selection），测试 CRM 本身是否有独立纠正价值。如果 SR > VLA-only (~11%)，说明 CRM correction 独立有效；如果 SR ≤ VLA-only，说明 multi-sample selection 是必要前提。Claim 1 (pipeline contribution) 的 ablation。\", \"parent\": \"eval-direct-correction-object-seed42-r2\", \"spec\": {\"command\": \"/root/miniconda3/bin/python -u src/evaluate.py --mode direct_correction --benchmark object --n_rollouts 10 --seed 42 --K 1 --checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/results_direct_correction_object_seed42.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO Object benchmark (10 tasks)\", \"data_count\": \"100 episodes (10 tasks x 10 rollouts)\", \"model_name\": \"obs_only CRM (327K params)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO Object\", \"gpu\": \"cuda:4\", \"pid\": 364076, \"tmux_session\": \"eval-dc-r2\", \"note\": \"Code patched: print every rollout instead of every 5. Root cause of prev failures: workers killed working processes because output interval was 7.5min (5 rollouts x 90s each).\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_direct_correction_object_seed42.log\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.14, \"total_episodes\": 100, \"successes\": 14, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 1, \"salad_dressing\": 1, \"bbq_sauce\": 4, \"ketchup\": 0, \"tomato_sauce\": 1, \"butter\": 1, \"milk\": 1, \"chocolate_pudding\": 3, \"orange_juice\": 2}}, \"completed_at\": \"2026-05-17T04:48:50.296Z\"}, \"eval-perdof-object-norm03-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T15:24:11.457Z\", \"updated_at\": \"2026-05-17T04:45:11.458Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl CUDA_VISIBLE_DEVICES=2 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_seed44.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"505419\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-norm03-seed44.log\", \"submitted_at\": \"2026-05-16T15:24:11.074Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"gpu_id\": \"cuda:2\", \"model_name\": \"crm_perdof_norm03\", \"seed\": 44, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"checkpoint_path\": \"N/A (eval only)\", \"wall_clock_seconds\": 48060.4, \"gpu_hours\": 13.35}, \"hypothesis\": \"perdof CRM (ε=0.3) seed=44 on LIBERO Object. 验证 perdof 在高 norm (0.3) 的退化程度（seed42=4%）。多 seed 确认 perdof progressive collapse 机制。\", \"reproduce\": {\"finished_at\": \"2026-05-17T04:41:11.191Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T04:41:18.547308+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"success_rate\": 0.04, \"total_episodes\": 100, \"successes\": 4, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 1, \"salad_dressing\": 0, \"bbq_sauce\": 1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 1, \"milk\": 0, \"chocolate_pudding\": 1, \"orange_juice\": 0}}, \"completed_at\": \"2026-05-17T04:45:11.458Z\"}, \"eval-mag-perdof-norm02-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:07:31.626Z\", \"updated_at\": \"2026-05-17T03:31:42.118Z\", \"spec\": {\"parent\": \"eval-acr-object-v4-perdof\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_perdof\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"object benchmark, max_correction_norm=0.2, K=10, n_rollouts=10\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"127732\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-perdof-norm02-object.log\"}, \"hypothesis\": \"Object magnitude sweep: perdof CRM v3-norm at norm=0.2 on LIBERO object benchmark. Paired with obs_only norm=0.2 (running, 18% at 5/10) for magnitude comparison figure. Tests perdof at moderate correction norm on object domain.\", \"metrics\": {\"tasks_done\": 10, \"tasks_total\": 10, \"overall_sr\": 0.11, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.1, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:04:45.416Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:04:48.447852+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"completed_at\": \"2026-05-16T07:12:35.145Z\", \"parent\": \"eval-acr-object-v3\"}, \"eval-acr-object-v4-scalar\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:53:44.102Z\", \"updated_at\": \"2026-05-17T03:31:41.215Z\", \"hypothesis\": \"D021: scalar_unc CRM v3-norm with max_correction_norm=0.1 on LIBERO object benchmark. Three-way ablation: perdof vs scalar_unc vs obs_only on object.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:3\"], \"pid\": \"14003\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-scalar.log\", \"submitted_at\": \"2026-05-15T02:53:43.910Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 47778.8, \"gpu_hours\": 13.27}, \"metrics\": {\"overall_sr\": 9, \"total_success\": 9, \"total_trials\": 100, \"n_tasks\": 10, \"n_rollouts_per_task\": 10, \"per_task\": {\"alphabet_soup\": {\"sr\": 0, \"success\": 0, \"trials\": 10}, \"cream_cheese\": {\"sr\": 0, \"success\": 0, \"trials\": 10}, \"salad_dressing\": {\"sr\": 10, \"success\": 1, \"trials\": 10}, \"bbq_sauce\": {\"sr\": 10, \"success\": 1, \"trials\": 10}, \"ketchup\": {\"sr\": 0, \"success\": 0, \"trials\": 10}, \"tomato_sauce\": {\"sr\": 0, \"success\": 0, \"trials\": 10}, \"butter\": {\"sr\": 10, \"success\": 1, \"trials\": 10}, \"milk\": {\"sr\": 10, \"success\": 1, \"trials\": 10}, \"chocolate_pudding\": {\"sr\": 30, \"success\": 3, \"trials\": 10}, \"orange_juice\": {\"sr\": 20, \"success\": 2, \"trials\": 10}}}, \"reproduce\": {\"finished_at\": \"2026-05-15T16:07:26.276Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:07:28.510451+00:00\"}]}, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-scalar.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T16:10:02.679Z\", \"parent\": \"crm-train-v2-scalar-unc\"}, \"eval-mag-obsonly-norm02\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:16:21.006Z\", \"updated_at\": \"2026-05-17T03:31:40.288Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --benchmark spatial --mode crm_obs_only --max_correction_norm 0.2 --n_rollouts 10 --K 10 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_mag_obs_only_norm02.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA + CRM-v3-norm-obs_only\", \"seed\": 42, \"checkpoint_source\": \"crm-train-v3-norm-obs_only\", \"eval_data\": \"LIBERO spatial\"}, \"gpu\": \"bjb2-28827:cuda:5\", \"pid\": 15190, \"metrics\": {\"T0_between_plate_ramekin\": 90, \"T1_next_to_ramekin\": 100, \"T2_table_center\": 0, \"T3_on_cookie_box\": 30, \"T4_top_drawer\": 10, \"T5_on_ramekin\": 0, \"T6_next_to_cookie_box\": 90, \"T7_on_stove\": 0, \"T8_next_to_plate\": 30, \"T9_on_wooden_cabinet\": 0, \"overall_sr\": 35, \"total_success\": 35, \"total_rollouts\": 100}, \"reproduce\": {\"finished_at\": \"2026-05-15T16:03:26.878Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:03:29.305763+00:00\"}]}, \"log_path\": \"/root/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm02.log\", \"conclusion\": \"negative\", \"checkpoint_path\": \"N/A (eval-only experiment)\", \"completed_at\": \"2026-05-15T16:06:23.063Z\", \"hypothesis\": \"obs_only CRM (ε=0.2) on LIBERO Spatial benchmark. Spatial benchmark 下 obs_only 最优 norm 是否同样为 0.2。如果 spatial 无明显分离，说明方法效果依赖 action distribution shift 程度。\", \"parent\": \"eval-acr-spatial-v3\"}, \"eval-mag-perdof-norm03\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:16:16.095Z\", \"updated_at\": \"2026-05-17T03:31:39.344Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --smolvla_path /root/autodl-tmp/models/smolvla_libero/\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_norm/perdof\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"/root/runs/acr-vla-conformal-refinement/eval-mag-perdof-norm03.log\"}, \"gpu\": \"bjb2-28827:cuda:3\", \"pid\": 14260, \"metrics\": {\"overall_sr_10task\": 0.26, \"T0_sr\": 0.7, \"T1_sr\": 0.5, \"T2_sr\": 0.1, \"T3_sr\": 0.1, \"T4_sr\": 0, \"T5_sr\": 0, \"T6_sr\": 0.9, \"T7_sr\": 0.1, \"T8_sr\": 0.2, \"T9_sr\": 0, \"total_successes\": 26, \"total_rollouts\": 100, \"benchmark\": \"spatial\", \"max_correction_norm\": 0.3}, \"reproduce\": {\"finished_at\": \"2026-05-15T16:53:04.031Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:53:08.939326+00:00\"}]}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T17:17:49.711Z\", \"hypothesis\": \"perdof CRM (ε=0.3) on LIBERO Spatial benchmark. 高 norm 下 perdof 在 spatial 是否也出现退化。如果 spatial 无 collapse（与 obs_only 接近），说明 failure mode 与 task complexity 相关。\", \"parent\": \"eval-acr-spatial-v3\"}, \"eval-mag-perdof-norm005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:16:10.924Z\", \"updated_at\": \"2026-05-17T03:31:38.448Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --benchmark spatial --mode acr_vla --max_correction_norm 0.05 --n_rollouts 10 --K 10 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_mag_perdof_norm005.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA + CRM-v3-norm-perdof\", \"seed\": 42, \"checkpoint_source\": \"crm-train-v3-norm-perdof\", \"eval_data\": \"LIBERO spatial\", \"log_path\": \"/root/runs/acr-vla-conformal-refinement/eval-mag-perdof-norm005.log\", \"checkpoint_path\": \"N/A (eval only)\"}, \"gpu\": \"bjb2-28827:cuda:1\", \"pid\": 13456, \"metrics\": {\"T0_between_plate_ramekin\": 50, \"T1_next_to_ramekin\": 100, \"T2_table_center\": 0, \"T3_on_cookie_box\": 30, \"T4_top_drawer\": 0, \"T5_on_ramekin\": 0, \"T6_next_to_cookie_box\": 100, \"T7_on_stove\": 0, \"T8_next_to_plate\": 30, \"T9_on_wooden_cabinet\": 0, \"avg_SR_10task\": 31}, \"reproduce\": {\"finished_at\": \"2026-05-15T16:52:50.451Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:52:53.898813+00:00\"}]}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T17:24:59.482Z\", \"hypothesis\": \"perdof CRM (ε=0.05) on LIBERO Spatial benchmark. 低 norm 下 perdof 在 spatial 的表现。如果与 obs_only-0.05 一致（35%），说明低 norm 约束消除了 conditioning 差异。\", \"parent\": \"eval-acr-spatial-v3\"}, \"eval-mag-perdof-norm003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:16:08.547Z\", \"updated_at\": \"2026-05-17T03:31:37.673Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --benchmark spatial --mode acr_vla --max_correction_norm 0.03 --n_rollouts 10 --K 10 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_mag_perdof_norm003.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA + CRM-v3-norm-perdof\", \"seed\": 42, \"checkpoint_source\": \"crm-train-v3-norm-perdof\", \"eval_data\": \"LIBERO spatial\"}, \"gpu\": \"bjb2-28827:cuda:0\", \"pid\": 13185, \"metrics\": {\"benchmark\": \"spatial\", \"mode\": \"acr_vla\", \"max_correction_norm\": 0.03, \"n_rollouts\": 10, \"K\": 10, \"seed\": 42, \"overall_sr\": 30, \"total_success\": 30, \"total_rollouts\": 100, \"tasks_done\": \"10/10\", \"per_task\": {\"T0_between_plate_ramekin\": 60, \"T1_next_to_ramekin\": 100, \"T2_table_center\": 0, \"T3_on_cookie_box\": 30, \"T4_top_drawer\": 10, \"T5_on_ramekin\": 0, \"T6_next_to_cookie_box\": 80, \"T7_on_stove\": 0, \"T8_next_to_plate\": 20, \"T9_on_wooden_cabinet\": 0}}, \"reproduce\": {\"finished_at\": \"2026-05-15T16:32:37.390Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:32:42.080703+00:00\"}]}, \"log_path\": \"/root/runs/acr-vla-conformal-refinement/eval-mag-perdof-norm003.log\", \"checkpoint_path\": \"N/A (eval-only)\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T16:40:16.878Z\", \"hypothesis\": \"perdof CRM (ε=0.03) on LIBERO Spatial benchmark. 极低 norm 下 perdof 在 spatial 的表现。与 obs_only-0.03 (34%) 对比，验证低 norm 安全区域。\", \"parent\": \"eval-acr-spatial-v3\"}, \"eval-vla-mean-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T03:10:44.114Z\", \"updated_at\": \"2026-05-17T03:15:31.664Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode vla_only --baseline_mode mean --benchmark spatial --n_rollouts 10 --seed 42\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"143106\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"SmolVLA K=10 mean action (no conformal)\", \"seed\": 42, \"hypothesis\": \"K=10 mean baseline isolates multi-sampling averaging contribution vs conformal correction. Expected between vla_only K=1 (30%) and ACR-VLA.\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"log_path\": \"/root/autodl-tmp/eval_results/eval-vla-mean-spatial.log\"}, \"metrics\": {\"overall_success_rate_10tasks\": 0.32, \"total_successes\": 32, \"total_trials\": 100, \"T1\": 0.7, \"T2\": 1, \"T3\": 0, \"T4\": 0.3, \"T5\": 0, \"T6\": 0, \"T7\": 0.8, \"T8\": 0, \"T9\": 0.3, \"T10\": 0.1}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T22:12:39.100Z\", \"log_path\": \"/root/autodl-tmp/eval_results/eval-vla-mean-spatial.log\", \"checkpoint_path\": \"N/A (eval experiment)\", \"hypothesis\": \"VLA mean action (average of K=10 samples) on LIBERO-Spatial provides a strong baseline by reducing sampling noise — establishes whether sample averaging alone matches or exceeds single-sample VLA\", \"parent\": \"eval-spatial-v7-full\"}, \"eval-acr-object-obs-only-norm02\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:20:46.639Z\", \"updated_at\": \"2026-05-17T03:15:28.368Z\", \"spec\": {\"hypothesis\": \"obs-only CRM with norm=0.2 on object benchmark. Cross-benchmark norm sensitivity test — paired with eval-mag-obsonly-norm02 on spatial. If obs-only at norm=0.2 > norm=0.1 on both benchmarks → robust 'observation-conditioned correction' story.\", \"parent\": \"eval-acr-object-v4-obs-only\", \"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02.json\", \"server\": \"bjb1-32546\", \"gpu\": \"cuda:4\", \"pid\": 44270, \"tmux_session\": \"eval-acr-object-obs-only-norm02\", \"data_path\": \"LIBERO object benchmark (10 tasks)\", \"data_count\": 100, \"model_name\": \"crm_obs_only (327198 params)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark, 10 tasks x 10 rollouts\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-obs-only-norm02.log\"}, \"metrics\": {\"overall_sr\": 0.22, \"total_success\": 22, \"total_rollouts\": 100, \"tasks_done\": 10, \"tasks_total\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.3, \"bbq_sauce\": 0.4, \"ketchup\": 0.2, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.2, \"chocolate_pudding\": 0.6, \"orange_juice\": 0.3}}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:35:34.272Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:35:39.374197+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-obs-only-norm02.log\", \"completed_at\": \"2026-05-15T17:37:08.420Z\", \"hypothesis\": \"ACR with obs-only CRM and max_correction_norm=0.2 on LIBERO-Object achieves meaningful improvement over VLA-only baseline by applying visually-guided corrections without requiring action history\", \"parent\": \"crm-train-v2-obs-only\"}, \"eval-spatial-v7-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T00:05:16.510Z\", \"updated_at\": \"2026-05-17T03:15:26.392Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 42\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"123761\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"lerobot/smolvla_libero\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/eval_results/eval-spatial-v7.log\", \"hypothesis\": \"SmolVLA baseline on libero_spatial with K=1 fix (vla_only single inference)\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.3, \"total_successes\": 30, \"total_episodes\": 100, \"n_tasks\": 10, \"n_rollouts\": 10, \"per_task\": {\"pick_up_black_bowl_between_plate_and_ramekin\": 0.6, \"pick_up_black_bowl_next_to_ramekin\": 1, \"pick_up_black_bowl_from_table_center\": 0, \"pick_up_black_bowl_on_cookie_box\": 0.2, \"pick_up_black_bowl_in_top_drawer\": 0, \"pick_up_black_bowl_on_ramekin\": 0, \"pick_up_black_bowl_next_to_cookie_box\": 0.9, \"pick_up_black_bowl_on_stove\": 0, \"pick_up_black_bowl_next_to_plate\": 0.3, \"pick_up_black_bowl_on_wooden_cabinet\": 0}}, \"checkpoint_path\": \"N/A (eval only)\", \"completed_at\": \"2026-05-14T01:45:58.391Z\", \"hypothesis\": \"Full ACR pipeline v7 (obs-only CRM, conformal selection, norm=0.1) on LIBERO-Spatial achieves improvement over VLA-only baseline (32%), validating the method on spatial reasoning tasks\", \"parent\": \"eval-smolvla-libero-spatial\"}, \"eval-object-v8-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T00:05:25.647Z\", \"updated_at\": \"2026-05-17T03:15:25.342Z\", \"spec\": {\"hypothesis\": \"SmolVLA baseline on libero_object with K=1 fix (vla_only single inference)\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"command\": \"CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode vla_only --benchmark object --n_rollouts 10 --seed 42\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"125830\", \"data_path\": \"/root/autodl-tmp/libero_data/libero_object/\", \"data_count\": 100, \"model_name\": \"smolvla_libero\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/eval_results/eval-object-v6.log\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.13, \"total_successes\": 13, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.2, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.2}}, \"checkpoint_path\": \"N/A (eval only)\", \"completed_at\": \"2026-05-14T03:10:30.457Z\", \"hypothesis\": \"Full ACR pipeline v8 (obs-only CRM, K=10 conformal selection, norm=0.1) on LIBERO-Object achieves consistent improvement over VLA-only baseline (9-12%) across all 10 tasks with optimized hyperparameters\", \"parent\": \"eval-smolvla-libero-spatial\"}, \"precompute-v5-shard2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:55:02.277Z\", \"updated_at\": \"2026-05-17T03:15:19.323Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 python -u src/train_crm.py --precompute --benchmark spatial object --cache_dir /root/autodl-tmp/crm_cache_v5/ --K 10 --shard_id 2 --num_shards 3 --max_demos_per_task 10 --precompute_batch_size 4 --save_every 500\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"180480\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v5-shard2.log\", \"submitted_at\": \"2026-05-14T07:56:37.531Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial + object)\", \"data_count\": \"~8900 samples (shard 2 of 3)\", \"model_name\": \"SmolVLA 450M (precompute K=10 features)\", \"seed\": 42, \"hypothesis\": \"Phase 2 precompute with 8D state fix (C1) for per-DOF CRM retraining\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache_v5/\", \"wall_clock_seconds\": 5491.8, \"gpu_hours\": 1.53}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T09:28:09.308Z\", \"hypothesis\": \"Precompute v5 (shard 2/3) with normalized correction targets and L2-clipped labels — final data version enabling stable CRM v3 training with bounded correction magnitudes\", \"parent\": \"precompute-v4-shard2\"}, \"precompute-v5-shard1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:55:00.276Z\", \"updated_at\": \"2026-05-17T03:15:18.177Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 python -u src/train_crm.py --precompute --benchmark spatial object --cache_dir /root/autodl-tmp/crm_cache_v5/ --K 10 --shard_id 1 --num_shards 3 --max_demos_per_task 10 --precompute_batch_size 4 --save_every 500\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"180400\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v5-shard1.log\", \"submitted_at\": \"2026-05-14T07:56:35.789Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial + object)\", \"data_count\": \"~8900 samples (shard 1 of 3)\", \"model_name\": \"SmolVLA 450M (precompute K=10 features)\", \"seed\": 42, \"hypothesis\": \"Phase 2 precompute with 8D state fix (C1) for per-DOF CRM retraining\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache_v5/\", \"wall_clock_seconds\": 5492.1, \"gpu_hours\": 1.53}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T09:28:07.934Z\", \"hypothesis\": \"Precompute v5 (shard 1/3) with normalized correction targets and L2-clipped labels — final data version enabling stable CRM v3 training with bounded correction magnitudes\", \"parent\": \"precompute-v4-shard1\"}, \"precompute-v5-shard0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:54:59.383Z\", \"updated_at\": \"2026-05-17T03:15:17.511Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 python -u src/train_crm.py --precompute --benchmark spatial object --cache_dir /root/autodl-tmp/crm_cache_v5/ --K 10 --shard_id 0 --num_shards 3 --max_demos_per_task 10 --precompute_batch_size 4 --save_every 500\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"180251\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v5-shard0.log\", \"submitted_at\": \"2026-05-14T07:56:33.414Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial + object)\", \"data_count\": \"~8900 samples (shard 0 of 3)\", \"model_name\": \"SmolVLA 450M (precompute K=10 features)\", \"seed\": 42, \"hypothesis\": \"Phase 2 precompute with 8D state fix (C1) for per-DOF CRM retraining\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache_v5/\", \"wall_clock_seconds\": 5493.2, \"gpu_hours\": 1.53}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T09:28:06.626Z\", \"hypothesis\": \"Precompute v5 (shard 0/3) with normalized correction targets and L2-clipped labels — final data version enabling stable CRM v3 training with bounded correction magnitudes\", \"parent\": \"precompute-v4-shard0\"}, \"precompute-v4-shard2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:58:14.301Z\", \"updated_at\": \"2026-05-17T03:15:16.391Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 2 --num_shards 3 --seed 42 --K 10 --cache_dir /root/autodl-tmp/crm_cache/ 2>&1\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"69937\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v4-shard2.log\", \"submitted_at\": \"2026-05-13T18:58:14.266Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache/\", \"wall_clock_seconds\": 173960.7, \"gpu_hours\": 48.32}, \"reproduce\": {\"finished_at\": \"2026-05-13T20:09:25.582Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:09:26.379476+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:17:35.000Z\", \"hypothesis\": \"Precompute v4 (shard 2/3) with corrected 8D state representation and proper conformal features — fixes data pipeline bugs from v1-v3 that caused downstream CRM training issues\", \"parent\": \"precompute-shard2\"}, \"precompute-v4-shard1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:58:12.183Z\", \"updated_at\": \"2026-05-17T03:15:15.362Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 1 --num_shards 3 --seed 42 --K 10 --cache_dir /root/autodl-tmp/crm_cache/ 2>&1\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"69793\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v4-shard1.log\", \"submitted_at\": \"2026-05-13T18:58:12.154Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache/\", \"wall_clock_seconds\": 173961.1, \"gpu_hours\": 48.32}, \"reproduce\": {\"finished_at\": \"2026-05-13T20:04:22.574Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:04:23.366356+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:17:33.288Z\", \"hypothesis\": \"Precompute v4 (shard 1/3) with corrected 8D state representation and proper conformal features — fixes data pipeline bugs from v1-v3 that caused downstream CRM training issues\", \"parent\": \"precompute-shard1\"}, \"precompute-v4-shard0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:58:09.830Z\", \"updated_at\": \"2026-05-17T03:15:14.415Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 0 --num_shards 3 --seed 42 --K 10 --cache_dir /root/autodl-tmp/crm_cache/ 2>&1\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"69647\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v4-shard0.log\", \"submitted_at\": \"2026-05-13T18:58:09.802Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache/\", \"wall_clock_seconds\": 173962.3, \"gpu_hours\": 48.32}, \"reproduce\": {\"finished_at\": \"2026-05-13T20:04:45.258Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:04:50.222546+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:17:32.128Z\", \"hypothesis\": \"Precompute v4 (shard 0/3) with corrected 8D state representation and proper conformal features — fixes data pipeline bugs from v1-v3 that caused downstream CRM training issues\", \"parent\": \"precompute-shard0\"}, \"eval-vla-mean-spatial-t10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:20:02.901Z\", \"updated_at\": \"2026-05-17T03:14:58.588Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode vla_only --baseline_mode mean --benchmark spatial --n_rollouts 10 --seed 42 --start_task 9 --output_file /root/autodl-tmp/eval_results/eval-vla-mean-spatial-t10.json\", \"server\": \"bjb2-40593\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 10, \"model_name\": \"smolvla_libero\", \"seed\": 42}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:32:23.773Z\", \"metrics\": {\"T10_on_wooden_shelf\": \"10% (1/10)\", \"note\": \"Only ran task 9 (start_task=9). T10 = wooden shelf task.\"}, \"log_path\": \"/root/autodl-tmp/eval_results/eval-vla-mean-spatial-t10.json\", \"checkpoint_path\": \"N/A (eval only)\", \"hypothesis\": \"VLA mean action on LIBERO-Spatial task 10 (wooden shelf) specifically — completing the last missing task from the earlier eval-vla-mean-spatial run to have full 10-task baseline numbers\", \"parent\": \"eval-vla-mean-spatial\"}, \"eval-reconvla-spatial-v3\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-13T23:04:34.297Z\", \"updated_at\": \"2026-05-17T03:14:57.896Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T11:07:49.901Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-13T23:34:14.141Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:34:15.524386+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:07:51.915540+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode reconvla --benchmark spatial --n_rollouts 10 --seed 42 --K 10\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"118108\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"SampleConsensus (scalar Euclidean argmin)\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/eval_results/eval-reconvla-spatial-v3.log\", \"hypothesis\": \"SampleConsensus scalar baseline for ACR-VLA comparison\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.34, \"total_successes\": 34, \"total_rollouts\": 100, \"per_task\": {\"pick_up_black_bowl_between_plate_and_ramekin\": 0.6, \"pick_up_black_bowl_next_to_ramekin\": 1, \"pick_up_black_bowl_from_table_center\": 0, \"pick_up_black_bowl_on_cookie_box\": 0.3, \"pick_up_black_bowl_in_top_drawer\": 0.1, \"pick_up_black_bowl_on_ramekin\": 0.1, \"pick_up_black_bowl_next_to_cookie_box\": 0.9, \"pick_up_black_bowl_on_stove\": 0, \"pick_up_black_bowl_next_to_plate\": 0.4, \"pick_up_black_bowl_on_wooden_cabinet\": 0}}, \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/root/autodl-tmp/eval_results/eval-reconvla-spatial-v3.log\", \"hypothesis\": \"ReconVLA (K=10 sample consensus without CRM) on LIBERO-Spatial establishes upper bound for pure sampling diversity benefit — if high, CRM correction adds value only at lower K; if low, confirms CRM is essential\", \"parent\": \"plan_014-reconvla-baseline\"}, \"eval-obs-only-spatial-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:43:42.283Z\", \"updated_at\": \"2026-05-17T03:14:57.225Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"203968\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-spatial-v2.log\", \"submitted_at\": \"2026-05-14T12:43:42.188Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"CRM obs_only v2 (990D, no conformal features)\", \"seed\": 42, \"hypothesis\": \"obs_only CRM ablation — CRM without conformal features tests whether per-DOF conformal intervals are necessary for effective correction\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"parent\": \"crm-train-v2-obs-only\", \"failure_reason\": \"Bug: evaluate.py line 266 CRM load condition missing crm_obs_only, CRM was None throughout eval, all rollouts 0%. Replaced by eval-obs-only-spatial-v3.\", \"wall_clock_seconds\": 185.5, \"gpu_hours\": 0.05}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T12:46:47.663Z\", \"hypothesis\": \"Obs-only CRM v2 retrained on spatial data resolves the dimension mismatch from v1 and achieves meaningful improvement on LIBERO-Spatial by using benchmark-matched visual features\", \"parent\": \"eval-obs-only-spatial\"}, \"crm-train-v2-scalar-unc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:30:43.696Z\", \"updated_at\": \"2026-05-17T03:14:56.290Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 python -u src/train_crm.py --benchmark spatial object --cache_dir /root/autodl-tmp/crm_cache_v5/ --output_dir /root/autodl-tmp/checkpoints/crm_v2/scalar_unc/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode scalar_unc --seed 42\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"186964\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v2-scalar-unc.log\", \"submitted_at\": \"2026-05-14T09:30:43.616Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/crm_cache_v5/\", \"data_count\": 26737, \"model_name\": \"CRM scalar-unc v2 (327K params, 8D state fix)\", \"seed\": 42, \"hypothesis\": \"Scalar CRM v2 ablation — per-DOF expected to outperform on task success rate despite similar val_loss\", \"wall_clock_seconds\": 9977.5, \"gpu_hours\": 2.77}, \"conclusion\": \"success\", \"metrics\": {\"best_val_loss\": 0.047202, \"best_epoch\": 48, \"total_epochs\": 50, \"final_train_loss\": 0.069679, \"comparison_vs_old\": \"old_6D_buggy=0.008379, new=0.047202 (loss metric changed with v2 fix)\"}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v2/scalar_unc/crm_best.pt\", \"log_path\": \"/root/runs/acr-vla-conformal-refinement/crm-train-v2-scalar-unc.log\", \"completed_at\": \"2026-05-14T12:17:01.093Z\", \"hypothesis\": \"Training CRM to predict scalar uncertainty enables confidence-based action selection via conformal prediction, allowing adaptive correction magnitude based on model confidence\", \"parent\": \"plan_001-crm-smolvla\"}, \"crm-train-v2-perdof\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:30:40.796Z\", \"updated_at\": \"2026-05-17T03:14:55.328Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 python -u src/train_crm.py --benchmark spatial object --cache_dir /root/autodl-tmp/crm_cache_v5/ --output_dir /root/autodl-tmp/checkpoints/crm_v2/perdof/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode full --seed 42\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"186823\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v2-perdof.log\", \"submitted_at\": \"2026-05-14T09:30:40.716Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/crm_cache_v5/\", \"data_count\": 26737, \"model_name\": \"CRM per-DOF v2 (337K params, 8D state fix, argmin base, L2 clip)\", \"seed\": 42, \"hypothesis\": \"Per-DOF CRM v2 with D016 fixes (8D state, argmin base, alpha=0.5, L2 clipping) improves over pre-fix version\", \"wall_clock_seconds\": 9979.5, \"gpu_hours\": 2.77}, \"conclusion\": \"success\", \"metrics\": {\"best_val_loss\": 0.051684, \"best_epoch\": 48, \"total_epochs\": 50, \"final_train_loss\": 0.076748, \"comparison_vs_old\": \"old_6D_buggy=0.009046, new=0.051684 (loss metric changed with v2 fix)\"}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v2/perdof/crm_best.pt\", \"log_path\": \"/root/runs/acr-vla-conformal-refinement/crm-train-v2-perdof.log\", \"completed_at\": \"2026-05-14T12:17:00.195Z\", \"hypothesis\": \"Training CRM with per-DoF (per degree-of-freedom) correction output produces more fine-grained corrections than a single scalar, improving downstream task performance on multi-joint manipulation\", \"parent\": \"plan_001-crm-smolvla\"}, \"crm-train-v2-obs-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:41:35.819Z\", \"updated_at\": \"2026-05-17T03:14:53.940Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=3 python -u src/train_crm.py --benchmark spatial object --cache_dir /root/autodl-tmp/crm_cache_v5/ --output_dir /root/autodl-tmp/checkpoints/crm_v2/obs_only/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode obs_only --seed 42\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"187913\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v2-obs-only.log\", \"submitted_at\": \"2026-05-14T09:41:35.736Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/crm_cache_v5/\", \"data_count\": 26737, \"model_name\": \"CRM obs_only v2\", \"seed\": 42, \"wall_clock_seconds\": 9366.4, \"gpu_hours\": 2.6}, \"conclusion\": \"success\", \"metrics\": {\"best_val_loss\": 0.050501, \"best_epoch\": 50, \"total_epochs\": 50, \"final_train_loss\": 0.074839, \"comparison_vs_old\": \"old_6D_buggy=0.018312, new=0.050501 (loss metric changed with v2 fix)\"}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\", \"log_path\": \"/root/runs/acr-vla-conformal-refinement/crm-train-v2-obs-only.log\", \"completed_at\": \"2026-05-14T12:17:42.122Z\", \"hypothesis\": \"Training a CRM with obs-only input (no action/proprio) can learn correction signals purely from visual observation features, enabling correction without access to action space information\", \"parent\": \"plan_001-crm-smolvla\"}, \"precompute-shard2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T11:57:48.056Z\", \"updated_at\": \"2026-05-17T03:13:50.200Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 2 --num_shards 3 --seed 42 --K 10\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"47186\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-shard2.log\", \"submitted_at\": \"2026-05-13T11:57:48.042Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache/\", \"wall_clock_seconds\": 12499.4, \"gpu_hours\": 3.47}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T15:26:07.463Z\", \"hypothesis\": \"Precomputing VLA action caches (shard 2/3) enables offline CRM training without repeated VLA inference — infrastructure prerequisite for scalable CRM training experiments\"}, \"precompute-shard1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T11:57:46.669Z\", \"updated_at\": \"2026-05-17T03:13:49.286Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 1 --num_shards 3 --seed 42 --K 10\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"47044\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-shard1.log\", \"submitted_at\": \"2026-05-13T11:57:46.654Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache/\", \"wall_clock_seconds\": 12499.8, \"gpu_hours\": 3.47}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T15:26:06.485Z\", \"hypothesis\": \"Precomputing VLA action caches (shard 1/3) enables offline CRM training without repeated VLA inference — infrastructure prerequisite for scalable CRM training experiments\"}, \"precompute-shard0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T11:57:45.284Z\", \"updated_at\": \"2026-05-17T03:13:43.682Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 0 --num_shards 3 --seed 42 --K 10\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"46966\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-shard0.log\", \"submitted_at\": \"2026-05-13T11:57:45.270Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache/\", \"wall_clock_seconds\": 12500.2, \"gpu_hours\": 3.47}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T15:26:05.433Z\", \"hypothesis\": \"Precomputing VLA action caches (shard 0/3) enables offline CRM training without repeated VLA inference — infrastructure prerequisite for scalable CRM training experiments\"}, \"precompute-k5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:15:37.603Z\", \"updated_at\": \"2026-05-17T03:13:41.787Z\", \"spec\": {\"command\": \"python -u src/train_crm.py --precompute --benchmark spatial object --K 5 --cache_dir /root/autodl-tmp/crm_cache_k5/\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"79517\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-k5.log\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 26737, \"model_name\": \"smolvla_libero\", \"seed\": 42, \"hypothesis\": \"K=5 precompute for K sensitivity ablation (plan_015)\"}, \"reproduce\": {\"finished_at\": \"2026-05-13T22:09:33.445Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T22:09:34.396952+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/crm_cache_k5/\", \"metrics\": {\"spatial_samples\": 12167, \"object_samples\": 14570, \"total_samples\": 26737, \"spatial_cache_mb\": 106, \"object_cache_mb\": 127, \"total_cache_mb\": 233, \"runtime_min\": 107}, \"completed_at\": \"2026-05-13T22:12:39.543Z\", \"hypothesis\": \"Precomputing K=5 VLA action samples provides sufficient diversity for conformal selection while reducing inference cost by 50% vs K=10 — testing efficiency-performance tradeoff\"}, \"plan_014-reconvla-baseline\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-13T06:56:12.892Z\", \"updated_at\": \"2026-05-17T03:13:39.823Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark spatial object --n_rollouts 20 --seed 42\", \"server\": \"autodl-4090\", \"gpu\": [\"cuda:0\"], \"pid\": \"50790\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/plan_014-reconvla-baseline.log\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial + object)\", \"data_count\": \"20 tasks x 20 rollouts = 400 episodes\", \"model_name\": \"SmolVLA (450M) + ReconVLA argmin selection\", \"seed\": 42, \"hypothesis\": \"ReconVLA (scalar Euclidean nonconformity + argmin selection) as baseline for ACR-VLA comparison\", \"fixes_applied\": [\"BDDL path: use benchmark_instance.get_task_bddl_file_path()\", \"LIBERO assets copied from GitHub repo\"]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T11:07:20.019Z\", \"hypothesis\": \"ReconVLA baseline implementation validates that sample consensus (K=10 argmin Euclidean) provides meaningful improvement over single-sample VLA, establishing competitive baseline for ACR comparison\"}, \"plan_001-crm-smolvla\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T03:01:07.682Z\", \"updated_at\": \"2026-05-17T03:13:37.890Z\", \"spec\": {\"command\": \"python -u src/train_crm.py --auto --benchmark spatial object --epochs 50 --batch_size 32 --lr 1e-3 --seed 42 --K 10\", \"server\": \"autodl-4090\", \"gpu\": [\"cuda:0\"], \"pid\": \"32811\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/plan_001-crm-smolvla.log\", \"submitted_at\": \"2026-05-13T04:54:14.975Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial + object)\", \"data_count\": 1000, \"model_name\": \"CRM (337K) + SmolVLA (450M)\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/\", \"hypothesis\": \"Per-DOF conformal features enable dimension-selective action correction on LIBERO\", \"wall_clock_seconds\": 2992.2, \"gpu_hours\": 0.83}, \"conclusion\": \"failed\", \"failure_reason\": \"startup recovery: process dead, no active cron monitor\", \"completed_at\": \"2026-05-13T05:44:07.131Z\", \"hypothesis\": \"Initial CRM + SmolVLA integration plan validates that conformal residual module can be trained and integrated with a pretrained VLA model for action refinement\"}, \"mvp-point-reaching\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T01:22:10.415Z\", \"updated_at\": \"2026-05-17T03:13:35.534Z\", \"spec\": {\"hypothesis\": \"Per-DOF uncertainty features carry more actionable information than scalar uncertainty summaries, enabling dimension-selective correction\", \"description\": \"3D point-reaching MVP: 3 MLP variants (scalar/per-DOF/no uncertainty) x 6 groups (3 anisotropy ratios x 2 uncertainty sources)\", \"server\": \"bjb2-40593\", \"gpu\": \"cuda:0\", \"data_count\": 20000, \"model_name\": \"CorrectionMLP(2-layer, 64-hidden)\", \"seed\": 42, \"command\": \"python -u run_mvp.py\", \"data_path\": \"synthetic (generated in-script)\", \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/mvp/\", \"log_path\": \"/root/acr-vla-conformal-refinement/mvp/mvp_results.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T01:44:00.055Z\", \"metrics\": {\"group1_oracle\": {\"A_scalar\": {\"mse_x\": 0.180218, \"mse_y\": 0.02497, \"mse_z\": 0.024232, \"total\": 0.076473}, \"B_perDOF\": {\"mse_x\": 0.172652, \"mse_y\": 0.015544, \"mse_z\": 0.01561, \"total\": 0.067935}, \"C_none\": {\"mse_x\": 0.22706, \"mse_y\": 0.025542, \"mse_z\": 0.024753, \"total\": 0.092451}}, \"group2_oracle\": {\"A_scalar\": {\"mse_x\": 0.064642, \"mse_y\": 0.023836, \"mse_z\": 0.022967, \"total\": 0.037148}, \"B_perDOF\": {\"mse_x\": 0.053403, \"mse_y\": 0.015695, \"mse_z\": 0.01573, \"total\": 0.028276}, \"C_none\": {\"mse_x\": 0.084178, \"mse_y\": 0.025427, \"mse_z\": 0.024798, \"total\": 0.044801}}, \"group3_oracle\": {\"A_scalar\": {\"mse_x\": 0.042948, \"mse_y\": 0.023218, \"mse_z\": 0.022365, \"total\": 0.02951}, \"B_perDOF\": {\"mse_x\": 0.033008, \"mse_y\": 0.015621, \"mse_z\": 0.015647, \"total\": 0.021425}, \"C_none\": {\"mse_x\": 0.053043, \"mse_y\": 0.025523, \"mse_z\": 0.024741, \"total\": 0.034436}}, \"group4_K10\": {\"A_scalar\": {\"mse_x\": 0.187418, \"mse_y\": 0.024701, \"mse_z\": 0.024277, \"total\": 0.078799}, \"B_perDOF\": {\"mse_x\": 0.182888, \"mse_y\": 0.019072, \"mse_z\": 0.018475, \"total\": 0.073478}, \"C_none\": {\"mse_x\": 0.21507, \"mse_y\": 0.02496, \"mse_z\": 0.024637, \"total\": 0.088223}}, \"group5_K10\": {\"A_scalar\": {\"mse_x\": 0.064895, \"mse_y\": 0.02386, \"mse_z\": 0.023596, \"total\": 0.037451}, \"B_perDOF\": {\"mse_x\": 0.05851, \"mse_y\": 0.018868, \"mse_z\": 0.018471, \"total\": 0.03195}, \"C_none\": {\"mse_x\": 0.077047, \"mse_y\": 0.024825, \"mse_z\": 0.02464, \"total\": 0.042171}}, \"group6_K10\": {\"A_scalar\": {\"mse_x\": 0.041848, \"mse_y\": 0.02344, \"mse_z\": 0.023207, \"total\": 0.029498}, \"B_perDOF\": {\"mse_x\": 0.036348, \"mse_y\": 0.018736, \"mse_z\": 0.018453, \"total\": 0.024512}, \"C_none\": {\"mse_x\": 0.048365, \"mse_y\": 0.024827, \"mse_z\": 0.024577, \"total\": 0.03259}}, \"pass_criteria\": {\"group1\": \"PASS\", \"group4\": \"PASS\", \"overall\": \"SUCCESS\"}, \"summary_pct_improvements\": {\"reference_group\": \"group4_K10 (sigma=0.5/0.1/0.1, K=10 estimated uncertainty)\", \"perDOF_vs_scalar_total\": 6.75, \"perDOF_vs_none_total\": 16.71, \"perDOF_vs_scalar_y_axis\": 22.79, \"perDOF_vs_scalar_z_axis\": 23.9, \"paper_claims\": {\"6.7_pct_over_scalar\": \"group4 total: (0.078799-0.073478)/0.078799 = 6.75%\", \"16.7_pct_over_none\": \"group4 total: (0.088223-0.073478)/0.088223 = 16.71%\", \"22_24_pct_per_axis\": \"group4 y: 22.79%, z: 23.90%\"}}}, \"hypothesis\": \"MVP validation: CRM correction signals improve point-reaching accuracy in simplified task — if corrections reliably move end-effector toward targets, the mechanism transfers to full manipulation\"}, \"eval-smolvla-libero-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T11:35:16.236Z\", \"updated_at\": \"2026-05-17T03:13:33.197Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 3 --seed 42\", \"server\": \"autodl-4090x4\", \"gpu\": [\"cuda:0\"], \"pid\": \"43809\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": \"10 tasks x 3 rollouts x 300 steps\", \"model_name\": \"lerobot/smolvla_libero (450M, full fine-tuned on libero_spatial)\", \"seed\": 42, \"hypothesis\": \"Validate smolvla_libero checkpoint with fixed wrapper (correct state repr, 256x256 images, 7D action) achieves >50% success on libero_spatial\", \"log_path\": \"/tmp/eval_spatial_full.log\", \"checkpoint_source\": \"lerobot/smolvla_libero (HuggingFace community checkpoint)\", \"failure_reason\": \"smolvla_libero 0% on spatial - 6 wrapper bugs: image flip/size/normalization, state 6D→8D, state normalization, action denormalization all missing\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T15:45:51.082Z\", \"hypothesis\": \"SmolVLA pretrained model evaluates directly on LIBERO-Spatial without any CRM or conformal processing — establishing raw VLA capability as absolute floor baseline\"}, \"eval-obs-only-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:17:10.843Z\", \"updated_at\": \"2026-05-17T03:13:04.533Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"197596\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-spatial.log\", \"submitted_at\": \"2026-05-14T12:17:10.754Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"CRM obs_only v2 (990D input, no conformal features)\", \"seed\": 42, \"hypothesis\": \"obs_only CRM ablation — CRM without conformal features\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"failure_reason\": \"evaluate.py has no crm_obs_only mode. --mode acr_vla loads CRM expecting 1030D input but obs_only checkpoint has 990D (no conformal features). Replaced by eval-obs-only-spatial-v2.\", \"wall_clock_seconds\": 1392.5, \"gpu_hours\": 0.39}, \"conclusion\": \"failed\", \"metrics\": {\"error\": \"size mismatch: obs_only CRM net.0.weight [256,990] vs acr_vla expects [256,1030] — no crm_obs_only mode in evaluate.py\"}, \"completed_at\": \"2026-05-14T12:40:23.205Z\", \"hypothesis\": \"Obs-only CRM trained on object benchmark generalizes to LIBERO-Spatial tasks without retraining — testing cross-benchmark transfer of visual correction signals\"}, \"eval-obs-only-object-default-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:13:41.913Z\", \"updated_at\": \"2026-05-17T03:09:38.443Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_seed44.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:5\"], \"pid\": \"229751\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-default-seed44.log\", \"submitted_at\": \"2026-05-16T07:13:41.570Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_norm_obs_only\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 48315.0, \"gpu_hours\": 13.42}, \"reproduce\": {\"finished_at\": \"2026-05-16T20:36:24.235Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T20:36:28.363366+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.16, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.1, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.4, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.2, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.3}}, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-default-seed44.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"completed_at\": \"2026-05-16T20:38:56.577Z\", \"hypothesis\": \"obs_only CRM (default norm ~1.42) seed=44 on LIBERO Object. 验证 obs_only 在 uncapped norm 下的跨 seed 稳定性（seed42=17%）。如果维持 15-20%，确认极端 magnitude 鲁棒性。\"}, \"eval-mag-perdof-norm005-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:56:58.178Z\", \"updated_at\": \"2026-05-17T03:09:30.045Z\", \"spec\": {\"hypothesis\": \"Object magnitude sweep: perdof CRM v3-norm at norm=0.05 on LIBERO object benchmark. Paired with obs_only norm=0.05 for magnitude comparison figure.\", \"parent\": \"eval-acr-object-v4-perdof\", \"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_perdof_norm005.json\", \"server\": \"bjb2-28827\", \"gpu\": \"1\", \"pid\": 109650, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 10, \"model_name\": \"crm_perdof\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object (10 tasks x 10 rollouts)\", \"log_path\": \"logs/nohup_eval_object_perdof_norm005.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\"}, \"metrics\": {\"overall_sr\": 0.14, \"successes\": 14, \"total\": 100, \"tasks_done\": 10, \"tasks_total\": 10}, \"reproduce\": {\"finished_at\": \"2026-05-16T08:36:33.616Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T08:36:35.355Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T08:36:40.842032+00:00\"}]}, \"hypothesis\": \"perdof CRM (ε=0.05) seed=42 on LIBERO Object. 验证 perdof 在极低 norm 下是否与 obs_only 接近（两者都受限于低 norm 纠正量）。magnitude curve 低端数据点。\"}, \"eval-mag-perdof-norm02-seed43-object-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:34:16.821Z\", \"updated_at\": \"2026-05-17T03:09:27.225Z\", \"spec\": {\"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_perdof\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed43_r3.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": \"144504\"}, \"metrics\": {\"overall_sr\": 0.09, \"successes\": 9, \"total\": 100, \"tasks_done\": 10, \"tasks_total\": 10, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.3}, \"vs_seed42\": \"-2pp (11% → 9%)\", \"pooled_2seed_perdof_02\": \"10% (20/200)\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T10:39:30.416Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T10:39:33.739829+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"logs/eval_object_perdof_norm02_seed43_r3.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T10:41:59.362Z\", \"hypothesis\": \"perdof CRM (ε=0.2) seed=43 on LIBERO Object. 验证 perdof 在 norm=0.2 的多 seed 数据（seed42=11%）。确认 perdof 在中间 norm 的退化幅度具有跨 seed 一致性。\"}, \"eval-mag-perdof-norm03-object-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:26:52.169Z\", \"updated_at\": \"2026-05-17T03:09:17.332Z\", \"spec\": {\"server\": \"bjb2-28827\", \"gpu\": \"cuda:2\", \"pid\": 140759, \"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --seed 42 --K 10 --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_r3.json\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_norm_perdof\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\"}, \"metrics\": {\"overall_sr\": 0.04, \"successes\": 4, \"total\": 100, \"tasks_done\": 10, \"tasks_total\": 10}, \"reproduce\": {\"finished_at\": \"2026-05-16T11:10:32.044Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T11:10:33.866Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T11:10:39.747200+00:00\"}]}, \"hypothesis\": \"perdof CRM (ε=0.3) seed=42 on LIBERO Object magnitude sweep. 验证 perdof 在 norm=0.3 的 collapse 程度。预期 SR 急剧下降（支持 progressive collapse 叙事）。\"}, \"eval-mag-obsonly-norm005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:16:18.917Z\", \"updated_at\": \"2026-05-17T03:09:15.263Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --benchmark spatial --mode crm_obs_only --max_correction_norm 0.05 --n_rollouts 10 --K 10 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_mag_obs_only_norm005.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA + CRM-v3-norm-obs_only\", \"seed\": 42, \"checkpoint_source\": \"crm-train-v3-norm-obs_only\", \"eval_data\": \"LIBERO spatial\"}, \"gpu\": \"bjb2-28827:cuda:4\", \"pid\": 14854, \"metrics\": {\"benchmark\": \"spatial\", \"mode\": \"crm_obs_only\", \"max_correction_norm\": 0.05, \"n_rollouts\": 10, \"K\": 10, \"overall_sr\": 35, \"total_success\": 35, \"total_episodes\": 100, \"per_task\": {\"T0_between_plate_ramekin\": 80, \"T1_next_to_ramekin\": 90, \"T2_table_center\": 0, \"T3_on_cookie_box\": 40, \"T4_top_drawer\": 10, \"T5_on_ramekin\": 0, \"T6_next_to_cookie_box\": 80, \"T7_on_stove\": 0, \"T8_next_to_plate\": 50, \"T9_on_wooden_cabinet\": 0}}, \"reproduce\": {\"finished_at\": \"2026-05-15T16:00:02.717Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:00:09.569232+00:00\"}]}, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm005.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T16:02:08.945Z\", \"hypothesis\": \"obs_only CRM (ε=0.05) on LIBERO Spatial benchmark. 低 norm 在 spatial 上的表现。与 object 的 0.05 数据点对比，检验 benchmark 间一致性。\"}, \"eval-mag-obsonly-norm003-b2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:20:45.606Z\", \"updated_at\": \"2026-05-17T03:09:11.273Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_mag_obsonly_norm003.json\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"225139\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm003-b2.log\", \"submitted_at\": \"2026-05-15T05:20:45.407Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/libero_spatial\", \"data_count\": 10, \"model_name\": \"crm_v3_norm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"libero_spatial\", \"wall_clock_seconds\": 70039.8, \"gpu_hours\": 19.46}, \"pid\": 227426, \"notes\": \"Ghost PID 211962 killed, b2 now running solo on bjb2-40593 cuda:0. PID 227434 confirmed alive (15min uptime, model loaded, eval executing, GPU 6185MiB/24564MiB, 12% util).\", \"metrics\": {\"overall_sr_10task\": 0.34, \"tasks_done\": 10, \"tasks_total\": 10, \"per_task\": {\"between_plate_and_ramekin\": 0.9, \"next_to_ramekin\": 1, \"from_table_center\": 0, \"on_cookie_box\": 0.3, \"in_top_drawer\": 0.1, \"on_ramekin\": 0, \"next_to_cookie_box\": 0.8, \"on_stove\": 0, \"next_to_plate\": 0.3, \"on_wooden_cabinet\": 0}}, \"reproduce\": {\"finished_at\": \"2026-05-16T00:42:50.652Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:43:27.876843+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_mag_obsonly_norm003.json\", \"completed_at\": \"2026-05-16T00:48:05.254Z\", \"hypothesis\": \"obs_only CRM (ε=0.03) on LIBERO Spatial benchmark. 极低 norm 下 obs_only 在 spatial 的表现（10-task SR）。验证 magnitude 效应在不同 benchmark 上的一致性。\"}, \"eval-mag-obsonly-norm03-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:29:02.155Z\", \"updated_at\": \"2026-05-17T03:09:10.586Z\", \"spec\": {\"hypothesis\": \"Object magnitude sweep: obs_only CRM v3-norm at norm=0.3 on LIBERO object benchmark. Tests degradation at higher correction norm on object domain. Key data for fig3.\", \"parent\": \"eval-acr-object-v4-obs-only\", \"command\": \"CUDA_VISIBLE_DEVICES=5 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03.json\", \"server\": \"bjb2-28827\", \"data_path\": \"simpler_env object benchmark\", \"data_count\": 10, \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"object benchmark, max_correction_norm=0.3, K=10, n_rollouts=10\", \"pid\": 103028, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm03.log\"}, \"metrics\": {\"tasks_done\": 10, \"tasks_total\": 10, \"overall_sr\": 0.19, \"successes\": 19, \"total\": 100}, \"reproduce\": {\"finished_at\": \"2026-05-16T07:35:42.126Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T07:35:43.889Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T07:35:47.235304+00:00\"}]}, \"hypothesis\": \"obs_only CRM (ε=0.3) on LIBERO Object magnitude sweep seed=42. 验证高 norm 下 obs_only 是否仍保持 graceful degradation（对比 perdof 在同 norm 的 collapse）。\"}, \"eval-mag-obsonly-norm005-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:29:00.724Z\", \"updated_at\": \"2026-05-17T03:09:06.864Z\", \"spec\": {\"hypothesis\": \"Object magnitude sweep: obs_only CRM v3-norm at norm=0.05 on LIBERO object benchmark. Builds object magnitude curve alongside norm=0.1 (19%) and norm=0.2 (18% partial). Key data for fig3.\", \"parent\": \"eval-acr-object-v4-obs-only\", \"command\": \"CUDA_VISIBLE_DEVICES=4 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.05 --output_file logs/eval_object_obs_only_norm005.json\", \"server\": \"bjb2-28827\", \"data_path\": \"simpler_env object benchmark\", \"data_count\": 10, \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"object benchmark, max_correction_norm=0.05, K=10, n_rollouts=10\", \"pid\": 101610, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm005.log\"}, \"metrics\": {\"overall_sr\": 0.13, \"tasks_completed\": 10, \"total_rollouts\": 100, \"successes\": 13, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.2, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}, \"conclusion\": \"success\", \"checkpoint_path\": \"logs/eval_object_obs_only_norm005.json\", \"completed_at\": \"2026-05-16T08:19:41.189Z\", \"hypothesis\": \"obs_only CRM (ε=0.05) on LIBERO Object magnitude sweep seed=42. 验证极低 norm 下 obs_only 表现。如果 SR 与 VLA-only 相近（12%），说明过低 norm 约束了 CRM 纠正能力。\"}, \"eval-direct-correction-object-seed42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T02:46:15.008Z\", \"updated_at\": \"2026-05-17T03:04:54.543Z\", \"hypothesis\": \"obs_only CRM 直接纠正单次 VLA 输出（K=1, 跳过 argmin selection），测试 CRM 本身是否有独立纠���价值。如果 SR > VLA-only (~11%)，说明 CRM correction 独立有效；如果 SR ≤ VLA-only，说明 multi-sample selection 是必要前提。Claim 1 (pipeline contribution) 的 ablation。\", \"parent\": \"eval-direct-correction-object-seed42\", \"spec\": {\"command\": \"/root/miniconda3/bin/python -u src/evaluate.py --mode direct_correction --benchmark object --n_rollouts 10 --seed 42 --K 1 --checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/results_direct_correction_object_seed42.json\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO Object benchmark (10 tasks)\", \"data_count\": \"100 episodes (10 tasks x 10 rollouts)\", \"model_name\": \"obs_only CRM (327K params)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO Object\", \"gpu\": \"cuda:4\", \"pid\": 364076, \"note\": \"Code patched to print every rollout (was every 5). Prev attempts killed working processes due to misinterpreting silence as stuck.\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T02:58:54.670Z\"}, \"failure_reason\": \"Agent误杀：wchar未增长30s被误判为stuck，实际是每5 rollout打印一次（~7.5min间隔）且MuJoCo/CUDA使用memory-mapped I/O不被/proc/PID/io追踪。进程实际正常运行中。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T02:58:57.101Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T02:59:01.101476+00:00\"}]}}, \"eval-direct-correction-object-seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T02:18:02.194Z\", \"updated_at\": \"2026-05-17T02:38:55.611Z\", \"hypothesis\": \"obs_only CRM 直接纠正单次 VLA 输出（跳过 K=10 采样+argmin 选择），测试 obs 特征鲁棒性在简化 pipeline 下是否成立。如果 SR > VLA-only (~11%)，说明 CRM 本身有独立价值；如果 SR < VLA-only，说明 selection 是必要前提。Claim 1 (pipeline contribution) 的 ablation。\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode direct_correction --benchmark object --n_rollouts 10 --seed 42 --K 1 --checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/results_direct_correction_object_seed42.json\", \"server\": \"bjb1-32546\", \"gpu\": \"1\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 10, \"model_name\": \"obs_only CRM v3-norm\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark (10 tasks x 10 rollouts)\", \"pid\": 353384, \"tmux_session\": \"eval-direct-correction-object-seed42\"}, \"failure_reason\": \"startup recovery: process dead, no active cron monitor\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T02:38:55.611Z\"}, \"eval-scalar-object-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:11:59.390Z\", \"updated_at\": \"2026-05-16T21:29:49.586Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_scalar_seed44_r2.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:0\"], \"pid\": \"226878\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-scalar-object-seed44-r2.log\", \"submitted_at\": \"2026-05-16T07:11:59.066Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_norm_scalar_unc\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 51470.5, \"gpu_hours\": 14.3}, \"reproduce\": {\"finished_at\": \"2026-05-16T21:11:40.494Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T21:11:48.900516+00:00\"}]}, \"hypothesis\": \"Scalar CRM seed=44 on LIBERO object benchmark. Retry of failed eval-scalar-object-seed44. Expects scalar variant underperforms obs_only but may match argmin baseline.\", \"conclusion\": \"negative\", \"metrics\": {\"overall_sr\": 0.06, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}, \"checkpoint_path\": \"N/A (eval only)\", \"completed_at\": \"2026-05-16T21:29:49.586Z\"}, \"eval-perdof-object-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:56:22.235Z\", \"updated_at\": \"2026-05-16T19:45:27.956Z\", \"hypothesis\": \"perdof CRM v3-norm seed=44 on LIBERO object benchmark. Completes seed=44 four-way comparison. seed42=11%, seed43=12%. Expected to confirm perdof < argmin.\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb1-18228\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T04:57:04.525Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --benchmark object --mode crm_perdof --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --K 10 --seed 44 --n_rollouts 10 --output_file logs/eval_object_perdof_seed44.json\\\"\", \"finished_at\": \"2026-05-16T18:13:35.112Z\", \"training_hours\": 13.28}, \"spec\": {\"data_path\": \"LIBERO_object\", \"data_count\": 100, \"model_name\": \"crm_perdof\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO_object_10tasks_10rollouts\"}, \"pid\": \"452982\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-seed44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T18:13:38.573783+00:00\"}]}, \"metrics\": {\"overall_sr\": 0.08, \"total_success\": 8, \"total_rollouts\": 100, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.1, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.3}}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"completed_at\": \"2026-05-16T19:45:27.956Z\"}, \"eval-obs-only-object-norm03-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:05:51.470Z\", \"updated_at\": \"2026-05-16T19:37:12.898Z\", \"hypothesis\": \"obs_only CRM v3-norm at norm=0.3 seed=44 on LIBERO object benchmark. Multi-seed magnitude curve coverage. seed42 norm=0.3 object still running on bjb2-28827. Pairs with seed44 norm=0.2 for norm sensitivity across seeds.\", \"server\": \"bjb1-32546\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb1-32546\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T06:06:08.369Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03_seed44.json\\\"\", \"finished_at\": \"2026-05-16T19:34:37.134Z\", \"training_hours\": 13.47}, \"spec\": {\"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_obs_only (327198 params)\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\"}, \"pid\": \"220777\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm03-seed44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T19:34:40.416412+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.18, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.1, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.4, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.2, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.3}}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"completed_at\": \"2026-05-16T19:37:12.898Z\"}, \"eval-vla-mean-object-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:58:30.713Z\", \"updated_at\": \"2026-05-16T18:36:08.965Z\", \"hypothesis\": \"VLA-mean baseline (K=10, mean aggregation) seed=44 on LIBERO object benchmark. Completes seed=44 six-way comparison. seed42=12%, seed43=15%.\", \"server\": \"bjb1-32546\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb1-32546\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T04:58:47.863Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --benchmark object --mode vla_only --baseline_mode mean --n_rollouts 10 --K 10 --seed 44 --output_file logs/eval_object_vla_mean_seed44.json\\\"\", \"finished_at\": \"2026-05-16T18:33:19.875Z\", \"training_hours\": 13.58}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --benchmark object --mode vla_only --baseline_mode mean --n_rollouts 10 --K 10 --seed 44 --output_file logs/eval_object_vla_mean_seed44.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": \"212655\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-mean-object-seed44.log\", \"submitted_at\": \"2026-05-16T04:58:50.101Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 49038.9, \"gpu_hours\": 13.62}, \"pid\": \"212655\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-mean-object-seed44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T18:33:23.084588+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.1, \"per_task_sr\": {\"pick_up_the_alphabet_soup_and_place_it_in_the_basket\": 0, \"pick_up_the_cream_cheese_and_place_it_in_the_basket\": 0, \"pick_up_the_salad_dressing_and_place_it_in_the_basket\": 0.1, \"pick_up_the_bbq_sauce_and_place_it_in_the_basket\": 0.3, \"pick_up_the_ketchup_and_place_it_in_the_basket\": 0.1, \"pick_up_the_tomato_sauce_and_place_it_in_the_basket\": 0.1, \"pick_up_the_butter_and_place_it_in_the_basket\": 0, \"pick_up_the_milk_and_place_it_in_the_basket\": 0, \"pick_up_the_chocolate_pudding_and_place_it_in_the_basket\": 0.2, \"pick_up_the_orange_juice_and_place_it_in_the_basket\": 0.2}}, \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_vla_mean_seed44.json\", \"completed_at\": \"2026-05-16T18:36:08.965Z\"}, \"eval-obs-only-object-norm02-seed44-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T14:48:54.894Z\", \"updated_at\": \"2026-05-16T15:36:08.207Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_seed44_r4.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"501420\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm02-seed44-r4.log\", \"submitted_at\": \"2026-05-16T14:49:19.300Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1956.7, \"gpu_hours\": 0.54}, \"hypothesis\": \"P0 retry #4: obs_only CRM v3-norm norm=0.2 seed=44 on LIBERO object. Third seed for Fisher test. seed42=22%, seed43=16%. Previous attempts failed (127/129/killed).\", \"pid\": 501420, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T15:21:56.018Z\", \"failure_reason\": \"r2 data valid (16%), r4 redundant. PID 501420 killed by worker at 2026-05-16T15:09.\"}, \"eval-argmin-object-seed44-r2\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T01:32:14.163Z\", \"updated_at\": \"2026-05-16T15:34:00.414Z\", \"hypothesis\": \"Retry of eval-argmin-object-seed44 (EXIT_CODE=127, missing conda activate). argmin baseline K=10 seed=44 on LIBERO object. Third seed for Fisher test. seed42=12%, seed43=17%.\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb1-18228\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-16T01:32:36.214Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 44 --K 10 --output_file logs/eval_object_reconvla_seed44.json\\\"\", \"finished_at\": \"2026-05-16T15:28:27.588Z\", \"training_hours\": 13.93}, \"completed_at\": \"2026-05-16T01:34:17.696Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"killed\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T15:28:32.358640+00:00\"}]}, \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 44 --K 10 --output_file logs/eval_object_reconvla_seed44.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"428117\", \"seed\": 44, \"model_name\": \"reconvla_argmin\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"metrics\": {\"overall_sr\": 0.13, \"successes\": 13, \"total\": 100, \"tasks_done\": 10, \"tasks_total\": 10, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.2, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"butter\": 0, \"milk\": 0.1, \"chocolate_pudding\": 0.5, \"orange_juice\": 0.2}, \"note\": \"EXIT_CODE=129 was SIGHUP after completion, results valid. log: logs/eval_object_reconvla_seed44.json\"}, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_reconvla_seed44.json\"}, \"eval-obs-only-object-norm03-seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:14:47.376Z\", \"updated_at\": \"2026-05-16T11:30:59.542Z\", \"spec\": {\"model_name\": \"crm_v3_norm_obs_only\", \"seed\": 45, \"data_path\": \"LIBERO object benchmark (10 tasks)\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 45 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_obs_only_norm03_seed45.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": \"248860\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm03-seed45.log\", \"submitted_at\": \"2026-05-16T11:14:47Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 972.5, \"gpu_hours\": 0.27}, \"hypothesis\": \"obs_only CRM v3-norm at norm=0.3 seed=45 on LIBERO object benchmark. Multi-seed magnitude curve data point. seed42 norm=0.3=19%, seed44 norm=0.3=running. Extends magnitude robustness evidence to 3rd seed.\", \"conclusion\": \"failed\", \"failure_reason\": \"killed to resolve cuda:3 GPU conflict\", \"completed_at\": \"2026-05-16T11:30:59.542Z\"}, \"eval-acr-object-v4-default-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:11:49.844Z\", \"updated_at\": \"2026-05-16T09:00:15.290Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_object_perdof_default_norm_r2.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"390936\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-default-r2.log\", \"submitted_at\": \"2026-05-16T02:11:20Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"libero_object\", \"data_count\": 10, \"model_name\": \"crm_perdof_default_norm\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"object\", \"wall_clock_seconds\": 24535.3, \"gpu_hours\": 6.82}, \"hypothesis\": \"v4-default (no magnitude control, norm≈1.42) on object benchmark — ablation to confirm catastrophic failure\", \"parent\": \"eval-acr-object-v4-default\", \"metrics\": {\"overall_sr\": 0, \"successes\": 0, \"total\": 100, \"tasks_done\": 10, \"tasks_total\": 10, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0, \"bbq_sauce\": 0, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0, \"orange_juice\": 0}, \"note\": \"actual mode=crm_perdof with default norm (~1.42), NOT crm_default. Confirms catastrophic failure at uncontrolled correction magnitude.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"completed_at\": \"2026-05-16T09:00:15.290Z\"}, \"eval-mag-perdof-norm003-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:47:32.591Z\", \"updated_at\": \"2026-05-16T08:37:12.296Z\", \"hypothesis\": \"Object magnitude sweep: perdof CRM v3-norm at norm=0.03 on LIBERO object benchmark. Paired with obs_only norm=0.03 for magnitude comparison figure. Tests perdof at smallest correction norm on object domain.\", \"spec\": {\"command\": \"python src/evaluate.py --mode crm_perdof --max_correction_norm 0.03 --K 10 --seed 42 --benchmark object\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:0\"], \"pid\": 105938, \"log_path\": \"logs/eval_object_perdof_norm003.json\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_perdof\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object\", \"parent\": \"eval-acr-object-v4-perdof\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"metrics\": {\"overall_success_rate\": 0.14, \"per_task_range\": \"0.0-0.4\"}}, \"metrics\": {\"tasks_done\": 10, \"tasks_total\": 10, \"overall_sr\": 0.14, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.2, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"butter\": 0.2, \"milk\": 0.1, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.1}}, \"reproduce\": {\"finished_at\": \"2026-05-16T08:09:00.286Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T08:09:03.327886+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_perdof_norm003.json\", \"completed_at\": \"2026-05-16T08:11:39.117Z\"}, \"eval-acr-object-obs-only-default\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:38:22.125Z\", \"updated_at\": \"2026-05-16T07:09:01.967Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_object_obs_only_default_norm.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": 134094, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-obs-only-default.log\", \"submitted_at\": \"2026-05-15T17:38:21.517Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_norm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark\", \"wall_clock_seconds\": 48640.4, \"gpu_hours\": 13.51}, \"hypothesis\": \"obs_only CRM v3-norm with DEFAULT max_correction_norm (~1.42, no magnitude control) on LIBERO object benchmark. Paired with eval-acr-object-v4-default (perdof default). Tests whether obs_only robustness holds even without magnitude capping — if yes, obs_only is fundamentally more robust than perdof regardless of norm setting.\", \"metrics\": {\"tasks_done\": 10, \"tasks_total\": 10, \"overall_sr\": 0.17, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.4, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.5, \"orange_juice\": 0.3}}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:41:19.269Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:41:22.516205+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"completed_at\": \"2026-05-16T07:09:01.967Z\"}, \"eval-scalar-object-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:02:31.432Z\", \"updated_at\": \"2026-05-16T06:04:05.747Z\", \"hypothesis\": \"D031: scalar_unc CRM v3-norm seed=43 on LIBERO object benchmark. Completes seed=43 six-way comparison table. scalar seed=42 was worst at 4% — seed=43 confirms.\", \"parent\": \"eval-acr-object-v4-scalar\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_scalar_seed43.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:2\"], \"pid\": \"114664\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-scalar-object-seed43.log\", \"submitted_at\": \"2026-05-15T16:03:30.400Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"libero_object\", \"data_count\": 10, \"model_name\": \"crm_scalar\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"eval_data\": \"object\", \"wall_clock_seconds\": 50435.3, \"gpu_hours\": 14.01}, \"metrics\": {\"tasks_done\": 10, \"tasks_total\": 10, \"avg_sr\": 10, \"per_task_sr\": {\"pick_up_the_alphabet_soup_and_place_it_in_the_basket\": 0, \"pick_up_the_cream_cheese_and_place_it_in_the_basket\": 0, \"pick_up_the_salad_dressing_and_place_it_in_the_basket\": 0, \"pick_up_the_bbq_sauce_and_place_it_in_the_basket\": 30, \"pick_up_the_ketchup_and_place_it_in_the_basket\": 0, \"pick_up_the_tomato_sauce_and_place_it_in_the_basket\": 0, \"pick_up_the_butter_and_place_it_in_the_basket\": 0, \"pick_up_the_milk_and_place_it_in_the_basket\": 10, \"pick_up_the_chocolate_pudding_and_place_it_in_the_basket\": 30, \"pick_up_the_orange_juice_and_place_it_in_the_basket\": 30}}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:01:42.952Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:01:45.993724+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_scalar_seed43.json\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_scalar_seed43.json\", \"completed_at\": \"2026-05-16T06:04:05.747Z\"}, \"eval-mag-obsonly-norm003-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:47:31.254Z\", \"updated_at\": \"2026-05-16T05:56:01.541Z\", \"hypothesis\": \"Object magnitude sweep: obs_only CRM v3-norm at norm=0.03 on LIBERO object benchmark. Completes 5-point magnitude curve (0.03/0.05/0.1/0.2/0.3). Tests minimum effective correction magnitude on object domain.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.03 --output_file logs/eval_object_obs_only_norm003.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:0\"], \"pid\": 121325, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm003-object.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"object benchmark, max_correction_norm=0.03, K=10, n_rollouts=10\", \"parent\": \"eval-acr-object-v4-obs-only\"}, \"metrics\": {\"overall_sr\": 0.16, \"tasks_done\": 100, \"tasks_total\": 100, \"per_task\": {\"pick_up_the_alphabet_soup_and_place_it_in_the_basket\": 0, \"pick_up_the_cream_cheese_and_place_it_in_the_basket\": 0.2, \"pick_up_the_salad_dressing_and_place_it_in_the_basket\": 0.1, \"pick_up_the_bbq_sauce_and_place_it_in_the_basket\": 0.4, \"pick_up_the_ketchup_and_place_it_in_the_basket\": 0, \"pick_up_the_tomato_sauce_and_place_it_in_the_basket\": 0, \"pick_up_the_butter_and_place_it_in_the_basket\": 0.1, \"pick_up_the_milk_and_place_it_in_the_basket\": 0.2, \"pick_up_the_chocolate_pudding_and_place_it_in_the_basket\": 0.3, \"pick_up_the_orange_juice_and_place_it_in_the_basket\": 0.3}}, \"reproduce\": {\"finished_at\": \"2026-05-16T05:35:17.752Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T05:35:20.742243+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T05:56:01.541Z\"}, \"eval-scalar-object-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:02:34.914Z\", \"updated_at\": \"2026-05-16T05:25:06.306Z\", \"hypothesis\": \"scalar_unc CRM v3-norm seed=44 on LIBERO object benchmark. Completes seed=44 six-way comparison. scalar seed42=9%, seed43 running (0% at 3/10). Expected worst CRM variant.\", \"server\": \"bjb2-40593\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb2-40593\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-16T05:02:50.780Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_scalar_seed44.json\\\"\", \"code_commit\": \"4b4e03d05161290989b1f19d6e13e077da681a41\", \"finished_at\": \"2026-05-16T05:05:30.084Z\", \"training_hours\": 0.04}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_scalar_seed44.json\\\"\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"310854\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-scalar-object-seed44.log\", \"submitted_at\": \"2026-05-16T05:25:05.983Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"pid\": \"309346\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-scalar-object-seed44.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T05:05:32.021Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T05:05:34.587431+00:00\"}]}}, \"eval-obs-only-object-norm02-seed44-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:34:30.429Z\", \"updated_at\": \"2026-05-16T04:59:20.094Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_seed44.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"431189\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm02-seed44-r3.log\", \"submitted_at\": \"2026-05-16T01:34:30.132Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12290.0, \"gpu_hours\": 3.41}, \"hypothesis\": \"Retry of eval-obs-only-object-norm02-seed44 (r1 EXIT_CODE=127, r2 killed by agent). obs_only CRM norm=0.2 seed=44 on LIBERO object. Third seed for Fisher test. seed42=22% (PROJECT HIGH).\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T04:59:20.095Z\"}, \"eval-argmin-object-seed44-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:34:28.047Z\", \"updated_at\": \"2026-05-16T04:59:17.975Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 44 --K 10 --output_file logs/eval_object_reconvla_seed44.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"430985\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-seed44-r3.log\", \"submitted_at\": \"2026-05-16T01:34:27.679Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12290.3, \"gpu_hours\": 3.41}, \"hypothesis\": \"Retry of eval-argmin-object-seed44 (r1 EXIT_CODE=127, r2 killed by agent). argmin baseline K=10 seed=44 on LIBERO object. Third seed for Fisher test. seed42=12%, seed43=17%.\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T04:59:17.975Z\"}, \"eval-vla-mean-object-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:46:28.667Z\", \"updated_at\": \"2026-05-16T04:53:17.141Z\", \"hypothesis\": \"D031: VLA-mean baseline (K=10, mean aggregation) seed=43 on LIBERO object benchmark. Completes seed=43 comparison table. If VLA-mean seed=43 ≈ obs_only seed=43 → CRM correction claim compressed.\", \"parent\": \"eval-vla-mean-object\", \"spec\": {\"command\": \"python -u src/evaluate.py --benchmark object --mode vla_only --baseline_mode mean --n_rollouts 10 --K 10 --seed 43 --output_file logs/eval_object_vla_mean_seed43.json\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:1\"], \"pid\": \"111709\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-mean-object-seed43.log\", \"submitted_at\": \"2026-05-15T15:47:37.968Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 43, \"model_name\": \"smolvla\", \"data_path\": \"libero/object\", \"data_count\": 10, \"checkpoint_source\": null, \"eval_data\": \"object\", \"wall_clock_seconds\": 47139.2, \"gpu_hours\": 13.09}, \"metrics\": {\"overall_sr\": 0.15, \"tasks_done\": 10, \"tasks_total\": 10, \"total_success\": 15, \"total_rollouts\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.3, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.1}}, \"reproduce\": {\"finished_at\": \"2026-05-16T04:48:28.380Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T04:48:31.493092+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only)\", \"completed_at\": \"2026-05-16T04:53:17.141Z\"}, \"eval-perdof-object-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:19:49.586Z\", \"updated_at\": \"2026-05-16T03:15:39.287Z\", \"hypothesis\": \"D031 supplementary: perdof CRM v3-norm seed=43 on LIBERO object benchmark. Completes three-way comparison (obs_only vs argmin vs perdof) with doubled samples. If perdof seed=43 ≈ argmin seed=43 → confirms obs_only uniquely better.\", \"parent\": \"eval-acr-object-v4-perdof\", \"spec\": {\"command\": \"python evaluate.py --benchmark object --mode crm_perdof --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1 --K 10 --seed 43 --n_rollouts 10 --output_file logs/eval_object_perdof_seed43.json\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:1\", \"pid\": 365925, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-perdof-object-seed43.log\", \"submitted_at\": \"2026-05-15T13:21:00.347Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"seed\": 43, \"model_name\": \"crm_perdof\", \"data_path\": \"LIBERO_object\", \"data_count\": 100, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO_object_10tasks_10rollouts\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"wall_clock_seconds\": 50078.9, \"gpu_hours\": 13.91}, \"metrics\": {\"overall_success_rate\": 0.12, \"tasks_done\": 10, \"tasks_total\": 10, \"total_rollouts\": 100, \"total_successes\": 12, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.3}}, \"reproduce\": {\"finished_at\": \"2026-05-16T03:12:36.498Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T03:12:39.589841+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:15:39.287Z\"}, \"eval-vla-only-object-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:29:00.342Z\", \"updated_at\": \"2026-05-16T01:33:29.678Z\", \"hypothesis\": \"D035 follow-up: VLA-only baseline (K=1) seed=44 on LIBERO object benchmark. Third seed reference point. seed42=12%, seed43=12%. Deployed on bjb2-40593.\", \"server\": \"bjb2-40593\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb2-40593\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-16T01:29:36.987Z\", \"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode vla_only --benchmark object --n_rollouts 10 --seed 44 --K 1 --output_file logs/eval_object_vla_only_seed44.json\\\"\", \"code_commit\": \"4b4e03d05161290989b1f19d6e13e077da681a41\", \"finished_at\": \"2026-05-16T01:30:26.640Z\", \"training_hours\": 0.01}, \"spec\": {\"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"vla_only\", \"seed\": 44, \"checkpoint_source\": \"N/A\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\"}, \"pid\": \"unknown\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-object-seed44.log\", \"failure_reason\": \"EXIT_CODE=127 (command not found) — bash -c wrapping 或环境激活路径错误，bjb2-40593 上系统性问题，三个 seed44 实验全部同样失败\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T01:30:33.143Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:30:38.635650+00:00\"}]}}, \"eval-obs-only-object-norm02-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:28:59.304Z\", \"updated_at\": \"2026-05-16T01:32:51.127Z\", \"hypothesis\": \"D035 follow-up: obs_only CRM v3-norm norm=0.2 seed=44 on LIBERO object benchmark. Third seed for Fisher exact test. ε=0.2 is PROJECT HIGH config (seed42=22%). Paired with eval-argmin-object-seed44.\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb1-18228\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T01:29:31.218Z\", \"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 44 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_seed44.json\\\"\", \"finished_at\": \"2026-05-16T01:30:14.217Z\", \"training_hours\": 0.01}, \"spec\": {\"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_obs_only (327198 params)\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\"}, \"pid\": \"unknown\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-object-norm02-seed44.log\", \"failure_reason\": \"EXIT_CODE=127: submit command missing conda activation (source /root/miniconda3/etc/profile.d/conda.sh && conda activate base). tmux runs sh, not bash — python not in PATH. Will retry as r2.\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T01:30:20.761Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:30:23.773246+00:00\"}]}}, \"eval-argmin-object-seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:28:58.358Z\", \"updated_at\": \"2026-05-16T01:32:49.190Z\", \"hypothesis\": \"D035 follow-up: argmin baseline (K=10) seed=44 on LIBERO object benchmark. Third seed for Fisher exact test statistical power. Paired with eval-obs-only-object-norm02-seed44. seed42=12%, seed43=17%.\", \"server\": \"bjb1-18228\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb1-18228\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-16T01:29:25.990Z\", \"command\": \"bash -c \\\"cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 44 --K 10 --output_file logs/eval_object_reconvla_seed44.json\\\"\", \"finished_at\": \"2026-05-16T01:30:04.115Z\", \"training_hours\": 0.01}, \"spec\": {\"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"ReconVLA (argmin baseline)\", \"seed\": 44, \"checkpoint_source\": \"N/A (no CRM)\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\"}, \"pid\": \"unknown\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-seed44.log\", \"failure_reason\": \"EXIT_CODE=127: submit command missing conda activation (source /root/miniconda3/etc/profile.d/conda.sh && conda activate base). tmux runs sh, not bash — python not in PATH. Will retry as r2.\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T01:30:06.598Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:30:09.864458+00:00\"}]}}, \"eval-obs-only-object-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:58:46.063Z\", \"updated_at\": \"2026-05-16T00:51:14.618Z\", \"hypothesis\": \"D031: obs_only CRM v3-norm seed=43 on LIBERO object benchmark. Doubles sample size for Fisher exact test. seed=42 shows obs_only 16% vs argmin 8% (+8pp, p≈0.19). Combined 200 trials target p < 0.05.\", \"parent\": \"eval-acr-object-v4-obs-only\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_object_obs_only_seed43.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"356490\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_seed43.json\", \"submitted_at\": \"2026-05-15T12:00:38.618Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_obs_only + SmolVLA\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 46070.8, \"gpu_hours\": 12.8, \"checkpoint_path\": \"N/A (eval only)\"}, \"metrics\": {\"overall_success_rate\": 0.12, \"tasks_done\": 10, \"tasks_total\": 10, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.1, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0, \"milk\": 0.1, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}, \"vs_argmin_seed43\": {\"obs_only\": 12, \"argmin\": 17, \"diff\": -5}, \"fisher_pooled\": {\"obs_only_total\": \"31/200\", \"argmin_total\": \"29/200\", \"pooled_obs_only_sr\": 0.155, \"pooled_argmin_sr\": 0.145, \"pooled_delta\": 0.01, \"odds_ratio\": 1.08, \"p_value_one_sided\": 0.4444, \"p_value_two_sided\": 0.8888}, \"source\": \"json_file_verified_by_worker\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T00:41:25.212Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:42:01.902179+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_seed43.json\", \"completed_at\": \"2026-05-16T00:48:29.446Z\"}, \"eval-mag-obsonly-norm03-b2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:05:41.192Z\", \"updated_at\": \"2026-05-16T00:49:21.141Z\", \"hypothesis\": \"Magnitude sweep: obs_only CRM v3-norm at norm=0.3 on spatial. Retry of eval-mag-obsonly-norm03 (EXIT_CODE=127). Fills obs_only norm=0.3 gap. perdof norm=0.3 shows T1 drop to 50% — if obs_only doesn't degrade, strong evidence for obs_only robustness.\", \"parent\": \"eval-mag-obsonly-norm03\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_mag_obsonly_norm03_b2.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": \"130104\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm03-b2.log\", \"submitted_at\": \"2026-05-15T19:11:50.323Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 20250.8, \"gpu_hours\": 5.63}, \"conclusion\": \"failed\", \"notes\": \"Killed: duplicate of eval-mag-obsonly-norm03-r2 on same cuda:0. r2 had 15min more progress. Both wrote same output_file, causing potential corruption.\", \"reproduce\": {\"finished_at\": \"2026-05-15T07:10:36.759Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:10:39.645469+00:00\"}]}, \"completed_at\": \"2026-05-16T00:49:21.141Z\"}, \"eval-argmin-object-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:58:46.739Z\", \"updated_at\": \"2026-05-16T00:37:43.289Z\", \"hypothesis\": \"D031: argmin baseline (K=10, scalar Euclidean argmin) seed=43 on LIBERO object benchmark. Paired with eval-obs-only-object-seed43 for Fisher exact test. Need both conditions under same seed for valid comparison.\", \"parent\": \"eval-reconvla-object\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark object --n_rollouts 10 --seed 43 --K 10 --output_file logs/eval_object_reconvla_seed43.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"356696\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-object-seed43.log\", \"submitted_at\": \"2026-05-15T12:00:40.708Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"ReconVLA (reconvla baseline)\", \"seed\": 43, \"checkpoint_source\": \"N/A (no CRM, pure VLA baseline)\", \"eval_data\": \"LIBERO object benchmark (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 45422.6, \"gpu_hours\": 12.62}, \"metrics\": {\"overall_success_rate\": 0.17, \"total_successes\": 17, \"total_trials\": 100, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.2, \"ketchup\": 0.1, \"tomato_sauce\": 0.1, \"butter\": 0.2, \"milk\": 0.3, \"chocolate_pudding\": 0.4, \"orange_juice\": 0.2}}, \"reproduce\": {\"finished_at\": \"2026-05-16T00:35:16.646Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:35:19.825582+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T00:37:43.289Z\"}, \"eval-mag-perdof-norm02-seed43-object-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:19:36.419Z\", \"updated_at\": \"2026-05-15T19:38:38.710Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed43.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"138858\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T19:19:36.128Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A (killed — GPU conflict on cuda:2, replaced by eval-mag-perdof-norm02-seed43-object-r3)\", \"wall_clock_seconds\": 951.1, \"gpu_hours\": 0.26}, \"hypothesis\": \"Object magnitude sweep: perdof CRM v3-norm norm=0.2 seed=43. Moved from bjb2-28827:cuda:3 (GPU conflict with obs_only spatial) to cuda:2. Tests perdof norm sensitivity with second seed.\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:35:27.220Z\"}, \"eval-mag-obsonly-norm03\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:43:48.583Z\", \"updated_at\": \"2026-05-15T19:38:31.587Z\", \"hypothesis\": \"Magnitude sweep: obs_only CRM v3-norm at norm=0.3 on spatial. Fills obs_only norm=0.3 gap. perdof norm=0.3 shows T1 drop to 50% — if obs_only doesn't degrade at same norm, strong evidence for obs_only robustness.\", \"parent\": \"eval-mag-obsonly-norm02\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_mag_obsonly_norm03.json\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T06:44:02.425Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A (EXIT_CODE=127, retried as eval-mag-obsonly-norm03-r2)\", \"wall_clock_seconds\": 46287.3, \"gpu_hours\": 12.86}, \"reproduce\": {\"finished_at\": \"2026-05-15T06:44:32.019Z\"}, \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"conclusion\": \"killed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:44:35.317393+00:00\"}]}, \"notes\": \"失败原因: EXIT_CODE=127 — tmux 用 sh 执行命令，python 不在 sh PATH 中。修复: bash -c 包裹。已
```

---

### Large event (continued)

````text
重试为 eval-mag-obsonly-norm03-r2。\", \"completed_at\": \"2026-05-15T19:35:29.718Z\"}, \"eval-mag-obsonly-norm02-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:26:53.269Z\", \"updated_at\": \"2026-05-15T19:34:07.651Z\", \"spec\": {\"hypothesis\": \"Object magnitude sweep: obs_only CRM v3-norm at norm=0.2 on LIBERO object benchmark. Fills the norm=0.2 gap in 5-point magnitude curve. Previous run reached 18% at 5/10 then stopped.\", \"parent\": \"eval-acr-object-v4-obs-only\", \"command\": \"CUDA_VISIBLE_DEVICES=3 python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_v2.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": 141024, \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark\", \"checkpoint_path\": \"N/A (duplicate of DONE eval-acr-object-obs-only-norm02, killed to free GPU)\", \"log_path\": \"N/A\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:34:07.651Z\"}, \"eval-mag-obsonly-norm03-b4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:14:01.998Z\", \"updated_at\": \"2026-05-15T19:27:30.465Z\", \"spec\": {\"command\": \"crm_obs_only spatial norm=0.3 (killed)\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"132816\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm03-b4.log\", \"submitted_at\": \"2026-05-15T19:14:01.050Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"spatial\", \"data_count\": 10, \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"spatial\", \"wall_clock_seconds\": 809.4, \"gpu_hours\": 0.22}, \"conclusion\": \"killed\", \"notes\": \"Redundant: spatial obs_only norm=0.3 already has 10t final data (36%). Killed from cuda:2 GPU contention cleanup on bjb2-28827 (2026-05-16).\", \"completed_at\": \"2026-05-15T19:27:30.465Z\"}, \"eval-mag-obsonly-norm03-b3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:13:38.067Z\", \"updated_at\": \"2026-05-15T19:27:28.479Z\", \"spec\": {\"command\": \"crm_obs_only spatial norm=0.3 (killed)\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"134532\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm03-b3.log\", \"submitted_at\": \"2026-05-15T19:14:52.972Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"spatial\", \"data_count\": 10, \"model_name\": \"crm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"spatial\", \"wall_clock_seconds\": 755.5, \"gpu_hours\": 0.21}, \"hypothesis\": \"Retry of eval-mag-obsonly-norm03-b2 (spatial magnitude sweep obs_only norm=0.3). Submitted on bjb2-28827:cuda:2 instead of bjb1-32546:cuda:3 (cuda:3 occupied by P0 obs-only-norm02-seed43-r2). Director approved.\", \"parent\": \"eval-mag-obsonly-norm03-b2\", \"conclusion\": \"killed\", \"notes\": \"Redundant: spatial obs_only norm=0.3 already has 10t final data (36%). Killed from cuda:2 GPU contention cleanup on bjb2-28827 (2026-05-16).\", \"completed_at\": \"2026-05-15T19:27:28.479Z\"}, \"eval-mag-perdof-norm02-seed43-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:15:19.724Z\", \"updated_at\": \"2026-05-15T19:25:28.957Z\", \"spec\": {\"hypothesis\": \"Object magnitude sweep: perdof CRM v3-norm norm=0.2 seed=43 on LIBERO object benchmark. Paired with obs_only norm=0.2 seed=43 for statistical comparison at the best obs_only norm.\", \"parent\": \"eval-mag-perdof-norm02-object\", \"command\": \"CUDA_VISIBLE_DEVICES=3 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_perdof_norm02_seed43.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": \"10 rollouts\", \"model_name\": \"crm_v3_norm/perdof\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark\"}, \"conclusion\": \"killed\", \"notes\": \"Killed during cuda:2/3 GPU cleanup on bjb2-28827 (2026-05-16). Was sharing cuda:2 with perdof norm=0.3 r2.\", \"completed_at\": \"2026-05-15T19:25:28.957Z\"}, \"eval-mag-perdof-norm03-object-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:15:16.452Z\", \"updated_at\": \"2026-05-15T19:25:28.055Z\", \"spec\": {\"hypothesis\": \"Object magnitude sweep: perdof CRM v3-norm at norm=0.3 on LIBERO object benchmark. Retry of killed eval-mag-perdof-norm0p3-object. Completes perdof 5-point magnitude curve on object domain.\", \"parent\": \"eval-acr-object-v4-perdof\", \"command\": \"CUDA_VISIBLE_DEVICES=2 python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_r2.json\", \"server\": \"bjb2-28827\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": \"10 rollouts\", \"model_name\": \"crm_v3_norm/perdof\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object benchmark\"}, \"conclusion\": \"killed\", \"notes\": \"GPU contention on cuda:2 (shared with perdof norm=0.2 seed=43). Killed 2026-05-16. Replaced by r3 clean restart.\", \"completed_at\": \"2026-05-15T19:25:28.055Z\"}, \"eval-acr-object-v4-scalar-b2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:55:02.698Z\", \"updated_at\": \"2026-05-15T19:17:41.948Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_scalar --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"7017\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-scalar-b2.log\", \"submitted_at\": \"2026-05-15T02:55:02.415Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 58959.5, \"gpu_hours\": 16.38}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:41.948Z\"}, \"eval-acr-object-v4-obs-only-b2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:55:00.179Z\", \"updated_at\": \"2026-05-15T19:17:40.199Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:1\"], \"pid\": \"6746\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-obs-only-b2.log\", \"submitted_at\": \"2026-05-15T02:54:59.912Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 58960.3, \"gpu_hours\": 16.38}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:40.199Z\"}, \"eval-spatial-v4-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:58:07.302Z\", \"updated_at\": \"2026-05-15T19:17:39.068Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl && python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 42 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ 2>&1\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"69379\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-spatial-v4-full.log\", \"submitted_at\": \"2026-05-13T18:58:07.274Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"D015: evaluate.py env_args 缺少 camera_names，SmolVLA 只收到单摄像头输入，结果系统性偏低\", \"wall_clock_seconds\": 173971.8, \"gpu_hours\": 48.33}, \"conclusion\": \"killed\", \"reproduce\": {\"finished_at\": \"2026-05-13T19:36:15.749Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:36:19.370112+00:00\"}]}, \"completed_at\": \"2026-05-15T19:17:39.068Z\"}, \"eval-reconvla-spatial-v1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:15:35.450Z\", \"updated_at\": \"2026-05-15T19:17:37.622Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --smolvla_path /root/autodl-tmp/models/smolvla_libero/\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"87787\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-reconvla-spatial-v1.log\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": \"10 tasks x 10 rollouts x 300 steps\", \"model_name\": \"lerobot/smolvla_libero (450M) + ReconVLA argmin selection K=10\", \"seed\": 42, \"hypothesis\": \"ReconVLA (scalar Euclidean nonconformity + argmin) as baseline for ACR-VLA comparison\", \"checkpoint_source\": \"lerobot/smolvla_libero\"}, \"reproduce\": {\"finished_at\": \"2026-05-13T22:59:43.231Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"killed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:26:37.521060+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T22:59:44.694612+00:00\"}]}, \"completed_at\": \"2026-05-15T19:17:37.622Z\"}, \"eval-object-v6-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:28:33.119Z\", \"updated_at\": \"2026-05-15T19:17:36.369Z\", \"spec\": {\"data_path\": \"/root/autodl-tmp/libero_data/ (object)\", \"data_count\": 100, \"model_name\": \"lerobot/smolvla_libero\", \"seed\": 42, \"hypothesis\": \"SmolVLA baseline success rate on libero_object with fixed evaluate.py (env.reset bug removed, 5-step zero-action stabilization)\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"libero_object 10 tasks x 10 rollouts\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:36.369Z\"}, \"precompute-v3-shard2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T17:39:04.708Z\", \"updated_at\": \"2026-05-15T19:17:30.541Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 2 --num_shards 3 --seed 42 --K 10 --cache_dir /root/autodl-tmp/crm_cache_v3\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"63218\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v3-shard2.log\", \"submitted_at\": \"2026-05-13T17:39:04.684Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"D014: wrapper 修复版从未部署到服务器，使用旧 buggy 代码运行，产出无效\", \"wall_clock_seconds\": 178705.9, \"gpu_hours\": 49.64}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:30.541Z\"}, \"precompute-v3-shard1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T17:39:02.628Z\", \"updated_at\": \"2026-05-15T19:17:29.292Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 1 --num_shards 3 --seed 42 --K 10 --cache_dir /root/autodl-tmp/crm_cache_v3\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"63075\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v3-shard1.log\", \"submitted_at\": \"2026-05-13T17:39:02.603Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"D014: wrapper 修复版从未部署到服务器，使用旧 buggy 代码运行，产出无效\", \"wall_clock_seconds\": 178706.7, \"gpu_hours\": 49.64}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:29.293Z\"}, \"precompute-v3-shard0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T17:39:00.259Z\", \"updated_at\": \"2026-05-15T19:17:27.703Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 && rm -rf /root/autodl-tmp/crm_cache_v3 && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 0 --num_shards 3 --seed 42 --K 10 --cache_dir /root/autodl-tmp/crm_cache_v3\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"62930\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v3-shard0.log\", \"submitted_at\": \"2026-05-13T17:39:00.236Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"D014: wrapper 修复版从未部署到服务器，使用旧 buggy 代码运行，产出无效\", \"wall_clock_seconds\": 178707.5, \"gpu_hours\": 49.64}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:27.703Z\"}, \"precompute-v2-shard2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T16:11:04.275Z\", \"updated_at\": \"2026-05-15T19:17:26.396Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 2 --num_shards 3 --seed 42 --K 10\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"57846\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v2-shard2.log\", \"submitted_at\": \"2026-05-13T16:11:04.255Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 183982.1, \"gpu_hours\": 51.11}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:26.396Z\"}, \"precompute-v2-shard1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T16:11:02.520Z\", \"updated_at\": \"2026-05-15T19:17:25.022Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 1 --num_shards 3 --seed 42 --K 10\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"57706\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v2-shard1.log\", \"submitted_at\": \"2026-05-13T16:11:02.500Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 183982.5, \"gpu_hours\": 51.11}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:25.022Z\"}, \"precompute-v2-shard0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T16:11:01.629Z\", \"updated_at\": \"2026-05-15T19:17:23.631Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && rm -rf /root/autodl-tmp/crm_cache/spatial /root/autodl-tmp/crm_cache/object && python -u src/train_crm.py --precompute --benchmark spatial object --max_demos_per_task 10 --shard_id 0 --num_shards 3 --seed 42 --K 10\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"57628\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/precompute-v2-shard0.log\", \"submitted_at\": \"2026-05-13T16:11:01.605Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 183982.0, \"gpu_hours\": 51.11}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:17:23.631Z\"}, \"eval-mag-perdof-norm0p3-object-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:58:30.091Z\", \"updated_at\": \"2026-05-15T19:13:43.549Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03_r2.json\\\"\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:2\"], \"pid\": \"127570\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-perdof-norm0p3-object-r2.log\", \"submitted_at\": \"2026-05-15T18:58:29.637Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"libero_object 10 tasks x 10 rollouts\", \"data_path\": \"/root/autodl-tmp/libero_data/ (object)\", \"data_count\": 100, \"model_name\": \"crm_perdof_v3_norm\", \"seed\": 42, \"wall_clock_seconds\": 885.6, \"gpu_hours\": 0.25}, \"hypothesis\": \"Object magnitude sweep: perdof CRM v3-norm at norm=0.3 on LIBERO object benchmark. Migrated from bjb1-32546:cuda:4 (GPU conflict) to bjb2-28827:cuda:2. Paired with obs_only norm=0.3 for magnitude comparison figure.\", \"parent\": \"eval-mag-perdof-norm0p3-object\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:13:15.247Z\", \"failure_reason\": \"Duplicate of eval-mag-perdof-norm03-object (PID 118886 on bjb2-28827:cuda:3, identical params). Killed to free cuda:2.\"}, \"eval-mag-perdof-norm0p3-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:34:52.454Z\", \"updated_at\": \"2026-05-15T18:58:11.790Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": \"144887\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-perdof-norm0p3-object.log\", \"submitted_at\": \"2026-05-15T18:37:26.089Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1245.7, \"gpu_hours\": 0.35}, \"hypothesis\": \"Retry of eval-mag-perdof-norm03-object (killed by SIGTERM). Object magnitude sweep: perdof CRM v3-norm at norm=0.3 on LIBERO object benchmark. Paired with obs_only norm=0.3 (running) for magnitude comparison figure.\", \"parent\": \"eval-mag-perdof-norm03-object\", \"conclusion\": \"killed\", \"failure_reason\": \"GPU conflict on bjb1-32546:cuda:4 (shared with obs-only-default). Killed lower priority perdof. Migrating to bjb2-28827:cuda:2 as r2.\", \"completed_at\": \"2026-05-15T18:58:11.790Z\"}, \"eval-obs-only-object-norm02-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:38:18.819Z\", \"updated_at\": \"2026-05-15T18:58:10.821Z\", \"hypothesis\": \"D031: obs_only CRM v3-norm norm=0.2 seed=43 on LIBERO object benchmark. norm=0.2 shows strongest signal (18% SR at 5/10 tasks in seed=42). Seed=43 doubling for statistical power on the best-performing configuration.\", \"parent\": \"eval-acr-object-obs-only-norm02\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.2 --output_file logs/eval_object_obs_only_norm02_seed43.json\", \"server\": \"bjb1-32546\", \"data_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only_norm02_seed43.json\", \"data_count\": 10, \"model_name\": \"crm_obs_only\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"object\"}, \"metrics\": {\"pid\": 118214, \"gpu\": 3, \"process_status\": \"alive\", \"log_file\": \"logs/eval_object_obs_only_norm02_seed43.log\"}, \"conclusion\": \"failed\", \"failure_reason\": \"Crashed after 1 task on bjb1-32546:cuda:3 (PID 118214). Reviewer confirmed. Restarting as r2.\", \"completed_at\": \"2026-05-15T18:58:10.821Z\"}, \"eval-acr-object-v4-default\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:18:17.209Z\", \"updated_at\": \"2026-05-15T17:38:37.815Z\", \"hypothesis\": \"Ablation: perdof CRM v3-norm with DEFAULT max_correction_norm (~1.42, no magnitude control) on LIBERO object benchmark. Tests whether magnitude control is essential on object domain too. If v4-default << v4-perdof (norm=0.1) → magnitude control is universally needed. If v4-default ≈ v4-perdof → spatial failure was anomalous.\", \"parent\": \"eval-acr-object-v4-perdof\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --output_file logs/eval_object_perdof_default_norm.json\", \"server\": \"bjb2-28827\", \"gpu\": [\"cuda:3\"], \"pid\": \"107658\", \"log_path\": \"logs/eval_object_perdof_default_norm.log\", \"submitted_at\": \"2026-05-16T00:51:00Z\", \"backend\": \"nohup\", \"account\": \"root\", \"data_path\": \"libero_object\", \"data_count\": 10, \"model_name\": \"crm_perdof_default_norm\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"object\"}, \"metrics\": {\"tasks_done\": 3, \"tasks_total\": 10, \"status\": \"DEAD\", \"partial_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0}, \"pid_42311\": \"not_found\", \"needs_restart\": true, \"checked_at\": \"2026-05-16T01:00Z\"}, \"notes\": \"Killed per Director instruction. 3/10 tasks all 0% SR, no magnitude control (norm≈1.42). Conclusion obvious — magnitude control is essential.\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T17:38:37.815Z\"}, \"eval-mag-perdof-norm03-object\": {\"status\": \"DEPLOYED\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:57:00.172Z\", \"updated_at\": \"2026-05-15T17:38:28.909Z\", \"spec\": {\"pid\": 115384, \"gpu_ids\": [2], \"server\": \"bjb2-28827\", \"command\": \"python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03.json\"}, \"server\": \"bjb2-28827\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"bjb2-28827\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-15T17:16:56.760Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_perdof --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_object_perdof_norm03.json\\\"\", \"finished_at\": \"2026-05-15T17:29:42.220Z\", \"training_hours\": 0.21}, \"pid\": 118886, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-perdof-norm03-object.log\", \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T17:29:45.210Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:29:48.614116+00:00\"}]}, \"notes\": \"Restarted on cuda:3 (PID 118886, tmux: eval-mag-perdof-norm03-object) after v4-default killed. Previous run killed by SIGTERM before first rollout.\"}, \"eval-mag-obsonly-norm03-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:49:38.786Z\", \"updated_at\": \"2026-05-15T17:22:51.755Z\", \"hypothesis\": \"Retry of eval-mag-obsonly-norm03 (EXIT_CODE=127 fix). Magnitude sweep: obs_only CRM v3-norm at norm=0.3 on spatial. Fills obs_only norm=0.3 gap. perdof norm=0.3 shows T1 drop to 50% — if obs_only doesn't degrade at same norm, strong evidence for obs_only robustness.\", \"parent\": \"eval-mag-obsonly-norm03\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_mag_obsonly_norm03.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": 325264, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm03-r2.log\", \"submitted_at\": \"2026-05-15T06:50:02.511Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_norm_obs_only\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 37969.2, \"gpu_hours\": 10.55}, \"metrics\": {\"bowl_between\": 0.9, \"next_to_ramekin\": 1, \"table_center\": 0, \"cookie_box\": 0.3, \"top_drawer\": 0.1, \"on_ramekin\": 0, \"next_to_cookie_box\": 1, \"stove\": 0, \"next_to_plate\": 0.3, \"wooden_cabinet\": 0, \"overall_SR\": 0.36}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:20:31.567Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:20:34.907634+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm03-r2.log\", \"completed_at\": \"2026-05-15T17:22:51.755Z\"}, \"eval-vla-mean-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:31:09.989Z\", \"updated_at\": \"2026-05-15T17:01:25.883Z\", \"spec\": {\"command\": \"python eval_vla.py --benchmark object --mode vla_only --baseline_mode mean --n_rollouts 10 --K 10 --seed 42\", \"server\": \"bjb1-32546\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": 100, \"model_name\": \"smolvla_libero\", \"seed\": 42, \"eval_data\": \"LIBERO object\", \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_vla_mean.log\"}, \"hypothesis\": \"VLA mean baseline (K=10, mean aggregation) on LIBERO object benchmark. Matches reconvla spatial baseline but on object tasks.\", \"metrics\": {\"benchmark\": \"object\", \"mode\": \"vla_only\", \"baseline_mode\": \"mean\", \"n_rollouts\": 10, \"K\": 10, \"seed\": 42, \"overall_sr\": 12, \"total_success\": 12, \"total_rollouts\": 100, \"tasks_done\": \"10/10\", \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 10, \"bbq_sauce\": 30, \"ketchup\": 10, \"tomato_sauce\": 10, \"butter\": 0, \"milk\": 20, \"chocolate_pudding\": 30, \"orange_juice\": 10}, \"json_output\": \"/root/acr-vla-conformal-refinement/logs/eval_object_vla_mean.json\"}, \"conclusion\": \"success\", \"gpu\": \"bjb1-32546:cuda:5\", \"pid\": 18808, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_vla_mean.log\", \"completed_at\": \"2026-05-15T17:01:25.883Z\"}, \"eval-reconvla-object\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:48:28.744Z\", \"updated_at\": \"2026-05-15T16:25:17.101Z\", \"spec\": {\"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_reconvla.log\", \"json_path\": \"/root/acr-vla-conformal-refinement/logs/eval_object_reconvla.json\"}, \"hypothesis\": \"ReconVLA baseline (scalar Euclidean argmin, K=10) on LIBERO object benchmark. Tests whether simple sample selection improves over VLA mean on object manipulation tasks. Provides baseline for CRM comparison on object domain.\", \"metrics\": {\"overall_sr\": 0.12, \"per_task\": {\"alphabet_soup\": 0, \"cream_cheese\": 0, \"salad_dressing\": 0.1, \"bbq_sauce\": 0.3, \"ketchup\": 0, \"tomato_sauce\": 0, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.3, \"orange_juice\": 0.3}, \"n_rollouts\": 10, \"total_episodes\": 100, \"total_successes\": 12}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T16:25:17.101Z\"}, \"eval-acr-object-v4-obs-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:53:41.689Z\", \"updated_at\": \"2026-05-15T16:23:01.718Z\", \"hypothesis\": \"D021: obs_only CRM v3-norm with max_correction_norm=0.1 on LIBERO object benchmark. Cross-benchmark validation — obs-only leads spatial at 57.5%.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode crm_obs_only --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:2\"], \"pid\": \"13797\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-obs-only.log\", \"submitted_at\": \"2026-05-15T02:53:41.526Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 47312.8, \"gpu_hours\": 13.14}, \"metrics\": {\"overall_sr\": \"19.0% (19/100)\", \"total_success\": 19, \"total_rollouts\": 100, \"mode\": \"obs_only\", \"benchmark\": \"object\", \"max_correction_norm\": 0.1, \"seed\": 42, \"K\": 10, \"tasks_done\": \"10/10\", \"per_task\": {\"alphabet_soup\": \"0%\", \"cream_cheese\": \"10%\", \"salad_dressing\": \"20%\", \"bbq_sauce\": \"40%\", \"ketchup\": \"10%\", \"tomato_sauce\": \"0%\", \"butter\": \"10%\", \"milk\": \"20%\", \"chocolate_pudding\": \"50%\", \"orange_juice\": \"30%\"}, \"json_output\": \"/root/acr-vla-conformal-refinement/logs/eval_object_obs_only.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:59:31.860Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:59:34.042176+00:00\"}]}, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-obs-only.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T16:02:14.366Z\"}, \"eval-acr-object-v4-perdof\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:49:13.626Z\", \"updated_at\": \"2026-05-15T15:45:38.531Z\", \"hypothesis\": \"D021: ACR-VLA perdof CRM v3-norm with max_correction_norm=0.1 on LIBERO object benchmark. Cross-benchmark validation of spatial findings.\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode acr_vla --benchmark object --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt --max_correction_norm 0.1\", \"server\": \"bjb1-32546\", \"gpu_ids\": [\"cuda:1\"], \"pid\": \"11116\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v3-norm perdof, max_correction_norm=0.1, object)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"checkpoint_path\": \"N/A (eval-only)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-object-v4-perdof.log\"}, \"metrics\": {\"overall_sr\": \"11.0% (11/100)\", \"total_success\": 11, \"total_rollouts\": 100, \"mode\": \"perdof\", \"benchmark\": \"object\", \"max_correction_norm\": 0.1, \"seed\": 42, \"K\": 10, \"per_task\": {\"alphabet_soup\": \"0%\", \"cream_cheese\": \"0%\", \"salad_dressing\": \"20%\", \"bbq_sauce\": \"30%\", \"ketchup\": \"0%\", \"tomato_sauce\": \"0%\", \"butter\": \"10%\", \"milk\": \"0%\", \"chocolate_pudding\": \"20%\", \"orange_juice\": \"30%\"}, \"note\": \"perdof object 11% vs argmin ~7% (partial). obs_only leads at ~14% (8/10). Confirms perdof not competitive on object.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T15:45:38.531Z\"}, \"eval-acr-spatial-v4-scalar-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:14:04.283Z\", \"updated_at\": \"2026-05-15T13:18:27.852Z\", \"hypothesis\": \"Restart from T3. scalar_unc CRM v3-norm with max_correction_norm=0.1 on spatial. Three-way ablation: perdof vs scalar_unc vs obs_only.\", \"parent\": \"eval-acr-spatial-v4-scalar\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_scalar --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt --max_correction_norm 0.1 --start_task 3\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": 311881, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-scalar-r2.log\", \"submitted_at\": \"2026-05-15T05:14:33.525Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial\", \"data_count\": 70, \"model_name\": \"ACR-VLA CRM scalar_unc v3-norm (restart from T3)\", \"seed\": 42, \"eval_data\": \"LIBERO spatial tasks 3-9\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"checkpoint_path\": \"N/A (eval-only)\", \"wall_clock_seconds\": 29034.3, \"gpu_hours\": 8.07}, \"metrics\": {\"overall_sr\": \"32.0% (32/100)\", \"total_success\": 32, \"total_rollouts\": 100, \"mode\": \"scalar_unc\", \"benchmark\": \"spatial\", \"max_correction_norm\": 0.1, \"seed\": 42, \"K\": 10, \"per_task\": {\"T0\": \"60%\", \"T1\": \"100%\", \"T2\": \"10%\", \"T3\": \"40%\", \"T4\": \"0%\", \"T5\": \"0%\", \"T6\": \"90%\", \"T7\": \"0%\", \"T8\": \"10%\", \"T9\": \"10%\"}, \"note\": \"D030 confirmed: scalar_unc spatial 32% vs argmin 34% = -2pp. T0-T2 from original eval-acr-spatial-v4-scalar, T3-T9 from r2 restart. All CRM variants dead on spatial.\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T13:15:46.765Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:15:49.226583+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T13:18:27.853Z\"}, \"eval-acr-spatial-v4-obs-only-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:14:05.934Z\", \"updated_at\": \"2026-05-15T11:15:11.801Z\", \"hypothesis\": \"Restart from T6. obs_only CRM v3-norm with max_correction_norm=0.1 on spatial. If obs_only >= perdof, conformal features need restructuring.\", \"parent\": \"eval-acr-spatial-v4-obs-only-r2\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --start_task 6\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": 312420, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-obs-only-r3.log\", \"submitted_at\": \"2026-05-15T05:14:38.600Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial\", \"data_count\": 40, \"model_name\": \"ACR-VLA CRM obs_only v3-norm (restart from T6)\", \"seed\": 42, \"eval_data\": \"LIBERO spatial tasks 6-9\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"wall_clock_seconds\": 21633.2, \"gpu_hours\": 6.01}, \"metrics\": {\"overall_sr\": \"35.0% (35/100)\", \"total_success\": 35, \"total_rollouts\": 100, \"mode\": \"crm_obs_only\", \"benchmark\": \"spatial\", \"max_correction_norm\": 0.1, \"seed\": 42, \"K\": 10, \"per_task\": {\"T0\": \"90%\", \"T1\": \"100%\", \"T2\": \"0%\", \"T3\": \"40%\", \"T4\": \"10%\", \"T5\": \"0%\", \"T6\": \"90%\", \"T7\": \"0%\", \"T8\": \"20%\", \"T9\": \"0%\"}, \"r3_subset_T6_T9\": \"27.5% (11/40)\", \"note\": \"D030: obs_only spatial 10-task = 35%. vs argmin 34% = +1pp. Scenario C threshold (>=39%) NOT MET. Earlier T0-T5 advantage (+5pp) wiped out by T6-T9.\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T10:15:39.276Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T10:15:44.340640+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-obs-only-r3.log\", \"completed_at\": \"2026-05-15T11:15:11.801Z\"}, \"eval-obs-only-spatial-seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:09:04.411Z\", \"updated_at\": \"2026-05-15T10:01:21.065Z\", \"hypothesis\": \"D029: obs_only seed=43 复现实验。obs_only 是项目唯一存活路径。seed=42 如果确认 +5pp over argmin，seed=43 增加统计力（200 vs 200 样本下 Fisher exact p ~0.12，配合 object benchmark 独立验证有望通过）。\", \"parent\": \"eval-acr-spatial-v4-obs-only-r3\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 43 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.1 --output_file logs/eval_obs_only_spatial_seed43.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"341873\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-spatial-seed43.log\", \"submitted_at\": \"2026-05-15T09:09:23.712Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": 100, \"model_name\": \"crm_v3_norm_obs_only\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 3117.4, \"gpu_hours\": 0.87}, \"notes\": \"D029: perdof spatial 35% vs argmin 34% = +1pp, kill criterion triggered. Per-DOF claim dead on spatial. obs_only 是唯一存活路径，seed=43 用于增加统计力。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T10:01:21.065Z\"}, \"eval-acr-spatial-v4-small-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:14:05.220Z\", \"updated_at\": \"2026-05-15T09:10:21.153Z\", \"hypothesis\": \"Restart from T7. ACR-VLA perdof CRM v3-norm with max_correction_norm=0.1 on spatial. Full per-DOF uncertainty pipeline.\", \"parent\": \"eval-acr-spatial-v4-small\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/crm_best.pt --max_correction_norm 0.1 --start_task 7\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": 312150, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-small-r2.log\", \"submitted_at\": \"2026-05-15T05:14:36.298Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial\", \"data_count\": 30, \"model_name\": \"ACR-VLA CRM perdof v3-norm (restart from T7)\", \"seed\": 42, \"eval_data\": \"LIBERO spatial tasks 7-9\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/crm_best.pt\", \"wall_clock_seconds\": 14053.7, \"gpu_hours\": 3.9}, \"notes\": \"[D027] Framing 暂不裁决。Scenario A/B/C 取决于 magnitude sweep + object benchmark 结果。spatial matched-task perdof=argmin (0pp) 意味着 Scenario A 在 spatial 上不可能。\", \"metrics\": {\"overall_sr\": \"35.0% (35/100)\", \"total_success\": 35, \"total_rollouts\": 100, \"mode\": \"perdof\", \"benchmark\": \"spatial\", \"max_correction_norm\": 0.1, \"seed\": 42, \"K\": 10, \"per_task\": {\"T0\": \"60%\", \"T1\": \"100%\", \"T2\": \"10%\", \"T3\": \"40%\", \"T4\": \"0%\", \"T5\": \"0%\", \"T6\": \"90%\", \"T7\": \"10%\", \"T8\": \"40%\", \"T9\": \"0%\"}, \"note\": \"D029: perdof spatial complete 10-task = 35%. vs argmin 34% = +1pp. Kill criterion triggered — per-DOF claim dead on spatial.\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T09:05:27.552Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:05:31.321347+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/crm_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-small-r2.log\", \"completed_at\": \"2026-05-15T09:08:50.017Z\"}, \"eval-mag-obsonly-norm-0.3-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:10:44.647Z\", \"updated_at\": \"2026-05-15T07:19:12.632Z\", \"hypothesis\": \"Magnitude sweep: obs_only CRM v3-norm at max_correction_norm=0.3 on spatial. perdof norm=0.3 shows T1 drop to 50% — if obs_only doesn't degrade at same norm, strong evidence for obs_only robustness over perdof.\", \"parent\": \"eval-mag-obsonly-norm02\", \"spec\": {\"command\": \"N/A (stale duplicate entry)\", \"server\": \"bjb1-18228\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\"}, \"conclusion\": \"killed\", \"checkpoint_path\": \"N/A (stale duplicate entry, never ran)\", \"log_path\": \"N/A\", \"notes\": \"Stale duplicate entry with dots in name. Actual experiment is eval-mag-obsonly-norm-0p3-r3 (also killed). Real running experiment is eval-mag-obsonly-norm03-r2.\", \"completed_at\": \"2026-05-15T07:19:12.632Z\"}, \"eval-mag-obsonly-norm-0p3-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:11:06.381Z\", \"updated_at\": \"2026-05-15T07:17:16.300Z\", \"hypothesis\": \"Magnitude sweep: obs_only CRM v3-norm at max_correction_norm=0.3 on spatial. perdof norm=0.3 shows T1 drop to 50% — if obs_only doesn't degrade at same norm, strong evidence for obs_only robustness over perdof.\", \"parent\": \"eval-mag-obsonly-norm02\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --max_correction_norm 0.3 --output_file logs/eval_mag_obsonly_norm_0p3.json\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"329871\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm-0p3-r3.log\", \"submitted_at\": \"2026-05-15T07:11:15.690Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": 100, \"model_name\": \"crm_obs_only_v3_norm\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial (10 tasks x 10 rollouts)\", \"wall_clock_seconds\": 360.6, \"gpu_hours\": 0.1}, \"conclusion\": \"killed\", \"notes\": \"Director 撤销部署指令。r2 (PID 325264) 实际未被误杀，r3 是基于信息差的重复部署。立即 kill r3 保留 r2。\", \"checkpoint_path\": \"N/A (killed before completion)\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm-0p3-r3.log\", \"completed_at\": \"2026-05-15T07:17:16.300Z\"}, \"eval-argmin-only-spatial-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:14:03.322Z\", \"updated_at\": \"2026-05-15T06:39:37.926Z\", \"hypothesis\": \"Restart from T9. ReconVLA baseline (scalar Euclidean argmin, K=10) on spatial. Isolate argmin base action selection from CRM correction.\", \"parent\": \"eval-argmin-only-spatial\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --start_task 9\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": 311609, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-argmin-only-spatial-r2.log\", \"submitted_at\": \"2026-05-15T05:14:30.112Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial\", \"data_count\": 10, \"model_name\": \"ReconVLA argmin K=10 (restart from T9)\", \"seed\": 42, \"eval_data\": \"LIBERO spatial task 9 only\", \"checkpoint_source\": \"N/A (reconvla mode, no CRM)\", \"wall_clock_seconds\": 5107.8, \"gpu_hours\": 1.42}, \"reproduce\": {\"finished_at\": \"2026-05-15T06:35:00.746Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:35:02.954210+00:00\"}]}, \"metrics\": {\"overall_success_rate\": 0.34, \"total_successes\": 34, \"total_trials\": 100, \"per_task\": {\"T0_between_plate_and_ramekin\": 0.6, \"T1_next_to_ramekin\": 1, \"T2_from_table_center\": 0, \"T3_on_cookie_box\": 0.3, \"T4_in_top_drawer\": 0.1, \"T5_on_ramekin\": 0.1, \"T6_next_to_cookie_box\": 0.9, \"T7_on_stove\": 0, \"T8_next_to_plate\": 0.3, \"T9_on_wooden_cabinet\": 0.1}, \"note\": \"T0-T8 from original run (eval-argmin-only-spatial), T9 from r2 restart. Combined 10-task result.\"}, \"conclusion\": \"success\", \"notes\": \"10-task complete. T9 (wooden_cabinet) = 10%. Overall 34% (34/100). T0-T8 from original run, T9 from r2 restart. Clean exit. bjb1-18228 cuda:0 now FREE.\", \"checkpoint_path\": \"N/A (eval-only, no checkpoint output)\", \"completed_at\": \"2026-05-15T06:39:37.926Z\"}, \"eval-mag-obsonly-norm003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:21:24.009Z\", \"updated_at\": \"2026-05-15T05:32:12.897Z\", \"hypothesis\": \"Magnitude sweep: obs_only CRM v3-norm at norm=0.03 on spatial. Completes obs_only norm curve (have 0.05, 0.2; adding 0.03).\", \"spec\": {\"command\": \"python -u src/evaluate.py --benchmark spatial --mode crm_obs_only --max_correction_norm 0.03 --n_rollouts 10 --K 10 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt --output_file logs/eval_mag_obsonly_norm003.json\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": 225144, \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-mag-obsonly-norm003-b2.log\", \"submitted_at\": \"2026-05-15T05:20:45Z\", \"submitted_via\": \"tmux (manual)\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO spatial benchmark\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA + CRM-v3-norm-obs_only\", \"seed\": 42, \"checkpoint_source\": \"crm-train-v3-norm-obs_only\", \"eval_data\": \"LIBERO spatial\", \"wall_clock_seconds\": 686.0, \"gpu_hours\": 0.19}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T05:32:10.962Z\", \"notes\": \"Duplicate experiment on same GPU. pid 225144 was actually the child python process of eval-mag-obsonly-norm003-b2's wrapper (pid 225139). Not a separate experiment. Killed, restarted b2 with new pid 227426.\"}, \"eval-vla-only-object-k1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:11:14.165Z\", \"updated_at\": \"2026-05-15T05:18:17.853Z\", \"hypothesis\": \"VLA-only baseline (K=1, single sample, no CRM) on LIBERO object benchmark. Lowest-bar baseline for object domain.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode vla_only --baseline_mode single --benchmark object --n_rollouts 10 --seed 42 --K 1 --output_file logs/eval_object_vla_only_k1.json\\\"\", \"server\": \"bjb1-32546\", \"gpu\": [\"cuda:4\"], \"pid\": \"39397\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-vla-only-object-k1.log\", \"submitted_at\": \"2026-05-15T05:11:22.634Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"LIBERO object benchmark\", \"data_count\": \"10 tasks x 10 rollouts\", \"model_name\": \"SmolVLA (VLA-only K=1 single sample)\", \"seed\": 42, \"eval_data\": \"LIBERO object\", \"checkpoint_source\": \"N/A (no CRM, single VLA sample)\", \"wall_clock_seconds\": 311.9, \"gpu_hours\": 0.09}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T05:16:34.574Z\", \"notes\": \"Duplicate of eval-vla-only-object (already DONE at 12% SR). Process killed to free bjb1-32546 cuda:4.\"}, \"eval-acr-spatial-v4-default-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:48:09.734Z\", \"updated_at\": \"2026-05-15T03:30:05.911Z\", \"hypothesis\": \"D018-D019 验证: perdof CRM v3-norm with DEFAULT max_correction_norm (~1.42). 如果 v4-default << v4-small (max_norm=0.1) → magnitude control 是必要的。如果 v4-default ≈ baseline → normalization 独自不够。补全 bjb1 上两次失败的实验。\", \"parent\": \"eval-acr-spatial-v4-default-r2\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=0 HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\\\"\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"212685\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-default-r3.log\", \"submitted_at\": \"2026-05-15T01:49:35.076Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v3-norm perdof, default max_correction_norm)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 6030.8, \"gpu_hours\": 1.68}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T03:30:05.911Z\"}, \"eval-tiny-correction-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:48:35.421Z\", \"updated_at\": \"2026-05-15T01:45:12.897Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v2/perdof/crm_best.pt --max_correction_norm 0.05\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"232815\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-tiny-correction-spatial.log\", \"submitted_at\": \"2026-05-14T17:48:35.317Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"gpu_ids\": [\"cuda:2\"], \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"ACR-VLA per-DOF CRM v2 with tiny correction (max_norm=0.05, 28x smaller than default 1.42)\", \"seed\": 42, \"hypothesis\": \"Extreme correction clipping (0.05 vs 1.42) tests whether compounding error from large CRM deltas is the primary failure mode. If tiny-correction >> full-correction, correction magnitude is the problem.\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v2/perdof/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"wall_clock_seconds\": 27771.0, \"gpu_hours\": 7.71}, \"metrics\": {\"tasks_done\": \"7/10\", \"partial_results\": {\"T1_between_plate_ramekin\": \"70% (7/10)\", \"T2_next_to_ramekin\": \"90% (9/10)\", \"T3_from_table_center\": \"0% (0/10)\", \"T4_on_cookie_box\": \"30% (3/10)\", \"T5_in_top_drawer\": \"0% (0/10)\", \"T6_on_ramekin\": \"0% (0/10)\", \"T7_next_to_cookie_box\": \"90% (9/10)\"}, \"running_avg_7tasks\": \"40% (28/70)\", \"process_status\": \"ACTUALLY ALIVE - bash wrapper PID 232815 dead but python child PID 232820 still running (07:48h, 139% CPU, 9.1GB RSS, GPU2)\", \"status_correction\": \"Registry incorrectly marked DONE, process is still completing remaining 3 tasks\", \"snapshot_time\": \"2026-05-15T09:40Z\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:31:26.353Z\", \"failure_reason\": \"D021: v2 checkpoint invalidated by crm_cache_v5 retraining. Replaced by eval-acr-spatial-v4-scalar on bjb1:2.\"}, \"eval-acr-spatial-v4-default-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:37.194Z\", \"updated_at\": \"2026-05-14T22:40:00.000Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\\\"\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"203217\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-acr-spatial-v4-default-r2.log\", \"submitted_at\": \"2026-05-14T22:29:03.489Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"D018 retry: Normalization alone fixes CRM correction degradation. v3-norm per-DOF checkpoint with default max_correction_norm (~1.42). If >30% baseline → normalization was the main fix. If still < 30% → magnitude control also needed (compare with v4-small at 0.1).\", \"parent\": \"eval-acr-spatial-v4-default\", \"conclusion\": \"killed\", \"failure_reason\": \"Superseded by D020 plan. Default norm=1.42 already proven to degrade (v4-default: 0/5). Not needed. Process killed on bjb2 (PID 203222 confirmed dead).\", \"completed_at\": \"2026-05-14T22:40:00.000Z\"}, \"eval-acr-spatial-v4-obs-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:08:53.421Z\", \"updated_at\": \"2026-05-14T22:16:05.788Z\", \"hypothesis\": \"D020: obs_only CRM (val_loss 0.0165, 54% better than perdof 0.0358) with max_correction_norm=0.1. If obs_only >= v4-small (perdof) → Claim 1 needs restructuring. If obs_only < v4-small → conformal features have unique value under distribution shift.\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3/obs_only/crm_best.pt\", \"server\": \"bjb2-40593\", \"gpu_ids\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v3 obs_only, default max_correction_norm=1.42)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"log_path\": \"/root/autodl-tmp/logs/eval-acr-spatial-v4-obs-only.log\", \"tmux_session\": \"eval-acr-spatial-v4-obs-only\", \"pid\": 199257}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T22:16:04.414Z\", \"failure_reason\": \"Wrong checkpoint (crm_v3 not crm_v3_norm) + wrong max_correction_norm (1.42 not 0.1). Killed and replaced by eval-acr-spatial-v4-obs-only-r2.\"}, \"eval-acr-spatial-v4-default\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:08:59.906Z\", \"updated_at\": \"2026-05-14T22:08:58.490Z\", \"hypothesis\": \"D018: Input normalization alone fixes CRM correction degradation. v3-norm checkpoint with default max_correction_norm=1.42. If >30% baseline → normalization was the main fix.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"server\": \"bjb1-18228\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (CRM v3-norm per-DOF, default correction)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\"}, \"metrics\": {\"tasks_done\": \"0/10\", \"status_alert\": \"NO PROCESS FOUND - registry says RUNNING but no matching PID or tmux session on bjb1-18228. GPU 0 occupied by stale eval-acr-spatial-v3 tmux + crm-train-obs-only. NEEDS RESTART.\", \"snapshot_time\": \"2026-05-15T05:26Z\"}, \"conclusion\": \"failed\", \"failure_reason\": \"Process died. D019: 0/5 on task 1 confirmed default norm=1.42 still degrades. Replaced by eval-acr-spatial-v4-obs-only on cuda:0.\", \"completed_at\": \"2026-05-14T22:08:58.490Z\"}, \"crm-train-v3-norm-scalar-unc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:09:01.250Z\", \"updated_at\": \"2026-05-14T22:05:42.608Z\", \"hypothesis\": \"Ablation: scalar_unc input mode (scalar uncertainty only) with normalization. Tests per-DOF vs scalar uncertainty contribution with proper normalization.\", \"spec\": {\"command\": \"python -u src/train_crm.py --benchmark spatial --cache_dir /root/autodl-tmp/crm_cache_v5 --output_dir /root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode scalar_unc --seed 42\", \"server\": \"bjb1-18228\", \"data_path\": \"/root/autodl-tmp/crm_cache_v5/spatial/\", \"data_count\": 12167, \"model_name\": \"CRM-MLP-Normalized (scalar_unc)\", \"seed\": 42}, \"metrics\": {\"best_epoch\": 46, \"best_val_loss\": 0.037354, \"final_train_loss\": 0.053422, \"final_val_loss\": 0.03737}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/scalar_unc/crm_best.pt\", \"log_path\": \"/tmp/crm_train_scalar_unc.log\", \"completed_at\": \"2026-05-14T22:05:42.608Z\"}, \"crm-train-v3-norm-obs-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:09:00.829Z\", \"updated_at\": \"2026-05-14T22:05:28.289Z\", \"hypothesis\": \"Ablation: obs_only input mode (no uncertainty features) with normalization. Isolates contribution of obs features vs conformal features.\", \"spec\": {\"command\": \"python -u src/train_crm.py --benchmark spatial --cache_dir /root/autodl-tmp/crm_cache_v5 --output_dir /root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode obs_only --seed 42\", \"server\": \"bjb1-18228\", \"data_path\": \"/root/autodl-tmp/crm_cache_v5/spatial/\", \"data_count\": 12167, \"model_name\": \"CRM-MLP-Normalized (obs_only)\", \"seed\": 42}, \"metrics\": {\"best_epoch\": 48, \"best_val_loss\": 0.01645, \"final_train_loss\": 0.025576, \"final_val_loss\": 0.01645, \"total_epochs\": 50}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/obs_only/crm_best.pt\", \"log_path\": \"/tmp/crm_train_obs_only.log\", \"completed_at\": \"2026-05-14T22:05:28.289Z\"}, \"crm-train-v3-norm\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:45:12.565Z\", \"updated_at\": \"2026-05-14T20:05:22.677Z\", \"hypothesis\": \"D018: Input normalization fixes 1500x scale imbalance in CRM inputs, enabling proper gradient flow and meaningful per-DOF correction learning\", \"parent\": \"crm-train-v3-perdof\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u src/train_crm.py --benchmark spatial --cache_dir /root/autodl-tmp/crm_cache_v5 --output_dir /root/autodl-tmp/checkpoints/crm_v3_norm/perdof/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode full --seed 42\", \"server\": \"bjb1-18228\", \"data_path\": \"/root/autodl-tmp/crm_cache_v5/spatial/\", \"data_count\": 12167, \"model_name\": \"CRM-MLP-337K-Normalized\", \"seed\": 42, \"checkpoint_source\": \"N/A (training from scratch)\", \"eval_data\": \"N/A (training experiment)\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3_norm/perdof/crm_best.pt\", \"log_path\": \"no log file (tee failed, output was in tmux pane only)\", \"completed_at\": \"2026-05-14T20:05:20.181Z\", \"results\": {\"best_epoch\": 47, \"best_val_loss\": 0.03578, \"final_train_loss\": 0.04992, \"final_val_loss\": 0.03578, \"total_epochs\": 50, \"normalization\": \"per-feature input normalization (mean/std stored in crm_best.pt as input_mean/input_std tensors)\"}}, \"crm-train-v3-scalar-unc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:05:00.968Z\", \"updated_at\": \"2026-05-14T18:37:14.400Z\", \"spec\": {\"command\": \"python -u src/train_crm.py --benchmark spatial --cache_dir /root/autodl-tmp/crm_cache/ --output_dir /root/autodl-tmp/checkpoints/crm_v3/scalar_unc/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode scalar_unc --seed 42 --norm_stats /root/autodl-tmp/checkpoints/crm_v3/norm_stats.pt\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"181896\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v3-scalar-unc.log\", \"submitted_at\": \"2026-05-14T18:05:00.862Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/crm_cache/\", \"data_count\": 0, \"model_name\": \"CRM-MLP-337K\", \"seed\": 42, \"wall_clock_seconds\": 1917.7, \"gpu_hours\": 0.53}, \"reproduce\": {\"finished_at\": \"2026-05-14T18:27:15.107Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:27:19.071535+00:00\"}]}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T18:36:58.566Z\", \"metrics\": {\"invalidation_reason\": \"Trained on bjb2 crm_cache v4 (6D state, pre-D016). Must retrain on bjb1 crm_cache_v5 (8D state).\", \"original_val_loss\": 1.195}}, \"crm-train-v3-obs-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:05:02.939Z\", \"updated_at\": \"2026-05-14T18:37:04.316Z\", \"spec\": {\"command\": \"python -u src/train_crm.py --benchmark spatial --cache_dir /root/autodl-tmp/crm_cache/ --output_dir /root/autodl-tmp/checkpoints/crm_v3/obs_only/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode obs_only --seed 42 --norm_stats /root/autodl-tmp/checkpoints/crm_v3/norm_stats.pt\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"181973\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v3-obs-only.log\", \"submitted_at\": \"2026-05-14T18:05:02.833Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/crm_cache/spatial\", \"data_count\": 2402, \"model_name\": \"CRM-MLP-337K\", \"seed\": 42, \"wall_clock_seconds\": 1802.8, \"gpu_hours\": 0.5}, \"reproduce\": {\"finished_at\": \"2026-05-14T18:27:22.983Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:27:25.410071+00:00\"}]}, \"conclusion\": \"killed\", \"metrics\": {\"invalidation_reason\": \"Trained on bjb2 crm_cache v4 (6D state, pre-D016). Must retrain on bjb1 crm_cache_v5 (8D state).\", \"original_val_loss\": 1.193424}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3/obs_only/crm_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v3-obs-only.log\", \"completed_at\": \"2026-05-14T18:35:05.626Z\"}, \"crm-train-v3-perdof\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:04:54.552Z\", \"updated_at\": \"2026-05-14T18:37:02.631Z\", \"spec\": {\"command\": \"python -u src/train_crm.py --benchmark spatial --cache_dir /root/autodl-tmp/crm_cache/ --output_dir /root/autodl-tmp/checkpoints/crm_v3/perdof/ --K 10 --epochs 50 --batch_size 512 --lr 0.016 --input_mode full --seed 42 --norm_stats /root/autodl-tmp/checkpoints/crm_v3/norm_stats.pt\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"181668\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v3-perdof.log\", \"submitted_at\": \"2026-05-14T18:04:54.446Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/crm_cache/\", \"data_count\": 0, \"model_name\": \"CRM-MLP-337K\", \"seed\": 42, \"wall_clock_seconds\": 1510.3, \"gpu_hours\": 0.42}, \"reproduce\": {\"finished_at\": \"2026-05-14T18:27:11.506Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:27:13.038696+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v3/perdof/crm_best.pt\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/crm-train-v3-perdof.log\", \"metrics\": {\"invalidation_reason\": \"Trained on bjb2 crm_cache v4 (6D state, pre-D016). Must retrain on bjb1 crm_cache_v5 (8D state).\", \"original_val_loss\": 1.191387}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T18:30:04.713Z\"}, \"eval-obs-only-spatial-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:49:43.787Z\", \"updated_at\": \"2026-05-14T17:47:54.523Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=2 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode crm_obs_only --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"211961\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-obs-only-spatial-v3.log\", \"submitted_at\": \"2026-05-14T12:49:43.691Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"CRM obs_only v2 (990D, no conformal features)\", \"seed\": 42, \"hypothesis\": \"obs_only CRM ablation — CRM without conformal features tests whether per-DOF conformal intervals are necessary\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"parent\": \"crm-train-v2-obs-only\", \"conclusion_note\": \"Director order: 0/30 after 3 tasks, no diagnostic value. Freed bjb1:2 for eval-tiny-correction-spatial.\", \"metrics\": {\"tasks_completed\": 3, \"total_tasks\": 10, \"success_rate\": 0, \"successes\": 0, \"rollouts\": 30}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v2/obs_only/crm_best.pt\", \"wall_clock_seconds\": 17890.8, \"gpu_hours\": 4.97}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T17:47:54.523Z\"}, \"eval-scalar-unc-spatial-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:17:08.413Z\", \"updated_at\": \"2026-05-14T17:47:53.188Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && CUDA_VISIBLE_DEVICES=1 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode crm_scalar --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm_v2/scalar_unc/crm_best.pt\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"197324\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-scalar-unc-spatial-v2.log\", \"submitted_at\": \"2026-05-14T12:17:08.325Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial benchmark)\", \"data_count\": 100, \"model_name\": \"CRM v2 scalar-uncertainty + SmolVLA K=10\", \"seed\": 42, \"hypothesis\": \"Scalar uncertainty CRM ablation — tests whether per-DOF conformal is superior to scalar aggregated uncertainty for action correction.\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm_v2/scalar_unc/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"conclusion_note\": \"Director order: 0/30 after 3 tasks, no diagnostic value. Freed bjb1:1 for eval-argmin-only-spatial.\", \"metrics\": {\"tasks_completed\": 3, \"total_tasks\": 10, \"success_rate\": 0, \"successes\": 0, \"rollouts\": 30}, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm_v2/scalar_unc/crm_best.pt\", \"wall_clock_seconds\": 19844.9, \"gpu_hours\": 5.51}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T17:47:53.188Z\"}, \"crm-train-a4-scalar-unc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:48:40.837Z\", \"updated_at\": \"2026-05-14T07:59:32.676Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u src/train_crm.py --benchmark spatial object --epochs 50 --batch_size 32 --lr 0.001 --K 10 --seed 42 --input_mode scalar_unc --output_dir /root/autodl-tmp/checkpoints/crm/scalar_unc/\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"121984\", \"data_path\": \"/root/autodl-tmp/crm_cache/\", \"data_count\": 26737, \"model_name\": \"CRM-scalar_unc (3D scalar uncertainty)\", \"seed\": 42, \"hypothesis\": \"CRM with scalar Euclidean uncertainty (3D) performs worse than per-DOF (40D), validating per-DOF advantage. Ablation A4, hyperparams matched to plan_001 (bs=32/lr=1e-3).\", \"log_path\": \"/root/autodl-tmp/checkpoints/crm/scalar_unc/train.log\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/scalar_unc/crm_best.pt\", \"conclusion_note\": \"Training converged. scalar val_loss 0.008379 < per-DOF 0.009046 — original hypothesis (scalar worse) NOT confirmed on val_loss. Hypothesis pending eval-scalar-unc-spatial task success rate validation.\"}, \"conclusion\": \"killed\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/scalar_unc/crm_best.pt\", \"log_path\": \"/root/autodl-tmp/checkpoints/crm/scalar_unc/train.log\", \"metrics\": {\"best_val_loss\": 0.008379, \"best_epoch\": 48, \"total_epochs\": 50, \"final_val_loss\": 0.008384, \"final_train_loss\": 0.012959}, \"completed_at\": \"2026-05-14T02:21:00.891Z\", \"conclusion_note\": \"invalidated by D016 C1 fix, 6D state mismatch — checkpoint trained on wrong features\"}, \"crm-train-a3-obs-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:56:28.643Z\", \"updated_at\": \"2026-05-14T07:59:31.277Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u src/train_crm.py --benchmark spatial object --epochs 50 --batch_size 512 --lr 0.016 --K 10 --seed 42 --input_mode obs_only --output_dir /root/autodl-tmp/checkpoints/crm/obs_only/\", \"server\": \"bjb1-18228\", \"data_path\": \"/root/autodl-tmp/crm_cache/\", \"data_count\": 26737, \"model_name\": \"CRM-obs_only\", \"seed\": 42, \"hypothesis\": \"CRM without conformal features (obs_only, 990D input) performs significantly worse than full CRM (1030D), validating that per-DOF conformal features are necessary for effective correction\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/obs_only/crm_best.pt\", \"log_path\": \"/root/autodl-tmp/checkpoints/crm/obs_only/train.log\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T23:43:51.534Z\", \"metrics\": {\"best_val_loss\": 0.018312, \"best_epoch\": 4, \"early_stopped_at_epoch\": \"~15-20\", \"early_stop_reason\": \"val_loss plateau at 0.018 for 10+ epochs (full CRM: 0.009, 2x gap confirms conformal features are critical)\", \"input_dim\": 990, \"params\": 327966}, \"conclusion_note\": \"invalidated by D016 C1 fix, 6D state mismatch — checkpoint trained on wrong features\"}, \"crm-train-v1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:10:36.535Z\", \"updated_at\": \"2026-05-14T07:59:30.290Z\", \"spec\": {\"command\": \"python -u src/train_crm.py --benchmark spatial object --epochs 50 --batch_size 32 --lr 1e-3 --K 10 --seed 42\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"78520\", \"log_path\": \"/root/runs/acr-vla-conformal-refinement/crm-train-v1.log\", \"data_path\": \"/root/autodl-tmp/crm_cache/ (spatial: 12167 + object: 14570 = 26737 samples)\", \"data_count\": 26737, \"model_name\": \"CRM MLP (337K params, 1030D→256→256→30D)\", \"seed\": 42, \"hypothesis\": \"CRM with per-DOF conformal features (1030D input) learns dimension-selective correction, achieving lower action MSE than scalar/no-uncertainty ablations\", \"checkpoint_source\": \"precompute-v4 (spatial+object)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/\"}, \"reproduce\": {\"finished_at\": \"2026-05-13T22:40:27.930Z\"}, \"failure_reason\": \"RESOLVED: EXIT_CODE=129 was SIGHUP after training completed (50/50 epochs). Not a real failure.\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T22:40:28.559Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T22:40:29.429643+00:00\"}]}, \"metrics\": {\"best_val_loss\": 0.009046, \"best_epoch\": 50, \"total_epochs\": 50, \"checkpoint\": \"crm_best.pt\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/crm_best.pt\", \"exit_code_note\": \"129 was false alarm - SIGHUP after training completed\"}, \"conclusion_note\": \"invalidated by D016 C1 fix, 6D state mismatch — checkpoint trained on wrong features\"}, \"crm-train-k5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:42:55.911Z\", \"updated_at\": \"2026-05-14T07:59:29.396Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u src/train_crm.py --benchmark spatial object --epochs 50 --batch_size 32 --lr 0.001 --K 5 --seed 42 --cache_dir /root/autodl-tmp/crm_cache_k5/ --output_dir /root/autodl-tmp/checkpoints/crm/k5/\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"139839\", \"data_path\": \"/root/autodl-tmp/crm_cache_k5/\", \"data_count\": 26737, \"model_name\": \"CRM (K=5, 337K params)\", \"seed\": 42, \"hypothesis\": \"CRM with K=5 conformal samples for K sensitivity ablation (K=10 baseline val_loss=0.009046)\", \"log_path\": \"/root/autodl-tmp/checkpoints/crm/k5/train.log\", \"checkpoint_source\": \"from_scratch\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/k5/crm_best.pt\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T04:12:42.247Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T04:12:44.286094+00:00\"}]}, \"conclusion\": \"killed\", \"metrics\": {\"best_val_loss\": 0.008996, \"best_epoch\": 50, \"total_epochs\": 50, \"comparison\": \"K=5 val_loss 0.008996 ≈ K=10 val_loss 0.009046, near identical\"}, \"completed_at\": \"2026-05-14T07:21:32.072Z\", \"conclusion_note\": \"invalidated by D016 C1 fix, 6D state mismatch — checkpoint trained on wrong features\"}, \"eval-scalar-unc-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:54:30.549Z\", \"updated_at\": \"2026-05-14T07:52:44.766Z\", \"spec\": {\"hypothesis\": \"Scalar CRM (3D unc) vs per-DOF CRM (40D unc) on spatial task success rate. Val_loss favored scalar (0.008 vs 0.009) but per-DOF expected to win on task success via dimension-selective correction.\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"CRM-scalar_unc (3D scalar uncertainty, 327K params)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm/scalar_unc/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"command\": \"CUDA_VISIBLE_DEVICES=3 python -u src/evaluate.py --mode crm_scalar --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm/scalar_unc/crm_best.pt\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:3\"], \"pid\": \"143206\", \"log_path\": \"/root/autodl-tmp/eval_results/eval-scalar-unc-spatial.log\", \"failure_reason\": \"D016: C1 (state 6D→8D mismatch). Scalar CRM trained on wrong features. Replaced by eval-scalar-unc-spatial-v2.\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T07:52:15.933Z\", \"conclusion_note\": \"invalidated by D016 C1 bug, pre-fix data collected\"}, \"eval-acr-spatial-v2\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-13T23:04:32.138Z\", \"updated_at\": \"2026-05-14T07:52:43.327Z\", \"reproduce\": {\"finished_at\": \"2026-05-13T23:31:30.005Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-13T23:31:31.129Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:31:32.734610+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm/crm_best.pt\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:1\"], \"pid\": \"117814\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"ACR-VLA (SmolVLA + CRM per-DOF)\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/eval_results/eval-acr-spatial-v2.log\", \"hypothesis\": \"ACR-VLA per-DOF correction improves over SmolVLA baseline on spatial\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"failure_reason\": \"D016: C1 (state 6D→8D mismatch) + W3 (alpha 0.1→0.5). CRM trained on wrong features + CGS quantile wrong. Replaced by eval-acr-spatial-v3.\"}, \"conclusion\": \"killed\", \"conclusion_note\": \"invalidated by D016 C1 bug, pre-fix data collected\"}, \"eval-k5-spatial\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T04:14:23.092Z\", \"updated_at\": \"2026-05-14T07:52:43.134Z\", \"spec\": {\"command\": \"MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 5 --crm_checkpoint /root/autodl-tmp/checkpoints/crm/k5/crm_best.pt\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"154189\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"ACR-VLA K=5 (CRM 337K + SmolVLA 450M)\", \"seed\": 42, \"hypothesis\": \"K=5 vs K=10 ACR-VLA on task success rate.\", \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm/k5/crm_best.pt\", \"eval_data\": \"LIBERO spatial 10 tasks x 10 rollouts\", \"log_path\": \"/root/autodl-tmp/eval_results/eval-k5-spatial.log\", \"failure_reason\": \"D016: C1 (state 6D→8D mismatch) + W3 (alpha 0.1→0.5). CRM K=5 trained on wrong features. Replaced by eval-k5-spatial-v2.\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T07:52:14.685Z\", \"conclusion_note\": \"invalidated by D016 C1 bug, pre-fix data collected\"}, \"eval-object-v7-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T00:03:35.642Z\", \"updated_at\": \"2026-05-14T01:45:48.892Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode vla_only --benchmark object --n_rollouts 10 --seed 42\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"125830\", \"data_path\": \"/root/autodl-tmp/libero_data/libero_object/\", \"data_count\": 100, \"model_name\": \"smolvla_libero\", \"seed\": 42, \"hypothesis\": \"SmolVLA baseline on libero_object with K=1 fix (single inference per step)\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"LIBERO object 10 tasks x 10 rollouts\", \"log_path\": \"/root/autodl-tmp/eval_results/eval-object-v6.log\", \"failure_reason\": \"Duplicate entry — same PID 125830 tracked by eval-object-v8-full. Cleaning up.\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T01:45:48.892Z\"}, \"eval-spatial-v6-full\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-13T23:04:28.766Z\", \"updated_at\": \"2026-05-14T00:05:22.619Z\", \"reproduce\": {\"finished_at\": \"2026-05-14T00:03:28.470Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-13T23:34:09.898Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:34:11.481851+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T00:03:30.351859+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 42\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"117486\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"lerobot/smolvla_libero\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/eval_results/eval-spatial-v6-full.log\", \"hypothesis\": \"SmolVLA baseline on libero_spatial with fixed evaluate.py (reset→set_init_state→zero-action)\", \"failure_reason\": \"vla_only mode running K=10 instead of K=1, wasting GPU. Killed and restarted with K=1 fix.\"}, \"conclusion\": \"killed\"}, \"eval-object-v5-full\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-13T23:17:35.776Z\", \"updated_at\": \"2026-05-14T00:04:26.792Z\", \"reproduce\": {\"finished_at\": \"2026-05-13T23:43:52.899Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-13T23:43:53.809Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:43:56.187212+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode vla_only --benchmark object --n_rollouts 10 --seed 42 --smolvla_path /root/autodl-tmp/models/smolvla_libero/\", \"server\": \"bjb2-40593\", \"data_path\": \"/root/autodl-tmp/libero_data/libero_object/\", \"data_count\": 100, \"model_name\": \"smolvla_libero\", \"seed\": 42, \"pid\": 117697, \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval-object-v5-full.log\", \"gpu\": \"cuda:0\", \"note\": \"restored from false DONE/failed — cron misdetected tmux pipe buffering as process exit\", \"failure_reason\": \"vla_only mode running K=10 multi-sampling (should be K=1). Killed by Director order, replaced by eval-object-v7-full with K=1 fix.\"}, \"conclusion\": \"killed\"}, \"eval-acr-vla-spatial-v1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:56:40.287Z\", \"updated_at\": \"2026-05-13T23:14:22.561Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm/crm_best.pt --output_file /root/autodl-tmp/eval_results/acr_vla_spatial_v1.json\", \"server\": \"bjb1-18228\", \"data_path\": \"LIBERO spatial benchmark (10 tasks)\", \"data_count\": 100, \"model_name\": \"ACR-VLA (SmolVLA + CRM perdof)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm/crm_best.pt\", \"eval_data\": \"LIBERO spatial, 10 tasks x 10 rollouts\", \"parent\": \"train-crm-v1\", \"failure_reason\": \"P0 bug: evaluate.py env.reset() 覆盖 set_init_state 的 demo 初始状态，结果不可信。已被 eval-acr-spatial-v2 替代\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T23:13:00.422Z\"}, \"eval-acr-spatial-v1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:54:28.535Z\", \"updated_at\": \"2026-05-13T23:12:11.315Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 MUJOCO_GL=egl MUJOCO_EGL_DEVICE_ID=0 python -u src/evaluate.py --mode acr_vla --benchmark spatial --n_rollouts 10 --seed 42 --K 10 --crm_checkpoint /root/autodl-tmp/checkpoints/crm/crm_best.pt --output_file /root/autodl-tmp/eval_results/eval-acr-spatial-v1.json\", \"server\": \"bjb1-18228\", \"data_path\": \"/root/autodl-tmp/libero_data/\", \"data_count\": 100, \"model_name\": \"ACR-VLA (SmolVLA + CRM)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/checkpoints/crm/crm_best.pt\", \"eval_data\": \"LIBERO spatial (10 tasks x 10 rollouts)\", \"checkpoint_path\": \"/root/autodl-tmp/checkpoints/crm/crm_best.pt\", \"log_path\": \"/root/autodl-tmp/eval_results/eval-acr-spatial-v1.log\", \"failure_reason\": \"P0 bug: evaluate.py env.reset() 覆盖 set_init_state 的 demo 初始状态，结果不可信\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T23:09:38.077Z\"}, \"eval-reconvla-spatial-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:29:41.730Z\", \"updated_at\": \"2026-05-13T23:12:10.958Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode reconvla --benchmark spatial --n_rollouts 10 --seed 42 --K 10\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:2\"], \"pid\": \"87787\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-reconvla-spatial-v1.log\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"smolvla_libero + ReconVLA argmin\", \"seed\": 42, \"hypothesis\": \"ReconVLA (scalar Euclidean nonconformity + argmin) as baseline for ACR-VLA comparison\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"libero_spatial 10 tasks\", \"failure_reason\": \"P0 bug: evaluate.py env.reset() 覆盖 set_init_state 的 demo 初始状态，结果不可信\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T23:09:40.252Z\"}, \"eval-object-v4-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T19:13:26.341Z\", \"updated_at\": \"2026-05-13T23:12:10.037Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode vla_only --benchmark object --n_rollouts 10 --seed 42\", \"server\": \"bjb2-40593\", \"gpu\": [\"cuda:0\"], \"pid\": \"103768\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-object-v4-full.log\", \"data_path\": \"/root/autodl-tmp/libero_data/ (object)\", \"data_count\": 100, \"model_name\": \"lerobot/smolvla_libero\", \"seed\": 42, \"hypothesis\": \"SmolVLA with verified-deployed wrapper achieves meaningful success rate on libero_object\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"libero_object 10 tasks\", \"failure_reason\": \"P0 bug: evaluate.py env.reset() 覆盖 set_init_state 的 demo 初始状态，结果不可信\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T23:09:39.017Z\"}, \"eval-spatial-v5-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T19:16:58.052Z\", \"updated_at\": \"2026-05-13T23:12:09.066Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 42\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"73756\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-spatial-v5-full.log\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": 100, \"model_name\": \"lerobot/smolvla_libero\", \"seed\": 42, \"hypothesis\": \"SmolVLA with verified wrapper + dual camera (agentview + eye_in_hand) achieves >50% on libero_spatial\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"eval_data\": \"libero_spatial 10 tasks\", \"failure_reason\": \"P0 bug: evaluate.py env.reset() 覆盖 set_init_state 的 demo 初始状态，结果不可信\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T23:09:39.445Z\"}, \"eval-spatial-v3-full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T17:38:57.194Z\", \"updated_at\": \"2026-05-13T19:09:00.612Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/acr-vla-conformal-refinement && export HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 MUJOCO_GL=egl && python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 10 --seed 42 --smolvla_path /root/autodl-tmp/models/smolvla_libero/ 2>&1\\\"\", \"server\": \"bjb1-18228\", \"gpu\": [\"cuda:0\"], \"pid\": \"62654\", \"log_path\": \"~/runs/acr-vla-conformal-refinement/eval-spatial-v3-full.log\", \"submitted_at\": \"2026-05-13T17:38:57.172Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": \"10 tasks x 10 rollouts x 300 steps\", \"model_name\": \"lerobot/smolvla_libero (450M, rewritten wrapper aligned with lerobot pipeline)\", \"seed\": 42, \"hypothesis\": \"Rewritten wrapper (fully aligned with lerobot SmolVLAPolicy) achieves >50% on libero_spatial with 10 rollouts\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"failure_reason\": \"D014: wrapper 修复版从未部署到服务器，使用旧 buggy 代码运行，产出无效\", \"wall_clock_seconds\": 5403.4, \"gpu_hours\": 1.5}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T19:09:00.612Z\"}, \"eval-spatial-reeval-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T16:08:51.171Z\", \"updated_at\": \"2026-05-13T16:14:40.934Z\", \"spec\": {\"command\": \"python -u src/evaluate.py --mode vla_only --benchmark spatial --n_rollouts 3 --seed 42 --smolvla_path /root/autodl-tmp/models/smolvla_libero/\", \"server\": \"autodl-4090x4\", \"gpu\": [\"cuda:0\"], \"pid\": \"87385\", \"data_path\": \"/root/autodl-tmp/libero_data/ (spatial)\", \"data_count\": \"10 tasks x 3 rollouts x 300 steps\", \"model_name\": \"lerobot/smolvla_libero (450M, full fine-tuned)\", \"seed\": 42, \"hypothesis\": \"Fixed wrapper (7 bugs) achieves >50% on libero_spatial\", \"log_path\": \"/tmp/eval_spatial.log\", \"checkpoint_source\": \"lerobot/smolvla_libero\", \"failure_reason\": \"Killed by Director - wrapper not fully fixed, 55.6% result unreliable. Redirected to full wrapper rewrite aligned with lerobot pipeline.\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-13T16:14:40.934Z\"}}, \"count\": 612, \"total\": 612, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.4669}}"
    }
  }
}
```

&lt;/details>

---


````

---

### Tool result

_source line 13 · 2026-05-21T16:45:57.848Z_

<details><summary>↩ Tool result · `toolu_01Xir2E5w7rrWyKCShrXXwtv`</summary>

```text
docs/paper/camera_ready_template/corl_2026_template_cameraready/example.tex
docs/paper/review_template/corl_2026_template_submission/example.tex
artifacts/dream_reports/dream_20260513T015051/best/paper.tex
artifacts/dream_reports/dream_20260513T015051/median/paper.tex
artifacts/dream_reports/dream_20260513T015051/worst/paper.tex
artifacts/dream_reports/dream_20260513T023849/best/paper.tex
artifacts/dream_reports/dream_20260513T023849/median/paper.tex
artifacts/dream_reports/dream_20260513T023849/worst/paper.tex
artifacts/method_section_draft.tex
artifacts/_project/paper/method_section_draft.tex
artifacts/figures/object_benchmark_table.tex
artifacts/figures/spatial_final_table.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/introduction_c83872.tex
artifacts/_project/paper/related_work_9c2927.tex
artifacts/_project/paper/related_work_80791f.tex
artifacts/_project/paper/method_fb526b.tex
artifacts/_project/paper/experiments_c64a8c.tex
artifacts/_project/paper/abstract_a1674b.tex
artifacts/_project/paper/sections/discussion.tex
artifacts/_project/paper/method.tex
artifacts/_project/paper/experiments_ac6246.tex
artifacts/_project/paper/introduction_scenarioC_607d8d.tex
artifacts/_project/paper/related_work.tex
artifacts/_project/paper/introduction_scenarioC.tex
artifacts/_project/paper/sections/introduction.tex
artifacts/_project/paper/experiments.tex
artifacts/_project/paper/abstract.tex
docs/paper/related_work.tex
docs/paper/abstract.tex
docs/paper/introduction.tex
docs/paper/main.tex
docs/paper/experiments.tex
docs/paper/appendix.tex
docs/paper/method.tex
docs/paper/discussion.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "36e6720e-32b8-4da8-ac10-3d298f3ae310",
  "tool_use_result": {
    "filenames": [
      "docs/paper/camera_ready_template/corl_2026_template_cameraready/example.tex",
      "docs/paper/review_template/corl_2026_template_submission/example.tex",
      "artifacts/dream_reports/dream_20260513T015051/best/paper.tex",
      "artifacts/dream_reports/dream_20260513T015051/median/paper.tex",
      "artifacts/dream_reports/dream_20260513T015051/worst/paper.tex",
      "artifacts/dream_reports/dream_20260513T023849/best/paper.tex",
      "artifacts/dream_reports/dream_20260513T023849/median/paper.tex",
      "artifacts/dream_reports/dream_20260513T023849/worst/paper.tex",
      "artifacts/method_section_draft.tex",
      "artifacts/_project/paper/method_section_draft.tex",
      "artifacts/figures/object_benchmark_table.tex",
      "artifacts/figures/spatial_final_table.tex",
      "artifacts/_project/paper/introduction.tex",
      "artifacts/_project/paper/introduction_c83872.tex",
      "artifacts/_project/paper/related_work_9c2927.tex",
      "artifacts/_project/paper/related_work_80791f.tex",
      "artifacts/_project/paper/method_fb526b.tex",
      "artifacts/_project/paper/experiments_c64a8c.tex",
      "artifacts/_project/paper/abstract_a1674b.tex",
      "artifacts/_project/paper/sections/discussion.tex",
      "artifacts/_project/paper/method.tex",
      "artifacts/_project/paper/experiments_ac6246.tex",
      "artifacts/_project/paper/introduction_scenarioC_607d8d.tex",
      "artifacts/_project/paper/related_work.tex",
      "artifacts/_project/paper/introduction_scenarioC.tex",
      "artifacts/_project/paper/sections/introduction.tex",
      "artifacts/_project/paper/experiments.tex",
      "artifacts/_project/paper/abstract.tex",
      "docs/paper/related_work.tex",
      "docs/paper/abstract.tex",
      "docs/paper/introduction.tex",
      "docs/paper/main.tex",
      "docs/paper/experiments.tex",
      "docs/paper/appendix.tex",
      "docs/paper/method.tex",
      "docs/paper/discussion.tex"
    ],
    "durationMs": 53,
    "numFiles": 36,
    "truncated": false
  }
}
```

</details>

---


### Tool result

_source line 14 · 2026-05-21T16:45:57.851Z_

<details><summary>↩ Tool result · `toolu_01CZEnFijAxVL8d8gU7GGBaN`</summary>

```text
docs/paper/camera_ready_template/corl_2026_template_cameraready/example.bib
docs/paper/review_template/corl_2026_template_submission/example.bib
artifacts/_project/paper/references_e9d4d2.bib
artifacts/_project/paper/references.bib
docs/paper/references.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "bcdc0036-e187-4071-a98b-ec650542c8d0",
  "tool_use_result": {
    "filenames": [
      "docs/paper/camera_ready_template/corl_2026_template_cameraready/example.bib",
      "docs/paper/review_template/corl_2026_template_submission/example.bib",
      "artifacts/_project/paper/references_e9d4d2.bib",
      "artifacts/_project/paper/references.bib",
      "docs/paper/references.bib"
    ],
    "durationMs": 49,
    "numFiles": 5,
    "truncated": false
  }
}
```

</details>

---


### Assistant

_source line 15_

<details><summary>Logged reasoning block</summary>

```text
The paper seems to be in `docs/paper/`. Let me read the main files and the bib file. I also need to check the registry data. Let me start reading the paper files and the registry data in parallel.

The registry result was too large and saved to a file. I'll need to query it more selectively. Let me focus on key experiments.

Let me read the main paper files and check for compilation infrastructure.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "58e76e44-2b66-48e3-8583-1c32eff61a65",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 16_

Paper is in `docs/paper/`. Let me read all the paper files and check for compilation setup.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "a44174e3-c17b-427c-aef8-97d97639851d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01Tw4mdTnzUnC4eGu3LG2khg`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "adb124ea-8b62-4d82-b61a-c51d289cc22f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 18 · 2026-05-21T16:46:07.284Z_

<details><summary>↩ Tool result · `toolu_01Tw4mdTnzUnC4eGu3LG2khg`</summary>

```text
1	\documentclass{article}
2	
3	\usepackage{corl_2026}
4	
5	\usepackage[utf8]{inputenc}
6	\usepackage[T1]{fontenc}
7	\usepackage{amsmath,amssymb,amsfonts}
8	\DeclareMathOperator*{\argmin}{arg\,min}
9	\DeclareMathOperator*{\argmax}{arg\,max}
10	\usepackage{graphicx}
11	\usepackage{booktabs}
12	\usepackage{enumitem}
13	\usepackage{multirow}
14	
15	\newcommand{\placeholder}[1]{---}
16	
17	\graphicspath{{figures/}}
18	
19	\title{When to Correct: Adaptive Inference-Time Compute\\Allocation for Frozen VLAs}
20	
21	\author{
22	  Anonymous
23	}
24	
25	\begin{document}
26	
27	\maketitle
28	
29	\begin{abstract}
30	\input{abstract}
31	\end{abstract}
32	
33	\keywords{Vision-Language-Action Models, Inference-Time Refinement, Robotic Manipulation}
34	
35	\input{introduction}
36	\input{related_work}
37	\input{method}
38	\input{experiments}
39	\input{discussion}
40	
41	\bibliography{references}
42	
43	\clearpage
44	\input{appendix}
45	
46	\end{document}
47	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "7be254ca-6e79-4c3e-8f11-d46c17eb19c7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/main.tex",
      "content": "\\documentclass{article}\n\n\\usepackage{corl_2026}\n\n\\usepackage[utf8]{inputenc}\n\\usepackage[T1]{fontenc}\n\\usepackage{amsmath,amssymb,amsfonts}\n\\DeclareMathOperator*{\\argmin}{arg\\,min}\n\\DeclareMathOperator*{\\argmax}{arg\\,max}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{enumitem}\n\\usepackage{multirow}\n\n\\newcommand{\\placeholder}[1]{---}\n\n\\graphicspath{{figures/}}\n\n\\title{When to Correct: Adaptive Inference-Time Compute\\\\Allocation for Frozen VLAs}\n\n\\author{\n  Anonymous\n}\n\n\\begin{document}\n\n\\maketitle\n\n\\begin{abstract}\n\\input{abstract}\n\\end{abstract}\n\n\\keywords{Vision-Language-Action Models, Inference-Time Refinement, Robotic Manipulation}\n\n\\input{introduction}\n\\input{related_work}\n\\input{method}\n\\input{experiments}\n\\input{discussion}\n\n\\bibliography{references}\n\n\\clearpage\n\\input{appendix}\n\n\\end{document}\n",
      "numLines": 47,
      "startLine": 1,
      "totalLines": 47
    }
  }
}
```

</details>

---


### Tool call

_source line 19_

<details open><summary>🔧 Tool call — Read · `toolu_013YBUzhbDiPz3zQMnDv7xvM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "e8b96d12-2cce-4502-985e-79f7bb30e701",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 20 · 2026-05-21T16:46:08.265Z_

<details><summary>↩ Tool result · `toolu_013YBUzhbDiPz3zQMnDv7xvM`</summary>

```text
1	Vision-Language-Action (VLA) models for robotic manipulation degrade under distribution shift, yet improving their outputs at inference time remains underexplored, particularly the question of \emph{when} additional compute is warranted.
2	We propose an adaptive inference-time compute pipeline for frozen flow-matching VLAs. The core mechanism is a $K{=}2$ pairwise $L_2$ distance that correlates near-perfectly with full $K{=}10$ sample variance ($\rho{=}0.9979$), providing a per-step uncertainty estimate at zero additional cost. Three alternative signals (FMVD, CRM correction magnitude) all fail ($\rho \leq 0.15$).
3	When uncertainty is low, the pipeline outputs the $K{=}2$ argmin sample directly; when high, it applies learned residual correction via a ${\sim}$327K-parameter Correction Residual Module (CRM) trained on task-specific VLA rollout data. The pipeline uses at most two forward passes---gains come from learned correction, not additional sampling.
4	The $K{=}2$ adaptive pipeline matches or exceeds fixed-$K{=}10$ unconditional correction with 80\% fewer VLA forward passes: $18.3 \pm 2.1$\% on LIBERO-Object ($+$7.3\,pp vs.\ VLA-only) and $35.0 \pm 1.0$\% on LIBERO-Spatial ($+$5.6\,pp), with selective CRM application (Object 83.7\%, Spatial 97.6\% trigger rate).
5	Component decomposition on fixed-$K$ analysis baselines reveals that learned correction contributes 55\% of the gain at $K{=}5$ and 78\% at $K{=}10$, while multi-sampling is an enabling condition ($K{=}1$ correction degrades below baseline). Three distribution shifts define operating boundaries: near-OOD task shift is adversarial ($-$12\,pp) while far-OOD is neutral.
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "4fd546cb-c0a8-45dc-9296-fdc6cccdd824",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/abstract.tex",
      "content": "Vision-Language-Action (VLA) models for robotic manipulation degrade under distribution shift, yet improving their outputs at inference time remains underexplored, particularly the question of \\emph{when} additional compute is warranted.\nWe propose an adaptive inference-time compute pipeline for frozen flow-matching VLAs. The core mechanism is a $K{=}2$ pairwise $L_2$ distance that correlates near-perfectly with full $K{=}10$ sample variance ($\\rho{=}0.9979$), providing a per-step uncertainty estimate at zero additional cost. Three alternative signals (FMVD, CRM correction magnitude) all fail ($\\rho \\leq 0.15$).\nWhen uncertainty is low, the pipeline outputs the $K{=}2$ argmin sample directly; when high, it applies learned residual correction via a ${\\sim}$327K-parameter Correction Residual Module (CRM) trained on task-specific VLA rollout data. The pipeline uses at most two forward passes---gains come from learned correction, not additional sampling.\nThe $K{=}2$ adaptive pipeline matches or exceeds fixed-$K{=}10$ unconditional correction with 80\\% fewer VLA forward passes: $18.3 \\pm 2.1$\\% on LIBERO-Object ($+$7.3\\,pp vs.\\ VLA-only) and $35.0 \\pm 1.0$\\% on LIBERO-Spatial ($+$5.6\\,pp), with selective CRM application (Object 83.7\\%, Spatial 97.6\\% trigger rate).\nComponent decomposition on fixed-$K$ analysis baselines reveals that learned correction contributes 55\\% of the gain at $K{=}5$ and 78\\% at $K{=}10$, while multi-sampling is an enabling condition ($K{=}1$ correction degrades below baseline). Three distribution shifts define operating boundaries: near-OOD task shift is adversarial ($-$12\\,pp) while far-OOD is neutral.\n",
      "numLines": 6,
      "startLine": 1,
      "totalLines": 6
    }
  }
}
```

</details>

---


### Tool call

_source line 21_

<details open><summary>🔧 Tool call — Read · `toolu_01VFj8bHFobs1HCZ2wSo9bgG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "0464deb6-c760-4f2a-8d5d-b032d13245e6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 22 · 2026-05-21T16:46:08.745Z_

<details><summary>↩ Tool result · `toolu_01VFj8bHFobs1HCZ2wSo9bgG`</summary>

```text
1	\section{Introduction}
2	\label{sec:intro}
3	
4	\looseness=-1 Deploying a pretrained Vision-Language-Action model (VLA) on a new task typically requires fine-tuning on task-specific demonstrations, yet collecting such data is expensive and the resulting checkpoint may not generalize further.
5	An alternative is to keep the VLA frozen and attach a lightweight post-hoc correction module trained on task-specific VLA rollout data, improving action quality at inference time without modifying the base model.
6	Flow-matching VLAs~\cite{black2024pi0,shukor2025smolvla,lipman2023flow} are natural candidates: each forward pass produces a stochastic action sample, so drawing multiple samples opens the door to selection and correction without changing model weights.
7	The question is not only how to use these samples but \emph{when} to invest the additional compute: most control steps are easy and do not benefit from multi-sample correction, while a minority of hard steps account for the majority of task failures.
8	
9	\looseness=-1 Recent robustness evaluations~\cite{fei2025liberoplus} show that state-of-the-art VLAs lose over 65 percentage points under common deployment perturbations, making inference-time correction practically relevant.
10	Training-time methods~\cite{srpo2025,robustvla2025,digflow2025,liu2026ttvla} improve the base policy through robustness-aware objectives or test-time RL, but require retraining and remain bounded by the training distribution.
11	Inference-time methods leave the policy frozen: ReconVLA~\cite{chen2026reconvla} provides uncertainty quantification but does not learn corrective residuals; A2C2~\cite{a2c2_2025} trains a per-step correction head on action chunks but applies correction unconditionally without adaptive compute allocation; VLA-Pilot~\cite{li2025vlapilot} applies evolutionary optimization at 2.41\,s per control step.
12	Despite growing interest, no prior work addresses a core efficiency question: how to determine per-step whether the VLA is uncertain enough to warrant additional sampling and correction.
13	
14	\looseness=-1 We introduce an adaptive inference-time compute pipeline for frozen flow-matching VLAs. The core insight is that the pairwise $L_2$ distance between just $K{=}2$ action samples from the frozen VLA correlates near-perfectly with the full $K{=}10$ sample variance ($\rho{=}0.9979$), providing a per-step uncertainty estimate at negligible additional cost (${\sim}$250\,ms with batched inference, comparable to single-sample latency). Three alternative uncertainty signals (FMVD, CRM correction magnitude at $K{=}1$ and $K{=}2$) all yield $\rho \leq 0.15$.
15	When the probe indicates low uncertainty, the pipeline outputs the $K{=}2$ argmin sample directly; when uncertainty is high, it applies a learned residual correction to the same sample through a lightweight Correction Residual Module (CRM, ${\sim}$327K parameters). The pipeline uses at most $K{=}2$ forward passes---performance gains come from learned correction, not additional sampling.
16	
17	\looseness=-1 The $K{=}2$ adaptive pipeline achieves $18.3 \pm 2.1$\% on LIBERO-Object ($+$7.3\,pp vs.\ $11.0 \pm 1.3$\% VLA-only, 8 seeds) and $35.0 \pm 1.0$\% on Spatial ($+$5.6\,pp), matching or exceeding fixed-$K{=}10$ unconditional correction ($16.8$\%, $34.4$\%) with 80\% fewer VLA forward passes. CRM triggers on 83.7\% of Object steps but 97.6\% of Spatial steps, reflecting that selectivity is task-difficulty-dependent.
18	Component decomposition on fixed-$K$ analysis baselines reveals that learned correction contributes 55\% of the gain at $K{=}5$ and 78\% at $K{=}10$, while multi-sampling is an enabling condition: $K{=}1$ correction alone falls below baseline (10.3\%).
19	Unlike LLM test-time compute scaling~\cite{snell2024scaling} where selection is primary, here the $K{=}2$ probe provides a centered starting point and uncertainty gate for learned correction.
20	
21	Our contributions are:
22	\begin{enumerate}[leftmargin=*,nosep]
23	  \item \textbf{$K{=}2$ adaptive pipeline} (Section~\ref{sec:adaptive_k_method}): selective CRM correction gated by a pairwise $L_2$ uncertainty probe ($\rho{=}0.9979$ vs.\ $K{=}10$ variance; three alternatives fail, $\rho \leq 0.15$). Achieves $18.3$\% Object / $35.0$\% Spatial ($+$7.3 / $+$5.6\,pp vs.\ VLA-only), matching fixed-$K{=}10$ with 80\% fewer VLA forward passes.
24	  \item \textbf{Selective $>$ unconditional correction} (Section~\ref{sec:main_results}): Plan~A exceeds $K{=}10$ unconditional CRM ($18.3$\% vs.\ $16.8$\% Object); trigger rate is task-dependent (Object 83.7\%, Spatial 97.6\%).
25	  \item \textbf{Correction mechanism decomposition} (Section~\ref{sec:main_results}): on fixed-$K$ analysis baselines, learned correction contributes 55--78\% of the gain; random selection fails to exceed VLA-only on either benchmark, confirming correction as the active ingredient.
26	  \item \textbf{Distribution shift boundaries} (Section~\ref{sec:failure_modes}): three shifts define operating boundaries; near-OOD is adversarial ($-$12\,pp), far-OOD neutral ($p{=}0.46$).
27	\end{enumerate}
28	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "c16586d4-ede0-4a0e-80fd-3307d9171e70",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:intro}\n\n\\looseness=-1 Deploying a pretrained Vision-Language-Action model (VLA) on a new task typically requires fine-tuning on task-specific demonstrations, yet collecting such data is expensive and the resulting checkpoint may not generalize further.\nAn alternative is to keep the VLA frozen and attach a lightweight post-hoc correction module trained on task-specific VLA rollout data, improving action quality at inference time without modifying the base model.\nFlow-matching VLAs~\\cite{black2024pi0,shukor2025smolvla,lipman2023flow} are natural candidates: each forward pass produces a stochastic action sample, so drawing multiple samples opens the door to selection and correction without changing model weights.\nThe question is not only how to use these samples but \\emph{when} to invest the additional compute: most control steps are easy and do not benefit from multi-sample correction, while a minority of hard steps account for the majority of task failures.\n\n\\looseness=-1 Recent robustness evaluations~\\cite{fei2025liberoplus} show that state-of-the-art VLAs lose over 65 percentage points under common deployment perturbations, making inference-time correction practically relevant.\nTraining-time methods~\\cite{srpo2025,robustvla2025,digflow2025,liu2026ttvla} improve the base policy through robustness-aware objectives or test-time RL, but require retraining and remain bounded by the training distribution.\nInference-time methods leave the policy frozen: ReconVLA~\\cite{chen2026reconvla} provides uncertainty quantification but does not learn corrective residuals; A2C2~\\cite{a2c2_2025} trains a per-step correction head on action chunks but applies correction unconditionally without adaptive compute allocation; VLA-Pilot~\\cite{li2025vlapilot} applies evolutionary optimization at 2.41\\,s per control step.\nDespite growing interest, no prior work addresses a core efficiency question: how to determine per-step whether the VLA is uncertain enough to warrant additional sampling and correction.\n\n\\looseness=-1 We introduce an adaptive inference-time compute pipeline for frozen flow-matching VLAs. The core insight is that the pairwise $L_2$ distance between just $K{=}2$ action samples from the frozen VLA correlates near-perfectly with the full $K{=}10$ sample variance ($\\rho{=}0.9979$), providing a per-step uncertainty estimate at negligible additional cost (${\\sim}$250\\,ms with batched inference, comparable to single-sample latency). Three alternative uncertainty signals (FMVD, CRM correction magnitude at $K{=}1$ and $K{=}2$) all yield $\\rho \\leq 0.15$.\nWhen the probe indicates low uncertainty, the pipeline outputs the $K{=}2$ argmin sample directly; when uncertainty is high, it applies a learned residual correction to the same sample through a lightweight Correction Residual Module (CRM, ${\\sim}$327K parameters). The pipeline uses at most $K{=}2$ forward passes---performance gains come from learned correction, not additional sampling.\n\n\\looseness=-1 The $K{=}2$ adaptive pipeline achieves $18.3 \\pm 2.1$\\% on LIBERO-Object ($+$7.3\\,pp vs.\\ $11.0 \\pm 1.3$\\% VLA-only, 8 seeds) and $35.0 \\pm 1.0$\\% on Spatial ($+$5.6\\,pp), matching or exceeding fixed-$K{=}10$ unconditional correction ($16.8$\\%, $34.4$\\%) with 80\\% fewer VLA forward passes. CRM triggers on 83.7\\% of Object steps but 97.6\\% of Spatial steps, reflecting that selectivity is task-difficulty-dependent.\nComponent decomposition on fixed-$K$ analysis baselines reveals that learned correction contributes 55\\% of the gain at $K{=}5$ and 78\\% at $K{=}10$, while multi-sampling is an enabling condition: $K{=}1$ correction alone falls below baseline (10.3\\%).\nUnlike LLM test-time compute scaling~\\cite{snell2024scaling} where selection is primary, here the $K{=}2$ probe provides a centered starting point and uncertainty gate for learned correction.\n\nOur contributions are:\n\\begin{enumerate}[leftmargin=*,nosep]\n  \\item \\textbf{$K{=}2$ adaptive pipeline} (Section~\\ref{sec:adaptive_k_method}): selective CRM correction gated by a pairwise $L_2$ uncertainty probe ($\\rho{=}0.9979$ vs.\\ $K{=}10$ variance; three alternatives fail, $\\rho \\leq 0.15$). Achieves $18.3$\\% Object / $35.0$\\% Spatial ($+$7.3 / $+$5.6\\,pp vs.\\ VLA-only), matching fixed-$K{=}10$ with 80\\% fewer VLA forward passes.\n  \\item \\textbf{Selective $>$ unconditional correction} (Section~\\ref{sec:main_results}): Plan~A exceeds $K{=}10$ unconditional CRM ($18.3$\\% vs.\\ $16.8$\\% Object); trigger rate is task-dependent (Object 83.7\\%, Spatial 97.6\\%).\n  \\item \\textbf{Correction mechanism decomposition} (Section~\\ref{sec:main_results}): on fixed-$K$ analysis baselines, learned correction contributes 55--78\\% of the gain; random selection fails to exceed VLA-only on either benchmark, confirming correction as the active ingredient.\n  \\item \\textbf{Distribution shift boundaries} (Section~\\ref{sec:failure_modes}): three shifts define operating boundaries; near-OOD is adversarial ($-$12\\,pp), far-OOD neutral ($p{=}0.46$).\n\\end{enumerate}\n",
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

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_01MQwUT6U4ma3itMfdGy17Xm`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "a3ff1893-3cda-4636-9bff-a5a6f2d3ba85",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 24 · 2026-05-21T16:46:09.226Z_

<details><summary>↩ Tool result · `toolu_01MQwUT6U4ma3itMfdGy17Xm`</summary>

```text
1	
2	\section{Experiments}
3	\label{sec:experiments}
4	
5	\looseness=-1 We evaluate the pipeline on two LIBERO task suites~\cite{liu2023libero}, asking: (i)~can a cheap uncertainty probe enable adaptive compute allocation? (ii)~what is the relative contribution of selection vs.\ correction? (iii)~how does conditioning interact with magnitude? (iv)~where does the pipeline fail?
6	
7	\subsection{Setup}
8	\label{sec:exp_setup}
9	
10	\paragraph{Benchmarks and base VLA.}
11	We use LIBERO-Object (10 tasks, novel object instances) and LIBERO-Spatial (10 tasks, spatial reasoning). Each task is evaluated over 10 rollouts (max 300 steps); success is binary.
12	We build on SmolVLA~\cite{shukor2025smolvla} (450M parameters, flow matching), using dual-camera RGB ($256{\times}256$) and 8D proprioceptive state. Actions are 7D (6D pose + 1D gripper); the gripper is thresholded outside the pipeline.
13	
14	\paragraph{Baselines.}
15	All use the same frozen SmolVLA: \textbf{VLA-only} ($K{=}1$, no correction), \textbf{Random} ($K{=}5{/}10$, uniform sample, no CRM), and \textbf{Argmin} ($K{=}5{/}10$, $L_2$ selection, no CRM).
16	
17	\paragraph{Training and statistics.}
18	CRM is trained on 26{,}737 samples (10 demos $\times$ 20 tasks, $K{=}10$ forward passes each), Adam $\mathrm{lr}{=}10^{-3}$, batch 32, 50 epochs, $\varepsilon{=}0.2$. All evaluation tasks are covered by CRM training data (in-distribution).
19	We report seed-level Mann-Whitney U tests (two-sided); 3--7 seeds per condition, none discarded.
20	
21	\subsection{Adaptive Inference-Time Compute}
22	\label{sec:adaptive_k}
23	
24	The key question is whether compute can be allocated adaptively per step rather than using a fixed $K$ for all steps. We validate the $K{=}2$ $L_2$ probe (Section~\ref{sec:adaptive_k_method}) and evaluate threshold-based adaptive allocation.
25	
26	\paragraph{Uncertainty signal validation.}
27	The pairwise $L_2$ distance from $K{=}2$ samples correlates near-perfectly with the full $K{=}10$ sample variance ($\rho{=}0.9979$, Spearman; Figure~\ref{fig:k2_correlation}). Three alternative signals fail: flow-matching velocity divergence (FMVD, $\rho{=}0.08$), CRM correction magnitude at $K{=}1$ ($\rho{=}0.15$), and CRM correction magnitude at $K{=}2$ ($\rho{=}0.13$). The $K{=}2$ $L_2$ distance is the only viable per-step uncertainty proxy among the four candidates tested.
28	
29	\begin{figure}[t]
30	\centering
31	\includegraphics[width=\linewidth]{figures/fig5_k2_correlation.pdf}
32	\caption{Per-step uncertainty signals vs.\ $K{=}10$ sample variance. (a)~$K{=}2$ $L_2$ pairwise distance achieves $\rho{=}0.9979$, validating it as a near-perfect proxy. (b)~FMVD ($\rho{=}0.08$) shows no correlation, confirming that ODE-space signals do not predict action-space variance.}
33	\label{fig:k2_correlation}
34	\end{figure}
35	
36	\paragraph{Threshold sweep (variable-$K$ protocol).}
37	To validate the $K{=}2$ probe as an uncertainty signal independently of Plan~A, we test a variable-$K$ protocol that expands to $K{=}10$ on high-uncertainty steps (details in Appendix~\ref{sec:spatial_adaptive}).
38	\looseness=-1 Table~\ref{tab:adaptive} reports performance on LIBERO-Object. Among variable-$K$ thresholds, P50 achieves the best trade-off (91\% of $K{=}10$ SR at 38\% compute). However, Plan~A ($K{=}2$ selective CRM) Pareto-dominates all thresholds: $18.3$\% at avg\_$K{=}2$, exceeding fixed $K{=}10$ ($16.8$\%) with 80\% fewer VLA forward passes. The sweep confirms the $K{=}2$ signal is effective, but selective CRM is its optimal utilization.
39	\looseness=-1 The optimal threshold shifts with task difficulty: on Spatial (easier), P90 reaches 33.0\% at avg\_$K{=}3.55$ while P25 drops to 31.7\%; on Object (harder) P50 is the sweet spot (Appendix~\ref{sec:spatial_adaptive}).
40	
41	\begin{table}[t]
42	\centering
43	\caption{Adaptive $K$ threshold sweep and Plan~A on LIBERO-Object ($n{=}3$ seeds unless noted). Thresholds $\tau$ on training-set $L_2$ distance: P90${=}$0.127, P75${=}$0.099, P50${=}$0.075, P25${=}$0.055. Plan~A Pareto-dominates all variable-$K$ thresholds. $^\ddagger$\,Seed set differs from Table~\ref{tab:main} ($11.0$\%, $n{=}8$). $^\S$\,$n{=}6$. $^\|$\,$n{=}8$.}
44	\label{tab:adaptive}
45	\small
46	\begin{tabular}{lcccc}
47	\toprule
48	$\tau$ & SR (\%) & avg\_$K$ & fast path (\%) & SR/SR$_{K{=}10}$ \\
49	\midrule
50	\textbf{Plan~A (ours)} & $\mathbf{18.3 \pm 2.1}$ & \textbf{2.0} & \textbf{16.3} & \textbf{109\%} \\
51	\midrule
52	P90 & $13.3 \pm 1.2$ & 2.62 & 92.2 & 79\% \\
53	P75 & $13.7 \pm 2.1$ & 3.08 & 86.5 & 82\% \\
54	P50 & $15.3 \pm 1.2$ & 3.81 & 77.3 & 91\% \\
55	P25 & $14.3 \pm 1.2$ & 4.79 & 65.1 & 85\% \\
56	\midrule
57	Fixed $K{=}10^\S$ & $16.8 \pm 1.8$ & 10.0 & 0 & 100\% \\
58	VLA-only$^{\ddagger\|}$ & $10.9 \pm 1.4$ & 1.0 & --- & 65\% \\
59	\bottomrule
60	\end{tabular}
61	\end{table}
62	
63	\subsection{Main Results and Component Decomposition}
64	\label{sec:main_results}
65	
66	Table~\ref{tab:main} compares Plan~A (Section~\ref{sec:adaptive_k_method}) with analysis baselines that isolate the contribution of selection and correction at fixed $K$.
67	
68	\paragraph{Plan~A: selective correction at $K{=}2$.}
69	\looseness=-1 The proposed pipeline achieves $18.3 \pm 2.1$\% on Object (3 seeds) and $35.0 \pm 1.0$\% on Spatial, exceeding CRM $K{=}10$ ($16.8$\%, $34.4$\%) with 80\% fewer VLA forward passes and matching CRM $K{=}20$ ($18.8$\%, $34.3$\%) at 90\% fewer (Appendix~\ref{sec:k_scaling}). The CRM trigger rate is task-dependent: 83.7\% on Object (16.3\% fast-path steps) and 97.6\% on Spatial, where correction is almost universally beneficial. Selective application outperforms unconditional correction at $K{=}10$, consistent with over-triggering degrading performance (P25 $<$ P50, Table~\ref{tab:adaptive}). With $K{=}2$, the centroid has lower variance than at $K{=}10$, providing a cleaner starting point for bounded correction.
70	
71	\begin{table}[t]
72	\centering
73	\caption{Task success rate (\%\,$\uparrow$) on LIBERO-Object and LIBERO-Spatial. Mean $\pm$ std; $n$: Object seeds. Spatial $n$: 5 (VLA-only), 4 ($K{=}5$), 3 (Random $K{=}10$, CRM $K{=}10$, Plan~A). $\Delta$: vs.\ VLA-only. Top: proposed method (Section~\ref{sec:adaptive_k_method}); middle/bottom: analysis baselines.}
74	\label{tab:main}
75	\small
76	\begin{tabular}{lccccc}
77	\toprule
78	Method & $K$ & Object (\%) & $n$ & Spatial (\%) & $\Delta$ Obj \\
79	\midrule
80	\textbf{Plan~A (ours)} & \textbf{2} & $\mathbf{18.3 \pm 2.1}$ & \textbf{3} & $\mathbf{35.0 \pm 1.0}$ & $\mathbf{+7.3}$ \\
81	\midrule
82	VLA-only & 1 & $11.0 \pm 1.3$ & 8 & $29.4 \pm 1.5$ & --- \\
83	Random & 5 & $10.5 \pm 2.9$ & 4 & --- & $-0.5$ \\
84	Argmin & 5 & $13.0 \pm 1.6$ & 4 & --- & $+2.0$ \\
85	CRM obs\_only & 5 & $16.0 \pm 2.2$ & 7 & $34.5 \pm 2.1$ & $+5.0$ \\
86	\midrule
87	Random & 10 & $9.7 \pm 1.5$ & 6 & $29.3 \pm 4.2$ & $-1.3$ \\
88	Argmin & 10 & $12.3 \pm 2.6$ & 6 & --- & $+1.3$ \\
89	CRM obs\_only & 10 & $16.8 \pm 1.8$ & 6 & $34.4 \pm 1.5$ & $+5.8$ \\
90	\midrule
91	CRM perdof & 10 & $11.0 \pm 1.8$ & 6 & --- & $\phantom{+}0.0$ \\
92	CRM scalar & 10 & $\phantom{0}8.5 \pm 1.5$ & 4 & --- & $-2.5$ \\
93	\bottomrule
94	\end{tabular}
95	\end{table}
96	
97	\paragraph{Component decomposition (fixed-$K$ analysis).}
98	\looseness=-2 The remaining rows of Table~\ref{tab:main} are analysis baselines at fixed $K$, not proposed methods. CRM obs\_only at $K{=}10$ reaches $16.8 \pm 1.8$\% on Object ($p{=}0.003$) and $34.4 \pm 1.5$\% on Spatial. Random selection fails to exceed VLA-only on either benchmark (Object $9.7$\% vs.\ $11.0$\%; Spatial $29.3$\% vs.\ $29.4$\%), confirming that sampling more actions without ranking is insufficient; argmin adds $+$1.3\,pp, and CRM correction contributes $+$4.5\,pp (78\% of the gain). At $K{=}5$, correction contributes 55\%. At $K{=}1$, correction without centering falls below baseline ($10.3$\%), validating the $K{\geq}2$ requirement.
99	
100	\vspace{-2pt}
101	\subsection{Conditioning, Magnitude, and Distribution Shift}
102	\label{sec:magnitude_results}
103	\label{sec:failure_modes}
104	
105	\looseness=-2 The CRM conditioning interacts with $\varepsilon$ (Appendix~\ref{sec:magnitude_appendix}): obs\_only is stable (12.5--16.8\%); perdof collapses (${\sim}$14\% $\to$ 0\%) because $K{=}10$ in $d{=}7$ yields effectively low-rank covariance and large $\varepsilon$ amplifies noisy per-DOF estimates; scalar (8.5\%) falls below VLA-only. Three distribution shifts define further boundaries: (1)~input ($K{=}1$, 10.3\%); (2)~task (near-OOD $-$12\,pp, far-OOD neutral $p{=}0.46$); (3)~feature (perdof $\to$ 0\%). All share a mechanism: CRM degrades when inputs depart from training distribution (Appendix~\ref{sec:per_task}). Plan~A runs 1.82$\times$ faster than $K{=}10$ with 0.28\,ms CRM overhead (Appendix~\ref{sec:latency}).
106	
107	We further validate cross-VLA generalization on $\pi_{0.5}$ (3.6B)~\cite{black2024pi0}; see Appendix~\ref{sec:cross_vla}.
108	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "fcfde1fc-9c09-4dc0-bd42-722d7063f675",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/experiments.tex",
      "content": "\n\\section{Experiments}\n\\label{sec:experiments}\n\n\\looseness=-1 We evaluate the pipeline on two LIBERO task suites~\\cite{liu2023libero}, asking: (i)~can a cheap uncertainty probe enable adaptive compute allocation? (ii)~what is the relative contribution of selection vs.\\ correction? (iii)~how does conditioning interact with magnitude? (iv)~where does the pipeline fail?\n\n\\subsection{Setup}\n\\label{sec:exp_setup}\n\n\\paragraph{Benchmarks and base VLA.}\nWe use LIBERO-Object (10 tasks, novel object instances) and LIBERO-Spatial (10 tasks, spatial reasoning). Each task is evaluated over 10 rollouts (max 300 steps); success is binary.\nWe build on SmolVLA~\\cite{shukor2025smolvla} (450M parameters, flow matching), using dual-camera RGB ($256{\\times}256$) and 8D proprioceptive state. Actions are 7D (6D pose + 1D gripper); the gripper is thresholded outside the pipeline.\n\n\\paragraph{Baselines.}\nAll use the same frozen SmolVLA: \\textbf{VLA-only} ($K{=}1$, no correction), \\textbf{Random} ($K{=}5{/}10$, uniform sample, no CRM), and \\textbf{Argmin} ($K{=}5{/}10$, $L_2$ selection, no CRM).\n\n\\paragraph{Training and statistics.}\nCRM is trained on 26{,}737 samples (10 demos $\\times$ 20 tasks, $K{=}10$ forward passes each), Adam $\\mathrm{lr}{=}10^{-3}$, batch 32, 50 epochs, $\\varepsilon{=}0.2$. All evaluation tasks are covered by CRM training data (in-distribution).\nWe report seed-level Mann-Whitney U tests (two-sided); 3--7 seeds per condition, none discarded.\n\n\\subsection{Adaptive Inference-Time Compute}\n\\label{sec:adaptive_k}\n\nThe key question is whether compute can be allocated adaptively per step rather than using a fixed $K$ for all steps. We validate the $K{=}2$ $L_2$ probe (Section~\\ref{sec:adaptive_k_method}) and evaluate threshold-based adaptive allocation.\n\n\\paragraph{Uncertainty signal validation.}\nThe pairwise $L_2$ distance from $K{=}2$ samples correlates near-perfectly with the full $K{=}10$ sample variance ($\\rho{=}0.9979$, Spearman; Figure~\\ref{fig:k2_correlation}). Three alternative signals fail: flow-matching velocity divergence (FMVD, $\\rho{=}0.08$), CRM correction magnitude at $K{=}1$ ($\\rho{=}0.15$), and CRM correction magnitude at $K{=}2$ ($\\rho{=}0.13$). The $K{=}2$ $L_2$ distance is the only viable per-step uncertainty proxy among the four candidates tested.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/fig5_k2_correlation.pdf}\n\\caption{Per-step uncertainty signals vs.\\ $K{=}10$ sample variance. (a)~$K{=}2$ $L_2$ pairwise distance achieves $\\rho{=}0.9979$, validating it as a near-perfect proxy. (b)~FMVD ($\\rho{=}0.08$) shows no correlation, confirming that ODE-space signals do not predict action-space variance.}\n\\label{fig:k2_correlation}\n\\end{figure}\n\n\\paragraph{Threshold sweep (variable-$K$ protocol).}\nTo validate the $K{=}2$ probe as an uncertainty signal independently of Plan~A, we test a variable-$K$ protocol that expands to $K{=}10$ on high-uncertainty steps (details in Appendix~\\ref{sec:spatial_adaptive}).\n\\looseness=-1 Table~\\ref{tab:adaptive} reports performance on LIBERO-Object. Among variable-$K$ thresholds, P50 achieves the best trade-off (91\\% of $K{=}10$ SR at 38\\% compute). However, Plan~A ($K{=}2$ selective CRM) Pareto-dominates all thresholds: $18.3$\\% at avg\\_$K{=}2$, exceeding fixed $K{=}10$ ($16.8$\\%) with 80\\% fewer VLA forward passes. The sweep confirms the $K{=}2$ signal is effective, but selective CRM is its optimal utilization.\n\\looseness=-1 The optimal threshold shifts with task difficulty: on Spatial (easier), P90 reaches 33.0\\% at avg\\_$K{=}3.55$ while P25 drops to 31.7\\%; on Object (harder) P50 is the sweet spot (Appendix~\\ref{sec:spatial_adaptive}).\n\n\\begin{table}[t]\n\\centering\n\\caption{Adaptive $K$ threshold sweep and Plan~A on LIBERO-Object ($n{=}3$ seeds unless noted). Thresholds $\\tau$ on training-set $L_2$ distance: P90${=}$0.127, P75${=}$0.099, P50${=}$0.075, P25${=}$0.055. Plan~A Pareto-dominates all variable-$K$ thresholds. $^\\ddagger$\\,Seed set differs from Table~\\ref{tab:main} ($11.0$\\%, $n{=}8$). $^\\S$\\,$n{=}6$. $^\\|$\\,$n{=}8$.}\n\\label{tab:adaptive}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n$\\tau$ & SR (\\%) & avg\\_$K$ & fast path (\\%) & SR/SR$_{K{=}10}$ \\\\\n\\midrule\n\\textbf{Plan~A (ours)} & $\\mathbf{18.3 \\pm 2.1}$ & \\textbf{2.0} & \\textbf{16.3} & \\textbf{109\\%} \\\\\n\\midrule\nP90 & $13.3 \\pm 1.2$ & 2.62 & 92.2 & 79\\% \\\\\nP75 & $13.7 \\pm 2.1$ & 3.08 & 86.5 & 82\\% \\\\\nP50 & $15.3 \\pm 1.2$ & 3.81 & 77.3 & 91\\% \\\\\nP25 & $14.3 \\pm 1.2$ & 4.79 & 65.1 & 85\\% \\\\\n\\midrule\nFixed $K{=}10^\\S$ & $16.8 \\pm 1.8$ & 10.0 & 0 & 100\\% \\\\\nVLA-only$^{\\ddagger\\|}$ & $10.9 \\pm 1.4$ & 1.0 & --- & 65\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Main Results and Component Decomposition}\n\\label{sec:main_results}\n\nTable~\\ref{tab:main} compares Plan~A (Section~\\ref{sec:adaptive_k_method}) with analysis baselines that isolate the contribution of selection and correction at fixed $K$.\n\n\\paragraph{Plan~A: selective correction at $K{=}2$.}\n\\looseness=-1 The proposed pipeline achieves $18.3 \\pm 2.1$\\% on Object (3 seeds) and $35.0 \\pm 1.0$\\% on Spatial, exceeding CRM $K{=}10$ ($16.8$\\%, $34.4$\\%) with 80\\% fewer VLA forward passes and matching CRM $K{=}20$ ($18.8$\\%, $34.3$\\%) at 90\\% fewer (Appendix~\\ref{sec:k_scaling}). The CRM trigger rate is task-dependent: 83.7\\% on Object (16.3\\% fast-path steps) and 97.6\\% on Spatial, where correction is almost universally beneficial. Selective application outperforms unconditional correction at $K{=}10$, consistent with over-triggering degrading performance (P25 $<$ P50, Table~\\ref{tab:adaptive}). With $K{=}2$, the centroid has lower variance than at $K{=}10$, providing a cleaner starting point for bounded correction.\n\n\\begin{table}[t]\n\\centering\n\\caption{Task success rate (\\%\\,$\\uparrow$) on LIBERO-Object and LIBERO-Spatial. Mean $\\pm$ std; $n$: Object seeds. Spatial $n$: 5 (VLA-only), 4 ($K{=}5$), 3 (Random $K{=}10$, CRM $K{=}10$, Plan~A). $\\Delta$: vs.\\ VLA-only. Top: proposed method (Section~\\ref{sec:adaptive_k_method}); middle/bottom: analysis baselines.}\n\\label{tab:main}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & $K$ & Object (\\%) & $n$ & Spatial (\\%) & $\\Delta$ Obj \\\\\n\\midrule\n\\textbf{Plan~A (ours)} & \\textbf{2} & $\\mathbf{18.3 \\pm 2.1}$ & \\textbf{3} & $\\mathbf{35.0 \\pm 1.0}$ & $\\mathbf{+7.3}$ \\\\\n\\midrule\nVLA-only & 1 & $11.0 \\pm 1.3$ & 8 & $29.4 \\pm 1.5$ & --- \\\\\nRandom & 5 & $10.5 \\pm 2.9$ & 4 & --- & $-0.5$ \\\\\nArgmin & 5 & $13.0 \\pm 1.6$ & 4 & --- & $+2.0$ \\\\\nCRM obs\\_only & 5 & $16.0 \\pm 2.2$ & 7 & $34.5 \\pm 2.1$ & $+5.0$ \\\\\n\\midrule\nRandom & 10 & $9.7 \\pm 1.5$ & 6 & $29.3 \\pm 4.2$ & $-1.3$ \\\\\nArgmin & 10 & $12.3 \\pm 2.6$ & 6 & --- & $+1.3$ \\\\\nCRM obs\\_only & 10 & $16.8 \\pm 1.8$ & 6 & $34.4 \\pm 1.5$ & $+5.8$ \\\\\n\\midrule\nCRM perdof & 10 & $11.0 \\pm 1.8$ & 6 & --- & $\\phantom{+}0.0$ \\\\\nCRM scalar & 10 & $\\phantom{0}8.5 \\pm 1.5$ & 4 & --- & $-2.5$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Component decomposition (fixed-$K$ analysis).}\n\\looseness=-2 The remaining rows of Table~\\ref{tab:main} are analysis baselines at fixed $K$, not proposed methods. CRM obs\\_only at $K{=}10$ reaches $16.8 \\pm 1.8$\\% on Object ($p{=}0.003$) and $34.4 \\pm 1.5$\\% on Spatial. Random selection fails to exceed VLA-only on either benchmark (Object $9.7$\\% vs.\\ $11.0$\\%; Spatial $29.3$\\% vs.\\ $29.4$\\%), confirming that sampling more actions without ranking is insufficient; argmin adds $+$1.3\\,pp, and CRM correction contributes $+$4.5\\,pp (78\\% of the gain). At $K{=}5$, correction contributes 55\\%. At $K{=}1$, correction without centering falls below baseline ($10.3$\\%), validating the $K{\\geq}2$ requirement.\n\n\\vspace{-2pt}\n\\subsection{Conditioning, Magnitude, and Distribution Shift}\n\\label{sec:magnitude_results}\n\\label{sec:failure_modes}\n\n\\looseness=-2 The CRM conditioning interacts with $\\varepsilon$ (Appendix~\\ref{sec:magnitude_appendix}): obs\\_only is stable (12.5--16.8\\%); perdof collapses (${\\sim}$14\\% $\\to$ 0\\%) because $K{=}10$ in $d{=}7$ yields effectively low-rank covariance and large $\\varepsilon$ amplifies noisy per-DOF estimates; scalar (8.5\\%) falls below VLA-only. Three distribution shifts define further boundaries: (1)~input ($K{=}1$, 10.3\\%); (2)~task (near-OOD $-$12\\,pp, far-OOD neutral $p{=}0.46$); (3)~feature (perdof $\\to$ 0\\%). All share a mechanism: CRM degrades when inputs depart from training distribution (Appendix~\\ref{sec:per_task}). Plan~A runs 1.82$\\times$ faster than $K{=}10$ with 0.28\\,ms CRM overhead (Appendix~\\ref{sec:latency}).\n\nWe further validate cross-VLA generalization on $\\pi_{0.5}$ (3.6B)~\\cite{black2024pi0}; see Appendix~\\ref{sec:cross_vla}.\n",
      "numLines": 108,
      "startLine": 1,
      "totalLines": 108
    }
  }
}
```

</details>

---


### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Read · `toolu_01CPZWZ6u2wLKRbWHn7pnKy1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d7e28cda-ef1f-4841-bae9-1d1cf279b610",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 26 · 2026-05-21T16:46:09.729Z_

<details><summary>↩ Tool result · `toolu_01CPZWZ6u2wLKRbWHn7pnKy1`</summary>

```text
1	
2	\section{Method}
3	\label{sec:method}
4	
5	\begin{figure}[t]
6	  \centering
7	  \includegraphics[width=\linewidth]{fig1_pipeline.pdf}
8	  \caption{Adaptive sample-select-correct pipeline. $K{=}2$ action samples are drawn from the frozen VLA; the argmin-to-centroid sample is selected, and a lightweight CRM applies bounded correction ($\|\boldsymbol{\delta}\|_2 \leq \varepsilon$) only when the pairwise $L_2$ distance exceeds the uncertainty threshold $\tau$.}
9	  \label{fig:pipeline}
10	\end{figure}
11	
12	\looseness=-1 Our method adaptively allocates inference-time compute for a frozen flow-matching VLA (Figure~\ref{fig:pipeline}). At each control step, a $K{=}2$ uncertainty probe determines whether the VLA is confident or uncertain; confident steps output the argmin-to-centroid sample directly, while uncertain steps apply a learned residual correction to the same sample via a lightweight module. The base VLA is never retrained.
13	
14	\subsection{Problem Setup}
15	\label{sec:problem_setup}
16	
17	Let $\pi_\theta$ be a frozen flow-matching VLA that, given an observation $o_t$ (image, language instruction, proprioceptive state), generates action chunks of length $C{=}50$ in $\mathbb{R}^{d \times C}$ with $d{=}6$ (3 translation + 3 rotation). Under receding-horizon execution, only the first $H{=}5$ steps of each chunk influence the robot before re-planning, so we discard the remainder. The gripper dimension is handled separately via direct thresholding and is excluded from the pipeline.
18	
19	\looseness=-1 Each forward pass of $\pi_\theta$ produces a stochastic action sample; querying independently $K$ times yields $K$ candidate chunks. Our goal is to produce a single action more accurate than any individual sample, with no changes to $\pi_\theta$. The method applies to any flow-matching VLA that produces diverse samples (Appendix~\ref{sec:applicability}).
20	
21	\subsection{Multi-Sample Selection}
22	\label{sec:selection}
23	
24	We draw $K$ action chunks from $\pi_\theta$ via independent flow-matching rollouts and truncate each to $H{=}5$ steps, yielding samples $\{a_h^{(k)}\}_{k=1}^K$ with $a_h^{(k)} \in \mathbb{R}^d$ for horizon step $h = 1, \dots, H$. For each step, we compute the sample mean $\boldsymbol{\mu}_h = \frac{1}{K}\sum_{k=1}^K a_h^{(k)}$ and select the sample with the smallest total $L_2$ distance to the mean across all horizon steps:
25	\begin{equation}
26	  a_{\mathrm{base}} = \argmin_{k \in \{1,\dots,K\}} \sum_{h=1}^{H} \bigl\|a_h^{(k)} - \boldsymbol{\mu}_h\bigr\|_2^2.
27	  \label{eq:argmin}
28	\end{equation}
29	Unlike the element-wise mean, which can blend incompatible modes, the argmin returns an actual sample and preserves within-sample temporal coherence.
30	
31	\subsection{Correction Module (CRM)}
32	\label{sec:crm}
33	
34	The CRM is a lightweight MLP that refines the selected action $a_{\mathrm{base}}$ by predicting a bounded residual correction conditioned on the current observation and the selected action itself.
35	
36	\paragraph{Architecture.}
37	\looseness=-1 The CRM consists of three fully connected layers with ReLU activations: $\mathrm{Linear}(n_{\mathrm{in}}, 256) \to \mathrm{ReLU} \to \mathrm{Linear}(256, 256) \to \mathrm{ReLU} \to \mathrm{Linear}(256, 30)$, preceded by input normalization. For the primary obs\_only variant ($n_{\mathrm{in}}{=}990$), the input is the concatenation of the frozen observation embedding $\mathbf{z}_{\mathrm{obs}} \in \mathbb{R}^{960}$ from SmolVLA's vision-language encoder and the selected action $a_{\mathrm{base}} \in \mathbb{R}^{30}$ ($H{=}5$ steps $\times$ $d{=}6$ DOFs), for a total of 327,198 parameters (${\sim}$327K). The output is a residual $\boldsymbol{\delta} \in \mathbb{R}^{30}$, and the corrected action is:
38	\begin{equation}
39	  \mathbf{a}^* = a_{\mathrm{base}} + \mathrm{clip}\bigl(\boldsymbol{\delta},\; \|\boldsymbol{\delta}\|_2 \leq \varepsilon\bigr),
40	  \label{eq:crm}
41	\end{equation}
42	where $\varepsilon$ is a norm bound that limits the correction magnitude (Section~\ref{sec:magnitude}). The CRM never sees individual action candidates: it receives only the already-selected $a_{\mathrm{base}}$ and predicts a correction toward the expert action.
43	
44	\paragraph{Conditioning variants.}
45	We compare three CRM variants that share the same MLP architecture but differ in their input:
46	\begin{itemize}[nosep]
47	  \item \textbf{obs\_only} (primary): $[\mathbf{z}_{\mathrm{obs}};\, a_{\mathrm{base}}] \in \mathbb{R}^{990}$, 327K parameters. No conformal or uncertainty features.
48	  \item \textbf{perdof}: $[\mathbf{z}_{\mathrm{obs}};\, a_{\mathrm{base}};\, \mathbf{u}_{\mathrm{dof}}] \in \mathbb{R}^{1030}$, 337K parameters. $\mathbf{u}_{\mathrm{dof}}$ concatenates per-DOF standard deviations, conformal prediction radii~\cite{angelopoulos2023gentle}, and covariance log-volumes~\cite{ledoit2004well} ($40$D total).
49	  \item \textbf{scalar}: $[\mathbf{z}_{\mathrm{obs}};\, a_{\mathrm{base}};\, u_s] \in \mathbb{R}^{991}$, 327K parameters, where $u_s$ is a single scalar uncertainty summary.
50	\end{itemize}
51	Section~\ref{sec:magnitude_results} shows that conformal features fail to improve closed-loop performance; obs\_only is our primary method.
52	
53	\paragraph{Training.}
54	\looseness=-1 The CRM is trained offline on demonstration trajectories from LIBERO~\cite{liu2023libero} with $L_2$ loss:
55	\begin{equation}
56	  \mathcal{L} = \bigl\|\mathbf{a}^* - \mathbf{a}_{\mathrm{expert}}\bigr\|_2^2,
57	  \label{eq:loss}
58	\end{equation}
59	where $\mathbf{a}_{\mathrm{expert}}$ is the demonstration action. The training set comprises 26{,}737 precomputed samples from 10 demonstrations per task across 20 LIBERO tasks. For each demonstration step, we run $K{=}10$ forward passes through the frozen SmolVLA, apply argmin selection~(\ref{eq:argmin}) to obtain $a_{\mathrm{base}}$, and train the CRM to predict the residual toward $\mathbf{a}_{\mathrm{expert}}$. Data augmentation (Gaussian noise on $a_{\mathrm{base}}$ and uncertainty features) improves generalization to the closed-loop state distribution~\cite{ross2011dagger}.
60	
61	\subsection{Magnitude Control}
62	\label{sec:magnitude}
63	
64	The norm bound $\varepsilon$ in~(\ref{eq:crm}) is critical for stable closed-loop performance. Without clipping, the CRM's natural output norm (${\approx}$1.42) causes compounding errors that destroy task performance (0\% success for the perdof variant). Constraining $\varepsilon$ to $[0.05, 0.2]$ yields stable corrections; we use $\varepsilon{=}0.2$ as the primary setting. Section~\ref{sec:magnitude_results} presents the full sensitivity analysis across conditioning variants and magnitude bounds.
65	
66	\subsection{Adaptive Inference-Time Compute}
67	\label{sec:adaptive_k_method}
68	
69	Two findings from our component analysis motivate an adaptive mechanism: (i)~learned correction is the dominant contributor to task improvement (Section~\ref{sec:main_results}), but (ii)~correction on uncentered inputs ($K{=}1$) degrades below baseline (Section~\ref{sec:failure_modes}). Fixed $K{=}10$ sampling is wasteful---most steps are easy---yet $K{=}1$ correction fails. The solution is a per-step uncertainty probe that decides \emph{when} to invest additional compute.
70	
71	\paragraph{Why $K{=}2$.}
72	\looseness=-1 $K{=}2$ is the minimum sample size that admits a pairwise disagreement measure. This probe is computationally free: under batched inference with shared prefix encoding, $K{=}2$ latency (${\sim}$255\,ms) matches $K{=}1$ (Appendix~\ref{sec:latency}). Empirically, the $K{=}2$ $L_2$ distance achieves $\rho{=}0.9979$ with $K{=}10$ sample variance (Section~\ref{sec:adaptive_k}); three alternative signals all fail ($\rho \leq 0.15$).
73	
74	\paragraph{Three-step adaptive pipeline.}
75	At each control step, the pipeline executes:
76	\begin{enumerate}[nosep,leftmargin=*]
77	  \item \textbf{Uncertainty probe.} Draw $K{=}2$ samples $a^{(1)}, a^{(2)}$ from $\pi_\theta$ in a single batched forward pass. Compute the centroid $\mathbf{c} = (a^{(1)} + a^{(2)})/2$ and the pairwise uncertainty $d_2 = \|a^{(1)} - a^{(2)}\|_2$. Select $\hat{a} = \argmin_{a \in \{a^{(1)}, a^{(2)}\}} \|a - \mathbf{c}\|_2$.
78	  \item \textbf{Adaptive decision.} If $d_2 \leq \tau$ (low uncertainty), output $\hat{a}$ directly---no further computation. If $d_2 > \tau$ (high uncertainty), pass $\hat{a}$ to the CRM for correction.
79	  \item \textbf{Learned correction.} For high-uncertainty steps only, the CRM predicts a bounded residual: $\hat{a}_{\mathrm{out}} = \hat{a} + \boldsymbol{\delta}$, where $\boldsymbol{\delta} = \mathrm{CRM}(o_t, \hat{a})$ and $\|\boldsymbol{\delta}\|_2 \leq \varepsilon$~(\ref{eq:crm}). The pipeline uses at most $K{=}2$ forward passes; performance gains come from learned correction, not brute-force sampling.
80	\end{enumerate}
81	\looseness=-1 The threshold $\tau$ is a percentile of the empirical $d_2$ distribution from CRM training data. Higher $\tau$ triggers correction on fewer steps; the optimal percentile is task-difficulty-dependent (Section~\ref{sec:adaptive_k}). CRM inference adds ${\sim}$0.3\,ms; the VLA forward pass (${\sim}$255\,ms) dominates latency.
82	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "58d07601-6d63-4f64-b7a6-2c6ab3ac5669",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/method.tex",
      "content": "\n\\section{Method}\n\\label{sec:method}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\linewidth]{fig1_pipeline.pdf}\n  \\caption{Adaptive sample-select-correct pipeline. $K{=}2$ action samples are drawn from the frozen VLA; the argmin-to-centroid sample is selected, and a lightweight CRM applies bounded correction ($\\|\\boldsymbol{\\delta}\\|_2 \\leq \\varepsilon$) only when the pairwise $L_2$ distance exceeds the uncertainty threshold $\\tau$.}\n  \\label{fig:pipeline}\n\\end{figure}\n\n\\looseness=-1 Our method adaptively allocates inference-time compute for a frozen flow-matching VLA (Figure~\\ref{fig:pipeline}). At each control step, a $K{=}2$ uncertainty probe determines whether the VLA is confident or uncertain; confident steps output the argmin-to-centroid sample directly, while uncertain steps apply a learned residual correction to the same sample via a lightweight module. The base VLA is never retrained.\n\n\\subsection{Problem Setup}\n\\label{sec:problem_setup}\n\nLet $\\pi_\\theta$ be a frozen flow-matching VLA that, given an observation $o_t$ (image, language instruction, proprioceptive state), generates action chunks of length $C{=}50$ in $\\mathbb{R}^{d \\times C}$ with $d{=}6$ (3 translation + 3 rotation). Under receding-horizon execution, only the first $H{=}5$ steps of each chunk influence the robot before re-planning, so we discard the remainder. The gripper dimension is handled separately via direct thresholding and is excluded from the pipeline.\n\n\\looseness=-1 Each forward pass of $\\pi_\\theta$ produces a stochastic action sample; querying independently $K$ times yields $K$ candidate chunks. Our goal is to produce a single action more accurate than any individual sample, with no changes to $\\pi_\\theta$. The method applies to any flow-matching VLA that produces diverse samples (Appendix~\\ref{sec:applicability}).\n\n\\subsection{Multi-Sample Selection}\n\\label{sec:selection}\n\nWe draw $K$ action chunks from $\\pi_\\theta$ via independent flow-matching rollouts and truncate each to $H{=}5$ steps, yielding samples $\\{a_h^{(k)}\\}_{k=1}^K$ with $a_h^{(k)} \\in \\mathbb{R}^d$ for horizon step $h = 1, \\dots, H$. For each step, we compute the sample mean $\\boldsymbol{\\mu}_h = \\frac{1}{K}\\sum_{k=1}^K a_h^{(k)}$ and select the sample with the smallest total $L_2$ distance to the mean across all horizon steps:\n\\begin{equation}\n  a_{\\mathrm{base}} = \\argmin_{k \\in \\{1,\\dots,K\\}} \\sum_{h=1}^{H} \\bigl\\|a_h^{(k)} - \\boldsymbol{\\mu}_h\\bigr\\|_2^2.\n  \\label{eq:argmin}\n\\end{equation}\nUnlike the element-wise mean, which can blend incompatible modes, the argmin returns an actual sample and preserves within-sample temporal coherence.\n\n\\subsection{Correction Module (CRM)}\n\\label{sec:crm}\n\nThe CRM is a lightweight MLP that refines the selected action $a_{\\mathrm{base}}$ by predicting a bounded residual correction conditioned on the current observation and the selected action itself.\n\n\\paragraph{Architecture.}\n\\looseness=-1 The CRM consists of three fully connected layers with ReLU activations: $\\mathrm{Linear}(n_{\\mathrm{in}}, 256) \\to \\mathrm{ReLU} \\to \\mathrm{Linear}(256, 256) \\to \\mathrm{ReLU} \\to \\mathrm{Linear}(256, 30)$, preceded by input normalization. For the primary obs\\_only variant ($n_{\\mathrm{in}}{=}990$), the input is the concatenation of the frozen observation embedding $\\mathbf{z}_{\\mathrm{obs}} \\in \\mathbb{R}^{960}$ from SmolVLA's vision-language encoder and the selected action $a_{\\mathrm{base}} \\in \\mathbb{R}^{30}$ ($H{=}5$ steps $\\times$ $d{=}6$ DOFs), for a total of 327,198 parameters (${\\sim}$327K). The output is a residual $\\boldsymbol{\\delta} \\in \\mathbb{R}^{30}$, and the corrected action is:\n\\begin{equation}\n  \\mathbf{a}^* = a_{\\mathrm{base}} + \\mathrm{clip}\\bigl(\\boldsymbol{\\delta},\\; \\|\\boldsymbol{\\delta}\\|_2 \\leq \\varepsilon\\bigr),\n  \\label{eq:crm}\n\\end{equation}\nwhere $\\varepsilon$ is a norm bound that limits the correction magnitude (Section~\\ref{sec:magnitude}). The CRM never sees individual action candidates: it receives only the already-selected $a_{\\mathrm{base}}$ and predicts a correction toward the expert action.\n\n\\paragraph{Conditioning variants.}\nWe compare three CRM variants that share the same MLP architecture but differ in their input:\n\\begin{itemize}[nosep]\n  \\item \\textbf{obs\\_only} (primary): $[\\mathbf{z}_{\\mathrm{obs}};\\, a_{\\mathrm{base}}] \\in \\mathbb{R}^{990}$, 327K parameters. No conformal or uncertainty features.\n  \\item \\textbf{perdof}: $[\\mathbf{z}_{\\mathrm{obs}};\\, a_{\\mathrm{base}};\\, \\mathbf{u}_{\\mathrm{dof}}] \\in \\mathbb{R}^{1030}$, 337K parameters. $\\mathbf{u}_{\\mathrm{dof}}$ concatenates per-DOF standard deviations, conformal prediction radii~\\cite{angelopoulos2023gentle}, and covariance log-volumes~\\cite{ledoit2004well} ($40$D total).\n  \\item \\textbf{scalar}: $[\\mathbf{z}_{\\mathrm{obs}};\\, a_{\\mathrm{base}};\\, u_s] \\in \\mathbb{R}^{991}$, 327K parameters, where $u_s$ is a single scalar uncertainty summary.\n\\end{itemize}\nSection~\\ref{sec:magnitude_results} shows that conformal features fail to improve closed-loop performance; obs\\_only is our primary method.\n\n\\paragraph{Training.}\n\\looseness=-1 The CRM is trained offline on demonstration trajectories from LIBERO~\\cite{liu2023libero} with $L_2$ loss:\n\\begin{equation}\n  \\mathcal{L} = \\bigl\\|\\mathbf{a}^* - \\mathbf{a}_{\\mathrm{expert}}\\bigr\\|_2^2,\n  \\label{eq:loss}\n\\end{equation}\nwhere $\\mathbf{a}_{\\mathrm{expert}}$ is the demonstration action. The training set comprises 26{,}737 precomputed samples from 10 demonstrations per task across 20 LIBERO tasks. For each demonstration step, we run $K{=}10$ forward passes through the frozen SmolVLA, apply argmin selection~(\\ref{eq:argmin}) to obtain $a_{\\mathrm{base}}$, and train the CRM to predict the residual toward $\\mathbf{a}_{\\mathrm{expert}}$. Data augmentation (Gaussian noise on $a_{\\mathrm{base}}$ and uncertainty features) improves generalization to the closed-loop state distribution~\\cite{ross2011dagger}.\n\n\\subsection{Magnitude Control}\n\\label{sec:magnitude}\n\nThe norm bound $\\varepsilon$ in~(\\ref{eq:crm}) is critical for stable closed-loop performance. Without clipping, the CRM's natural output norm (${\\approx}$1.42) causes compounding errors that destroy task performance (0\\% success for the perdof variant). Constraining $\\varepsilon$ to $[0.05, 0.2]$ yields stable corrections; we use $\\varepsilon{=}0.2$ as the primary setting. Section~\\ref{sec:magnitude_results} presents the full sensitivity analysis across conditioning variants and magnitude bounds.\n\n\\subsection{Adaptive Inference-Time Compute}\n\\label{sec:adaptive_k_method}\n\nTwo findings from our component analysis motivate an adaptive mechanism: (i)~learned correction is the dominant contributor to task improvement (Section~\\ref{sec:main_results}), but (ii)~correction on uncentered inputs ($K{=}1$) degrades below baseline (Section~\\ref{sec:failure_modes}). Fixed $K{=}10$ sampling is wasteful---most steps are easy---yet $K{=}1$ correction fails. The solution is a per-step uncertainty probe that decides \\emph{when} to invest additional compute.\n\n\\paragraph{Why $K{=}2$.}\n\\looseness=-1 $K{=}2$ is the minimum sample size that admits a pairwise disagreement measure. This probe is computationally free: under batched inference with shared prefix encoding, $K{=}2$ latency (${\\sim}$255\\,ms) matches $K{=}1$ (Appendix~\\ref{sec:latency}). Empirically, the $K{=}2$ $L_2$ distance achieves $\\rho{=}0.9979$ with $K{=}10$ sample variance (Section~\\ref{sec:adaptive_k}); three alternative signals all fail ($\\rho \\leq 0.15$).\n\n\\paragraph{Three-step adaptive pipeline.}\nAt each control step, the pipeline executes:\n\\begin{enumerate}[nosep,leftmargin=*]\n  \\item \\textbf{Uncertainty probe.} Draw $K{=}2$ samples $a^{(1)}, a^{(2)}$ from $\\pi_\\theta$ in a single batched forward pass. Compute the centroid $\\mathbf{c} = (a^{(1)} + a^{(2)})/2$ and the pairwise uncertainty $d_2 = \\|a^{(1)} - a^{(2)}\\|_2$. Select $\\hat{a} = \\argmin_{a \\in \\{a^{(1)}, a^{(2)}\\}} \\|a - \\mathbf{c}\\|_2$.\n  \\item \\textbf{Adaptive decision.} If $d_2 \\leq \\tau$ (low uncertainty), output $\\hat{a}$ directly---no further computation. If $d_2 > \\tau$ (high uncertainty), pass $\\hat{a}$ to the CRM for correction.\n  \\item \\textbf{Learned correction.} For high-uncertainty steps only, the CRM predicts a bounded residual: $\\hat{a}_{\\mathrm{out}} = \\hat{a} + \\boldsymbol{\\delta}$, where $\\boldsymbol{\\delta} = \\mathrm{CRM}(o_t, \\hat{a})$ and $\\|\\boldsymbol{\\delta}\\|_2 \\leq \\varepsilon$~(\\ref{eq:crm}). The pipeline uses at most $K{=}2$ forward passes; performance gains come from learned correction, not brute-force sampling.\n\\end{enumerate}\n\\looseness=-1 The threshold $\\tau$ is a percentile of the empirical $d_2$ distribution from CRM training data. Higher $\\tau$ triggers correction on fewer steps; the optimal percentile is task-difficulty-dependent (Section~\\ref{sec:adaptive_k}). CRM inference adds ${\\sim}$0.3\\,ms; the VLA forward pass (${\\sim}$255\\,ms) dominates latency.\n",
      "numLines": 82,
      "startLine": 1,
      "totalLines": 82
    }
  }
}
```

</details>

---


### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Read · `toolu_019PqQ1NSc6UpaK6m12fWD3h`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "e30b525b-f2d8-4ae1-9586-482211604ddb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 28 · 2026-05-21T16:46:10.655Z_

<details><summary>↩ Tool result · `toolu_019PqQ1NSc6UpaK6m12fWD3h`</summary>

```text
1	
2	\enlargethispage{1\baselineskip}
3	\vspace{-6pt}
4	\section{Conclusion}
5	\label{sec:conclusion}
6	\vspace{-2pt}
7	
8	\looseness=-2 We presented an adaptive inference-time compute pipeline for frozen flow-matching VLAs. The $K{=}2$ $L_2$ probe ($\rho{=}0.9979$) gates selective CRM correction, achieving $18.3$\% Object / $35.0$\% Spatial ($+$7.3 / $+$5.6\,pp vs.\ VLA-only) while matching fixed-$K{=}10$ with 80\% fewer VLA forward passes. On fixed-$K$ baselines, learned correction contributes 55--78\% of the gain.
9	\textbf{Limitations.}\enspace All experiments use LIBERO in simulation with SmolVLA (450M); real-robot transfer and larger VLAs are untested. The CRM requires task-specific calibration ($-$12\,pp on unseen tasks) and stochastic sample diversity, excluding tokenized VLAs (Appendix~\ref{sec:applicability}); generalization to diffusion-based VLAs is open. AI tools assisted with code and manuscript.
10	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "812e15a3-fd06-4045-bb0e-f8bd63a8e3cd",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/discussion.tex",
      "content": "\n\\enlargethispage{1\\baselineskip}\n\\vspace{-6pt}\n\\section{Conclusion}\n\\label{sec:conclusion}\n\\vspace{-2pt}\n\n\\looseness=-2 We presented an adaptive inference-time compute pipeline for frozen flow-matching VLAs. The $K{=}2$ $L_2$ probe ($\\rho{=}0.9979$) gates selective CRM correction, achieving $18.3$\\% Object / $35.0$\\% Spatial ($+$7.3 / $+$5.6\\,pp vs.\\ VLA-only) while matching fixed-$K{=}10$ with 80\\% fewer VLA forward passes. On fixed-$K$ baselines, learned correction contributes 55--78\\% of the gain.\n\\textbf{Limitations.}\\enspace All experiments use LIBERO in simulation with SmolVLA (450M); real-robot transfer and larger VLAs are untested. The CRM requires task-specific calibration ($-$12\\,pp on unseen tasks) and stochastic sample diversity, excluding tokenized VLAs (Appendix~\\ref{sec:applicability}); generalization to diffusion-based VLAs is open. AI tools assisted with code and manuscript.\n",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  }
}
```

</details>

---


### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Read · `toolu_01S3zUWCLy9b8ynvuky7Er61`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "1932f562-1e4b-4bf9-b628-fa8c60298066",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 30 · 2026-05-21T16:46:11.126Z_

<details><summary>↩ Tool result · `toolu_01S3zUWCLy9b8ynvuky7Er61`</summary>

```text
1	
2	\appendix
3	
4	\section{Component Decomposition Figure}
5	\label{sec:decomposition_appendix}
6	
7	\begin{figure}[h]
8	\centering
9	\includegraphics[width=\linewidth]{figures/fig3_decomposition.pdf}
10	\caption{Component decomposition at $K{=}5$ and $K{=}10$ on LIBERO-Object. At both operating points, correction (CRM bar height above argmin) accounts for the majority of the gain. Random selection at $K{=}5$ is harmful (below VLA-only dashed line).}
11	\label{fig:decomposition}
12	\end{figure}
13	
14	\section{Conditioning-Magnitude Dose-Response}
15	\label{sec:magnitude_appendix}
16	
17	\begin{figure}[h]
18	\centering
19	\includegraphics[width=\linewidth]{figures/fig2_magnitude.pdf}
20	\caption{Success rate vs.\ magnitude bound $\varepsilon$ on LIBERO-Object. obs\_only (blue) remains above VLA-only (dashed) across all $\varepsilon$ including uncapped (${\approx}$1.42). perdof (orange) collapses progressively to 0\%. Error bars: $\pm$1 std.}
21	\label{fig:magnitude}
22	\end{figure}
23	
24	\section{Inference-Time Scaling with $K$}
25	\label{sec:k_scaling}
26	
27	Figure~\ref{fig:kvalue} plots task success rate against the number of VLA samples $K$.
28	
29	\begin{figure}[h]
30	\centering
31	\includegraphics[width=\linewidth]{figures/fig3_kvalue.pdf}
32	\caption{Success rate (\%) vs.\ number of VLA samples $K$ on LIBERO-Object (obs\_only, $\varepsilon{=}0.2$). Reference lines: VLA-only ($11.0$\%, 8 seeds) and Argmin-only ($12.3$\%, 6 seeds). Error bars: $\pm$1 std. Note: figure reference lines reflect seed sets used at generation time; Table~\ref{tab:main} reports final aggregated statistics.}
33	\label{fig:kvalue}
34	\end{figure}
35	
36	Table~\ref{tab:k_ablation} reports the full $K$-ablation on both benchmarks.
37	
38	\begin{table}[h]
39	\centering
40	\caption{Success rate (\%) vs.\ number of VLA samples $K$ on LIBERO-Object and LIBERO-Spatial. Plan~A uses $K{=}2$ with selective CRM; all other CRM rows use unconditional correction at fixed $K$. Plan~A matches CRM $K{=}20$ with 90\% fewer VLA forward passes.}
41	\label{tab:k_ablation}
42	\small
43	\begin{tabular}{llcc}
44	\toprule
45	Method & $K$ & Object (\%) & Spatial (\%) \\
46	\midrule
47	VLA-only & 1 & $11.0 \pm 1.3$ & $29.4 \pm 1.5$ \\
48	\textbf{Plan~A (ours)} & \textbf{2} & $\mathbf{18.3 \pm 2.1}$ & $\mathbf{35.0 \pm 1.0}$ \\
49	CRM obs\_only & 5 & $16.0 \pm 2.2$ & $34.5 \pm 2.1$ \\
50	CRM obs\_only & 10 & $16.8 \pm 1.8$ & $34.4 \pm 1.5$ \\
51	CRM obs\_only & 20 & $18.8 \pm 1.0$ & $34.3 \pm 0.6$ \\
52	\bottomrule
53	\end{tabular}
54	\end{table}
55	
56	Performance improves with $K$ but saturates: Object rises from $11.0$\% ($K{=}1$) to $16.0$\% ($K{=}5$, $+$5.0\,pp) to $16.8$\% ($K{=}10$, $+$0.8\,pp) to $18.8$\% ($K{=}20$, $+$2.0\,pp, 4 seeds). On Spatial, CRM at $K{=}5{/}10{/}20$ clusters within 0.2\,pp ($34.3$--$34.5$\%), indicating complete saturation.
57	Plan~A ($K{=}2$) matches CRM $K{=}20$ on Object ($18.3$\% vs.\ $18.8$\%) and exceeds it on Spatial ($35.0$\% vs.\ $34.3$\%), using 90\% fewer VLA forward passes. This confirms that the gains derive from learned correction, not brute-force sampling.
58	At $K{=}1$, CRM correction alone falls below the VLA-only baseline (10.3\% vs.\ $11.0$\%), because the single sample lacks argmin centering and shifts outside the CRM's training distribution. Multi-sample selection is an enabling condition for effective correction.
59	The diminishing-returns pattern is loosely analogous to inference-time compute scaling in LLMs~\cite{snell2024scaling}, though the mechanism differs: in our setting, additional samples improve the starting point for correction rather than enabling better selection.
60	With batched inference (shared KV cache), $K{=}10$ sampling takes ${\sim}$255\,ms, plus $<$\,1\,ms for CRM inference and argmin selection. See Appendix~\ref{sec:latency} for the full timing breakdown.
61	
62	
63	\section{Spatial Adaptive $K$ Threshold Sweep}
64	\label{sec:spatial_adaptive}
65	
66	Table~\ref{tab:adaptive_spatial} reports the adaptive $K$ threshold sweep on LIBERO-Spatial, complementing the Object sweep in Table~\ref{tab:adaptive}.
67	
68	\begin{table}[h]
69	\centering
70	\caption{Adaptive $K$ threshold sweep and Plan~A on LIBERO-Spatial ($n{=}3$ seeds unless noted). Same thresholds $\tau$ as Table~\ref{tab:adaptive}. Plan~A Pareto-dominates all variable-$K$ thresholds: highest SR at lowest avg\_$K$. $^\dagger$\,$n{=}2$ (seed 44 pending).}
71	\label{tab:adaptive_spatial}
72	\small
73	\begin{tabular}{lcccc}
74	\toprule
75	$\tau$ & SR (\%) & avg\_$K$ & fast path (\%) & SR/SR$_{K{=}10}$ \\
76	\midrule
77	\textbf{Plan~A (ours)} & $\mathbf{35.0 \pm 1.0}$ & \textbf{2.0} & \textbf{84} & \textbf{102\%} \\
78	\midrule
79	P90$^\dagger$ & $31.5$ & 3.55 & 80.6 & 92\% \\
80	P75 & $32.7 \pm 1.5$ & 5.02 & 62.1 & 95\% \\
81	P50 & $32.0 \pm 1.7$ & 6.35 & 45.6 & 93\% \\
82	P25 & $31.7 \pm 1.5$ & 7.65 & 29.4 & 92\% \\
83	\midrule
84	Fixed $K{=}10$ & $34.4 \pm 1.5$ & 10.0 & 0 & 100\% \\
85	\bottomrule
86	\end{tabular}
87	\end{table}
88	
89	Plan~A ($K{=}2$ selective CRM) Pareto-dominates all variable-$K$ thresholds on Spatial: $35.0 \pm 1.0$\% at avg\_$K{=}2$ versus the best variable-$K$ threshold P75 at $32.7$\% with avg\_$K{=}5.02$. The variable-$K$ thresholds show a monotonic SR decrease from P90 to P25, contrasting with the non-monotonic Object pattern (P50 $>$ P25 $>$ P75). This confirms that the optimal correction frequency is task-difficulty-dependent and that the uncertainty signal is effective---but its optimal utilization is $K{=}2$ selective CRM rather than variable-$K$ expansion.
90	
91	
92	\section{Applicability Boundary: Stochastic VLA Diversity}
93	\label{sec:applicability}
94	
95	The multi-sample pipeline requires stochastic action diversity across samples. We test this prerequisite by comparing SmolVLA (flow-matching, 450M) with OpenVLA~\cite{kim2024openvla} (autoregressive tokenization, 7B).
96	
97	\begin{figure}[h]
98	\centering
99	\includegraphics[width=\linewidth]{figures/fig4_diversity.pdf}
100	\caption{Per-DOF action variance (log scale) across $K{=}10$ samples for SmolVLA (flow-matching) and OpenVLA (tokenized). OpenVLA produces 8/10 identical samples at temperature $T{=}0.5$, with per-DOF variance below $10^{-30}$ for most dimensions.}
101	\label{fig:diversity}
102	\end{figure}
103	
104	Figure~\ref{fig:diversity} shows the contrast: SmolVLA produces meaningfully diverse samples across all action dimensions, while OpenVLA at temperature $T{=}0.5$ generates 8 out of 10 identical action sequences, with per-DOF variance below $10^{-30}$ for most dimensions.
105	This near-determinism arises from autoregressive token selection: the argmax decoding at each token position collapses the distribution to a single mode, and moderate temperature fails to overcome the peaked distribution.
106	
107	This result establishes an applicability boundary: multi-sample inference-time correction is specific to stochastic generative VLAs (flow-matching, diffusion). Tokenized VLAs lack the action diversity that selection and correction rely on.
108	The boundary is architectural, not a limitation of our method: any inference-time approach that draws multiple action candidates requires the base policy to produce diverse samples.
109	
110	
111	\section{Per-Task Analysis}
112	\label{sec:per_task}
113	
114	Table~\ref{tab:pertask} reports per-task success rates on LIBERO-Object (seed 42) for the VLA-only baseline, Argmin selection, and obs\_only at two magnitude bounds.
115	
116	\begin{table}[h]
117	\centering
118	\caption{Per-task success rate (\%) on LIBERO-Object (seed 42, 10 rollouts per task). Tasks ordered by obs\_only $\varepsilon{=}0.2$ improvement over VLA-only.}
119	\label{tab:pertask}
120	\small
121	\begin{tabular}{lcccc}
122	\toprule
123	Task & VLA-only & Argmin & obs\_only 0.1 & obs\_only 0.2 \\
124	\midrule
125	chocolate\_pudding & 20 & 30 & 50 & \textbf{60} \\
126	ketchup            &  0 &  0 & 10 & \textbf{20} \\
127	bbq\_sauce         & 20 & 30 & \textbf{40} & \textbf{40} \\
128	salad\_dressing    & 20 & 10 & 20 & \textbf{30} \\
129	butter             &  0 & \textbf{10} & \textbf{10} & \textbf{10} \\
130	milk               & 10 & 10 & \textbf{20} & \textbf{20} \\
131	orange\_juice      & \textbf{30} & \textbf{30} & \textbf{30} & \textbf{30} \\
132	tomato\_sauce      & \textbf{10} &  0 &  0 & \textbf{10} \\
133	alphabet\_soup     &  0 &  0 &  0 &  0 \\
134	cream\_cheese      & \textbf{10} &  0 & \textbf{10} &  0 \\
135	\bottomrule
136	\end{tabular}
137	\end{table}
138	
139	Improvement concentrates on medium-difficulty tasks.
140	The largest improvements appear on tasks where the frozen VLA partially succeeds but makes correctable errors: chocolate\_pudding (+40\,pp, from 20\% to 60\%), bbq\_sauce and ketchup (+20\,pp each), and salad\_dressing (+10\,pp).
141	These four tasks account for 9 of the 10 additional successes.
142	Conversely, four tasks (alphabet\_soup, cream\_cheese, tomato\_sauce, butter) remain at 0--10\% across all methods.
143	For these tasks, the base policy fails so completely that local action-level correction cannot recover a viable trajectory.
144	
145	Correction benefits tasks where the frozen VLA partially succeeds but makes correctable errors, rather than tasks where the base policy fails catastrophically or already succeeds reliably.
146	This pattern is expected for a residual correction approach bounded by $\varepsilon$: the CRM can fix small deviations in grasp pose or approach angle, but cannot recover from fundamental planning failures.
147	The concentrated improvement profile also addresses the question of effect size: the aggregate +10\,pp is not a uniform +1\,pp across 10 tasks, but a substantial +20--40\,pp on specific tasks diluted by tasks outside the correctable regime.
148	
149	
150	\section{Latency Breakdown}
151	\label{sec:latency}
152	
153	Table~\ref{tab:latency} reports per-component wall-clock timing under batched inference on a single NVIDIA RTX 4090 (CUDA 12.8, $N{=}1{,}000$ runs).
154	
155	\begin{table}[h]
156	\centering
157	\caption{Per-step latency breakdown (ms, batched inference). CRM inference adds 0.28\,ms ($<$\,0.1\% overhead). Plan~A fast path runs at ${\sim}$4.0\,Hz; full path at ${\sim}$2.2\,Hz.}
158	\label{tab:latency}
159	\small
160	\begin{tabular}{lc}
161	\toprule
162	Component & Mean (ms) \\
163	\midrule
164	VLA E2E $K{=}1$ (batched) & 256.5 \\
165	VLA E2E $K{=}10$ (batched) & 253.2 \\
166	CRM forward & 0.28 \\
167	\midrule
168	Plan~A fast path ($K{=}2$, no CRM) & 252.9 \\
169	Plan~A full path ($K{=}2$ + CRM) & 459.6 \\
170	\midrule
171	Adaptive speedup vs.\ $K{=}10$ & $1.82{\times}$ \\
172	\bottomrule
173	\end{tabular}
174	\end{table}
175	
176	Under batched inference with shared KV cache, $K{=}2$ latency (${\sim}$253\,ms) is comparable to $K{=}1$ (${\sim}$257\,ms) because the flow-matching denoising of both samples runs in parallel. CRM inference adds only 0.28\,ms, making the correction overhead negligible. Plan~A's $K{=}2$ pipeline is 1.82$\times$ faster than the $K{=}10$ analysis baseline while achieving equal or higher success rate, because the 80\% reduction in VLA forward passes far outweighs the CRM overhead ($-$1.66\% net latency vs.\ $K{=}10$).
177	
178	
179	\section{Cross-VLA Generalization}
180	\label{sec:cross_vla}
181	
182	To test whether the pipeline generalizes beyond SmolVLA, we evaluate on $\pi_{0.5}$~\cite{black2024pi0}, a 3.6B-parameter flow-matching VLA built on PaliGemma2 (vision) and Gemma2 (language) with 50-step action chunking. We use the same LIBERO-Object and LIBERO-Spatial benchmarks with identical evaluation protocol (10 rollouts per task, 3 seeds). The CRM architecture is unchanged; only the input projection differs, mapping $\pi_{0.5}$'s 2048-dimensional observation features to the CRM input via a learned linear layer (vs.\ SmolVLA's 960D direct concatenation).
183	
184	\begin{table}[h]
185	\centering
186	\caption{Cross-VLA generalization: $\pi_{0.5}$ (3.6B) on LIBERO. The $\pi_{0.5}$ baseline operates at $81$--$85$\% SR, substantially above SmolVLA's $11$--$29$\%, constraining the headroom for correction. $n{=}3$ seeds.}
187	\label{tab:cross_vla}
188	\small
189	\begin{tabular}{lccc}
190	\toprule
191	Method & $K$ & Object (\%) & Spatial (\%) \\
192	\midrule
193	$\pi_{0.5}$ VLA-only & 1 & $81.5 \pm 0.5$ & $84.2 \pm 1.0$ \\
194	$\pi_{0.5}$ Plan~A & 2 & \placeholder{} & \placeholder{} \\
195	\bottomrule
196	\end{tabular}
197	\end{table}
198	
199	Table~\ref{tab:cross_vla} reports results. The $\pi_{0.5}$ baseline already achieves $81.5 \pm 0.5$\% on Object and $84.2 \pm 1.0$\% on Spatial---substantially above SmolVLA's $11.0$\% / $29.4$\%---leaving limited headroom for post-hoc correction. Plan~A results are pending (\placeholder{}).
200	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "78c7dca1-ee79-4cce-a1d4-e51c23c81f85",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/appendix.tex",
      "content": "\n\\appendix\n\n\\section{Component Decomposition Figure}\n\\label{sec:decomposition_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/fig3_decomposition.pdf}\n\\caption{Component decomposition at $K{=}5$ and $K{=}10$ on LIBERO-Object. At both operating points, correction (CRM bar height above argmin) accounts for the majority of the gain. Random selection at $K{=}5$ is harmful (below VLA-only dashed line).}\n\\label{fig:decomposition}\n\\end{figure}\n\n\\section{Conditioning-Magnitude Dose-Response}\n\\label{sec:magnitude_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/fig2_magnitude.pdf}\n\\caption{Success rate vs.\\ magnitude bound $\\varepsilon$ on LIBERO-Object. obs\\_only (blue) remains above VLA-only (dashed) across all $\\varepsilon$ including uncapped (${\\approx}$1.42). perdof (orange) collapses progressively to 0\\%. Error bars: $\\pm$1 std.}\n\\label{fig:magnitude}\n\\end{figure}\n\n\\section{Inference-Time Scaling with $K$}\n\\label{sec:k_scaling}\n\nFigure~\\ref{fig:kvalue} plots task success rate against the number of VLA samples $K$.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/fig3_kvalue.pdf}\n\\caption{Success rate (\\%) vs.\\ number of VLA samples $K$ on LIBERO-Object (obs\\_only, $\\varepsilon{=}0.2$). Reference lines: VLA-only ($11.0$\\%, 8 seeds) and Argmin-only ($12.3$\\%, 6 seeds). Error bars: $\\pm$1 std. Note: figure reference lines reflect seed sets used at generation time; Table~\\ref{tab:main} reports final aggregated statistics.}\n\\label{fig:kvalue}\n\\end{figure}\n\nTable~\\ref{tab:k_ablation} reports the full $K$-ablation on both benchmarks.\n\n\\begin{table}[h]\n\\centering\n\\caption{Success rate (\\%) vs.\\ number of VLA samples $K$ on LIBERO-Object and LIBERO-Spatial. Plan~A uses $K{=}2$ with selective CRM; all other CRM rows use unconditional correction at fixed $K$. Plan~A matches CRM $K{=}20$ with 90\\% fewer VLA forward passes.}\n\\label{tab:k_ablation}\n\\small\n\\begin{tabular}{llcc}\n\\toprule\nMethod & $K$ & Object (\\%) & Spatial (\\%) \\\\\n\\midrule\nVLA-only & 1 & $11.0 \\pm 1.3$ & $29.4 \\pm 1.5$ \\\\\n\\textbf{Plan~A (ours)} & \\textbf{2} & $\\mathbf{18.3 \\pm 2.1}$ & $\\mathbf{35.0 \\pm 1.0}$ \\\\\nCRM obs\\_only & 5 & $16.0 \\pm 2.2$ & $34.5 \\pm 2.1$ \\\\\nCRM obs\\_only & 10 & $16.8 \\pm 1.8$ & $34.4 \\pm 1.5$ \\\\\nCRM obs\\_only & 20 & $18.8 \\pm 1.0$ & $34.3 \\pm 0.6$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nPerformance improves with $K$ but saturates: Object rises from $11.0$\\% ($K{=}1$) to $16.0$\\% ($K{=}5$, $+$5.0\\,pp) to $16.8$\\% ($K{=}10$, $+$0.8\\,pp) to $18.8$\\% ($K{=}20$, $+$2.0\\,pp, 4 seeds). On Spatial, CRM at $K{=}5{/}10{/}20$ clusters within 0.2\\,pp ($34.3$--$34.5$\\%), indicating complete saturation.\nPlan~A ($K{=}2$) matches CRM $K{=}20$ on Object ($18.3$\\% vs.\\ $18.8$\\%) and exceeds it on Spatial ($35.0$\\% vs.\\ $34.3$\\%), using 90\\% fewer VLA forward passes. This confirms that the gains derive from learned correction, not brute-force sampling.\nAt $K{=}1$, CRM correction alone falls below the VLA-only baseline (10.3\\% vs.\\ $11.0$\\%), because the single sample lacks argmin centering and shifts outside the CRM's training distribution. Multi-sample selection is an enabling condition for effective correction.\nThe diminishing-returns pattern is loosely analogous to inference-time compute scaling in LLMs~\\cite{snell2024scaling}, though the mechanism differs: in our setting, additional samples improve the starting point for correction rather than enabling better selection.\nWith batched inference (shared KV cache), $K{=}10$ sampling takes ${\\sim}$255\\,ms, plus $<$\\,1\\,ms for CRM inference and argmin selection. See Appendix~\\ref{sec:latency} for the full timing breakdown.\n\n\n\\section{Spatial Adaptive $K$ Threshold Sweep}\n\\label{sec:spatial_adaptive}\n\nTable~\\ref{tab:adaptive_spatial} reports the adaptive $K$ threshold sweep on LIBERO-Spatial, complementing the Object sweep in Table~\\ref{tab:adaptive}.\n\n\\begin{table}[h]\n\\centering\n\\caption{Adaptive $K$ threshold sweep and Plan~A on LIBERO-Spatial ($n{=}3$ seeds unless noted). Same thresholds $\\tau$ as Table~\\ref{tab:adaptive}. Plan~A Pareto-dominates all variable-$K$ thresholds: highest SR at lowest avg\\_$K$. $^\\dagger$\\,$n{=}2$ (seed 44 pending).}\n\\label{tab:adaptive_spatial}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n$\\tau$ & SR (\\%) & avg\\_$K$ & fast path (\\%) & SR/SR$_{K{=}10}$ \\\\\n\\midrule\n\\textbf{Plan~A (ours)} & $\\mathbf{35.0 \\pm 1.0}$ & \\textbf{2.0} & \\textbf{84} & \\textbf{102\\%} \\\\\n\\midrule\nP90$^\\dagger$ & $31.5$ & 3.55 & 80.6 & 92\\% \\\\\nP75 & $32.7 \\pm 1.5$ & 5.02 & 62.1 & 95\\% \\\\\nP50 & $32.0 \\pm 1.7$ & 6.35 & 45.6 & 93\\% \\\\\nP25 & $31.7 \\pm 1.5$ & 7.65 & 29.4 & 92\\% \\\\\n\\midrule\nFixed $K{=}10$ & $34.4 \\pm 1.5$ & 10.0 & 0 & 100\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nPlan~A ($K{=}2$ selective CRM) Pareto-dominates all variable-$K$ thresholds on Spatial: $35.0 \\pm 1.0$\\% at avg\\_$K{=}2$ versus the best variable-$K$ threshold P75 at $32.7$\\% with avg\\_$K{=}5.02$. The variable-$K$ thresholds show a monotonic SR decrease from P90 to P25, contrasting with the non-monotonic Object pattern (P50 $>$ P25 $>$ P75). This confirms that the optimal correction frequency is task-difficulty-dependent and that the uncertainty signal is effective---but its optimal utilization is $K{=}2$ selective CRM rather than variable-$K$ expansion.\n\n\n\\section{Applicability Boundary: Stochastic VLA Diversity}\n\\label{sec:applicability}\n\nThe multi-sample pipeline requires stochastic action diversity across samples. We test this prerequisite by comparing SmolVLA (flow-matching, 450M) with OpenVLA~\\cite{kim2024openvla} (autoregressive tokenization, 7B).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/fig4_diversity.pdf}\n\\caption{Per-DOF action variance (log scale) across $K{=}10$ samples for SmolVLA (flow-matching) and OpenVLA (tokenized). OpenVLA produces 8/10 identical samples at temperature $T{=}0.5$, with per-DOF variance below $10^{-30}$ for most dimensions.}\n\\label{fig:diversity}\n\\end{figure}\n\nFigure~\\ref{fig:diversity} shows the contrast: SmolVLA produces meaningfully diverse samples across all action dimensions, while OpenVLA at temperature $T{=}0.5$ generates 8 out of 10 identical action sequences, with per-DOF variance below $10^{-30}$ for most dimensions.\nThis near-determinism arises from autoregressive token selection: the argmax decoding at each token position collapses the distribution to a single mode, and moderate temperature fails to overcome the peaked distribution.\n\nThis result establishes an applicability boundary: multi-sample inference-time correction is specific to stochastic generative VLAs (flow-matching, diffusion). Tokenized VLAs lack the action diversity that selection and correction rely on.\nThe boundary is architectural, not a limitation of our method: any inference-time approach that draws multiple action candidates requires the base policy to produce diverse samples.\n\n\n\\section{Per-Task Analysis}\n\\label{sec:per_task}\n\nTable~\\ref{tab:pertask} reports per-task success rates on LIBERO-Object (seed 42) for the VLA-only baseline, Argmin selection, and obs\\_only at two magnitude bounds.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-task success rate (\\%) on LIBERO-Object (seed 42, 10 rollouts per task). Tasks ordered by obs\\_only $\\varepsilon{=}0.2$ improvement over VLA-only.}\n\\label{tab:pertask}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nTask & VLA-only & Argmin & obs\\_only 0.1 & obs\\_only 0.2 \\\\\n\\midrule\nchocolate\\_pudding & 20 & 30 & 50 & \\textbf{60} \\\\\nketchup            &  0 &  0 & 10 & \\textbf{20} \\\\\nbbq\\_sauce         & 20 & 30 & \\textbf{40} & \\textbf{40} \\\\\nsalad\\_dressing    & 20 & 10 & 20 & \\textbf{30} \\\\\nbutter             &  0 & \\textbf{10} & \\textbf{10} & \\textbf{10} \\\\\nmilk               & 10 & 10 & \\textbf{20} & \\textbf{20} \\\\\norange\\_juice      & \\textbf{30} & \\textbf{30} & \\textbf{30} & \\textbf{30} \\\\\ntomato\\_sauce      & \\textbf{10} &  0 &  0 & \\textbf{10} \\\\\nalphabet\\_soup     &  0 &  0 &  0 &  0 \\\\\ncream\\_cheese      & \\textbf{10} &  0 & \\textbf{10} &  0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nImprovement concentrates on medium-difficulty tasks.\nThe largest improvements appear on tasks where the frozen VLA partially succeeds but makes correctable errors: chocolate\\_pudding (+40\\,pp, from 20\\% to 60\\%), bbq\\_sauce and ketchup (+20\\,pp each), and salad\\_dressing (+10\\,pp).\nThese four tasks account for 9 of the 10 additional successes.\nConversely, four tasks (alphabet\\_soup, cream\\_cheese, tomato\\_sauce, butter) remain at 0--10\\% across all methods.\nFor these tasks, the base policy fails so completely that local action-level correction cannot recover a viable trajectory.\n\nCorrection benefits tasks where the frozen VLA partially succeeds but makes correctable errors, rather than tasks where the base policy fails catastrophically or already succeeds reliably.\nThis pattern is expected for a residual correction approach bounded by $\\varepsilon$: the CRM can fix small deviations in grasp pose or approach angle, but cannot recover from fundamental planning failures.\nThe concentrated improvement profile also addresses the question of effect size: the aggregate +10\\,pp is not a uniform +1\\,pp across 10 tasks, but a substantial +20--40\\,pp on specific tasks diluted by tasks outside the correctable regime.\n\n\n\\section{Latency Breakdown}\n\\label{sec:latency}\n\nTable~\\ref{tab:latency} reports per-component wall-clock timing under batched inference on a single NVIDIA RTX 4090 (CUDA 12.8, $N{=}1{,}000$ runs).\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-step latency breakdown (ms, batched inference). CRM inference adds 0.28\\,ms ($<$\\,0.1\\% overhead). Plan~A fast path runs at ${\\sim}$4.0\\,Hz; full path at ${\\sim}$2.2\\,Hz.}\n\\label{tab:latency}\n\\small\n\\begin{tabular}{lc}\n\\toprule\nComponent & Mean (ms) \\\\\n\\midrule\nVLA E2E $K{=}1$ (batched) & 256.5 \\\\\nVLA E2E $K{=}10$ (batched) & 253.2 \\\\\nCRM forward & 0.28 \\\\\n\\midrule\nPlan~A fast path ($K{=}2$, no CRM) & 252.9 \\\\\nPlan~A full path ($K{=}2$ + CRM) & 459.6 \\\\\n\\midrule\nAdaptive speedup vs.\\ $K{=}10$ & $1.82{\\times}$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nUnder batched inference with shared KV cache, $K{=}2$ latency (${\\sim}$253\\,ms) is comparable to $K{=}1$ (${\\sim}$257\\,ms) because the flow-matching denoising of both samples runs in parallel. CRM inference adds only 0.28\\,ms, making the correction overhead negligible. Plan~A's $K{=}2$ pipeline is 1.82$\\times$ faster than the $K{=}10$ analysis baseline while achieving equal or higher success rate, because the 80\\% reduction in VLA forward passes far outweighs the CRM overhead ($-$1.66\\% net latency vs.\\ $K{=}10$).\n\n\n\\section{Cross-VLA Generalization}\n\\label{sec:cross_vla}\n\nTo test whether the pipeline generalizes beyond SmolVLA, we evaluate on $\\pi_{0.5}$~\\cite{black2024pi0}, a 3.6B-parameter flow-matching VLA built on PaliGemma2 (vision) and Gemma2 (language) with 50-step action chunking. We use the same LIBERO-Object and LIBERO-Spatial benchmarks with identical evaluation protocol (10 rollouts per task, 3 seeds). The CRM architecture is unchanged; only the input projection differs, mapping $\\pi_{0.5}$'s 2048-dimensional observation features to the CRM input via a learned linear layer (vs.\\ SmolVLA's 960D direct concatenation).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-VLA generalization: $\\pi_{0.5}$ (3.6B) on LIBERO. The $\\pi_{0.5}$ baseline operates at $81$--$85$\\% SR, substantially above SmolVLA's $11$--$29$\\%, constraining the headroom for correction. $n{=}3$ seeds.}\n\\label{tab:cross_vla}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nMethod & $K$ & Object (\\%) & Spatial (\\%) \\\\\n\\midrule\n$\\pi_{0.5}$ VLA-only & 1 & $81.5 \\pm 0.5$ & $84.2 \\pm 1.0$ \\\\\n$\\pi_{0.5}$ Plan~A & 2 & \\placeholder{} & \\placeholder{} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:cross_vla} reports results. The $\\pi_{0.5}$ baseline already achieves $81.5 \\pm 0.5$\\% on Object and $84.2 \\pm 1.0$\\% on Spatial---substantially above SmolVLA's $11.0$\\% / $29.4$\\%---leaving limited headroom for post-hoc correction. Plan~A results are pending (\\placeholder{}).\n",
      "numLines": 200,
      "startLine": 1,
      "totalLines": 200
    }
  }
}
```

</details>

---


### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Read · `toolu_01HvtR3Tp7gBokahuK84ge4n`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "98cb36a9-fdf5-47ed-957b-256b0db8f45f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 32 · 2026-05-21T16:46:11.609Z_

<details><summary>↩ Tool result · `toolu_01HvtR3Tp7gBokahuK84ge4n`</summary>

```text
1	\section{Related Work}\label{sec:related_work}
2	
3	\subsection{VLA Robustness}
4	
5	\looseness=-1 Vision-language-action models have progressed from tokenized action prediction~\cite{brohan2023rt2,kim2024openvla,ghosh2024octo} to generative approaches based on diffusion~\cite{chi2023diffusion_policy} and flow matching~\cite{black2024pi0,shukor2025smolvla}. Generative VLAs produce stochastic action samples that enable multi-sample inference; tokenized VLAs, by contrast, yield near-identical outputs across draws and cannot support sample-based refinement. Robustness evaluations~\cite{fei2025liberoplus} show that current VLAs lose over 65 percentage points under common deployment perturbations, motivating both training-time and inference-time defenses.
6	
7	\paragraph{Training-time methods.}
8	\looseness=-1 Recent approaches improve robustness through modified training. SRPO~\cite{srpo2025} and RobustVLA~\cite{robustvla2025} apply reinforcement learning post-training: the former uses the policy's own rollouts as reward references, while the latter adds Jacobian and smoothness regularization for stability under observation noise. DiG-Flow~\cite{digflow2025} operates at the representation level, gating control signals via distributional discrepancy between observation and action embeddings. TT-VLA~\cite{liu2026ttvla} adapts parameters at test time through progress-reward RL but requires per-task reward design. All four methods require retraining, reward engineering, or environment interaction and cannot serve as drop-in improvements to a frozen VLA.
9	
10	\paragraph{Inference-time methods.}
11	ReconVLA~\cite{chen2026reconvla} applies conformal quantile regression to calibrate per-action uncertainty bounds but does not learn corrective residuals. SC-VLA~\cite{liu2026scvla} performs online refinement through sparse world imagination combined with residual RL, but still requires task-level RL training. VLA-Pilot~\cite{li2025vlapilot} uses evolutionary diffusion optimization guided by an MLLM verifier at 2.41\,s per control step.
12	
13	\looseness=-1 A2C2~\cite{a2c2_2025} is the closest concurrent work. It learns a lightweight correction head that adjusts each action within a pre-generated chunk at every control step, addressing \emph{temporal staleness}: as new observations arrive mid-chunk, A2C2 corrects actions planned under stale context. Our pipeline targets a complementary problem, \emph{initial action quality}, by improving the action before execution. The two approaches could in principle be composed. Our pipeline differs in three ways: (1)~multi-sample selection precedes correction and centers the initial candidate; (2)~explicit $L_2$ norm clipping controls correction magnitude (Section~\ref{sec:magnitude_results}); and (3)~the correction module conditions on the frozen VLA's observation embedding rather than temporal action features.
14	
15	\subsection{Residual Policy Learning}
16	
17	\looseness=-1 Residual policy learning augments a base controller with a learned additive correction~\cite{silver2018residual,johannink2019residual}. The central challenge is magnitude control: unconstrained residuals can dominate the base policy and effectively learn from scratch. TRANSIC~\cite{jiang2024transic} mitigates this with a learned binary gate that disables correction when the base policy suffices; without the gate, performance collapses. PLD~\cite{xiao2026pld} bounds corrections within $[-\xi, \xi]$ via off-policy RL, and DRC~\cite{pan2025drc} applies exponential decay to correction magnitude over training. All three rely on RL and environment interaction. Our correction module uses fixed $L_2$ norm clipping with supervised $L_2$ loss on demonstration data. It requires no RL, no reward design, and no online rollouts.
18	
19	\subsection{Inference-Time Compute Scaling}
20	
21	Test-time compute scaling in language models improves output quality by generating multiple candidates and selecting among them~\cite{snell2024scaling}. RoVer~\cite{dai2025rover} transfers this principle to VLAs with a reward model that scores candidates in a best-of-N scheme. DA-SIP~\cite{chun2025dasip} adapts the number of denoising steps based on per-step difficulty rather than using a fixed budget.
22	
23	\looseness=-1 In the language domain, selection among candidates is the primary mechanism for quality improvement. Our decomposition reveals a different pattern in low-dimensional continuous action spaces: learned correction accounts for 78\% of the gain at $K{=}10$ and 55\% at $K{=}5$ (Section~\ref{sec:main_results}), while multi-sample selection provides centering but not the dominant contribution. This asymmetry motivates per-step adaptive allocation: a cheap $K{=}2$ uncertainty probe ($\rho{=}0.9979$ vs.\ $K{=}10$ variance) determines whether to extend sampling and apply correction, achieving 91\% of fixed-$K{=}10$ performance at 38\% of the compute (Section~\ref{sec:adaptive_k}). Unlike DA-SIP, which adapts denoising steps within a diffusion policy, our probe operates in action space and triggers a qualitatively different computation path (selection + learned correction) rather than adjusting iteration count.
24	Conformal prediction~\cite{angelopoulos2023gentle} has been applied to robotics for safety constraints~\cite{zhou2025acp_cbf,wang2025cploop} and teleoperation calibration~\cite{zhao2024conformalized}; we test CP scores as correction features and find they do not improve over observation-only conditioning (Section~\ref{sec:magnitude_results}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "24df45c5-02e7-4e01-8fcf-0779c280a905",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\\label{sec:related_work}\n\n\\subsection{VLA Robustness}\n\n\\looseness=-1 Vision-language-action models have progressed from tokenized action prediction~\\cite{brohan2023rt2,kim2024openvla,ghosh2024octo} to generative approaches based on diffusion~\\cite{chi2023diffusion_policy} and flow matching~\\cite{black2024pi0,shukor2025smolvla}. Generative VLAs produce stochastic action samples that enable multi-sample inference; tokenized VLAs, by contrast, yield near-identical outputs across draws and cannot support sample-based refinement. Robustness evaluations~\\cite{fei2025liberoplus} show that current VLAs lose over 65 percentage points under common deployment perturbations, motivating both training-time and inference-time defenses.\n\n\\paragraph{Training-time methods.}\n\\looseness=-1 Recent approaches improve robustness through modified training. SRPO~\\cite{srpo2025} and RobustVLA~\\cite{robustvla2025} apply reinforcement learning post-training: the former uses the policy's own rollouts as reward references, while the latter adds Jacobian and smoothness regularization for stability under observation noise. DiG-Flow~\\cite{digflow2025} operates at the representation level, gating control signals via distributional discrepancy between observation and action embeddings. TT-VLA~\\cite{liu2026ttvla} adapts parameters at test time through progress-reward RL but requires per-task reward design. All four methods require retraining, reward engineering, or environment interaction and cannot serve as drop-in improvements to a frozen VLA.\n\n\\paragraph{Inference-time methods.}\nReconVLA~\\cite{chen2026reconvla} applies conformal quantile regression to calibrate per-action uncertainty bounds but does not learn corrective residuals. SC-VLA~\\cite{liu2026scvla} performs online refinement through sparse world imagination combined with residual RL, but still requires task-level RL training. VLA-Pilot~\\cite{li2025vlapilot} uses evolutionary diffusion optimization guided by an MLLM verifier at 2.41\\,s per control step.\n\n\\looseness=-1 A2C2~\\cite{a2c2_2025} is the closest concurrent work. It learns a lightweight correction head that adjusts each action within a pre-generated chunk at every control step, addressing \\emph{temporal staleness}: as new observations arrive mid-chunk, A2C2 corrects actions planned under stale context. Our pipeline targets a complementary problem, \\emph{initial action quality}, by improving the action before execution. The two approaches could in principle be composed. Our pipeline differs in three ways: (1)~multi-sample selection precedes correction and centers the initial candidate; (2)~explicit $L_2$ norm clipping controls correction magnitude (Section~\\ref{sec:magnitude_results}); and (3)~the correction module conditions on the frozen VLA's observation embedding rather than temporal action features.\n\n\\subsection{Residual Policy Learning}\n\n\\looseness=-1 Residual policy learning augments a base controller with a learned additive correction~\\cite{silver2018residual,johannink2019residual}. The central challenge is magnitude control: unconstrained residuals can dominate the base policy and effectively learn from scratch. TRANSIC~\\cite{jiang2024transic} mitigates this with a learned binary gate that disables correction when the base policy suffices; without the gate, performance collapses. PLD~\\cite{xiao2026pld} bounds corrections within $[-\\xi, \\xi]$ via off-policy RL, and DRC~\\cite{pan2025drc} applies exponential decay to correction magnitude over training. All three rely on RL and environment interaction. Our correction module uses fixed $L_2$ norm clipping with supervised $L_2$ loss on demonstration data. It requires no RL, no reward design, and no online rollouts.\n\n\\subsection{Inference-Time Compute Scaling}\n\nTest-time compute scaling in language models improves output quality by generating multiple candidates and selecting among them~\\cite{snell2024scaling}. RoVer~\\cite{dai2025rover} transfers this principle to VLAs with a reward model that scores candidates in a best-of-N scheme. DA-SIP~\\cite{chun2025dasip} adapts the number of denoising steps based on per-step difficulty rather than using a fixed budget.\n\n\\looseness=-1 In the language domain, selection among candidates is the primary mechanism for quality improvement. Our decomposition reveals a different pattern in low-dimensional continuous action spaces: learned correction accounts for 78\\% of the gain at $K{=}10$ and 55\\% at $K{=}5$ (Section~\\ref{sec:main_results}), while multi-sample selection provides centering but not the dominant contribution. This asymmetry motivates per-step adaptive allocation: a cheap $K{=}2$ uncertainty probe ($\\rho{=}0.9979$ vs.\\ $K{=}10$ variance) determines whether to extend sampling and apply correction, achieving 91\\% of fixed-$K{=}10$ performance at 38\\% of the compute (Section~\\ref{sec:adaptive_k}). Unlike DA-SIP, which adapts denoising steps within a diffusion policy, our probe operates in action space and triggers a qualitatively different computation path (selection + learned correction) rather than adjusting iteration count.\nConformal prediction~\\cite{angelopoulos2023gentle} has been applied to robotics for safety constraints~\\cite{zhou2025acp_cbf,wang2025cploop} and teleoperation calibration~\\cite{zhao2024conformalized}; we test CP scores as correction features and find they do not improve over observation-only conditioning (Section~\\ref{sec:magnitude_results}).",
      "numLines": 24,
      "startLine": 1,
      "totalLines": 24
    }
  }
}
```

</details>

---


### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Read · `toolu_01AHC3HSySJWPH3CZho5fhVb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "2e9f4a3f-9a5d-434d-adf5-7d916768ccd2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 34 · 2026-05-21T16:46:12.132Z_

<details><summary>↩ Tool result · `toolu_01AHC3HSySJWPH3CZho5fhVb`</summary>

```text
1	@misc{a2c2_2025,
2	    title={Leave No Observation Behind: Real-time Correction for VLA Action Chunks},
3	    author={Kohei Sendai and Maxime Alvarez and Tatsuya Matsushima and Yutaka Matsuo and Yusuke Iwasawa},
4	    year={2025},
5	    eprint={2509.23224},
6	    archivePrefix={arXiv},
7	    primaryClass={cs.RO}
8	}
9	
10	@article{angelopoulos2023gentle,
11	    title={A Gentle Introduction to Conformal Prediction and Distribution-Free Uncertainty Quantification},
12	    author={Anastasios N. Angelopoulos and Stephen Bates},
13	    journal={Foundations and Trends in Machine Learning},
14	    year={2023},
15	    eprint={2107.07511},
16	    archivePrefix={arXiv},
17	    primaryClass={cs.LG}
18	}
19	
20	
21	@misc{black2024pi0,
22	    title={$\pi_0$: A Vision-Language-Action Flow Model for General Robot Control},
23	    author={Kevin Black and Noah Brown and Danny Driess and Adnan Esmail and Michael Equi and Chelsea Finn and Niccolo Fusai and Lachy Groom and Karol Hausman and Brian Ichter and Szymon Jakubczak and Tim Jones and Liyiming Ke and Sergey Levine and Adrian Li-Bell and Mohith Mothukuri and Suraj Nair and Karl Pertsch and Lucy Xiaoyang Shi and James Tanner and Quan Vuong and Anna Walling and Haohuan Wang and Ury Zhilinsky},
24	    year={2024},
25	    eprint={2410.24164},
26	    archivePrefix={arXiv},
27	    primaryClass={cs.RO}
28	}
29	
30	@misc{brohan2023rt2,
31	    title={RT-2: Vision-Language-Action Models Transfer Web Knowledge to Robotic Control},
32	    author={Anthony Brohan and Noah Brown and Justice Carbajal and Yevgen Chebotar and Xi Chen and Krzysztof Choromanski and Tianli Ding and Danny Driess and Avinava Dubey and Chelsea Finn and Pete Florence and Chuyuan Fu and Montse Gonzalez Arenas and Keerthana Gopalakrishnan and Kehang Han and Karol Hausman and Alexander Herzog and Jasmine Hsu and Brian Ichter and Alex Irpan and Nikhil Joshi and Ryan Julian and Dmitry Kalashnikov and Yuheng Kuang and Isabel Leal and Lisa Lee and Tsang-Wei Edward Lee and Sergey Levine and Yao Lu and Henryk Michalewski and Igor Mordatch and Karl Pertsch and Kanishka Rao and Krista Reymann and Michael Ryoo and Grecia Salazar and Pannag Sanketi and Pierre Sermanet and Jaspiar Singh and Anikait Singh and Radu Soricut and Huong Tran and Vincent Vanhoucke and Quan Vuong and Ayzaan Wahid and Stefan Welker and Paul Wohlhart and Jialin Wu and Fei Xia and Ted Xiao and Peng Xu and Sichun Xu and Tianhe Yu and Brianna Zitkovich},
33	    year={2023},
34	    eprint={2307.15818},
35	    archivePrefix={arXiv},
36	    primaryClass={cs.RO}
37	}
38	
39	@misc{chen2026reconvla,
40	    title={ReconVLA: An Uncertainty-Guided and Failure-Aware Vision-Language-Action Framework for Robotic Control},
41	    author={Lingling Chen and Zongyao Lyu and William J. Beksi},
42	    year={2026},
43	    eprint={2604.16677},
44	    archivePrefix={arXiv},
45	    primaryClass={cs.RO}
46	}
47	
48	
49	@misc{digflow2025,
50	    title={DiG-Flow: Discrepancy-Guided Flow Matching for Robust VLA Models},
51	    author={Wanpeng Zhang and Ye Wang and Hao Luo and Haoqi Yuan and Yicheng Feng and Sipeng Zheng and Qin Jin and Zongqing Lu},
52	    year={2025},
53	    eprint={2512.01715},
54	    archivePrefix={arXiv},
55	    primaryClass={cs.RO}
56	}
57	
58	@misc{fei2025liberoplus,
59	    title={LIBERO-Plus: In-depth Robustness Analysis of Vision-Language-Action Models},
60	    author={Senyu Fei and Siyin Wang and Junhao Shi and Zihao Dai and Jikun Cai and Pengfang Qian and Li Ji and Xinzhe He and Shiduo Zhang and Zhaoye Fei and Jinlan Fu and Jingjing Gong and Xipeng Qiu},
61	    year={2025},
62	    eprint={2510.13626},
63	    archivePrefix={arXiv},
64	    primaryClass={cs.RO}
65	}
66	
67	
68	@misc{ghosh2024octo,
69	    title={Octo: An Open-Source Generalist Robot Policy},
70	    author={Dibya Ghosh and Homer Walke and Karl Pertsch and Kevin Black and Oier Mees and Sudeep Dasari and Joey Hejna and Tobias Kreiman and Charles Xu and Jianlan Luo and You Liang Tan and Lawrence Yunliang Chen and Pannag Sanketi and Quan Vuong and Ted Xiao and Dorsa Sadigh and Chelsea Finn and Sergey Levine},
71	    year={2024},
72	    eprint={2405.12213},
73	    archivePrefix={arXiv},
74	    primaryClass={cs.RO}
75	}
76	
77	
78	
79	@misc{kim2024openvla,
80	    title={OpenVLA: An Open-Source Vision-Language-Action Model},
81	    author={Moo Jin Kim and Karl Pertsch and Siddharth Karamcheti and Ted Xiao and Ashwin Balakrishna and Suraj Nair and Rafael Rafailov and Ethan Foster and Grace Lam and Pannag Sanketi and Quan Vuong and Thomas Kollar and Benjamin Burchfiel and Russ Tedrake and Dorsa Sadigh and Sergey Levine and Percy Liang and Chelsea Finn},
82	    year={2024},
83	    eprint={2406.09246},
84	    archivePrefix={arXiv},
85	    primaryClass={cs.RO}
86	}
87	
88	
89	@article{ledoit2004well,
90	    title={A Well-Conditioned Estimator for Large-Dimensional Covariance Matrices},
91	    author={Olivier Ledoit and Michael Wolf},
92	    journal={Journal of Multivariate Analysis},
93	    volume={88},
94	    number={2},
95	    pages={365--411},
96	    year={2004}
97	}
98	
99	@inproceedings{lipman2023flow,
100	    title={Flow Matching for Generative Modeling},
101	    author={Yaron Lipman and Ricky T. Q. Chen and Heli Ben-Hamu and Maximilian Nickel and Matt Le},
102	    booktitle={International Conference on Learning Representations (ICLR)},
103	    year={2023}
104	}
105	
106	@inproceedings{liu2023libero,
107	    title={LIBERO: Benchmarking Knowledge Transfer for Lifelong Robot Learning},
108	    author={Bo Liu and Yifeng Zhu and Chongkai Gao and Yihao Feng and Qiang Liu and Yuke Zhu and Peter Stone},
109	    booktitle={Advances in Neural Information Processing Systems (NeurIPS)},
110	    year={2023}
111	}
112	
113	@misc{liu2026ttvla,
114	    title={On-the-Fly VLA Adaptation via Test-Time Reinforcement Learning},
115	    author={Changyu Liu and Yiyang Liu and Taowen Wang and Qiao Zhuang and James Chenhao Liang and Wenhao Yang and Renjing Xu and Qifan Wang and Dongfang Liu and Cheng Han},
116	    year={2026},
117	    eprint={2601.06748},
118	    archivePrefix={arXiv},
119	    primaryClass={cs.RO}
120	}
121	
122	
123	@misc{robustvla2025,
124	    title={RobustVLA: Robustness-Aware Reinforcement Post-Training for Vision-Language-Action Models},
125	    author={Hongyin Zhang and Shuo Zhang and Junxi Jin and Qixin Zeng and Runze Li and Donglin Wang},
126	    year={2025},
127	    eprint={2511.01331},
128	    archivePrefix={arXiv},
129	    primaryClass={cs.RO}
130	}
131	
132	
133	
134	@misc{shukor2025smolvla,
135	    title={SmolVLA: A Vision-Language-Action Model for Affordable and Efficient Robotics},
136	    author={Mustafa Shukor and Dana Aubakirova and Francesco Capuano and Pepijn Kooijmans and Steven Palma and Adil Zouitine and Michel Aractingi and Caroline Pascal and Martino Russi and Andres Marafioti and Simon Alibert and Matthieu Cord and Thomas Wolf and Remi Cadene},
137	    year={2025},
138	    eprint={2506.01844},
139	    archivePrefix={arXiv},
140	    primaryClass={cs.RO}
141	}
142	
143	@misc{srpo2025,
144	    title={SRPO: Self-Referential Policy Optimization for Vision-Language-Action Models},
145	    author={Senyu Fei and Siyin Wang and Li Ji and Ao Li and Shiduo Zhang and Liming Liu and Jinlong Hou and Jingjing Gong and Xianzhong Zhao and Xipeng Qiu},
146	    year={2025},
147	    eprint={2511.15605},
148	    archivePrefix={arXiv},
149	    primaryClass={cs.RO}
150	}
151	
152	
153	@misc{wang2025cploop,
154	    title={Conformal Prediction in The Loop: A Feedback-Based Uncertainty Model for Trajectory Optimization},
155	    author={Han Wang and Chao Ning},
156	    year={2025},
157	    eprint={2510.16376},
158	    archivePrefix={arXiv},
159	    primaryClass={cs.RO}
160	}
161	
162	
163	
164	@inproceedings{chi2023diffusion_policy,
165	    title={Diffusion Policy: Visuomotor Policy Learning via Action Diffusion},
166	    author={Cheng Chi and Zhenjia Xu and Siyuan Feng and Eric Cousineau and Benjamin Burchfiel and Shuran Song},
167	    booktitle={Robotics: Science and Systems (RSS)},
168	    year={2023},
169	    note={Also published in IJRR 2024. arXiv:2303.04137}
170	}
171	
172	@inproceedings{zhao2024conformalized,
173	    title={Conformalized Teleoperation: Confidently Mapping Human Inputs to High-Dimensional Robot Actions},
174	    author={Michelle Zhao and Reid Simmons and Henny Admoni and Andrea Bajcsy},
175	    booktitle={Robotics: Science and Systems (RSS)},
176	    year={2024}
177	}
178	
179	@inproceedings{silver2018residual,
180	    title={Residual Policy Learning},
181	    author={Tom Silver and Kelsey Allen and Josh Tenenbaum and Leslie Kaelbling},
182	    booktitle={Robotics: Science and Systems (RSS)},
183	    year={2018},
184	    note={arXiv:1812.06298}
185	}
186	
187	@inproceedings{jiang2024transic,
188	    title={TRANSIC: Sim-to-Real Policy Transfer by Learning from Online Correction},
189	    author={Yunfan Jiang and Chen Wang and Ruohan Zhang and Jiajun Wu and Li Fei-Fei},
190	    booktitle={Conference on Robot Learning (CoRL)},
191	    year={2024},
192	    note={arXiv:2405.10315}
193	}
194	
195	@inproceedings{johannink2019residual,
196	    title={Residual Reinforcement Learning for Robot Control},
197	    author={Tobias Johannink and Shikhar Bahl and Ashvin Nair and Jianlan Luo and Avinash Kumar and Matthias Loskyll and Juan Aparicio Ojea and Eugen Solowjow and Sergey Levine},
198	    booktitle={IEEE International Conference on Robotics and Automation (ICRA)},
199	    year={2019},
200	    pages={6023--6029}
201	}
202	
203	@inproceedings{xiao2026pld,
204	    title={Self-Improving Vision-Language-Action Models with Data Generation via Residual RL},
205	    author={Wenli Xiao and Haotian Lin and Andy Peng and Haoru Xue and Tairan He and Yuqi Xie and Fengyuan Hu and Jimmy Wu and Zhengyi Luo and Linxi Fan and Guanya Shi and Yuke Zhu},
206	    booktitle={International Conference on Learning Representations (ICLR)},
207	    year={2026},
208	    note={arXiv:2511.00091}
209	}
210	
211	@misc{pan2025drc,
212	    title={Online Imitation Learning for Manipulation via Decaying Relative Correction through Teleoperation},
213	    author={Cheng Pan and Hung Hon Cheng and Josie Hughes},
214	    year={2025},
215	    eprint={2503.15368},
216	    archivePrefix={arXiv},
217	    primaryClass={cs.RO}
218	}
219	
220	@inproceedings{zhou2025acp_cbf,
221	    title={Computationally and Sample Efficient Safe Reinforcement Learning Using Adaptive Conformal Prediction},
222	    author={Hao Zhou and Yanze Zhang and Wenhao Luo},
223	    booktitle={IEEE International Conference on Robotics and Automation (ICRA)},
224	    year={2025},
225	    note={arXiv:2503.17678}
226	}
227	
228	
229	@inproceedings{ross2011dagger,
230	    title={A Reduction of Imitation Learning and Structured Prediction to No-Regret Online Learning},
231	    author={St{\'e}phane Ross and Geoffrey J. Gordon and J. Andrew Bagnell},
232	    booktitle={International Conference on Artificial Intelligence and Statistics (AISTATS)},
233	    year={2011}
234	}
235	
236	
237	@misc{liu2026scvla,
238	    title={Self-Correcting VLA: Online Action Refinement via Sparse World Imagination},
239	    author={Chenyv Liu and Wentao Tan and Lei Zhu and Fengling Li and Jingjing Li and Guoli Yang and Heng Tao Shen},
240	    year={2026},
241	    eprint={2602.21633},
242	    archivePrefix={arXiv},
243	    primaryClass={cs.RO}
244	}
245	
246	@misc{li2025vlapilot,
247	    title={Towards Deploying VLA without Fine-Tuning: Plug-and-Play Inference-Time VLA Policy Steering via Embodied Evolutionary Diffusion},
248	    author={Zhuo Li and Junjia Liu and Zhipeng Dong and Tao Teng and Quentin Rouxel and Darwin Caldwell and Fei Chen},
249	    year={2025},
250	    eprint={2511.14178},
251	    archivePrefix={arXiv},
252	    primaryClass={cs.RO}
253	}
254	
255	
256	@inproceedings{snell2024scaling,
257	    title={Scaling LLM Test-Time Compute Optimally Can be More Effective than Scaling Parameters for Reasoning},
258	    author={Charlie Snell and Jaehoon Lee and Kelvin Xu and Aviral Kumar},
259	    year={2025},
260	    eprint={2408.03314},
261	    archivePrefix={arXiv},
262	    primaryClass={cs.LG},
263	    booktitle={International Conference on Learning Representations (ICLR)}
264	}
265	
266	@misc{dai2025rover,
267	    title={RoVer: Robot Reward Model as Test-Time Verifier for Vision-Language-Action Model},
268	    author={Yufeng Dai and Haolun Liu and Zhihao Bai and Yuxin Liu and Jiaming Wang and Hongyuan Su and Chenyv Chen and Jiaying Lin and Liangjun Wu},
269	    year={2025},
270	    eprint={2510.10975},
271	    archivePrefix={arXiv},
272	    primaryClass={cs.RO}
273	}
274	
275	@inproceedings{chun2025dasip,
276	    title={Dynamic Test-Time Compute Scaling in Control Policy: Difficulty-Aware Stochastic Interpolant Policy},
277	    author={Seonghyeon Chun and Jaehyun Lee and Michael S. Albergo and Lisa Xie and Eric Vanden-Eijnden},
278	    year={2025},
279	    eprint={2511.20906},
280	    archivePrefix={arXiv},
281	    primaryClass={cs.LG},
282	    booktitle={Advances in Neural Information Processing Systems (NeurIPS)}
283	}
284	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "26552411-9245-41ed-8f7f-a567ccf4467b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper/references.bib",
      "content": "@misc{a2c2_2025,\n    title={Leave No Observation Behind: Real-time Correction for VLA Action Chunks},\n    author={Kohei Sendai and Maxime Alvarez and Tatsuya Matsushima and Yutaka Matsuo and Yusuke Iwasawa},\n    year={2025},\n    eprint={2509.23224},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@article{angelopoulos2023gentle,\n    title={A Gentle Introduction to Conformal Prediction and Distribution-Free Uncertainty Quantification},\n    author={Anastasios N. Angelopoulos and Stephen Bates},\n    journal={Foundations and Trends in Machine Learning},\n    year={2023},\n    eprint={2107.07511},\n    archivePrefix={arXiv},\n    primaryClass={cs.LG}\n}\n\n\n@misc{black2024pi0,\n    title={$\\pi_0$: A Vision-Language-Action Flow Model for General Robot Control},\n    author={Kevin Black and Noah Brown and Danny Driess and Adnan Esmail and Michael Equi and Chelsea Finn and Niccolo Fusai and Lachy Groom and Karol Hausman and Brian Ichter and Szymon Jakubczak and Tim Jones and Liyiming Ke and Sergey Levine and Adrian Li-Bell and Mohith Mothukuri and Suraj Nair and Karl Pertsch and Lucy Xiaoyang Shi and James Tanner and Quan Vuong and Anna Walling and Haohuan Wang and Ury Zhilinsky},\n    year={2024},\n    eprint={2410.24164},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@misc{brohan2023rt2,\n    title={RT-2: Vision-Language-Action Models Transfer Web Knowledge to Robotic Control},\n    author={Anthony Brohan and Noah Brown and Justice Carbajal and Yevgen Chebotar and Xi Chen and Krzysztof Choromanski and Tianli Ding and Danny Driess and Avinava Dubey and Chelsea Finn and Pete Florence and Chuyuan Fu and Montse Gonzalez Arenas and Keerthana Gopalakrishnan and Kehang Han and Karol Hausman and Alexander Herzog and Jasmine Hsu and Brian Ichter and Alex Irpan and Nikhil Joshi and Ryan Julian and Dmitry Kalashnikov and Yuheng Kuang and Isabel Leal and Lisa Lee and Tsang-Wei Edward Lee and Sergey Levine and Yao Lu and Henryk Michalewski and Igor Mordatch and Karl Pertsch and Kanishka Rao and Krista Reymann and Michael Ryoo and Grecia Salazar and Pannag Sanketi and Pierre Sermanet and Jaspiar Singh and Anikait Singh and Radu Soricut and Huong Tran and Vincent Vanhoucke and Quan Vuong and Ayzaan Wahid and Stefan Welker and Paul Wohlhart and Jialin Wu and Fei Xia and Ted Xiao and Peng Xu and Sichun Xu and Tianhe Yu and Brianna Zitkovich},\n    year={2023},\n    eprint={2307.15818},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@misc{chen2026reconvla,\n    title={ReconVLA: An Uncertainty-Guided and Failure-Aware Vision-Language-Action Framework for Robotic Control},\n    author={Lingling Chen and Zongyao Lyu and William J. Beksi},\n    year={2026},\n    eprint={2604.16677},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n@misc{digflow2025,\n    title={DiG-Flow: Discrepancy-Guided Flow Matching for Robust VLA Models},\n    author={Wanpeng Zhang and Ye Wang and Hao Luo and Haoqi Yuan and Yicheng Feng and Sipeng Zheng and Qin Jin and Zongqing Lu},\n    year={2025},\n    eprint={2512.01715},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@misc{fei2025liberoplus,\n    title={LIBERO-Plus: In-depth Robustness Analysis of Vision-Language-Action Models},\n    author={Senyu Fei and Siyin Wang and Junhao Shi and Zihao Dai and Jikun Cai and Pengfang Qian and Li Ji and Xinzhe He and Shiduo Zhang and Zhaoye Fei and Jinlan Fu and Jingjing Gong and Xipeng Qiu},\n    year={2025},\n    eprint={2510.13626},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n@misc{ghosh2024octo,\n    title={Octo: An Open-Source Generalist Robot Policy},\n    author={Dibya Ghosh and Homer Walke and Karl Pertsch and Kevin Black and Oier Mees and Sudeep Dasari and Joey Hejna and Tobias Kreiman and Charles Xu and Jianlan Luo and You Liang Tan and Lawrence Yunliang Chen and Pannag Sanketi and Quan Vuong and Ted Xiao and Dorsa Sadigh and Chelsea Finn and Sergey Levine},\n    year={2024},\n    eprint={2405.12213},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n\n@misc{kim2024openvla,\n    title={OpenVLA: An Open-Source Vision-Language-Action Model},\n    author={Moo Jin Kim and Karl Pertsch and Siddharth Karamcheti and Ted Xiao and Ashwin Balakrishna and Suraj Nair and Rafael Rafailov and Ethan Foster and Grace Lam and Pannag Sanketi and Quan Vuong and Thomas Kollar and Benjamin Burchfiel and Russ Tedrake and Dorsa Sadigh and Sergey Levine and Percy Liang and Chelsea Finn},\n    year={2024},\n    eprint={2406.09246},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n@article{ledoit2004well,\n    title={A Well-Conditioned Estimator for Large-Dimensional Covariance Matrices},\n    author={Olivier Ledoit and Michael Wolf},\n    journal={Journal of Multivariate Analysis},\n    volume={88},\n    number={2},\n    pages={365--411},\n    year={2004}\n}\n\n@inproceedings{lipman2023flow,\n    title={Flow Matching for Generative Modeling},\n    author={Yaron Lipman and Ricky T. Q. Chen and Heli Ben-Hamu and Maximilian Nickel and Matt Le},\n    booktitle={International Conference on Learning Representations (ICLR)},\n    year={2023}\n}\n\n@inproceedings{liu2023libero,\n    title={LIBERO: Benchmarking Knowledge Transfer for Lifelong Robot Learning},\n    author={Bo Liu and Yifeng Zhu and Chongkai Gao and Yihao Feng and Qiang Liu and Yuke Zhu and Peter Stone},\n    booktitle={Advances in Neural Information Processing Systems (NeurIPS)},\n    year={2023}\n}\n\n@misc{liu2026ttvla,\n    title={On-the-Fly VLA Adaptation via Test-Time Reinforcement Learning},\n    author={Changyu Liu and Yiyang Liu and Taowen Wang and Qiao Zhuang and James Chenhao Liang and Wenhao Yang and Renjing Xu and Qifan Wang and Dongfang Liu and Cheng Han},\n    year={2026},\n    eprint={2601.06748},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n@misc{robustvla2025,\n    title={RobustVLA: Robustness-Aware Reinforcement Post-Training for Vision-Language-Action Models},\n    author={Hongyin Zhang and Shuo Zhang and Junxi Jin and Qixin Zeng and Runze Li and Donglin Wang},\n    year={2025},\n    eprint={2511.01331},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n\n@misc{shukor2025smolvla,\n    title={SmolVLA: A Vision-Language-Action Model for Affordable and Efficient Robotics},\n    author={Mustafa Shukor and Dana Aubakirova and Francesco Capuano and Pepijn Kooijmans and Steven Palma and Adil Zouitine and Michel Aractingi and Caroline Pascal and Martino Russi and Andres Marafioti and Simon Alibert and Matthieu Cord and Thomas Wolf and Remi Cadene},\n    year={2025},\n    eprint={2506.01844},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@misc{srpo2025,\n    title={SRPO: Self-Referential Policy Optimization for Vision-Language-Action Models},\n    author={Senyu Fei and Siyin Wang and Li Ji and Ao Li and Shiduo Zhang and Liming Liu and Jinlong Hou and Jingjing Gong and Xianzhong Zhao and Xipeng Qiu},\n    year={2025},\n    eprint={2511.15605},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n@misc{wang2025cploop,\n    title={Conformal Prediction in The Loop: A Feedback-Based Uncertainty Model for Trajectory Optimization},\n    author={Han Wang and Chao Ning},\n    year={2025},\n    eprint={2510.16376},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n\n@inproceedings{chi2023diffusion_policy,\n    title={Diffusion Policy: Visuomotor Policy Learning via Action Diffusion},\n    author={Cheng Chi and Zhenjia Xu and Siyuan Feng and Eric Cousineau and Benjamin Burchfiel and Shuran Song},\n    booktitle={Robotics: Science and Systems (RSS)},\n    year={2023},\n    note={Also published in IJRR 2024. arXiv:2303.04137}\n}\n\n@inproceedings{zhao2024conformalized,\n    title={Conformalized Teleoperation: Confidently Mapping Human Inputs to High-Dimensional Robot Actions},\n    author={Michelle Zhao and Reid Simmons and Henny Admoni and Andrea Bajcsy},\n    booktitle={Robotics: Science and Systems (RSS)},\n    year={2024}\n}\n\n@inproceedings{silver2018residual,\n    title={Residual Policy Learning},\n    author={Tom Silver and Kelsey Allen and Josh Tenenbaum and Leslie Kaelbling},\n    booktitle={Robotics: Science and Systems (RSS)},\n    year={2018},\n    note={arXiv:1812.06298}\n}\n\n@inproceedings{jiang2024transic,\n    title={TRANSIC: Sim-to-Real Policy Transfer by Learning from Online Correction},\n    author={Yunfan Jiang and Chen Wang and Ruohan Zhang and Jiajun Wu and Li Fei-Fei},\n    booktitle={Conference on Robot Learning (CoRL)},\n    year={2024},\n    note={arXiv:2405.10315}\n}\n\n@inproceedings{johannink2019residual,\n    title={Residual Reinforcement Learning for Robot Control},\n    author={Tobias Johannink and Shikhar Bahl and Ashvin Nair and Jianlan Luo and Avinash Kumar and Matthias Loskyll and Juan Aparicio Ojea and Eugen Solowjow and Sergey Levine},\n    booktitle={IEEE International Conference on Robotics and Automation (ICRA)},\n    year={2019},\n    pages={6023--6029}\n}\n\n@inproceedings{xiao2026pld,\n    title={Self-Improving Vision-Language-Action Models with Data Generation via Residual RL},\n    author={Wenli Xiao and Haotian Lin and Andy Peng and Haoru Xue and Tairan He and Yuqi Xie and Fengyuan Hu and Jimmy Wu and Zhengyi Luo and Linxi Fan and Guanya Shi and Yuke Zhu},\n    booktitle={International Conference on Learning Representations (ICLR)},\n    year={2026},\n    note={arXiv:2511.00091}\n}\n\n@misc{pan2025drc,\n    title={Online Imitation Learning for Manipulation via Decaying Relative Correction through Teleoperation},\n    author={Cheng Pan and Hung Hon Cheng and Josie Hughes},\n    year={2025},\n    eprint={2503.15368},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@inproceedings{zhou2025acp_cbf,\n    title={Computationally and Sample Efficient Safe Reinforcement Learning Using Adaptive Conformal Prediction},\n    author={Hao Zhou and Yanze Zhang and Wenhao Luo},\n    booktitle={IEEE International Conference on Robotics and Automation (ICRA)},\n    year={2025},\n    note={arXiv:2503.17678}\n}\n\n\n@inproceedings{ross2011dagger,\n    title={A Reduction of Imitation Learning and Structured Prediction to No-Regret Online Learning},\n    author={St{\\'e}phane Ross and Geoffrey J. Gordon and J. Andrew Bagnell},\n    booktitle={International Conference on Artificial Intelligence and Statistics (AISTATS)},\n    year={2011}\n}\n\n\n@misc{liu2026scvla,\n    title={Self-Correcting VLA: Online Action Refinement via Sparse World Imagination},\n    author={Chenyv Liu and Wentao Tan and Lei Zhu and Fengling Li and Jingjing Li and Guoli Yang and Heng Tao Shen},\n    year={2026},\n    eprint={2602.21633},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@misc{li2025vlapilot,\n    title={Towards Deploying VLA without Fine-Tuning: Plug-and-Play Inference-Time VLA Policy Steering via Embodied Evolutionary Diffusion},\n    author={Zhuo Li and Junjia Liu and Zhipeng Dong and Tao Teng and Quentin Rouxel and Darwin Caldwell and Fei Chen},\n    year={2025},\n    eprint={2511.14178},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n\n@inproceedings{snell2024scaling,\n    title={Scaling LLM Test-Time Compute Optimally Can be More Effective than Scaling Parameters for Reasoning},\n    author={Charlie Snell and Jaehoon Lee and Kelvin Xu and Aviral Kumar},\n    year={2025},\n    eprint={2408.03314},\n    archivePrefix={arXiv},\n    primaryClass={cs.LG},\n    booktitle={International Conference on Learning Representations (ICLR)}\n}\n\n@misc{dai2025rover,\n    title={RoVer: Robot Reward Model as Test-Time Verifier for Vision-Language-Action Model},\n    author={Yufeng Dai and Haolun Liu and Zhihao Bai and Yuxin Liu and Jiaming Wang and Hongyuan Su and Chenyv Chen and Jiaying Lin and Liangjun Wu},\n    year={2025},\n    eprint={2510.10975},\n    archivePrefix={arXiv},\n    primaryClass={cs.RO}\n}\n\n@inproceedings{chun2025dasip,\n    title={Dynamic Test-Time Compute Scaling in Control Policy: Difficulty-Aware Stochastic Interpolant Policy},\n    author={Seonghyeon Chun and Jaehyun Lee and Michael S. Albergo and Lisa Xie and Eric Vanden-Eijnden},\n    year={2025},\n    eprint={2511.20906},\n    archivePrefix={arXiv},\n    primaryClass={cs.LG},\n    booktitle={Advances in Neural Information Processing Systems (NeurIPS)}\n}\n",
      "numLines": 284,
      "startLine": 1,
      "totalLines": 284
    }
  }
}
```

</details>

---


### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Glob · `toolu_01D6P5MhuoSzFghu2G6kTsL3`</summary>

```json
{
  "pattern": "Makefile",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "fa5bb2d9-8d5c-4e11-844f-3d4026a1eb45",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 36 · 2026-05-21T16:46:13.234Z_

<details><summary>↩ Tool result · `toolu_01D6P5MhuoSzFghu2G6kTsL3`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "3310627a-11f2-474f-b732-bafaddf67dfb",
  "tool_use_result": {
    "filenames": [],
    "durationMs": 5,
    "numFiles": 0,
    "truncated": false
  }
}
```

</details>

---


### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Glob · `toolu_01Mx5KC8eEqHnxS7eQn2qZ5c`</summary>

```json
{
  "pattern": "*.sh",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "61d6298c-a540-46b4-bef8-cb61a5548944",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016WdxG9gBmwKk8AEnDxs8k9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11876,
      "cache_read_input_tokens": 25075,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11876
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

_source line 38 · 2026-05-21T16:46:13.600Z_

<details><summary>↩ Tool result · `toolu_01Mx5KC8eEqHnxS7eQn2qZ5c`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d50d1470-8d26-4a90-b0c7-3a4106ee472a",
  "tool_use_result": {
    "filenames": [],
    "durationMs": 11,
    "numFiles": 0,
    "truncated": false
  }
}
```

</details>

---


### Assistant

_source line 39_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the paper content. Let me now:

1. Try to compile the paper to check for errors
2. Check registry data for number consistency
3. Check for π0.5 section gaps
4. Check citations

Let me start with compilation and detailed checks. I need to:
1. Check if pdflatex is available and try compilation
2. Read the registry data file for key experiments to cross-check numbers
3. Check all \cite{} references against the bib file

Let me do these in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "5e2c3579-5373-4661-bc38-168c71024f71",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H7DAqDVSJrmRsNopRhdYQz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 47454,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 47454
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

_source line 40_

Now let me compile the paper and check the registry for key experiments. I'll also extract all citation keys from the tex files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "9f6aa607-8e40-43b7-8b6a-7f3f76013cc1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H7DAqDVSJrmRsNopRhdYQz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 47454,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 47454
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

_source line 41_

<details open><summary>🔧 Tool call — Bash · `toolu_01Fo8kiSagZrY38NcPjBfxwp`</summary>

```json
{
  "command": "which pdflatex latexmk 2>/dev/null; dpkg -l texlive-latex-base 2>/dev/null | grep -c ii",
  "description": "Check if LaTeX is installed"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "b9eaeaa5-4bc1-4b2f-89da-f22183d18225",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H7DAqDVSJrmRsNopRhdYQz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 47454,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 47454
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

_source line 42 · 2026-05-21T16:46:21.922Z_

<details><summary>↩ Tool result · `toolu_01Fo8kiSagZrY38NcPjBfxwp`</summary>

```text
/usr/bin/pdflatex
/usr/bin/latexmk
1
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d93b82c7-ce52-465c-948b-6f752a19aae3",
  "tool_use_result": {
    "stdout": "/usr/bin/pdflatex\n/usr/bin/latexmk\n1",
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

_source line 43_

<details open><summary>🔧 Tool call — Bash · `toolu_01UUWM1YUuQ4ZZhwH3TwNU4v`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper && grep -ohP '\\\\\\\\cite\\{[^}]+\\}' *.tex | sed 's/\\\\\\\\cite{//;s/}//' | tr ',' '\\n' | sed 's/^ *//;s/ *$//' | sort -u",
  "description": "Extract all citation keys used in tex files"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "5d61cc56-efc2-4e48-b6a2-e933cc1d7a4f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H7DAqDVSJrmRsNopRhdYQz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 47454,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 47454
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

_source line 44 · 2026-05-21T16:46:25.110Z_

<details><summary>↩ Tool result · `toolu_01UUWM1YUuQ4ZZhwH3TwNU4v`</summary>

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
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "dc2dce30-ab0a-49a1-9d1e-36abc22f7a7f",
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


### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Bash · `toolu_016qRKu98BVMaj4XByYW8CzS`</summary>

```json
{
  "command": "grep -oP '@\\w+\\{([^,]+),' references.bib | sed 's/@[^{]*{//;s/,$//' | sort -u",
  "description": "Extract all bib entry keys"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "57650b81-f28c-464f-9d7b-366c4352eee5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H7DAqDVSJrmRsNopRhdYQz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 47454,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 47454
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

_source line 46 · 2026-05-21T16:46:27.030Z_

<details><summary>↩ Tool result · `toolu_016qRKu98BVMaj4XByYW8CzS`</summary>

```text
a2c2_2025
angelopoulos2023gentle
black2024pi0
brohan2023rt2
chen2026reconvla
chi2023diffusion_policy
chun2025dasip
dai2025rover
digflow2025
fei2025liberoplus
ghosh2024octo
jiang2024transic
johannink2019residual
kim2024openvla
ledoit2004well
li2025vlapilot
lipman2023flow
liu2023libero
liu2026scvla
liu2026ttvla
pan2025drc
robustvla2025
ross2011dagger
shukor2025smolvla
silver2018residual
snell2024scaling
srpo2025
wang2025cploop
xiao2026pld
zhao2024conformalized
zhou2025acp_cbf
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "e68e6624-e342-49d5-9738-4c6d285b123f",
  "tool_use_result": {
    "stdout": "a2c2_2025\nangelopoulos2023gentle\nblack2024pi0\nbrohan2023rt2\nchen2026reconvla\nchi2023diffusion_policy\nchun2025dasip\ndai2025rover\ndigflow2025\nfei2025liberoplus\nghosh2024octo\njiang2024transic\njohannink2019residual\nkim2024openvla\nledoit2004well\nli2025vlapilot\nlipman2023flow\nliu2023libero\nliu2026scvla\nliu2026ttvla\npan2025drc\nrobustvla2025\nross2011dagger\nshukor2025smolvla\nsilver2018residual\nsnell2024scaling\nsrpo2025\nwang2025cploop\nxiao2026pld\nzhao2024conformalized\nzhou2025acp_cbf",
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

_source line 47_

<details open><summary>🔧 Tool call — Bash · `toolu_01KUwRotRwg3tMFcwdY7Vrpk`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement && cat /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result.get('data', result) if isinstance(result, dict) else result\nif isinstance(exps, list):\n    for e in exps:\n        eid = e.get('exp_id','?')\n        status = e.get('status','?')\n        metrics = e.get('metrics',{})\n        conclusion = e.get('conclusion','')\n        if any(k in eid.lower() for k in ['plan-a','adaptive','crm-k10','crm-k5','vla-only','random-selection','argmin','spatial','openvla','pi0']):\n            print(f'{eid} | {status} | metrics={metrics} | conclusion={conclusion[:120]}')\n\" 2>&1 | head -80",
  "description": "Extract key experiment metrics from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "3602fa07-9aaf-4d1d-90ee-e993bf1e3d9a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H7DAqDVSJrmRsNopRhdYQz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 47454,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 47454
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

_source line 48 · 2026-05-21T16:46:34.863Z_

<details><summary>↩ Tool result · `toolu_01KUwRotRwg3tMFcwdY7Vrpk`</summary>

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
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "bc5c39cb-86ab-4952-9d49-7476bdfdcdf5",
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

_source line 49_

<details><summary>Logged reasoning block</summary>

```text
The grep for citation keys from tex files returned empty. Let me fix the grep command. Also let me try compiling the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "9daa7c5f-3c3d-42a7-806b-4bfc18bdb433",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6Nvd56neVhVxN8dcDMPvs",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1275,
      "cache_read_input_tokens": 59295,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1275
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

_source line 50_

<details open><summary>🔧 Tool call — Bash · `toolu_01EGCrhuZJbXFvwKtCN9BPcE`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper && grep -ohP '\\\\cite\\{[^}]+\\}' *.tex | sed 's/\\\\cite{//;s/}//' | tr ',' '\\n' | sed 's/^ *//;s/ *$//' | sort -u",
  "description": "Extract citation keys from tex files"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d844649d-66db-4f7f-9a6e-076bf0b0abe9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6Nvd56neVhVxN8dcDMPvs",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1275,
      "cache_read_input_tokens": 59295,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1275
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

_source line 51 · 2026-05-21T16:46:40.045Z_

<details><summary>↩ Tool result · `toolu_01EGCrhuZJbXFvwKtCN9BPcE`</summary>

```text
a2c2_2025
angelopoulos2023gentle
black2024pi0
brohan2023rt2
chen2026reconvla
chi2023diffusion_policy
chun2025dasip
dai2025rover
digflow2025
fei2025liberoplus
ghosh2024octo
jiang2024transic
johannink2019residual
kim2024openvla
ledoit2004well
li2025vlapilot
lipman2023flow
liu2023libero
liu2026scvla
liu2026ttvla
pan2025drc
robustvla2025
ross2011dagger
shukor2025smolvla
silver2018residual
snell2024scaling
srpo2025
wang2025cploop
xiao2026pld
zhao2024conformalized
zhou2025acp_cbf
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "4f0ea07e-b118-4141-9342-c8638f5554a3",
  "tool_use_result": {
    "stdout": "a2c2_2025\nangelopoulos2023gentle\nblack2024pi0\nbrohan2023rt2\nchen2026reconvla\nchi2023diffusion_policy\nchun2025dasip\ndai2025rover\ndigflow2025\nfei2025liberoplus\nghosh2024octo\njiang2024transic\njohannink2019residual\nkim2024openvla\nledoit2004well\nli2025vlapilot\nlipman2023flow\nliu2023libero\nliu2026scvla\nliu2026ttvla\npan2025drc\nrobustvla2025\nross2011dagger\nshukor2025smolvla\nsilver2018residual\nsnell2024scaling\nsrpo2025\nwang2025cploop\nxiao2026pld\nzhao2024conformalized\nzhou2025acp_cbf",
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

<details open><summary>🔧 Tool call — Bash · `toolu_019hJBrmGbN6tgFNaL3BDqkk`</summary>

```json
{
  "command": "ls figures/ 2>/dev/null || echo \"NO_FIGURES_DIR\"; ls *.sty *.cls 2>/dev/null || echo \"NO_STYLE_FILES\"",
  "description": "Check figures directory and style files"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "35114719-eb71-48d0-8f6e-d7f1989b81bf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6Nvd56neVhVxN8dcDMPvs",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1275,
      "cache_read_input_tokens": 59295,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1275
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

_source line 53 · 2026-05-21T16:46:41.955Z_

<details><summary>↩ Tool result · `toolu_019hJBrmGbN6tgFNaL3BDqkk`</summary>

```text
fig1_pipeline.pdf
fig1_pipeline.png
fig2_magnitude.pdf
fig3_decomposition.pdf
fig3_kvalue.pdf
fig4_diversity.pdf
fig5_k2_correlation.pdf
fig5_k2_correlation.png
fig_magnitude_curve.py
magnitude_curve.pdf
magnitude_curve.png
corl_2026.sty
NO_STYLE_FILES
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "2158cca3-fa85-490f-9abc-bf3255a07bd5",
  "tool_use_result": {
    "stdout": "fig1_pipeline.pdf\nfig1_pipeline.png\nfig2_magnitude.pdf\nfig3_decomposition.pdf\nfig3_kvalue.pdf\nfig4_diversity.pdf\nfig5_k2_correlation.pdf\nfig5_k2_correlation.png\nfig_magnitude_curve.py\nmagnitude_curve.pdf\nmagnitude_curve.png\ncorl_2026.sty\nNO_STYLE_FILES",
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

_source line 54_

<details open><summary>🔧 Tool call — Bash · `toolu_01HACUmVf8ewuUDmZ1LMwN8G`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement && python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\nexps = result.get('data', [])\n# Print all experiment IDs and their key metrics\nfor e in exps:\n    eid = e.get('exp_id','?')\n    status = e.get('status','?')\n    metrics = e.get('metrics',{})\n    if metrics:\n        print(f'{eid} | {status} | {json.dumps(metrics)}')\n\" 2>&1 | head -100",
  "description": "Extract all experiment metrics from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "4396685a-0663-4077-80f3-1677a7149e7c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6Nvd56neVhVxN8dcDMPvs",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1275,
      "cache_read_input_tokens": 59295,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1275
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

_source line 55 · 2026-05-21T16:46:45.106Z_

<details><summary>↩ Tool result · `toolu_01HACUmVf8ewuUDmZ1LMwN8G`</summary>

```text
Traceback (most recent call last):
  File "&lt;string>", line 9, in &lt;module>
    eid = e.get('exp_id','?')
          ^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "afe0ff52-bcaa-4677-a9c2-025e8576f01a",
  "tool_use_result": {
    "stdout": "Traceback (most recent call last):\n  File \"&lt;string>\", line 9, in &lt;module>\n    eid = e.get('exp_id','?')\n          ^^^^^\nAttributeError: 'str' object has no attribute 'get'",
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

_source line 56_

<details><summary>Logged reasoning block</summary>

```text
Let me fix the registry parsing and also try to compile the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "aaec41da-01e3-4457-8e3a-38558441f83d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RJpb4qtmen8q5TgLdg7SG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1094,
      "cache_read_input_tokens": 60570,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1094
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

_source line 57_

<details open><summary>🔧 Tool call — Bash · `toolu_01ESiS8xDaTkydV39Hb9bVT8`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper && pdflatex -interaction=nonstopmode main.tex 2>&1 | tail -50",
  "description": "Compile LaTeX paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "8854e17a-4fb6-40b7-8900-d84a402f504d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RJpb4qtmen8q5TgLdg7SG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1094,
      "cache_read_input_tokens": 60570,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1094
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

_source line 58 · 2026-05-21T16:46:49.439Z_

<details><summary>↩ Tool result · `toolu_01ESiS8xDaTkydV39Hb9bVT8`</summary>

```text
Package hyperref Warning: Token not allowed in a PDF string (Unicode):
(hyperref)                removing `math shift' on input line 24.


LaTeX Warning: `h' float specifier changed to `ht'.


LaTeX Warning: `h' float specifier changed to `ht'.

[11 <./figures/fig3_decomposition.pdf> <./figures/fig2_magnitude.pdf>]

Package hyperref Warning: Token not allowed in a PDF string (Unicode):
(hyperref)                removing `math shift' on input line 63.


Package hyperref Warning: Token not allowed in a PDF string (Unicode):
(hyperref)                removing `math shift' on input line 63.


Underfull \vbox (badness 10000) has occurred while \output is active [12 <./fig
ures/fig3_kvalue.pdf>] [13 <./figures/fig4_diversity.pdf>]

LaTeX Warning: `h' float specifier changed to `ht'.

[14]) [15] (./main.aux) )
(see the transcript file for additional information) &lt;/home/ubuntu/.texlive2025
/texmf-var/fonts/pk/ljfour/jknappen/ec/ectt1000.600pk>&lt;/usr/share/texlive/texmf
-dist/fonts/type1/public/amsfonts/cm/cmbx10.pfb>&lt;/usr/share/texlive/texmf-dist/
fonts/type1/public/amsfonts/cm/cmbx9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/t
ype1/public/amsfonts/cm/cmex10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/p
ublic/amsfonts/cm/cmmi10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/
amsfonts/cm/cmmi12.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfon
ts/cm/cmmi6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/c
mmi7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi9.pf
b>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmib10.pfb>&lt;/u
sr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr10.pfb>&lt;/usr/shar
e/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr5.pfb>&lt;/usr/share/texliv
e/texmf-dist/fonts/type1/public/amsfonts/cm/cmr6.pfb>&lt;/usr/share/texlive/texmf-
dist/fonts/type1/public/amsfonts/cm/cmr7.pfb>&lt;/usr/share/texlive/texmf-dist/fon
ts/type1/public/amsfonts/cm/cmr9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1
/public/amsfonts/cm/cmsy10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/publi
c/amsfonts/cm/cmsy6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfo
nts/cm/cmsy7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/
cmsy9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/symbols/ms
bm10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/helvetic/uhvr8a.pfb>&lt;/u
sr/share/texlive/texmf-dist/fonts/type1/urw/times/utmb8a.pfb>&lt;/usr/share/texliv
e/texmf-dist/fonts/type1/urw/times/utmr8a.pfb>&lt;/usr/share/texlive/texmf-dist/fo
nts/type1/urw/times/utmri8a.pfb>
Output written on main.pdf (15 pages, 544260 bytes).
Transcript written on main.log.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "cffdb164-2575-467a-aedc-d67ebea55b5f",
  "tool_use_result": {
    "stdout": "Package hyperref Warning: Token not allowed in a PDF string (Unicode):\n(hyperref)                removing `math shift' on input line 24.\n\n\nLaTeX Warning: `h' float specifier changed to `ht'.\n\n\nLaTeX Warning: `h' float specifier changed to `ht'.\n\n[11 <./figures/fig3_decomposition.pdf> <./figures/fig2_magnitude.pdf>]\n\nPackage hyperref Warning: Token not allowed in a PDF string (Unicode):\n(hyperref)                removing `math shift' on input line 63.\n\n\nPackage hyperref Warning: Token not allowed in a PDF string (Unicode):\n(hyperref)                removing `math shift' on input line 63.\n\n\nUnderfull \\vbox (badness 10000) has occurred while \\output is active [12 <./fig\nures/fig3_kvalue.pdf>] [13 <./figures/fig4_diversity.pdf>]\n\nLaTeX Warning: `h' float specifier changed to `ht'.\n\n[14]) [15] (./main.aux) )\n(see the transcript file for additional information) &lt;/home/ubuntu/.texlive2025\n/texmf-var/fonts/pk/ljfour/jknappen/ec/ectt1000.600pk>&lt;/usr/share/texlive/texmf\n-dist/fonts/type1/public/amsfonts/cm/cmbx10.pfb>&lt;/usr/share/texlive/texmf-dist/\nfonts/type1/public/amsfonts/cm/cmbx9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/t\nype1/public/amsfonts/cm/cmex10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/p\nublic/amsfonts/cm/cmmi10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/\namsfonts/cm/cmmi12.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfon\nts/cm/cmmi6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/c\nmmi7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi9.pf\nb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmib10.pfb>&lt;/u\nsr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr10.pfb>&lt;/usr/shar\ne/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmr5.pfb>&lt;/usr/share/texliv\ne/texmf-dist/fonts/type1/public/amsfonts/cm/cmr6.pfb>&lt;/usr/share/texlive/texmf-\ndist/fonts/type1/public/amsfonts/cm/cmr7.pfb>&lt;/usr/share/texlive/texmf-dist/fon\nts/type1/public/amsfonts/cm/cmr9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1\n/public/amsfonts/cm/cmsy10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/publi\nc/amsfonts/cm/cmsy6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfo\nnts/cm/cmsy7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/\ncmsy9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/symbols/ms\nbm10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/helvetic/uhvr8a.pfb>&lt;/u\nsr/share/texlive/texmf-dist/fonts/type1/urw/times/utmb8a.pfb>&lt;/usr/share/texliv\ne/texmf-dist/fonts/type1/urw/times/utmr8a.pfb>&lt;/usr/share/texlive/texmf-dist/fo\nnts/type1/urw/times/utmri8a.pfb>\nOutput written on main.pdf (15 pages, 544260 bytes).\nTranscript written on main.log.",
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

_source line 59_

<details open><summary>🔧 Tool call — Bash · `toolu_0158BusA5vxExZ6YjDKWtaxS`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement && python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\n# Inspect structure\nif isinstance(result, dict):\n    for k,v in result.items():\n        if isinstance(v, list):\n            print(f'Key={k}, len={len(v)}, type[0]={type(v[0]).__name__ if v else \\\"empty\\\"}')\n            if v and isinstance(v[0], dict):\n                print(f'  sample keys: {list(v[0].keys())[:10]}')\n                print(f'  sample exp_id: {v[0].get(\\\"exp_id\\\",\\\"?\\\")}')\n        elif isinstance(v, dict):\n            print(f'Key={k}, dict keys={list(v.keys())[:5]}')\n        else:\n            print(f'Key={k}, type={type(v).__name__}, val={str(v)[:100]}')\nelif isinstance(result, list):\n    print(f'list len={len(result)}, type[0]={type(result[0]).__name__}')\n    if result and isinstance(result[0], dict):\n        print(f'  sample keys: {list(result[0].keys())[:10]}')\nelse:\n    print(f'type={type(result).__name__}')\n\" 2>&1",
  "description": "Inspect registry data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "157b3eed-d53a-4acf-9301-4beab8446a4c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RJpb4qtmen8q5TgLdg7SG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1094,
      "cache_read_input_tokens": 60570,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1094
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

_source line 60 · 2026-05-21T16:46:54.995Z_

<details><summary>↩ Tool result · `toolu_0158BusA5vxExZ6YjDKWtaxS`</summary>

```text
Key=success, type=bool, val=True
Key=data, dict keys=['experiments', 'count', 'total', 'baseline']
Key=error, type=NoneType, val=None
Key=metadata, dict keys=['elapsed_seconds']
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "60fedc62-f166-4a8a-843c-7b7fb609c20c",
  "tool_use_result": {
    "stdout": "Key=success, type=bool, val=True\nKey=data, dict keys=['experiments', 'count', 'total', 'baseline']\nKey=error, type=NoneType, val=None\nKey=metadata, dict keys=['elapsed_seconds']",
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

_source line 61_

<details open><summary>🔧 Tool call — Bash · `toolu_01JDyaW9yN3dkDv46KRdwCck`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper && bibtex main 2>&1",
  "description": "Run bibtex to resolve citations"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "1a4838a7-6216-41f6-8038-d11ce8e80111",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015aqCoD7CbXYviBQpCp8bAo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 61664,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2075
      },
      "output_tokens": 38,
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

_source line 62 · 2026-05-21T16:47:01.355Z_

<details><summary>↩ Tool result · `toolu_01JDyaW9yN3dkDv46KRdwCck`</summary>

```text
This is BibTeX, Version 0.99d (TeX Live 2025/Debian)
The top-level auxiliary file: main.aux
The style file: corlabbrvnat.bst
Database file #1: references.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "112e8530-86bf-4f39-9aac-10ef21bc96b2",
  "tool_use_result": {
    "stdout": "This is BibTeX, Version 0.99d (TeX Live 2025/Debian)\nThe top-level auxiliary file: main.aux\nThe style file: corlabbrvnat.bst\nDatabase file #1: references.bib",
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

_source line 63_

<details open><summary>🔧 Tool call — Bash · `toolu_01X3vrfEcGGYFx7S5CS1SXkD`</summary>

```json
{
  "command": "grep -c \"Warning\\|Error\\|Underfull\\|Overfull\" main.log",
  "description": "Count warnings and errors in LaTeX log"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "ea86c4bb-f8c7-44be-b748-49ea3393467d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015aqCoD7CbXYviBQpCp8bAo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 61664,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2075
      },
      "output_tokens": 38,
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

_source line 64 · 2026-05-21T16:47:01.770Z_

<details><summary>↩ Tool result · `toolu_01X3vrfEcGGYFx7S5CS1SXkD`</summary>

```text
12
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d2b196ed-3a4e-4bf5-bfd9-fde7a410e316",
  "tool_use_result": {
    "stdout": "12",
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

_source line 65_

<details open><summary>🔧 Tool call — Bash · `toolu_013M24eDmvXnsJFKrABau1ZN`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement && python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Get key experiments with metrics\nfor e in exps:\n    eid = e.get('exp_id','?')\n    metrics = e.get('metrics',{})\n    status = e.get('status','?')\n    conclusion = e.get('conclusion','')[:150]\n    # Filter for key experiments\n    keywords = ['plan-a','plan_a','adaptive','crm-obs','vla-only','random-sel','argmin-k','k-value','magnitude','lto','spatial','openvla','pi0','perdof']\n    if any(k in eid.lower() for k in keywords):\n        print(f'=== {eid} === [{status}]')\n        if metrics:\n            print(f'  metrics: {json.dumps(metrics)[:200]}')\n        if conclusion:\n            print(f'  conclusion: {conclusion}')\n        print()\n\" 2>&1 | head -200",
  "description": "Extract key experiment data from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "9651cb82-3928-45dd-9adb-17a0fee28d17",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015aqCoD7CbXYviBQpCp8bAo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 61664,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2075
      },
      "output_tokens": 38,
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

_source line 66 · 2026-05-21T16:47:10.879Z_

<details><summary>↩ Tool result · `toolu_013M24eDmvXnsJFKrABau1ZN`</summary>

```text
Traceback (most recent call last):
  File "&lt;string>", line 9, in &lt;module>
    eid = e.get('exp_id','?')
          ^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "0ec39e3b-117b-4f9e-b4af-6e04b23ee42c",
  "tool_use_result": {
    "stdout": "Traceback (most recent call last):\n  File \"&lt;string>\", line 9, in &lt;module>\n    eid = e.get('exp_id','?')\n          ^^^^^\nAttributeError: 'str' object has no attribute 'get'",
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

_source line 67_

<details open><summary>🔧 Tool call — Bash · `toolu_01972gvtR6F4jat8actSg32F`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\nexps_data = result['data']['experiments']\n# Check type of experiments\nprint(f'Type: {type(exps_data).__name__}')\nif isinstance(exps_data, dict):\n    keys = list(exps_data.keys())[:5]\n    print(f'Dict keys (first 5): {keys}')\n    for k in keys:\n        v = exps_data[k]\n        print(f'  {k}: type={type(v).__name__}, val={str(v)[:100]}')\nelif isinstance(exps_data, list):\n    print(f'Len: {len(exps_data)}')\n    print(f'Type[0]: {type(exps_data[0]).__name__}')\n    print(f'Val[0]: {str(exps_data[0])[:200]}')\n\" 2>&1",
  "description": "Debug registry experiments structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "3e382081-23e7-4259-9799-d22e155d665b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NBzApxRkbsn9w8Ry2PhXFe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 861,
      "cache_read_input_tokens": 63739,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 861
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

_source line 68 · 2026-05-21T16:47:17.845Z_

<details><summary>↩ Tool result · `toolu_01972gvtR6F4jat8actSg32F`</summary>

```text
Type: dict
Dict keys (first 5): ['crm-pipeline-auto', 'precompute-pi05-obj-s6-r2', 'precompute-pi05-obj-s9-r2', 'precompute-pi05-obj-s8-r2', 'precompute-pi05-obj-s7-r2']
  crm-pipeline-auto: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T16:37:34.472Z', 'updated_at': '2
  precompute-pi05-obj-s6-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T15:04:33.582Z', 'updated_at': '2
  precompute-pi05-obj-s9-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T14:19:39.622Z', 'updated_at': '2
  precompute-pi05-obj-s8-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T14:19:35.288Z', 'updated_at': '2
  precompute-pi05-obj-s7-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T14:19:30.950Z', 'updated_at': '2
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "e9b8fbc0-e001-41b7-b12e-a80e3326ab5b",
  "tool_use_result": {
    "stdout": "Type: dict\nDict keys (first 5): ['crm-pipeline-auto', 'precompute-pi05-obj-s6-r2', 'precompute-pi05-obj-s9-r2', 'precompute-pi05-obj-s8-r2', 'precompute-pi05-obj-s7-r2']\n  crm-pipeline-auto: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T16:37:34.472Z', 'updated_at': '2\n  precompute-pi05-obj-s6-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T15:04:33.582Z', 'updated_at': '2\n  precompute-pi05-obj-s9-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T14:19:39.622Z', 'updated_at': '2\n  precompute-pi05-obj-s8-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T14:19:35.288Z', 'updated_at': '2\n  precompute-pi05-obj-s7-r2: type=dict, val={'status': 'PREPARING', 'retry_count': 0, 'created_at': '2026-05-21T14:19:30.950Z', 'updated_at': '2",
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

_source line 69_

<details open><summary>🔧 Tool call — Bash · `toolu_01G3aJZrXtXkCf9ULVCxdvjW`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_8/projects/acr-vla-conformal-refinement/docs/paper && grep -nE \"Warning|Error|Underfull|Overfull\" main.log | head -30",
  "description": "Show all LaTeX warnings and errors"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "277f534e-57c6-4b43-9f4b-0d59783d8d18",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NBzApxRkbsn9w8Ry2PhXFe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 861,
      "cache_read_input_tokens": 63739,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 861
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

_source line 70 · 2026-05-21T16:47:18.842Z_

<details><summary>↩ Tool result · `toolu_01G3aJZrXtXkCf9ULVCxdvjW`</summary>

```text
504:Underfull \hbox (badness 3690) in paragraph at lines 33--33
514:Underfull \hbox (badness 1194) in paragraph at lines 8--9
526:Underfull \vbox (badness 10000) has occurred while \output is active []
529:Underfull \hbox (badness 1502) in paragraph at lines 37--38
562:Package hyperref Warning: Token not allowed in a PDF string (Unicode):
566:Package hyperref Warning: Token not allowed in a PDF string (Unicode):
575:LaTeX Warning: `h' float specifier changed to `ht'.
578:LaTeX Warning: `h' float specifier changed to `ht'.
584:Package hyperref Warning: Token not allowed in a PDF string (Unicode):
588:Package hyperref Warning: Token not allowed in a PDF string (Unicode):
592:Underfull \vbox (badness 10000) has occurred while \output is active []
602:LaTeX Warning: `h' float specifier changed to `ht'.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "5dec73f8-4947-43db-a3d7-5417736a75d3",
  "tool_use_result": {
    "stdout": "504:Underfull \\hbox (badness 3690) in paragraph at lines 33--33\n514:Underfull \\hbox (badness 1194) in paragraph at lines 8--9\n526:Underfull \\vbox (badness 10000) has occurred while \\output is active []\n529:Underfull \\hbox (badness 1502) in paragraph at lines 37--38\n562:Package hyperref Warning: Token not allowed in a PDF string (Unicode):\n566:Package hyperref Warning: Token not allowed in a PDF string (Unicode):\n575:LaTeX Warning: `h' float specifier changed to `ht'.\n578:LaTeX Warning: `h' float specifier changed to `ht'.\n584:Package hyperref Warning: Token not allowed in a PDF string (Unicode):\n588:Package hyperref Warning: Token not allowed in a PDF string (Unicode):\n592:Underfull \\vbox (badness 10000) has occurred while \\output is active []\n602:LaTeX Warning: `h' float specifier changed to `ht'.",
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

_source line 71_

<details open><summary>🔧 Tool call — Bash · `toolu_01LzPjbBbthnS5hU8LnKQsmB`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Now iterate over dict\nkeywords = ['plan-a','plan_a','adaptive','obs-only','vla-only','random-sel','argmin','spatial','openvla','pi0','perdof','lto','magnitude','k-value','k1-','k5-','k10-','k20-']\nfor eid, edata in exps.items():\n    if any(k in eid.lower() for k in keywords):\n        metrics = edata.get('metrics',{})\n        status = edata.get('status','?')\n        conclusion = edata.get('conclusion','')[:200]\n        print(f'=== {eid} === [{status}]')\n        if metrics:\n            print(f'  metrics: {json.dumps(metrics)[:300]}')\n        if conclusion:\n            print(f'  conclusion: {conclusion}')\n        print()\n\" 2>&1 | head -300",
  "description": "Extract key experiment data from registry dict"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "8865e031-ffce-4dd9-9994-3e808ca9ebe1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BTSUuBujMASAQsY2VtjKtx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1280,
      "cache_read_input_tokens": 64600,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1280
      },
      "output_tokens": 50,
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

_source line 72 · 2026-05-21T16:47:29.748Z_

<details><summary>↩ Tool result · `toolu_01LzPjbBbthnS5hU8LnKQsmB`</summary>

```text
=== precompute-pi05-obj-s6-r2 === [PREPARING]

=== precompute-pi05-obj-s9-r2 === [PREPARING]

=== precompute-pi05-obj-s8-r2 === [PREPARING]

=== precompute-pi05-obj-s7-r2 === [PREPARING]

=== precompute-pi05-obj-s0-r2 === [PREPARING]

=== precompute-pi05-obj-s5-r2 === [PREPARING]

=== precompute-pi05-obj-s4-r2 === [PREPARING]

=== precompute-pi05-obj-s3-r2 === [PREPARING]

=== precompute-pi05-obj-s2-r2 === [PREPARING]

=== precompute-pi05-obj-s1-r2 === [PREPARING]

=== precompute-pi05-obj-s9-fix === [PREPARING]

=== precompute-pi05-obj-s8-fix === [PREPARING]

=== precompute-pi05-obj-s7-fix === [PREPARING]

=== precompute-pi05-obj-s6-fix === [PREPARING]

=== precompute-pi05-obj-s5-fix === [PREPARING]

=== precompute-pi05-obj-shard9 === [PREPARING]

=== precompute-pi05-obj-shard8 === [PREPARING]

=== precompute-pi05-obj-shard7 === [PREPARING]

=== precompute-pi05-obj-shard6 === [PREPARING]

=== precompute-pi05-obj-shard5 === [PREPARING]

=== precompute-pi05-spatial-shard6 === [PREPARING]

=== precompute-pi05-spatial-shard5 === [PREPARING]

=== precompute-pi05-spatial-shard4 === [PREPARING]

=== precompute-pi05-spatial-shard3 === [PREPARING]

=== precompute-pi05-spatial-shard2 === [PREPARING]

=== precompute-pi05-spatial-shard1 === [PREPARING]

=== precompute-pi05-spatial-shard0 === [PREPARING]

=== precompute-pi05-shard0 === [PREPARING]

=== precompute-pi05-shard9 === [PREPARING]

=== precompute-pi05-shard8 === [PREPARING]

=== precompute-pi05-shard7 === [PREPARING]

=== precompute-pi05-shard6 === [PREPARING]

=== precompute-pi05-shard5 === [PREPARING]

=== precompute-pi05-shard4 === [PREPARING]

=== precompute-pi05-shard3 === [PREPARING]

=== precompute-pi05-shard2 === [PREPARING]

=== precompute-pi05-shard1 === [PREPARING]

=== eval-pi05-vla-only-spatial-seed45 === [DONE]
  metrics: {"success_rate": 0.85, "n_tasks": 10, "total_rollouts": 200}
  conclusion: success

=== eval-pi05-vla-only-spatial-seed43-r3 === [DONE]
  metrics: {"success_rate": 0.83, "n_tasks": 10, "total_rollouts": 200}
  conclusion: success

=== eval-pi05-vla-only-spatial-seed42-r3 === [DONE]
  metrics: {"success_rate": 0.845, "n_tasks": 10, "total_rollouts": 200}
  conclusion: success

=== eval-pi05-vla-only-object-seed44-r3 === [DONE]
  metrics: {"success_rate": 0.81, "n_tasks": 10, "total_rollouts": 200}
  conclusion: success

=== eval-pi05-vla-only-object-seed43-r3 === [DONE]
  metrics: {"success_rate": 0.815, "n_tasks": 10, "total_rollouts": 200}
  conclusion: success

=== eval-pi05-vla-only-object-seed42-r3 === [DONE]
  metrics: {"success_rate": 0.82, "n_tasks": 10, "total_rollouts": 200}
  conclusion: success

=== precompute-pi05-features-object === [PREPARING]

=== eval-spatial-obs-only-seed45 === [DONE]
  metrics: {"overall_sr": 0.34, "per_task_sr": [0.9, 0.9, 0, 0.4, 0.1, 0, 0.8, 0, 0.3, 0], "total_rollouts": 100, "n_tasks": 10, "n_rollouts_per_task": 10}
  conclusion: success

=== eval-pi05-vla-only-object-seed44 === [DONE]
  metrics: {"overall_sr": 0, "per_task_sr": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], "total_rollouts": 200, "n_tasks": 10, "n_rollouts_per_task": 20}
  conclusion: failed

=== eval-pi05-vla-only-object-seed43 === [DONE]
  metrics: {"overall_sr": 0, "per_task_sr": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], "total_rollouts": 200, "n_tasks": 10, "n_rollouts_per_task": 20}
  conclusion: failed

=== eval-pi05-vla-only-object-seed42 === [DONE]
  metrics: {"overall_sr": 0, "per_task_sr": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], "total_rollouts": 200, "n_tasks": 10, "n_rollouts_per_task": 20}
  conclusion: failed

=== eval-pi05-vla-only-spatial-seed44 === [DONE]
  conclusion: failed

=== eval-pi05-vla-only-spatial-seed43 === [DONE]
  conclusion: failed

=== eval-pi05-vla-only-spatial-seed42 === [DONE]
  conclusion: failed

=== eval-pi05-baseline-object-seed42-r2 === [PREPARING]
  conclusion: killed

=== eval-k20-obs-only-spatial-seed44 === [DONE]
  metrics: {"overall_success_rate": 0.34, "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "checkpoint_path": "obs_only_K10_eps02_default", "log_path": "/root/acr-vla-conformal-refinement/logs/eval_k20_spatial_seed44.json"}
  conclusion: success

=== eval-k20-obs-only-spatial-seed43 === [DONE]
  metrics: {"overall_success_rate": 0.34, "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "checkpoint_path": "obs_only_K10_eps02_default", "log_path": "/root/acr-vla-conformal-refinement/logs/eval_k20_spatial_seed43.json"}
  conclusion: success

=== eval-k20-obs-only-spatial-seed42 === [DONE]
  metrics: {"overall_success_rate": 0.35, "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "checkpoint_path": "obs_only_K10_eps02_default", "log_path": "/root/acr-vla-conformal-refinement/logs/eval_k20_spatial_seed42.json"}
  conclusion: success

=== eval-k20-obs-only-object-seed45 === [DONE]
  metrics: {"overall_success_rate": 0.19, "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "checkpoint_path": "obs_only_K10_eps02_default", "log_path": "/root/acr-vla-conformal-refinement/logs/eval_k20_object_seed45.json"}
  conclusion: success

=== eval-adaptive-k-spatial-p90-seed44-bjb2 === [DONE]
  conclusion: failed

=== eval-obs-only-object-norm003-seed66 === [DONE]
  metrics: {"overall_success_rate": 0.115, "total_successes": 23, "total_rollouts": 200, "n_rollouts_per_task": 20, "n_tasks": 10, "output_json": "/root/logs/eval_object_crm_obs_only_norm0.03_seed66.json"}
  conclusion: success

=== eval-obs-only-object-norm01-seed66 === [DONE]
  metrics: {"overall_success_rate": 0.135, "total_successes": 27, "total_rollouts": 200, "n_rollouts_per_task": 20, "n_tasks": 10, "output_json": "/root/logs/eval_object_crm_obs_only_norm0.1_seed66.json"}
  conclusion: success

=== eval-obs-only-object-norm005-seed66 === [DONE]
  metrics: {"overall_success_rate": 0.11, "total_successes": 22, "total_rollouts": 200, "n_rollouts_per_task": 20, "n_tasks": 10, "output_json": "/root/logs/eval_object_crm_obs_only_norm0.05_seed66.json"}
  conclusion: success

=== eval-obs-only-object-norm003-seed67 === [DONE]
  metrics: {"overall_success_rate": 0.14}
  conclusion: success

=== eval-k20-obs-only-object-seed44 === [DONE]
  metrics: {"overall_success_rate": 0.18}
  conclusion: success

=== eval-k20-obs-only-object-seed43 === [DONE]
  metrics: {"overall_success_rate": 0.18}
  conclusion: success

=== eval-k20-obs-only-object-seed42 === [DONE]
  metrics: {"overall_success_rate": 0.2}
  conclusion: success

=== eval-crm-object-k20-seed44 === [DONE]
  metrics: {"overall_success_rate": 0.18}
  conclusion: success

=== eval-crm-object-k20-seed42 === [DONE]
  metrics: {"overall_success_rate": 0.2}
  conclusion: success

=== eval-obs-only-object-norm02-seed53 === [DONE]
  metrics: {"overall_success_rate": 0.16}
  conclusion: success

=== eval-obs-only-object-norm02-seed52 === [DONE]
  metrics: {"overall_success_rate": 0.15}
  conclusion: success

=== eval-obs-only-object-norm02-seed51 === [DONE]
  metrics: {"overall_success_rate": 0.17}
  conclusion: success

=== eval-obs-only-object-norm02-seed50 === [DONE]
  metrics: {"overall_success_rate": 0.18}
  conclusion: success

=== eval-obs-only-object-norm02-seed48-r2 === [DONE]
  metrics: {"overall_success_rate": 0.18}
  conclusion: success

=== eval-obs-only-object-norm02-seed47 === [DONE]
  metrics: {"overall_success_rate": 0.2}
  conclusion: success

=== eval-obs-only-object-norm02-seed46 === [DONE]
  metrics: {"overall_success_rate": 0.15}
  conclusion: success

=== eval-obs-only-object-norm02-seed45 === [DONE]
  metrics: {"overall_success_rate": 0.16}
  conclusion: success

=== eval-obs-only-object-norm02-seed44-r2 === [DONE]
  metrics: {"overall_success_rate": 0.16}
  conclusion: success

=== eval-obs-only-object-norm02-seed43-r3 === [DONE]
  metrics: {"overall_success_rate": 0.16}
  conclusion: success

=== eval-obs-only-object-norm02-seed43-r2 === [DONE]
  metrics: {"overall_success_rate": 0.16}
  conclusion: success

=== eval-obs-only-object-norm005-seed67 === [DONE]
  metrics: {"overall_success_rate": 0.1}
  conclusion: success

=== eval-obs-only-object-norm01-seed67 === [DONE]
  metrics: {"overall_success_rate": 0.14}
  conclusion: success

=== eval-vla-only-object-seed50 === [DONE]
  metrics: {"overall_success_rate": 0.09}
  conclusion: success

=== eval-vla-only-object-seed49 === [DONE]
  metrics: {"overall_success_rate": 0.1}
  conclusion: success

=== eval-vla-only-object-seed48 === [DONE]
  metrics: {"overall_success_rate": 0.1}
  conclusion: success

=== eval-vla-only-object-seed46 === [DONE]
  metrics: {"overall_success_rate": 0.13}
  conclusion: success

=== eval-vla-only-object-seed45 === [DONE]
  metrics: {"overall_success_rate": 0.09}
  conclusion: success

=== eval-vla-only-object-seed44-r2 === [DONE]
  metrics: {"overall_success_rate": 0.1}
  conclusion: success

=== eval-plan-a-object-seed42 === [DONE]
  metrics: {"success_rate": 0.19, "sr_pct": "19.0%", "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "mean_uncertainty": 0.1468, "trigger_rate": 0.838}
  conclusion: success

=== eval-vla-only-object-seed43 === [DONE]
  metrics: {"overall_success_rate": 0.12}
  conclusion: success

=== eval-vla-only-object === [DONE]
  metrics: {"overall_success_rate": 0.12}
  conclusion: success

=== eval-plan-a-spatial-seed43 === [DONE]
  metrics: {"success_rate": 0.35, "total_rollouts": 100, "total_successes": 35, "mean_uncertainty": 0.2619, "trigger_rate": 0.98}
  conclusion: success

=== eval-plan-a-object-seed44 === [DONE]
  metrics: {"success_rate": 0.2, "sr_pct": "20.0%", "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "mean_uncertainty": 0.1448, "trigger_rate": 0.832}
  conclusion: success

=== eval-plan-a-spatial-seed42 === [DONE]
  metrics: {"success_rate": 0.34, "total_rollouts": 100, "total_successes": 34, "mean_uncertainty": 0.2679, "trigger_rate": 0.976}
  conclusion: success

=== eval-plan-a-spatial-seed44 === [DONE]
  metrics: {"success_rate": 0.36, "sr_pct": "36.0%", "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "mean_uncertainty": 0.2661, "trigger_rate": 0.978}
  conclusion: success

=== eval-plan-a-object-seed43 === [DONE]
  metrics: {"success_rate": 0.16, "sr_pct": "16.0%", "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "mean_uncertainty": 0.1457, "trigger_rate": 0.84}
  conclusion: success

=== eval-random-selection-object-seed44 === [DONE]
  metrics: {"overall_success_rate": 0.11, "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "per_task_sr": {"alphabet_soup": 0, "cream_cheese": 0.1, "salad_dressing": 0.2, "bbq_sauce": 0.2, "ketchup": 0, "tomato_sauce": 0.1, "butter": 0.1, "milk": 0.1, "chocolate_pudding": 0.2, "orange_juice": 0.1}}
  conclusion: success

=== eval-random-selection-object-seed43 === [DONE]
  metrics: {"success_rate": 0.09, "n_tasks": 10, "n_rollouts": 10, "total_rollouts": 100, "per_task_sr": [0, 0, 0.1, 0.1, 0, 0.1, 0, 0.1, 0.2, 0.3]}
  conclusion: success

=== eval-random-selection-object-seed42-r3 === [PREPARING]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "c74f27c9-edd1-4136-b307-29f3199a3d5b",
  "tool_use_result": {
    "stdout": "=== precompute-pi05-obj-s6-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s9-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s8-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s7-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s0-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s5-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s4-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s3-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s2-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s1-r2 === [PREPARING]\n\n=== precompute-pi05-obj-s9-fix === [PREPARING]\n\n=== precompute-pi05-obj-s8-fix === [PREPARING]\n\n=== precompute-pi05-obj-s7-fix === [PREPARING]\n\n=== precompute-pi05-obj-s6-fix === [PREPARING]\n\n=== precompute-pi05-obj-s5-fix === [PREPARING]\n\n=== precompute-pi05-obj-shard9 === [PREPARING]\n\n=== precompute-pi05-obj-shard8 === [PREPARING]\n\n=== precompute-pi05-obj-shard7 === [PREPARING]\n\n=== precompute-pi05-obj-shard6 === [PREPARING]\n\n=== precompute-pi05-obj-shard5 === [PREPARING]\n\n=== precompute-pi05-spatial-shard6 === [PREPARING]\n\n=== precompute-pi05-spatial-shard5 === [PREPARING]\n\n=== precompute-pi05-spatial-shard4 === [PREPARING]\n\n=== precompute-pi05-spatial-shard3 === [PREPARING]\n\n=== precompute-pi05-spatial-shard2 === [PREPARING]\n\n=== precompute-pi05-spatial-shard1 === [PREPARING]\n\n=== precompute-pi05-spatial-shard0 === [PREPARING]\n\n=== precompute-pi05-shard0 === [PREPARING]\n\n=== precompute-pi05-shard9 === [PREPARING]\n\n=== precompute-pi05-shard8 === [PREPARING]\n\n=== precompute-pi05-shard7 === [PREPARING]\n\n=== precompute-pi05-shard6 === [PREPARING]\n\n=== precompute-pi05-shard5 === [PREPARING]\n\n=== precompute-pi05-shard4 === [PREPARING]\n\n=== precompute-pi05-shard3 === [PREPARING]\n\n=== precompute-pi05-shard2 === [PREPARING]\n\n=== precompute-pi05-shard1 === [PREPARING]\n\n=== eval-pi05-vla-only-spatial-seed45 === [DONE]\n  metrics: {\"success_rate\": 0.85, \"n_tasks\": 10, \"total_rollouts\": 200}\n  conclusion: success\n\n=== eval-pi05-vla-only-spatial-seed43-r3 === [DONE]\n  metrics: {\"success_rate\": 0.83, \"n_tasks\": 10, \"total_rollouts\": 200}\n  conclusion: success\n\n=== eval-pi05-vla-only-spatial-seed42-r3 === [DONE]\n  metrics: {\"success_rate\": 0.845, \"n_tasks\": 10, \"total_rollouts\": 200}\n  conclusion: success\n\n=== eval-pi05-vla-only-object-seed44-r3 === [DONE]\n  metrics: {\"success_rate\": 0.81, \"n_tasks\": 10, \"total_rollouts\": 200}\n  conclusion: success\n\n=== eval-pi05-vla-only-object-seed43-r3 === [DONE]\n  metrics: {\"success_rate\": 0.815, \"n_tasks\": 10, \"total_rollouts\": 200}\n  conclusion: success\n\n=== eval-pi05-vla-only-object-seed42-r3 === [DONE]\n  metrics: {\"success_rate\": 0.82, \"n_tasks\": 10, \"total_rollouts\": 200}\n  conclusion: success\n\n=== precompute-pi05-features-object === [PREPARING]\n\n=== eval-spatial-obs-only-seed45 === [DONE]\n  metrics: {\"overall_sr\": 0.34, \"per_task_sr\": [0.9, 0.9, 0, 0.4, 0.1, 0, 0.8, 0, 0.3, 0], \"total_rollouts\": 100, \"n_tasks\": 10, \"n_rollouts_per_task\": 10}\n  conclusion: success\n\n=== eval-pi05-vla-only-object-seed44 === [DONE]\n  metrics: {\"overall_sr\": 0, \"per_task_sr\": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], \"total_rollouts\": 200, \"n_tasks\": 10, \"n_rollouts_per_task\": 20}\n  conclusion: failed\n\n=== eval-pi05-vla-only-object-seed43 === [DONE]\n  metrics: {\"overall_sr\": 0, \"per_task_sr\": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], \"total_rollouts\": 200, \"n_tasks\": 10, \"n_rollouts_per_task\": 20}\n  conclusion: failed\n\n=== eval-pi05-vla-only-object-seed42 === [DONE]\n  metrics: {\"overall_sr\": 0, \"per_task_sr\": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], \"total_rollouts\": 200, \"n_tasks\": 10, \"n_rollouts_per_task\": 20}\n  conclusion: failed\n\n=== eval-pi05-vla-only-spatial-seed44 === [DONE]\n  conclusion: failed\n\n=== eval-pi05-vla-only-spatial-seed43 === [DONE]\n  conclusion: failed\n\n=== eval-pi05-vla-only-spatial-seed42 === [DONE]\n  conclusion: failed\n\n=== eval-pi05-baseline-object-seed42-r2 === [PREPARING]\n  conclusion: killed\n\n=== eval-k20-obs-only-spatial-seed44 === [DONE]\n  metrics: {\"overall_success_rate\": 0.34, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"checkpoint_path\": \"obs_only_K10_eps02_default\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k20_spatial_seed44.json\"}\n  conclusion: success\n\n=== eval-k20-obs-only-spatial-seed43 === [DONE]\n  metrics: {\"overall_success_rate\": 0.34, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"checkpoint_path\": \"obs_only_K10_eps02_default\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k20_spatial_seed43.json\"}\n  conclusion: success\n\n=== eval-k20-obs-only-spatial-seed42 === [DONE]\n  metrics: {\"overall_success_rate\": 0.35, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"checkpoint_path\": \"obs_only_K10_eps02_default\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k20_spatial_seed42.json\"}\n  conclusion: success\n\n=== eval-k20-obs-only-object-seed45 === [DONE]\n  metrics: {\"overall_success_rate\": 0.19, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"checkpoint_path\": \"obs_only_K10_eps02_default\", \"log_path\": \"/root/acr-vla-conformal-refinement/logs/eval_k20_object_seed45.json\"}\n  conclusion: success\n\n=== eval-adaptive-k-spatial-p90-seed44-bjb2 === [DONE]\n  conclusion: failed\n\n=== eval-obs-only-object-norm003-seed66 === [DONE]\n  metrics: {\"overall_success_rate\": 0.115, \"total_successes\": 23, \"total_rollouts\": 200, \"n_rollouts_per_task\": 20, \"n_tasks\": 10, \"output_json\": \"/root/logs/eval_object_crm_obs_only_norm0.03_seed66.json\"}\n  conclusion: success\n\n=== eval-obs-only-object-norm01-seed66 === [DONE]\n  metrics: {\"overall_success_rate\": 0.135, \"total_successes\": 27, \"total_rollouts\": 200, \"n_rollouts_per_task\": 20, \"n_tasks\": 10, \"output_json\": \"/root/logs/eval_object_crm_obs_only_norm0.1_seed66.json\"}\n  conclusion: success\n\n=== eval-obs-only-object-norm005-seed66 === [DONE]\n  metrics: {\"overall_success_rate\": 0.11, \"total_successes\": 22, \"total_rollouts\": 200, \"n_rollouts_per_task\": 20, \"n_tasks\": 10, \"output_json\": \"/root/logs/eval_object_crm_obs_only_norm0.05_seed66.json\"}\n  conclusion: success\n\n=== eval-obs-only-object-norm003-seed67 === [DONE]\n  metrics: {\"overall_success_rate\": 0.14}\n  conclusion: success\n\n=== eval-k20-obs-only-object-seed44 === [DONE]\n  metrics: {\"overall_success_rate\": 0.18}\n  conclusion: success\n\n=== eval-k20-obs-only-object-seed43 === [DONE]\n  metrics: {\"overall_success_rate\": 0.18}\n  conclusion: success\n\n=== eval-k20-obs-only-object-seed42 === [DONE]\n  metrics: {\"overall_success_rate\": 0.2}\n  conclusion: success\n\n=== eval-crm-object-k20-seed44 === [DONE]\n  metrics: {\"overall_success_rate\": 0.18}\n  conclusion: success\n\n=== eval-crm-object-k20-seed42 === [DONE]\n  metrics: {\"overall_success_rate\": 0.2}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed53 === [DONE]\n  metrics: {\"overall_success_rate\": 0.16}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed52 === [DONE]\n  metrics: {\"overall_success_rate\": 0.15}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed51 === [DONE]\n  metrics: {\"overall_success_rate\": 0.17}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed50 === [DONE]\n  metrics: {\"overall_success_rate\": 0.18}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed48-r2 === [DONE]\n  metrics: {\"overall_success_rate\": 0.18}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed47 === [DONE]\n  metrics: {\"overall_success_rate\": 0.2}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed46 === [DONE]\n  metrics: {\"overall_success_rate\": 0.15}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed45 === [DONE]\n  metrics: {\"overall_success_rate\": 0.16}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed44-r2 === [DONE]\n  metrics: {\"overall_success_rate\": 0.16}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed43-r3 === [DONE]\n  metrics: {\"overall_success_rate\": 0.16}\n  conclusion: success\n\n=== eval-obs-only-object-norm02-seed43-r2 === [DONE]\n  metrics: {\"overall_success_rate\": 0.16}\n  conclusion: success\n\n=== eval-obs-only-object-norm005-seed67 === [DONE]\n  metrics: {\"overall_success_rate\": 0.1}\n  conclusion: success\n\n=== eval-obs-only-object-norm01-seed67 === [DONE]\n  metrics: {\"overall_success_rate\": 0.14}\n  conclusion: success\n\n=== eval-vla-only-object-seed50 === [DONE]\n  metrics: {\"overall_success_rate\": 0.09}\n  conclusion: success\n\n=== eval-vla-only-object-seed49 === [DONE]\n  metrics: {\"overall_success_rate\": 0.1}\n  conclusion: success\n\n=== eval-vla-only-object-seed48 === [DONE]\n  metrics: {\"overall_success_rate\": 0.1}\n  conclusion: success\n\n=== eval-vla-only-object-seed46 === [DONE]\n  metrics: {\"overall_success_rate\": 0.13}\n  conclusion: success\n\n=== eval-vla-only-object-seed45 === [DONE]\n  metrics: {\"overall_success_rate\": 0.09}\n  conclusion: success\n\n=== eval-vla-only-object-seed44-r2 === [DONE]\n  metrics: {\"overall_success_rate\": 0.1}\n  conclusion: success\n\n=== eval-plan-a-object-seed42 === [DONE]\n  metrics: {\"success_rate\": 0.19, \"sr_pct\": \"19.0%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"mean_uncertainty\": 0.1468, \"trigger_rate\": 0.838}\n  conclusion: success\n\n=== eval-vla-only-object-seed43 === [DONE]\n  metrics: {\"overall_success_rate\": 0.12}\n  conclusion: success\n\n=== eval-vla-only-object === [DONE]\n  metrics: {\"overall_success_rate\": 0.12}\n  conclusion: success\n\n=== eval-plan-a-spatial-seed43 === [DONE]\n  metrics: {\"success_rate\": 0.35, \"total_rollouts\": 100, \"total_successes\": 35, \"mean_uncertainty\": 0.2619, \"trigger_rate\": 0.98}\n  conclusion: success\n\n=== eval-plan-a-object-seed44 === [DONE]\n  metrics: {\"success_rate\": 0.2, \"sr_pct\": \"20.0%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"mean_uncertainty\": 0.1448, \"trigger_rate\": 0.832}\n  conclusion: success\n\n=== eval-plan-a-spatial-seed42 === [DONE]\n  metrics: {\"success_rate\": 0.34, \"total_rollouts\": 100, \"total_successes\": 34, \"mean_uncertainty\": 0.2679, \"trigger_rate\": 0.976}\n  conclusion: success\n\n=== eval-plan-a-spatial-seed44 === [DONE]\n  metrics: {\"success_rate\": 0.36, \"sr_pct\": \"36.0%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"mean_uncertainty\": 0.2661, \"trigger_rate\": 0.978}\n  conclusion: success\n\n=== eval-plan-a-object-seed43 === [DONE]\n  metrics: {\"success_rate\": 0.16, \"sr_pct\": \"16.0%\", \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"mean_uncertainty\": 0.1457, \"trigger_rate\": 0.84}\n  conclusion: success\n\n=== eval-random-selection-object-seed44 === [DONE]\n  metrics: {\"overall_success_rate\": 0.11, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"per_task_sr\": {\"alphabet_soup\": 0, \"cream_cheese\": 0.1, \"salad_dressing\": 0.2, \"bbq_sauce\": 0.2, \"ketchup\": 0, \"tomato_sauce\": 0.1, \"butter\": 0.1, \"milk\": 0.1, \"chocolate_pudding\": 0.2, \"orange_juice\": 0.1}}\n  conclusion: success\n\n=== eval-random-selection-object-seed43 === [DONE]\n  metrics: {\"success_rate\": 0.09, \"n_tasks\": 10, \"n_rollouts\": 10, \"total_rollouts\": 100, \"per_task_sr\": [0, 0, 0.1, 0.1, 0, 0.1, 0, 0.1, 0.2, 0.3]}\n  conclusion: success\n\n=== eval-random-selection-object-seed42-r3 === [PREPARING]",
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

_source line 73_

<details><summary>Logged reasoning block</summary>

```text
Let me get more data from the registry for key experiments and also check for π0.5 related experiments more specifically.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "b0be43b4-7ab5-4602-916c-47c22c34bda1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NoXGvGUsBjVydmgo2NVFgo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5015,
      "cache_read_input_tokens": 65880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5015
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

_source line 74_

Let me get more registry data and run the full LaTeX compilation.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "3657fab5-d87e-424b-b979-ed6a6a8a9ef0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NoXGvGUsBjVydmgo2NVFgo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5015,
      "cache_read_input_tokens": 65880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5015
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

_source line 75_

<details open><summary>🔧 Tool call — Bash · `toolu_01APAwdVCBuFqgeGx64ZSLHp`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get ALL experiments with metrics for comprehensive check\nfor eid, edata in exps.items():\n    metrics = edata.get('metrics',{})\n    status = edata.get('status','?')\n    # Focus on eval experiments with metrics\n    if metrics and status == 'DONE' and 'eval' in eid:\n        sr = metrics.get('overall_success_rate') or metrics.get('success_rate') or metrics.get('overall_sr')\n        if sr is not None:\n            print(f'{eid}: SR={sr} ({sr*100:.1f}%)')\n\" 2>&1 | sort",
  "description": "Get all eval experiments with success rates"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "e4f36062-be07-453e-81a9-5792fd2981c7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NoXGvGUsBjVydmgo2NVFgo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5015,
      "cache_read_input_tokens": 65880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5015
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

_source line 76 · 2026-05-21T16:47:42.717Z_

<details><summary>↩ Tool result · `toolu_01APAwdVCBuFqgeGx64ZSLHp`</summary>

```text
                            ^^^^^^^^^^^^
    print(f'{eid}: SR={sr} ({sr*100:.1f}%)')
  File "&lt;string>", line 16, in &lt;module>
Traceback (most recent call last):
ValueError: Unknown format code 'f' for object of type 'str'
eval-acr-object-obs-only-default: SR=0.17 (17.0%)
eval-acr-object-obs-only-norm02: SR=0.22 (22.0%)
eval-acr-object-v4-default-r2: SR=0 (0.0%)
eval-acr-object-v4-scalar: SR=9 (900.0%)
eval-acr-spatial-v3: SR=0.025 (2.5%)
eval-adaptive-k-p25-seed42: SR=0.15 (15.0%)
eval-adaptive-k-p25-seed43: SR=0.13 (13.0%)
eval-adaptive-k-p25-seed44-r2: SR=0.15 (15.0%)
eval-adaptive-k-p50-seed42: SR=0.16 (16.0%)
eval-adaptive-k-p50-seed43: SR=0.16 (16.0%)
eval-adaptive-k-p50-seed44: SR=0.14 (14.0%)
eval-adaptive-k-p75-seed42: SR=0.12 (12.0%)
eval-adaptive-k-p75-seed43: SR=0.13 (13.0%)
eval-adaptive-k-p75-seed44: SR=0.16 (16.0%)
eval-adaptive-k-p90-seed42: SR=0.12 (12.0%)
eval-adaptive-k-p90-seed43: SR=0.14 (14.0%)
eval-adaptive-k-p90-seed44: SR=0.14 (14.0%)
eval-adaptive-k-spatial-p25-seed42: SR=0.33 (33.0%)
eval-adaptive-k-spatial-p50-seed43-r2: SR=0.33 (33.0%)
eval-adaptive-k-spatial-p50-seed44-r2: SR=0.33 (33.0%)
eval-adaptive-k-spatial-p75-seed43: SR=34 (3400.0%)
eval-adaptive-k-spatial-p90-seed42: SR=0.31 (31.0%)
eval-adaptive-k-spatial-p90-seed43: SR=0.32 (32.0%)
eval-adaptive-k-spatial-p90-seed44: SR=0.36 (36.0%)
eval-adaptive-unc-head-object-seed42: SR=0.14 (14.0%)
eval-adaptive-unc-head-object-seed43: SR=0.11 (11.0%)
eval-adaptive-unc-head-object-seed44: SR=0.11 (11.0%)
eval-argmin-object-seed43: SR=0.17 (17.0%)
eval-argmin-object-seed44-r2: SR=0.13 (13.0%)
eval-argmin-object-seed45: SR=0.12 (12.0%)
eval-argmin-object-seed46: SR=0.1 (10.0%)
eval-argmin-object-seed47: SR=0.1 (10.0%)
eval-argmin-object-seed48: SR=0.15 (15.0%)
eval-argmin-object-seed49: SR=0.16 (16.0%)
eval-argmin-object-seed50: SR=0.13 (13.0%)
eval-crm-goal-seed42: SR=0.67 (67.0%)
eval-crm-goal-seed43: SR=0.72 (72.0%)
eval-crm-goal-seed44-r2: SR=0.64 (64.0%)
eval-crm-goal-seed45-r2: SR=0.65 (65.0%)
eval-crm-goal-seed46: SR=0.72 (72.0%)
eval-crm-long-seed42: SR=0.17 (17.0%)
eval-crm-long-seed43: SR=0.15 (15.0%)
eval-crm-long-seed44: SR=0.2 (20.0%)
eval-crm-long-seed45: SR=0.18 (18.0%)
eval-crm-long-seed46: SR=0.18 (18.0%)
eval-crm-long-seed47: SR=0.17 (17.0%)
eval-crm-long-seed50: SR=0.14 (14.0%)
eval-crm-object-k20-seed42: SR=0.2 (20.0%)
eval-crm-object-k20-seed43: SR=0.18 (18.0%)
eval-crm-object-k20-seed44: SR=0.18 (18.0%)
eval-crm-spatial-k10-seed51: SR=0.36 (36.0%)
eval-direct-correction-object-seed42-r3: SR=0.14 (14.0%)
eval-k1-crm-accg-object-seed42: SR=0.11 (11.0%)
eval-k1-crm-accg-object-seed43: SR=0.12 (12.0%)
eval-k1-crm-accg-object-seed44: SR=0.07 (7.0%)
eval-k1-crm-multiscale-object-seed42: SR=0.12 (12.0%)
eval-k1-crm-multiscale-object-seed43-r2: SR=0.09 (9.0%)
eval-k1-crm-multiscale-object-seed43: SR=0.09 (9.0%)
eval-k1-crm-multiscale-object-seed44-r2: SR=0.1 (10.0%)
eval-k1-crm-multiscale-object-seed44: SR=0.1 (10.0%)
eval-k20-obs-only-object-seed42: SR=0.2 (20.0%)
eval-k20-obs-only-object-seed43: SR=0.18 (18.0%)
eval-k20-obs-only-object-seed44: SR=0.18 (18.0%)
eval-k20-obs-only-object-seed45: SR=0.19 (19.0%)
eval-k20-obs-only-spatial-seed42: SR=0.35 (35.0%)
eval-k20-obs-only-spatial-seed43: SR=0.34 (34.0%)
eval-k20-obs-only-spatial-seed44: SR=0.34 (34.0%)
eval-k5-obs-only-object-seed44: SR=0.14 (14.0%)
eval-lto-splitA-heldout-r2: SR=0.02 (2.0%)
eval-lto-splitA-heldout-v2: SR=0.02 (2.0%)
eval-lto-splitA-vla-only-r2: SR=0.14 (14.0%)
eval-lto-splitA-vla-only-r3: SR=0.14 (14.0%)
eval-lto-splitA-vla-only-v2: SR=0.14 (14.0%)
eval-mag-obsonly-norm003-object: SR=0.16 (16.0%)
eval-mag-obsonly-norm005-object: SR=0.13 (13.0%)
eval-mag-obsonly-norm005: SR=35 (3500.0%)
eval-mag-obsonly-norm02: SR=35 (3500.0%)
eval-mag-obsonly-norm03-object: SR=0.19 (19.0%)
eval-mag-perdof-norm003-object: SR=0.14 (14.0%)
eval-mag-perdof-norm003: SR=30 (3000.0%)
eval-mag-perdof-norm005-object: SR=0.14 (14.0%)
eval-mag-perdof-norm02-object: SR=0.11 (11.0%)
eval-mag-perdof-norm02-seed43-object-r3: SR=0.09 (9.0%)
eval-mag-perdof-norm03-object-r3: SR=0.04 (4.0%)
eval-object-v8-full: SR=0.13 (13.0%)
eval-obs-only-goal-norm02-seed52: SR=0.68 (68.0%)
eval-obs-only-object-default-seed44: SR=0.16 (16.0%)
eval-obs-only-object-default-seed45: SR=0.12 (12.0%)
eval-obs-only-object-default-seed46: SR=0.15 (15.0%)
eval-obs-only-object-default-seed47: SR=0.16 (16.0%)
eval-obs-only-object-default-seed48-r2: SR=0.17 (17.0%)
eval-obs-only-object-default-seed48: SR=0.17 (17.0%)
eval-obs-only-object-norm003-seed43-r2: SR=0.14 (14.0%)
eval-obs-only-object-norm003-seed43: SR=0.14 (14.0%)
eval-obs-only-object-norm003-seed44-bjb2: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed44-r2: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed44: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed45: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed46: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed47-r2: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed48: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed56: SR=0.15 (15.0%)
eval-obs-only-object-norm003-seed59: SR=0.13 (13.0%)
eval-obs-only-object-norm003-seed64: SR=0.17 (17.0%)
eval-obs-only-object-norm003-seed65: SR=0.17 (17.0%)
eval-obs-only-object-norm003-seed66: SR=0.115 (11.5%)
eval-obs-only-object-norm003-seed67: SR=0.14 (14.0%)
eval-obs-only-object-norm003-seed73: SR=0.16 (16.0%)
eval-obs-only-object-norm005-seed43-r2: SR=0.14 (14.0%)
eval-obs-only-object-norm005-seed43: SR=0.13 (13.0%)
eval-obs-only-object-norm005-seed44: SR=0.12 (12.0%)
eval-obs-only-object-norm005-seed47: SR=0.13 (13.0%)
eval-obs-only-object-norm005-seed48: SR=0.13 (13.0%)
eval-obs-only-object-norm005-seed49: SR=0.15 (15.0%)
eval-obs-only-object-norm005-seed50: SR=0.13 (13.0%)
eval-obs-only-object-norm005-seed55: SR=0.15 (15.0%)
eval-obs-only-object-norm005-seed58: SR=0.16 (16.0%)
eval-obs-only-object-norm005-seed61: SR=0.15 (15.0%)
eval-obs-only-object-norm005-seed64: SR=0.15 (15.0%)
eval-obs-only-object-norm005-seed65: SR=0.14 (14.0%)
eval-obs-only-object-norm005-seed66: SR=0.11 (11.0%)
eval-obs-only-object-norm005-seed67: SR=0.1 (10.0%)
eval-obs-only-object-norm005-seed72: SR=0.11 (11.0%)
eval-obs-only-object-norm005-seed75: SR=0.15 (15.0%)
eval-obs-only-object-norm01-seed44: SR=0.16 (16.0%)
eval-obs-only-object-norm01-seed45-r2: SR=0.17 (17.0%)
eval-obs-only-object-norm01-seed45: SR=0.14 (14.0%)
eval-obs-only-object-norm01-seed46-r3: SR=0.18 (18.0%)
eval-obs-only-object-norm01-seed47: SR=0.17 (17.0%)
eval-obs-only-object-norm01-seed48: SR=0.13 (13.0%)
eval-obs-only-object-norm01-seed49: SR=0.16 (16.0%)
eval-obs-only-object-norm01-seed50: SR=0.14 (14.0%)
eval-obs-only-object-norm01-seed51-r3: SR=0.11 (11.0%)
eval-obs-only-object-norm01-seed51: SR=0.11 (11.0%)
eval-obs-only-object-norm01-seed52-r3: SR=0.15 (15.0%)
eval-obs-only-object-norm01-seed52: SR=0.15 (15.0%)
eval-obs-only-object-norm01-seed53: SR=0.19 (19.0%)
eval-obs-only-object-norm01-seed54: SR=0.15 (15.0%)
eval-obs-only-object-norm01-seed57: SR=0.19 (19.0%)
eval-obs-only-object-norm01-seed60: SR=0.15 (15.0%)
eval-obs-only-object-norm01-seed64: SR=0.15 (15.0%)
eval-obs-only-object-norm01-seed65: SR=0.15 (15.0%)
eval-obs-only-object-norm01-seed66: SR=0.135 (13.5%)
eval-obs-only-object-norm01-seed67: SR=0.14 (14.0%)
eval-obs-only-object-norm01-seed71: SR=0.16 (16.0%)
eval-obs-only-object-norm01-seed74: SR=0.13 (13.0%)
eval-obs-only-object-norm02-k5-seed42: SR=0.14 (14.0%)
eval-obs-only-object-norm02-k5-seed43: SR=0.19 (19.0%)
eval-obs-only-object-norm02-k5-seed44: SR=0.17 (17.0%)
eval-obs-only-object-norm02-k5-seed45: SR=0.15 (15.0%)
eval-obs-only-object-norm02-k5-seed46: SR=0.16 (16.0%)
eval-obs-only-object-norm02-k5-seed47: SR=0.13 (13.0%)
eval-obs-only-object-norm02-k5-seed48: SR=0.18 (18.0%)
eval-obs-only-object-norm02-seed42: SR=0.2 (20.0%)
eval-obs-only-object-norm02-seed43-r2: SR=0.16 (16.0%)
eval-obs-only-object-norm02-seed43-r3: SR=0.16 (16.0%)
eval-obs-only-object-norm02-seed44-r2: SR=0.16 (16.0%)
eval-obs-only-object-norm02-seed45: SR=0.16 (16.0%)
eval-obs-only-object-norm02-seed46: SR=0.15 (15.0%)
eval-obs-only-object-norm02-seed47: SR=0.2 (20.0%)
eval-obs-only-object-norm02-seed48-r2: SR=0.18 (18.0%)
eval-obs-only-object-norm02-seed49: SR=0.14 (14.0%)
eval-obs-only-object-norm02-seed50: SR=0.18 (18.0%)
eval-obs-only-object-norm02-seed51: SR=0.17 (17.0%)
eval-obs-only-object-norm02-seed52: SR=0.15 (15.0%)
eval-obs-only-object-norm02-seed53: SR=0.16 (16.0%)
eval-obs-only-object-norm03-seed44: SR=0.18 (18.0%)
eval-obs-only-object-norm03-seed45-r2: SR=14 (1400.0%)
eval-obs-only-object-norm03-seed46: SR=0.17 (17.0%)
eval-obs-only-object-norm03-seed48: SR=0.16 (16.0%)
eval-obs-only-object-seed43: SR=0.12 (12.0%)
eval-obs-only-spatial-norm02-k5-seed42: SR=0.35 (35.0%)
eval-obs-only-spatial-norm02-k5-seed43: SR=0.32 (32.0%)
eval-obs-only-spatial-norm02-k5-seed44-r2: SR=0.37 (37.0%)
eval-obs-only-spatial-norm02-k5-seed45-r2: SR=0.34 (34.0%)
eval-obs-only-spatial-norm02-seed43-r2: SR=0.34 (34.0%)
eval-obs-only-spatial-norm02-seed44: SR=0.36 (36.0%)
eval-obs-only-spatial-norm02-seed45: SR=0.34 (34.0%)
eval-obs-only-spatial-norm02-seed47: SR=0.32 (32.0%)
eval-obs-only-spatial-norm02-seed48: SR=0.35 (35.0%)
eval-obs-only-spatial-norm02-seed50: SR=0.35 (35.0%)
eval-obs-only-spatial-norm02-seed52: SR=0.33 (33.0%)
eval-obs-only-spatial-seed48: SR=0.35 (35.0%)
eval-openvla-object-vla-only-seed42-v2: SR=0.69 (69.0%)
eval-perdof-object-default-seed44: SR=0 (0.0%)
eval-perdof-object-norm003-seed43: SR=0.13 (13.0%)
eval-perdof-object-norm003-seed46: SR=0.09 (9.0%)
eval-perdof-object-norm003-seed47: SR=0.15 (15.0%)
eval-perdof-object-norm003-seed48: SR=0.13 (13.0%)
eval-perdof-object-norm005-seed43: SR=0.13 (13.0%)
eval-perdof-object-norm005-seed44: SR=0.09 (9.0%)
eval-perdof-object-norm005-seed45-r2: SR=0.1 (10.0%)
eval-perdof-object-norm005-seed46: SR=0.11 (11.0%)
eval-perdof-object-norm005-seed47: SR=0.1 (10.0%)
eval-perdof-object-norm01-seed44: SR=0.08 (8.0%)
eval-perdof-object-norm01-seed45: SR=0.11 (11.0%)
eval-perdof-object-norm01-seed46-r2: SR=0.1 (10.0%)
eval-perdof-object-norm01-seed46: SR=0.1 (10.0%)
eval-perdof-object-norm01-seed47-bjb1: SR=0.14 (14.0%)
eval-perdof-object-norm01-seed48: SR=0.12 (12.0%)
eval-perdof-object-norm02-seed43-r3: SR=0.09 (9.0%)
eval-perdof-object-norm02-seed43: SR=0.09 (9.0%)
eval-perdof-object-norm02-seed44: SR=0.1 (10.0%)
eval-perdof-object-norm02-seed45-r3: SR=0.12 (12.0%)
eval-perdof-object-norm02-seed45: SR=0.09 (9.0%)
eval-perdof-object-norm02-seed46: SR=0.09 (9.0%)
eval-perdof-object-norm02-seed47: SR=0.11 (11.0%)
eval-perdof-object-norm02-seed49: SR=0.12 (12.0%)
eval-perdof-object-norm02-seed50: SR=0.1 (10.0%)
eval-perdof-object-norm03-seed44-r2: SR=0.04 (4.0%)
eval-perdof-object-norm03-seed44: SR=0.04 (4.0%)
eval-perdof-object-norm03-seed45-r2: SR=0.06 (6.0%)
eval-perdof-object-norm03-seed46: SR=0.04 (4.0%)
eval-perdof-object-norm03-seed47: SR=0.05 (5.0%)
eval-perdof-object-seed43: SR=0.12 (12.0%)
eval-perdof-object-seed44: SR=0.08 (8.0%)
eval-pi05-vla-only-object-seed42-r3: SR=0.82 (82.0%)
eval-pi05-vla-only-object-seed42: SR=0 (0.0%)
eval-pi05-vla-only-object-seed43-r3: SR=0.815 (81.5%)
eval-pi05-vla-only-object-seed43: SR=0 (0.0%)
eval-pi05-vla-only-object-seed44-r3: SR=0.81 (81.0%)
eval-pi05-vla-only-object-seed44: SR=0 (0.0%)
eval-pi05-vla-only-spatial-seed42-r3: SR=0.845 (84.5%)
eval-pi05-vla-only-spatial-seed43-r3: SR=0.83 (83.0%)
eval-pi05-vla-only-spatial-seed45: SR=0.85 (85.0%)
eval-plan-a-object-seed42: SR=0.19 (19.0%)
eval-plan-a-object-seed43: SR=0.16 (16.0%)
eval-plan-a-object-seed44: SR=0.2 (20.0%)
eval-plan-a-spatial-seed42: SR=0.34 (34.0%)
eval-plan-a-spatial-seed43: SR=0.35 (35.0%)
eval-plan-a-spatial-seed44: SR=0.36 (36.0%)
eval-random-selection-object-k5-seed42-r2: SR=0.14 (14.0%)
eval-random-selection-object-k5-seed43-r2: SR=0.11 (11.0%)
eval-random-selection-object-k5-seed44-r2: SR=0.1 (10.0%)
eval-random-selection-object-k5-seed45-r2: SR=0.07 (7.0%)
eval-random-selection-object-seed42: SR=0.11 (11.0%)
eval-random-selection-object-seed43: SR=0.09 (9.0%)
eval-random-selection-object-seed44: SR=0.11 (11.0%)
eval-random-selection-object-seed45: SR=0.1 (10.0%)
eval-random-selection-object-seed46-r3: SR=0.1 (10.0%)
eval-random-selection-object-seed48: SR=0.1 (10.0%)
eval-random-selection-object-seed49: SR=0.12 (12.0%)
eval-random-selection-spatial-seed42-r3: SR=0.34 (34.0%)
eval-random-selection-spatial-seed43: SR=0.26 (26.0%)
eval-random-selection-spatial-seed44: SR=0.28 (28.0%)
eval-reconvla-object: SR=0.12 (12.0%)
eval-reconvla-spatial-v3: SR=0.34 (34.0%)
eval-scalar-object-seed44-r2: SR=0.06 (6.0%)
eval-scalar-object-seed45-r2: SR=0.07 (7.0%)
eval-scalar-object-seed45: SR=0.09 (9.0%)
eval-scalar-object-seed46: SR=0.09 (9.0%)
eval-spatial-obs-only-seed45: SR=0.34 (34.0%)
eval-spatial-v7-full: SR=0.3 (30.0%)
eval-vla-mean-object-seed43: SR=0.15 (15.0%)
eval-vla-mean-object-seed44: SR=0.1 (10.0%)
eval-vla-mean-object-seed45: SR=0.13 (13.0%)
eval-vla-mean-object: SR=12 (1200.0%)
eval-vla-only-goal-seed42: SR=0.71 (71.0%)
eval-vla-only-goal-seed43: SR=0.69 (69.0%)
eval-vla-only-goal-seed45: SR=0.63 (63.0%)
eval-vla-only-goal-seed46: SR=0.71 (71.0%)
eval-vla-only-goal-seed49: SR=0.65 (65.0%)
eval-vla-only-long-seed42: SR=0.11 (11.0%)
eval-vla-only-long-seed43: SR=0.13 (13.0%)
eval-vla-only-long-seed44: SR=0.12 (12.0%)
eval-vla-only-long-seed45: SR=0.17 (17.0%)
eval-vla-only-long-seed46: SR=0.18 (18.0%)
eval-vla-only-long-seed47: SR=0.14 (14.0%)
eval-vla-only-long-seed48: SR=0.14 (14.0%)
eval-vla-only-long-seed50: SR=0.16 (16.0%)
eval-vla-only-long-seed51: SR=0.15 (15.0%)
eval-vla-only-long-seed52: SR=0.17 (17.0%)
eval-vla-only-object-seed43: SR=0.12 (12.0%)
eval-vla-only-object-seed44-r2: SR=0.1 (10.0%)
eval-vla-only-object-seed45-r2: SR=0.11 (11.0%)
eval-vla-only-object-seed45: SR=0.09 (9.0%)
eval-vla-only-object-seed46: SR=0.13 (13.0%)
eval-vla-only-object-seed47: SR=0.1 (10.0%)
eval-vla-only-object-seed48-r2: SR=0.11 (11.0%)
eval-vla-only-object-seed48: SR=0.1 (10.0%)
eval-vla-only-object-seed49: SR=0.1 (10.0%)
eval-vla-only-object-seed50: SR=0.09 (9.0%)
eval-vla-only-object: SR=0.12 (12.0%)
eval-vla-only-spatial-seed42: SR=0.3 (30.0%)
eval-vla-only-spatial-seed43: SR=0.29 (29.0%)
eval-vla-only-spatial-seed44: SR=0.31 (31.0%)
eval-vla-only-spatial-seed45: SR=0.27 (27.0%)
eval-vla-only-spatial-seed46: SR=0.3 (30.0%)
eval-vla-only-spatial-seed47: SR=0.3 (30.0%)
eval-vla-only-spatial-seed48: SR=0.3 (30.0%)
eval_obs_only_norm01_seed48: SR=0.18 (18.0%)
eval_obs_only_norm03_seed48: SR=0.16 (16.0%)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "557aea80-d989-443e-800d-0bc959893f6b",
  "tool_use_result": {
    "stdout": "                            ^^^^^^^^^^^^\n    print(f'{eid}: SR={sr} ({sr*100:.1f}%)')\n  File \"&lt;string>\", line 16, in &lt;module>\nTraceback (most recent call last):\nValueError: Unknown format code 'f' for object of type 'str'\neval-acr-object-obs-only-default: SR=0.17 (17.0%)\neval-acr-object-obs-only-norm02: SR=0.22 (22.0%)\neval-acr-object-v4-default-r2: SR=0 (0.0%)\neval-acr-object-v4-scalar: SR=9 (900.0%)\neval-acr-spatial-v3: SR=0.025 (2.5%)\neval-adaptive-k-p25-seed42: SR=0.15 (15.0%)\neval-adaptive-k-p25-seed43: SR=0.13 (13.0%)\neval-adaptive-k-p25-seed44-r2: SR=0.15 (15.0%)\neval-adaptive-k-p50-seed42: SR=0.16 (16.0%)\neval-adaptive-k-p50-seed43: SR=0.16 (16.0%)\neval-adaptive-k-p50-seed44: SR=0.14 (14.0%)\neval-adaptive-k-p75-seed42: SR=0.12 (12.0%)\neval-adaptive-k-p75-seed43: SR=0.13 (13.0%)\neval-adaptive-k-p75-seed44: SR=0.16 (16.0%)\neval-adaptive-k-p90-seed42: SR=0.12 (12.0%)\neval-adaptive-k-p90-seed43: SR=0.14 (14.0%)\neval-adaptive-k-p90-seed44: SR=0.14 (14.0%)\neval-adaptive-k-spatial-p25-seed42: SR=0.33 (33.0%)\neval-adaptive-k-spatial-p50-seed43-r2: SR=0.33 (33.0%)\neval-adaptive-k-spatial-p50-seed44-r2: SR=0.33 (33.0%)\neval-adaptive-k-spatial-p75-seed43: SR=34 (3400.0%)\neval-adaptive-k-spatial-p90-seed42: SR=0.31 (31.0%)\neval-adaptive-k-spatial-p90-seed43: SR=0.32 (32.0%)\neval-adaptive-k-spatial-p90-seed44: SR=0.36 (36.0%)\neval-adaptive-unc-head-object-seed42: SR=0.14 (14.0%)\neval-adaptive-unc-head-object-seed43: SR=0.11 (11.0%)\neval-adaptive-unc-head-object-seed44: SR=0.11 (11.0%)\neval-argmin-object-seed43: SR=0.17 (17.0%)\neval-argmin-object-seed44-r2: SR=0.13 (13.0%)\neval-argmin-object-seed45: SR=0.12 (12.0%)\neval-argmin-object-seed46: SR=0.1 (10.0%)\neval-argmin-object-seed47: SR=0.1 (10.0%)\neval-argmin-object-seed48: SR=0.15 (15.0%)\neval-argmin-object-seed49: SR=0.16 (16.0%)\neval-argmin-object-seed50: SR=0.13 (13.0%)\neval-crm-goal-seed42: SR=0.67 (67.0%)\neval-crm-goal-seed43: SR=0.72 (72.0%)\neval-crm-goal-seed44-r2: SR=0.64 (64.0%)\neval-crm-goal-seed45-r2: SR=0.65 (65.0%)\neval-crm-goal-seed46: SR=0.72 (72.0%)\neval-crm-long-seed42: SR=0.17 (17.0%)\neval-crm-long-seed43: SR=0.15 (15.0%)\neval-crm-long-seed44: SR=0.2 (20.0%)\neval-crm-long-seed45: SR=0.18 (18.0%)\neval-crm-long-seed46: SR=0.18 (18.0%)\neval-crm-long-seed47: SR=0.17 (17.0%)\neval-crm-long-seed50: SR=0.14 (14.0%)\neval-crm-object-k20-seed42: SR=0.2 (20.0%)\neval-crm-object-k20-seed43: SR=0.18 (18.0%)\neval-crm-object-k20-seed44: SR=0.18 (18.0%)\neval-crm-spatial-k10-seed51: SR=0.36 (36.0%)\neval-direct-correction-object-seed42-r3: SR=0.14 (14.0%)\neval-k1-crm-accg-object-seed42: SR=0.11 (11.0%)\neval-k1-crm-accg-object-seed43: SR=0.12 (12.0%)\neval-k1-crm-accg-object-seed44: SR=0.07 (7.0%)\neval-k1-crm-multiscale-object-seed42: SR=0.12 (12.0%)\neval-k1-crm-multiscale-object-seed43-r2: SR=0.09 (9.0%)\neval-k1-crm-multiscale-object-seed43: SR=0.09 (9.0%)\neval-k1-crm-multiscale-object-seed44-r2: SR=0.1 (10.0%)\neval-k1-crm-multiscale-object-seed44: SR=0.1 (10.0%)\neval-k20-obs-only-object-seed42: SR=0.2 (20.0%)\neval-k20-obs-only-object-seed43: SR=0.18 (18.0%)\neval-k20-obs-only-object-seed44: SR=0.18 (18.0%)\neval-k20-obs-only-object-seed45: SR=0.19 (19.0%)\neval-k20-obs-only-spatial-seed42: SR=0.35 (35.0%)\neval-k20-obs-only-spatial-seed43: SR=0.34 (34.0%)\neval-k20-obs-only-spatial-seed44: SR=0.34 (34.0%)\neval-k5-obs-only-object-seed44: SR=0.14 (14.0%)\neval-lto-splitA-heldout-r2: SR=0.02 (2.0%)\neval-lto-splitA-heldout-v2: SR=0.02 (2.0%)\neval-lto-splitA-vla-only-r2: SR=0.14 (14.0%)\neval-lto-splitA-vla-only-r3: SR=0.14 (14.0%)\neval-lto-splitA-vla-only-v2: SR=0.14 (14.0%)\neval-mag-obsonly-norm003-object: SR=0.16 (16.0%)\neval-mag-obsonly-norm005-object: SR=0.13 (13.0%)\neval-mag-obsonly-norm005: SR=35 (3500.0%)\neval-mag-obsonly-norm02: SR=35 (3500.0%)\neval-mag-obsonly-norm03-object: SR=0.19 (19.0%)\neval-mag-perdof-norm003-object: SR=0.14 (14.0%)\neval-mag-perdof-norm003: SR=30 (3000.0%)\neval-mag-perdof-norm005-object: SR=0.14 (14.0%)\neval-mag-perdof-norm02-object: SR=0.11 (11.0%)\neval-mag-perdof-norm02-seed43-object-r3: SR=0.09 (9.0%)\neval-mag-perdof-norm03-object-r3: SR=0.04 (4.0%)\neval-object-v8-full: SR=0.13 (13.0%)\neval-obs-only-goal-norm02-seed52: SR=0.68 (68.0%)\neval-obs-only-object-default-seed44: SR=0.16 (16.0%)\neval-obs-only-object-default-seed45: SR=0.12 (12.0%)\neval-obs-only-object-default-seed46: SR=0.15 (15.0%)\neval-obs-only-object-default-seed47: SR=0.16 (16.0%)\neval-obs-only-object-default-seed48-r2: SR=0.17 (17.0%)\neval-obs-only-object-default-seed48: SR=0.17 (17.0%)\neval-obs-only-object-norm003-seed43-r2: SR=0.14 (14.0%)\neval-obs-only-object-norm003-seed43: SR=0.14 (14.0%)\neval-obs-only-object-norm003-seed44-bjb2: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed44-r2: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed44: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed45: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed46: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed47-r2: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed48: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed56: SR=0.15 (15.0%)\neval-obs-only-object-norm003-seed59: SR=0.13 (13.0%)\neval-obs-only-object-norm003-seed64: SR=0.17 (17.0%)\neval-obs-only-object-norm003-seed65: SR=0.17 (17.0%)\neval-obs-only-object-norm003-seed66: SR=0.115 (11.5%)\neval-obs-only-object-norm003-seed67: SR=0.14 (14.0%)\neval-obs-only-object-norm003-seed73: SR=0.16 (16.0%)\neval-obs-only-object-norm005-seed43-r2: SR=0.14 (14.0%)\neval-obs-only-object-norm005-seed43: SR=0.13 (13.0%)\neval-obs-only-object-norm005-seed44: SR=0.12 (12.0%)\neval-obs-only-object-norm005-seed47: SR=0.13 (13.0%)\neval-obs-only-object-norm005-seed48: SR=0.13 (13.0%)\neval-obs-only-object-norm005-seed49: SR=0.15 (15.0%)\neval-obs-only-object-norm005-seed50: SR=0.13 (13.0%)\neval-obs-only-object-norm005-seed55: SR=0.15 (15.0%)\neval-obs-only-object-norm005-seed58: SR=0.16 (16.0%)\neval-obs-only-object-norm005-seed61: SR=0.15 (15.0%)\neval-obs-only-object-norm005-seed64: SR=0.15 (15.0%)\neval-obs-only-object-norm005-seed65: SR=0.14 (14.0%)\neval-obs-only-object-norm005-seed66: SR=0.11 (11.0%)\neval-obs-only-object-norm005-seed67: SR=0.1 (10.0%)\neval-obs-only-object-norm005-seed72: SR=0.11 (11.0%)\neval-obs-only-object-norm005-seed75: SR=0.15 (15.0%)\neval-obs-only-object-norm01-seed44: SR=0.16 (16.0%)\neval-obs-only-object-norm01-seed45-r2: SR=0.17 (17.0%)\neval-obs-only-object-norm01-seed45: SR=0.14 (14.0%)\neval-obs-only-object-norm01-seed46-r3: SR=0.18 (18.0%)\neval-obs-only-object-norm01-seed47: SR=0.17 (17.0%)\neval-obs-only-object-norm01-seed48: SR=0.13 (13.0%)\neval-obs-only-object-norm01-seed49: SR=0.16 (16.0%)\neval-obs-only-object-norm01-seed50: SR=0.14 (14.0%)\neval-obs-only-object-norm01-seed51-r3: SR=0.11 (11.0%)\neval-obs-only-object-norm01-seed51: SR=0.11 (11.0%)\neval-obs-only-object-norm01-seed52-r3: SR=0.15 (15.0%)\neval-obs-only-object-norm01-seed52: SR=0.15 (15.0%)\neval-obs-only-object-norm01-seed53: SR=0.19 (19.0%)\neval-obs-only-object-norm01-seed54: SR=0.15 (15.0%)\neval-obs-only-object-norm01-seed57: SR=0.19 (19.0%)\neval-obs-only-object-norm01-seed60: SR=0.15 (15.0%)\neval-obs-only-object-norm01-seed64: SR=0.15 (15.0%)\neval-obs-only-object-norm01-seed65: SR=0.15 (15.0%)\neval-obs-only-object-norm01-seed66: SR=0.135 (13.5%)\neval-obs-only-object-norm01-seed67: SR=0.14 (14.0%)\neval-obs-only-object-norm01-seed71: SR=0.16 (16.0%)\neval-obs-only-object-norm01-seed74: SR=0.13 (13.0%)\neval-obs-only-object-norm02-k5-seed42: SR=0.14 (14.0%)\neval-obs-only-object-norm02-k5-seed43: SR=0.19 (19.0%)\neval-obs-only-object-norm02-k5-seed44: SR=0.17 (17.0%)\neval-obs-only-object-norm02-k5-seed45: SR=0.15 (15.0%)\neval-obs-only-object-norm02-k5-seed46: SR=0.16 (16.0%)\neval-obs-only-object-norm02-k5-seed47: SR=0.13 (13.0%)\neval-obs-only-object-norm02-k5-seed48: SR=0.18 (18.0%)\neval-obs-only-object-norm02-seed42: SR=0.2 (20.0%)\neval-obs-only-object-norm02-seed43-r2: SR=0.16 (16.0%)\neval-obs-only-object-norm02-seed43-r3: SR=0.16 (16.0%)\neval-obs-only-object-norm02-seed44-r2: SR=0.16 (16.0%)\neval-obs-only-object-norm02-seed45: SR=0.16 (16.0%)\neval-obs-only-object-norm02-seed46: SR=0.15 (15.0%)\neval-obs-only-object-norm02-seed47: SR=0.2 (20.0%)\neval-obs-only-object-norm02-seed48-r2: SR=0.18 (18.0%)\neval-obs-only-object-norm02-seed49: SR=0.14 (14.0%)\neval-obs-only-object-norm02-seed50: SR=0.18 (18.0%)\neval-obs-only-object-norm02-seed51: SR=0.17 (17.0%)\neval-obs-only-object-norm02-seed52: SR=0.15 (15.0%)\neval-obs-only-object-norm02-seed53: SR=0.16 (16.0%)\neval-obs-only-object-norm03-seed44: SR=0.18 (18.0%)\neval-obs-only-object-norm03-seed45-r2: SR=14 (1400.0%)\neval-obs-only-object-norm03-seed46: SR=0.17 (17.0%)\neval-obs-only-object-norm03-seed48: SR=0.16 (16.0%)\neval-obs-only-object-seed43: SR=0.12 (12.0%)\neval-obs-only-spatial-norm02-k5-seed42: SR=0.35 (35.0%)\neval-obs-only-spatial-norm02-k5-seed43: SR=0.32 (32.0%)\neval-obs-only-spatial-norm02-k5-seed44-r2: SR=0.37 (37.0%)\neval-obs-only-spatial-norm02-k5-seed45-r2: SR=0.34 (34.0%)\neval-obs-only-spatial-norm02-seed43-r2: SR=0.34 (34.0%)\neval-obs-only-spatial-norm02-seed44: SR=0.36 (36.0%)\neval-obs-only-spatial-norm02-seed45: SR=0.34 (34.0%)\neval-obs-only-spatial-norm02-seed47: SR=0.32 (32.0%)\neval-obs-only-spatial-norm02-seed48: SR=0.35 (35.0%)\neval-obs-only-spatial-norm02-seed50: SR=0.35 (35.0%)\neval-obs-only-spatial-norm02-seed52: SR=0.33 (33.0%)\neval-obs-only-spatial-seed48: SR=0.35 (35.0%)\neval-openvla-object-vla-only-seed42-v2: SR=0.69 (69.0%)\neval-perdof-object-default-seed44: SR=0 (0.0%)\neval-perdof-object-norm003-seed43: SR=0.13 (13.0%)\neval-perdof-object-norm003-seed46: SR=0.09 (9.0%)\neval-perdof-object-norm003-seed47: SR=0.15 (15.0%)\neval-perdof-object-norm003-seed48: SR=0.13 (13.0%)\neval-perdof-object-norm005-seed43: SR=0.13 (13.0%)\neval-perdof-object-norm005-seed44: SR=0.09 (9.0%)\neval-perdof-object-norm005-seed45-r2: SR=0.1 (10.0%)\neval-perdof-object-norm005-seed46: SR=0.11 (11.0%)\neval-perdof-object-norm005-seed47: SR=0.1 (10.0%)\neval-perdof-object-norm01-seed44: SR=0.08 (8.0%)\neval-perdof-object-norm01-seed45: SR=0.11 (11.0%)\neval-perdof-object-norm01-seed46-r2: SR=0.1 (10.0%)\neval-perdof-object-norm01-seed46: SR=0.1 (10.0%)\neval-perdof-object-norm01-seed47-bjb1: SR=0.14 (14.0%)\neval-perdof-object-norm01-seed48: SR=0.12 (12.0%)\neval-perdof-object-norm02-seed43-r3: SR=0.09 (9.0%)\neval-perdof-object-norm02-seed43: SR=0.09 (9.0%)\neval-perdof-object-norm02-seed44: SR=0.1 (10.0%)\neval-perdof-object-norm02-seed45-r3: SR=0.12 (12.0%)\neval-perdof-object-norm02-seed45: SR=0.09 (9.0%)\neval-perdof-object-norm02-seed46: SR=0.09 (9.0%)\neval-perdof-object-norm02-seed47: SR=0.11 (11.0%)\neval-perdof-object-norm02-seed49: SR=0.12 (12.0%)\neval-perdof-object-norm02-seed50: SR=0.1 (10.0%)\neval-perdof-object-norm03-seed44-r2: SR=0.04 (4.0%)\neval-perdof-object-norm03-seed44: SR=0.04 (4.0%)\neval-perdof-object-norm03-seed45-r2: SR=0.06 (6.0%)\neval-perdof-object-norm03-seed46: SR=0.04 (4.0%)\neval-perdof-object-norm03-seed47: SR=0.05 (5.0%)\neval-perdof-object-seed43: SR=0.12 (12.0%)\neval-perdof-object-seed44: SR=0.08 (8.0%)\neval-pi05-vla-only-object-seed42-r3: SR=0.82 (82.0%)\neval-pi05-vla-only-object-seed42: SR=0 (0.0%)\neval-pi05-vla-only-object-seed43-r3: SR=0.815 (81.5%)\neval-pi05-vla-only-object-seed43: SR=0 (0.0%)\neval-pi05-vla-only-object-seed44-r3: SR=0.81 (81.0%)\neval-pi05-vla-only-object-seed44: SR=0 (0.0%)\neval-pi05-vla-only-spatial-seed42-r3: SR=0.845 (84.5%)\neval-pi05-vla-only-spatial-seed43-r3: SR=0.83 (83.0%)\neval-pi05-vla-only-spatial-seed45: SR=0.85 (85.0%)\neval-plan-a-object-seed42: SR=0.19 (19.0%)\neval-plan-a-object-seed43: SR=0.16 (16.0%)\neval-plan-a-object-seed44: SR=0.2 (20.0%)\neval-plan-a-spatial-seed42: SR=0.34 (34.0%)\neval-plan-a-spatial-seed43: SR=0.35 (35.0%)\neval-plan-a-spatial-seed44: SR=0.36 (36.0%)\neval-random-selection-object-k5-seed42-r2: SR=0.14 (14.0%)\neval-random-selection-object-k5-seed43-r2: SR=0.11 (11.0%)\neval-random-selection-object-k5-seed44-r2: SR=0.1 (10.0%)\neval-random-selection-object-k5-seed45-r2: SR=0.07 (7.0%)\neval-random-selection-object-seed42: SR=0.11 (11.0%)\neval-random-selection-object-seed43: SR=0.09 (9.0%)\neval-random-selection-object-seed44: SR=0.11 (11.0%)\neval-random-selection-object-seed45: SR=0.1 (10.0%)\neval-random-selection-object-seed46-r3: SR=0.1 (10.0%)\neval-random-selection-object-seed48: SR=0.1 (10.0%)\neval-random-selection-object-seed49: SR=0.12 (12.0%)\neval-random-selection-spatial-seed42-r3: SR=0.34 (34.0%)\neval-random-selection-spatial-seed43: SR=0.26 (26.0%)\neval-random-selection-spatial-seed44: SR=0.28 (28.0%)\neval-reconvla-object: SR=0.12 (12.0%)\neval-reconvla-spatial-v3: SR=0.34 (34.0%)\neval-scalar-object-seed44-r2: SR=0.06 (6.0%)\neval-scalar-object-seed45-r2: SR=0.07 (7.0%)\neval-scalar-object-seed45: SR=0.09 (9.0%)\neval-scalar-object-seed46: SR=0.09 (9.0%)\neval-spatial-obs-only-seed45: SR=0.34 (34.0%)\neval-spatial-v7-full: SR=0.3 (30.0%)\neval-vla-mean-object-seed43: SR=0.15 (15.0%)\neval-vla-mean-object-seed44: SR=0.1 (10.0%)\neval-vla-mean-object-seed45: SR=0.13 (13.0%)\neval-vla-mean-object: SR=12 (1200.0%)\neval-vla-only-goal-seed42: SR=0.71 (71.0%)\neval-vla-only-goal-seed43: SR=0.69 (69.0%)\neval-vla-only-goal-seed45: SR=0.63 (63.0%)\neval-vla-only-goal-seed46: SR=0.71 (71.0%)\neval-vla-only-goal-seed49: SR=0.65 (65.0%)\neval-vla-only-long-seed42: SR=0.11 (11.0%)\neval-vla-only-long-seed43: SR=0.13 (13.0%)\neval-vla-only-long-seed44: SR=0.12 (12.0%)\neval-vla-only-long-seed45: SR=0.17 (17.0%)\neval-vla-only-long-seed46: SR=0.18 (18.0%)\neval-vla-only-long-seed47: SR=0.14 (14.0%)\neval-vla-only-long-seed48: SR=0.14 (14.0%)\neval-vla-only-long-seed50: SR=0.16 (16.0%)\neval-vla-only-long-seed51: SR=0.15 (15.0%)\neval-vla-only-long-seed52: SR=0.17 (17.0%)\neval-vla-only-object-seed43: SR=0.12 (12.0%)\neval-vla-only-object-seed44-r2: SR=0.1 (10.0%)\neval-vla-only-object-seed45-r2: SR=0.11 (11.0%)\neval-vla-only-object-seed45: SR=0.09 (9.0%)\neval-vla-only-object-seed46: SR=0.13 (13.0%)\neval-vla-only-object-seed47: SR=0.1 (10.0%)\neval-vla-only-object-seed48-r2: SR=0.11 (11.0%)\neval-vla-only-object-seed48: SR=0.1 (10.0%)\neval-vla-only-object-seed49: SR=0.1 (10.0%)\neval-vla-only-object-seed50: SR=0.09 (9.0%)\neval-vla-only-object: SR=0.12 (12.0%)\neval-vla-only-spatial-seed42: SR=0.3 (30.0%)\neval-vla-only-spatial-seed43: SR=0.29 (29.0%)\neval-vla-only-spatial-seed44: SR=0.31 (31.0%)\neval-vla-only-spatial-seed45: SR=0.27 (27.0%)\neval-vla-only-spatial-seed46: SR=0.3 (30.0%)\neval-vla-only-spatial-seed47: SR=0.3 (30.0%)\neval-vla-only-spatial-seed48: SR=0.3 (30.0%)\neval_obs_only_norm01_seed48: SR=0.18 (18.0%)\neval_obs_only_norm03_seed48: SR=0.16 (16.0%)",
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

<details open><summary>🔧 Tool call — Bash · `toolu_01FaSzXM556JSav5E6bsWbVm`</summary>

```json
{
  "command": "pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex 2>&1 | grep -E \"Warning.*Citation|Warning.*Reference|Error\" | head -20",
  "description": "Run pdflatex twice to check citation/reference warnings"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "1c7c94f5-63e1-4889-b39b-b45e3b7d0d04",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NoXGvGUsBjVydmgo2NVFgo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5015,
      "cache_read_input_tokens": 65880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5015
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

_source line 78 · 2026-05-21T16:47:46.300Z_

<details><summary>↩ Tool result · `toolu_01FaSzXM556JSav5E6bsWbVm`</summary>

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
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "05661ba8-59a0-41f8-8b62-941d4f23d38d",
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


### Tool call

_source line 79_

<details open><summary>🔧 Tool call — Bash · `toolu_01NuS44WGzRXAiNWvSLqt1J2`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Check for pi0.5 / pi05 CRM eval experiments\nfor eid, edata in exps.items():\n    if 'pi0' in eid.lower():\n        metrics = edata.get('metrics',{})\n        status = edata.get('status','?')\n        conclusion = edata.get('conclusion','')[:100]\n        print(f'{eid}: status={status}, metrics={json.dumps(metrics)[:200]}, conclusion={conclusion}')\n\" 2>&1 | sort",
  "description": "Get all π0.5 experiments from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "cfe06b11-1a22-451a-a9b4-cd239f813c39",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NoXGvGUsBjVydmgo2NVFgo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5015,
      "cache_read_input_tokens": 65880,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5015
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

_source line 80 · 2026-05-21T16:47:48.087Z_

<details><summary>↩ Tool result · `toolu_01NuS44WGzRXAiNWvSLqt1J2`</summary>

```text
eval-pi05-baseline-object-seed42-r2: status=PREPARING, metrics={}, conclusion=killed
eval-pi05-baseline-object-seed42: status=DONE, metrics={"overall_success_rate": 0}, conclusion=failed
eval-pi05-vla-only-object-seed42-r3: status=DONE, metrics={"success_rate": 0.82, "n_tasks": 10, "total_rollouts": 200}, conclusion=success
eval-pi05-vla-only-object-seed42: status=DONE, metrics={"overall_sr": 0, "per_task_sr": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], "total_rollouts": 200, "n_tasks": 10, "n_rollouts_per_task": 20}, conclusion=failed
eval-pi05-vla-only-object-seed43-r3: status=DONE, metrics={"success_rate": 0.815, "n_tasks": 10, "total_rollouts": 200}, conclusion=success
eval-pi05-vla-only-object-seed43: status=DONE, metrics={"overall_sr": 0, "per_task_sr": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], "total_rollouts": 200, "n_tasks": 10, "n_rollouts_per_task": 20}, conclusion=failed
eval-pi05-vla-only-object-seed44-r3: status=DONE, metrics={"success_rate": 0.81, "n_tasks": 10, "total_rollouts": 200}, conclusion=success
eval-pi05-vla-only-object-seed44: status=DONE, metrics={"overall_sr": 0, "per_task_sr": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], "total_rollouts": 200, "n_tasks": 10, "n_rollouts_per_task": 20}, conclusion=failed
eval-pi05-vla-only-spatial-seed42-r3: status=DONE, metrics={"success_rate": 0.845, "n_tasks": 10, "total_rollouts": 200}, conclusion=success
eval-pi05-vla-only-spatial-seed42: status=DONE, metrics={}, conclusion=failed
eval-pi05-vla-only-spatial-seed43-r3: status=DONE, metrics={"success_rate": 0.83, "n_tasks": 10, "total_rollouts": 200}, conclusion=success
eval-pi05-vla-only-spatial-seed43: status=DONE, metrics={}, conclusion=failed
eval-pi05-vla-only-spatial-seed44: status=DONE, metrics={}, conclusion=failed
eval-pi05-vla-only-spatial-seed45: status=DONE, metrics={"success_rate": 0.85, "n_tasks": 10, "total_rollouts": 200}, conclusion=success
precompute-pi05-features-object: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s0-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s1-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s2-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s3-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s4-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s5-fix: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s5-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s6-fix: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s6-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s7-fix: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s7-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s8-fix: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s8-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s9-fix: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-s9-r2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-shard5: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-shard6: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-shard7: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-shard8: status=PREPARING, metrics={}, conclusion=
precompute-pi05-obj-shard9: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard0: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard1: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard3: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard4: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard5: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard6: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard7: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard8: status=PREPARING, metrics={}, conclusion=
precompute-pi05-shard9: status=PREPARING, metrics={}, conclusion=
precompute-pi05-spatial-shard0: status=PREPARING, metrics={}, conclusion=
precompute-pi05-spatial-shard1: status=PREPARING, metrics={}, conclusion=
precompute-pi05-spatial-shard2: status=PREPARING, metrics={}, conclusion=
precompute-pi05-spatial-shard3: status=PREPARING, metrics={}, conclusion=
precompute-pi05-spatial-shard4: status=PREPARING, metrics={}, conclusion=
precompute-pi05-spatial-shard5: status=PREPARING, metrics={}, conclusion=
precompute-pi05-spatial-shard6: status=PREPARING, metrics={}, conclusion=
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "2b9e4a11-7978-40a2-8a31-f1d5842adc83",
  "tool_use_result": {
    "stdout": "eval-pi05-baseline-object-seed42-r2: status=PREPARING, metrics={}, conclusion=killed\neval-pi05-baseline-object-seed42: status=DONE, metrics={\"overall_success_rate\": 0}, conclusion=failed\neval-pi05-vla-only-object-seed42-r3: status=DONE, metrics={\"success_rate\": 0.82, \"n_tasks\": 10, \"total_rollouts\": 200}, conclusion=success\neval-pi05-vla-only-object-seed42: status=DONE, metrics={\"overall_sr\": 0, \"per_task_sr\": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], \"total_rollouts\": 200, \"n_tasks\": 10, \"n_rollouts_per_task\": 20}, conclusion=failed\neval-pi05-vla-only-object-seed43-r3: status=DONE, metrics={\"success_rate\": 0.815, \"n_tasks\": 10, \"total_rollouts\": 200}, conclusion=success\neval-pi05-vla-only-object-seed43: status=DONE, metrics={\"overall_sr\": 0, \"per_task_sr\": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], \"total_rollouts\": 200, \"n_tasks\": 10, \"n_rollouts_per_task\": 20}, conclusion=failed\neval-pi05-vla-only-object-seed44-r3: status=DONE, metrics={\"success_rate\": 0.81, \"n_tasks\": 10, \"total_rollouts\": 200}, conclusion=success\neval-pi05-vla-only-object-seed44: status=DONE, metrics={\"overall_sr\": 0, \"per_task_sr\": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], \"total_rollouts\": 200, \"n_tasks\": 10, \"n_rollouts_per_task\": 20}, conclusion=failed\neval-pi05-vla-only-spatial-seed42-r3: status=DONE, metrics={\"success_rate\": 0.845, \"n_tasks\": 10, \"total_rollouts\": 200}, conclusion=success\neval-pi05-vla-only-spatial-seed42: status=DONE, metrics={}, conclusion=failed\neval-pi05-vla-only-spatial-seed43-r3: status=DONE, metrics={\"success_rate\": 0.83, \"n_tasks\": 10, \"total_rollouts\": 200}, conclusion=success\neval-pi05-vla-only-spatial-seed43: status=DONE, metrics={}, conclusion=failed\neval-pi05-vla-only-spatial-seed44: status=DONE, metrics={}, conclusion=failed\neval-pi05-vla-only-spatial-seed45: status=DONE, metrics={\"success_rate\": 0.85, \"n_tasks\": 10, \"total_rollouts\": 200}, conclusion=success\nprecompute-pi05-features-object: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s0-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s1-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s2-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s3-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s4-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s5-fix: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s5-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s6-fix: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s6-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s7-fix: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s7-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s8-fix: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s8-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s9-fix: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-s9-r2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-shard5: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-shard6: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-shard7: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-shard8: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-obj-shard9: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard0: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard1: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard3: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard4: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard5: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard6: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard7: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard8: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-shard9: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-spatial-shard0: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-spatial-shard1: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-spatial-shard2: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-spatial-shard3: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-spatial-shard4: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-spatial-shard5: status=PREPARING, metrics={}, conclusion=\nprecompute-pi05-spatial-shard6: status=PREPARING, metrics={}, conclusion=",
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

_source line 81_

<details><summary>Logged reasoning block</summary>

```text
Excellent! Now I have comprehensive data. Let me compile all the findings:

## 1. Compilation Check
- Paper compiles successfully (15 pages, 544KB)
- No errors
- Warnings: 12 total (minor, all cosmetic):
  - 5 Underfull hbox/vbox (badness) - common and harmless
  - 4 hyperref warnings about math in PDF strings
  - 3 `h` float specifier changed to `ht`
- Bibtex runs clean with no warnings
- All citations resolve (no "Citation undefined" warnings after 2 passes)
  
## 2. Number Consistency Check

Now I'm cross-checking the key numbers across the paper and registry data. The VLA-only object baseline shows 11.0 ± 1.3% (n=8) in Table 1, but when I look at the individual seed results in the registry, I'm getting slightly different values that don't quite align with what's reported—there's a discrepancy between the paper's reported mean and the actual seed-by-seed data, and the footnote seems to reference different sample sizes. Looking at the registry data more carefully, I see that seed45 and seed48 were both retested with updated results in round 2. If I use those updated values for the nine seeds, the average comes to about 10.8%, which matches the paper_framing notation. But the paper itself reports 11.0% with n=8, so I need to figure out which eight seeds were actually included in that calculation. excluding seed50?): 12+12+10+11+13+10+11+10 = 89/8 = 11.125% ≈ 11.0%. This uses seed45=11% and seed48=11% (r2 values).

Actually the paper Table 2 (VLA-only row) says $11.0 \pm 1.3$ with n=8. The paper_framing says 10.8±1.3% (n=9). The abstract says $11.0 \pm 1.3$% VLA-only, 8 seeds. So the paper uses n=8 with the updated r2 values. The discrepancy between paper (11.0%, n=8) and paper_framing (10.8%, n=9) is a minor inconsistency but not necessarily wrong - they may be using different seed sets. But there IS an inconsistency - the paper intro says "11.0 ± 1.3%" while paper_framing reports 10.8%, so I should note this discrepancy.

Now I'm checking the Plan A results. For the Object condition, the paper reports 18.3 ± 2.1% with n=3, and when I calculate from the registry seeds (42, 43, 44 with values 19%, 16%, 20%), I get a mean of 18.33% and standard deviation of about 2.08%, which matches. For the Spatial condition, the paper shows 35.0 ± 1.0% with n=3, and the registry has seed42=34% and seed43=35%, so I need to find the third seed value to verify this.

Now I'm moving to the CRM obs_only K=10 Object results. The paper lists 16.8 ± 1.8% with n=6, but paper_framing shows 16.8±1.8% with n=7 excluding seed42. I'm trying to reconcile which seeds are actually included and whether there's a discrepancy in the sample size or seed selection. I'm working through the standard deviation calculation for these seed values, trying to figure out whether the paper used n=6 or n=7 in their computation, and recalculating more carefully to match their reported mean and standard deviation. the paper numbers are verified correct. Now I'm checking the CRM results for K=10 Spatial against the registry—the paper reports 34.4 ± 1.5% with n=3, but when I calculate from the available seeds, I'm getting slightly different values, so I need to identify which exact three seeds were used in the paper. Completing the calculation: with seeds 43, 44, and 45, that gives 34.67%, which still doesn't match the paper's 34.4%. Let me check if there's a different seed combination—maybe seeds 42, 43, and 44 with seed42=35 would give 35.0%, but that's also off. The paper mentions CRM K=10 should have n=3, so I'm looking for those specific experiments in the registry to see if I can find the exact results they used. Looking at the different seed combinations, none of them produce exactly 34.4%. The paper reports 34.4±1.5% with n=3, but when I try various three-seed combinations from the available data, I get values like 35.0%, 34.33%, or 34.0% — all slightly off. I should check whether the paper might be using experiments with different rollout counts or if there's a specific subset of seeds I'm missing. I'm noticing the percentages only increment by 1% given the evaluation setup, so there might be a discrepancy between the paper's reported 34.4±1.5% and the closest registry value of 34.67% from seeds 43-45. The paper could have used a different or updated evaluation set, so I'll move forward. Now looking at the VLA-only Spatial results, the paper reports 29.4±1.5% with n=5, and I'm checking the registry seeds to see which five best match that mean. Looking at the completed seeds more carefully—seed42 through seed49—I'm getting 10.17% when I recalculate, which still doesn't match the paper's reported 9.7%, so there's a discrepancy I need to resolve.

Wait, I'm noticing the paper_framing actually lists two different values for Random K=10: one showing 11.67% with n=3, and another showing 9.7% with n=6, which suggests these might be from different experimental runs or subsets that I need to track down. I notice there's a discrepancy between the paper's reported value for seed42 (13%) and what's in the registry (11%), likely due to different rollout counts used in different experiment runs. Now I'm checking the K=5 random object results—the registry values average to 10.5%, which matches the paper's reported mean, so I'm verifying the standard deviation calculation.

For the argmin K=5 object, the paper reports 13.0±1.6% with n=4, but the paper_framing document shows 13.7±1.2% with n=3 seeds. I need to figure out which seeds are actually included and whether seed44 has completed to resolve this discrepancy. So seed44 should be 11% to get the mean of 13.0 and standard deviation of 1.6. Now I'm checking the CRM obs_only results with K=5 against the paper's reported 16.0 ± 2.2% across seven runs, comparing against the registry values I'm pulling. Now I'm verifying the K=20 Object results match the paper's reported mean and standard deviation, and they check out. Moving to the K=20 Spatial configuration, I'm calculating the mean across three seeds which gives 34.33%, matching the paper's 34.3%, and working through the standard deviation calculation.

For K=5 Spatial, I'm seeing four seed runs with results ranging from 32% to 37%, which average to 34.5% as reported. The standard deviation calculation accounts for the wider spread in these results, yielding approximately 2.1%.

Moving to K=10 Spatial with Random, I have three seeds producing 34%, 26%, and 28% respectively. These average to 29.3% with a standard deviation of 4.2%, matching the paper's reported values. Now checking the π0.5 VLA-only Object results, where three seeds cluster around 81-82%, and I'm verifying these match the paper's reported mean and standard deviation. Finishing the standard deviation calculation for the spatial configuration, then moving on to verify the adaptive K threshold results—the object detection metrics show a mean of 15.3% with a standard deviation of 1.2% for the P50 case, and I'm now checking the P90 numbers. Finishing up the P25 calculation—the registry values match the paper's reported 14.3 ± 1.2%. Now moving on to check the LTO results, where the registry shows a -12pp difference between the two evaluation splits, which aligns with what the paper reports. For the Argmin K=10 Object metric, I'm looking through the registry to find the relevant seeds and verify the 12.3 ± 2.6% result.

Compiling the argmin object results across seeds 42-47 and calculating the mean as 12.3%, which matches the paper. Now I need to finish computing the standard deviation to confirm the ±2.6% uncertainty.

For the CRM perdof K=10 results, I'm checking which epsilon value in the paper corresponds to the reported 11.0±1.8%, since the registry shows perdof was evaluated across multiple epsilon settings.

Looking at the individual seed results for perdof-object-norm01, I'm getting values ranging from 8% to 14%, and I need to figure out which seeds to include to match the paper's n=6 sample size and calculate the mean properly. I'm noticing the obs_only results don't align perfectly with the paper_framing values either—the registry shows individual seed results averaging around 15.25% for ε=0.03, but paper_framing reports 15.75%, so I'll treat paper_framing as the authoritative reference for these aggregated numbers. lowest ε point: ε=0.05 ~14%. ε=0.03 ~15.75%. So the lowest is actually around 14% for ε=0.05, not 12.5%. Unless there's a specific seed/ε combo at 12.5%. Looking at ε=0.03: seed66=11.5%, seed59=13%, seed67=14%. These are larger seed numbers suggesting they might be from a different seed set. Maybe the paper uses a different set of seeds for the magnitude analysis.

Hmm, the paper says the obs_only range is 12.5-16.8%. From the registry, eval-obs-only-object-norm003-seed66 = 11.5% and eval-obs-only-object-norm005-seed67 = 10%. So if individual seeds can go that low, but the reported MEAN should be higher.

OK, I think the obs_only "12.5-16.8%" range in the paper refers to the range of MEAN values across different ε settings, not individual seeds. Looking at the norm005 registry entries, when I average the first five seeds I get around 13.4%, which aligns better with the paper's reported range.

For the CRM scalar K=10 object result, the paper reports 8.5 ± 1.5% with n=4, but I'm having trouble finding exactly four matching seeds in the registry. I have seed44=6%, seed45=9%, seed46=9%, and seed45-r2=7%, though using the same seed twice seems problematic. The closest valid set would be three seeds at 6%, 7%, and 9%, which averages to 7.3%—lower than the paper's reported 8.5%.

Now that I've mapped out the major discrepancies, let me verify the specific numbers I've identified: the VLA-only object baseline differs slightly between sources (11.0±1.3% versus 10.8±1.3%), and the obs_only magnitude range has a lower bound discrepancy of about 0.9 percentage points.

For the CRM and Random K=10 results, I'm seeing sample size mismatches—the CRM object n value is 6 in the paper but 7 in paper_framing, and the Random K=10 object percentages don't quite align with what I'd expect from the seed registry, suggesting they might be using different evaluation protocols. The CRM K=10 spatial result is also problematic since no combination of three seeds from the registry produces exactly 34.4%.

Now I'm checking where π0.5 appears in the paper and what's missing—it's mentioned in the experiments section as a cross-VLA validation, and there's a table in the appendix with baseline results for the π0.5 model, but the Plan A results are still placeholders that need to be filled in.

There's also an inconsistency in the discussion section that claims larger VLAs are untested, but the paper already includes π0.5 data, so that statement needs to be reconciled with what's actually been evaluated. The VLA-only baseline is complete, but I still need to run the CRM training and evaluation. Let me verify the citations and figures are all accounted for—checking that the 31 cite keys match the bibliography entries and all six figures exist in the directory. I should also scan through the reference commands to make sure everything is properly linked.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "5efee8a3-b42a-4abe-ba3e-65cf1480ed07",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012pGR42CFyCMBYTXPpUVz33",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10270,
      "cache_read_input_tokens": 70895,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10270
      },
      "output_tokens": 11,
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

_source line 82_

Let me run full compilation cycle and check for unresolved references.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "dee991a9-f0cb-432f-9d61-a22749293974",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012pGR42CFyCMBYTXPpUVz33",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10270,
      "cache_read_input_tokens": 70895,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10270
      },
      "output_tokens": 11,
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

_source line 83_

<details open><summary>🔧 Tool call — Bash · `toolu_01DpTGnJWEC7kcCMBJAg38ew`</summary>

```json
{
  "command": "pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && bibtex main > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex > /dev/null 2>&1 && pdflatex -interaction=nonstopmode main.tex 2>&1 | grep -iE \"Citation.*undefined|Reference.*undefined|multiply.*defined|LaTeX Error\" | head -20; echo \"---WARNINGS---\"; grep -c \"Warning\" main.log; echo \"---PAGE COUNT---\"; grep \"Output written\" main.log",
  "description": "Full LaTeX compilation cycle and check for issues"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "773fa0c5-5a2a-4544-a35b-bf7932ca4f9e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012pGR42CFyCMBYTXPpUVz33",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10270,
      "cache_read_input_tokens": 70895,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10270
      },
      "output_tokens": 11,
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

_source line 84 · 2026-05-21T16:50:59.675Z_

<details><summary>↩ Tool result · `toolu_01DpTGnJWEC7kcCMBJAg38ew`</summary>

```text
---WARNINGS---
7
---PAGE COUNT---
Output written on main.pdf (15 pages, 544260 bytes).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "6c2e2a0e-06a5-4007-aef2-69fab7b545c4",
  "tool_use_result": {
    "stdout": "---WARNINGS---\n7\n---PAGE COUNT---\nOutput written on main.pdf (15 pages, 544260 bytes).",
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

_source line 85_

<details open><summary>🔧 Tool call — Bash · `toolu_01MsXduUiCtdLPM1tucqU5oP`</summary>

```json
{
  "command": "grep -oP '\\\\\\\\ref\\{[^}]+\\}' *.tex | sed 's/.*\\\\\\\\ref{//;s/}//' | sort -u > /tmp/refs_used.txt && grep -oP '\\\\\\\\label\\{[^}]+\\}' *.tex | sed 's/.*\\\\\\\\label{//;s/}//' | sort -u > /tmp/labels_defined.txt && echo \"=== Used refs ===\" && cat /tmp/refs_used.txt && echo \"=== Defined labels ===\" && cat /tmp/labels_defined.txt && echo \"=== Missing labels ===\" && comm -23 /tmp/refs_used.txt /tmp/labels_defined.txt",
  "description": "Check for unresolved references"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "31ffc345-d620-4587-ae91-84e4e89f949d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012pGR42CFyCMBYTXPpUVz33",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10270,
      "cache_read_input_tokens": 70895,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10270
      },
      "output_tokens": 11,
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

_source line 86 · 2026-05-21T16:51:00.533Z_

<details><summary>↩ Tool result · `toolu_01MsXduUiCtdLPM1tucqU5oP`</summary>

```text
=== Used refs ===
=== Defined labels ===
=== Missing labels ===
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "201471dd-a190-44c9-b31f-f3c1b11e1842",
  "tool_use_result": {
    "stdout": "=== Used refs ===\n=== Defined labels ===\n=== Missing labels ===",
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

_source line 87_

<details open><summary>🔧 Tool call — Bash · `toolu_01CXMrBr5Jdtobix4CmyKk4Q`</summary>

```json
{
  "command": "grep -ohP '\\\\ref\\{[^}]+\\}' *.tex | sed 's/\\\\ref{//;s/}//' | sort -u",
  "description": "Extract ref keys from tex files"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d754fcab-4b82-494d-b457-ba54ee58e85f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014R4QmeJsLqiHDfp1ZL27jc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10667,
      "cache_read_input_tokens": 81165,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10667
      },
      "output_tokens": 37,
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

_source line 88 · 2026-05-21T16:51:06.068Z_

<details><summary>↩ Tool result · `toolu_01CXMrBr5Jdtobix4CmyKk4Q`</summary>

```text
eq:argmin
eq:crm
fig:diversity
fig:k2_correlation
fig:kvalue
fig:pipeline
sec:adaptive_k
sec:adaptive_k_method
sec:applicability
sec:cross_vla
sec:failure_modes
sec:k_scaling
sec:latency
sec:magnitude
sec:magnitude_appendix
sec:magnitude_results
sec:main_results
sec:per_task
sec:spatial_adaptive
tab:adaptive
tab:adaptive_spatial
tab:cross_vla
tab:k_ablation
tab:latency
tab:main
tab:pertask
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "5a23e6d3-cb03-472c-98ec-8cf10e528d16",
  "tool_use_result": {
    "stdout": "eq:argmin\neq:crm\nfig:diversity\nfig:k2_correlation\nfig:kvalue\nfig:pipeline\nsec:adaptive_k\nsec:adaptive_k_method\nsec:applicability\nsec:cross_vla\nsec:failure_modes\nsec:k_scaling\nsec:latency\nsec:magnitude\nsec:magnitude_appendix\nsec:magnitude_results\nsec:main_results\nsec:per_task\nsec:spatial_adaptive\ntab:adaptive\ntab:adaptive_spatial\ntab:cross_vla\ntab:k_ablation\ntab:latency\ntab:main\ntab:pertask",
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

_source line 89_

<details open><summary>🔧 Tool call — Bash · `toolu_014vtQM5Wuqm77yMkAmbUNcX`</summary>

```json
{
  "command": "grep -ohP '\\\\label\\{[^}]+\\}' *.tex | sed 's/\\\\label{//;s/}//' | sort -u",
  "description": "Extract label keys from tex files"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d622ec75-9856-43b9-bf1f-dce9ec28279b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014R4QmeJsLqiHDfp1ZL27jc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10667,
      "cache_read_input_tokens": 81165,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10667
      },
      "output_tokens": 37,
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

_source line 90 · 2026-05-21T16:51:06.632Z_

<details><summary>↩ Tool result · `toolu_014vtQM5Wuqm77yMkAmbUNcX`</summary>

```text
eq:argmin
eq:crm
eq:loss
fig:decomposition
fig:diversity
fig:k2_correlation
fig:kvalue
fig:magnitude
fig:pipeline
sec:adaptive_k
sec:adaptive_k_method
sec:applicability
sec:conclusion
sec:crm
sec:cross_vla
sec:decomposition_appendix
sec:exp_setup
sec:experiments
sec:failure_modes
sec:intro
sec:k_scaling
sec:latency
sec:magnitude
sec:magnitude_appendix
sec:magnitude_results
sec:main_results
sec:method
sec:per_task
sec:problem_setup
sec:related_work
sec:selection
sec:spatial_adaptive
tab:adaptive
tab:adaptive_spatial
tab:cross_vla
tab:k_ablation
tab:latency
tab:main
tab:pertask
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "af824b86-1d25-42ba-971c-76e101f2fd86",
  "tool_use_result": {
    "stdout": "eq:argmin\neq:crm\neq:loss\nfig:decomposition\nfig:diversity\nfig:k2_correlation\nfig:kvalue\nfig:magnitude\nfig:pipeline\nsec:adaptive_k\nsec:adaptive_k_method\nsec:applicability\nsec:conclusion\nsec:crm\nsec:cross_vla\nsec:decomposition_appendix\nsec:exp_setup\nsec:experiments\nsec:failure_modes\nsec:intro\nsec:k_scaling\nsec:latency\nsec:magnitude\nsec:magnitude_appendix\nsec:magnitude_results\nsec:main_results\nsec:method\nsec:per_task\nsec:problem_setup\nsec:related_work\nsec:selection\nsec:spatial_adaptive\ntab:adaptive\ntab:adaptive_spatial\ntab:cross_vla\ntab:k_ablation\ntab:latency\ntab:main\ntab:pertask",
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

_source line 91_

<details><summary>Logged reasoning block</summary>

```text
All \ref{} keys have matching \label{} definitions. No missing labels or unresolved refs.

Let me now also check if the paper has the `\placeholder{}` macro and find all uses of it.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "359fb721-9063-4d89-b575-e89f2581d76f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PioATA5c86dHKzpK2wEdhc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 618,
      "cache_read_input_tokens": 91832,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 618
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

_source line 92_

<details open><summary>🔧 Tool call — Bash · `toolu_01AUM63R6MMQSdzhUm7d9AnN`</summary>

```json
{
  "command": "grep -n \"placeholder\" *.tex",
  "description": "Find all placeholder uses in paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "fd3f9490-92f1-4cd2-9006-452f21129bdc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PioATA5c86dHKzpK2wEdhc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 618,
      "cache_read_input_tokens": 91832,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 618
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

_source line 93 · 2026-05-21T16:51:10.938Z_

<details><summary>↩ Tool result · `toolu_01AUM63R6MMQSdzhUm7d9AnN`</summary>

```text
appendix.tex:194:$\pi_{0.5}$ Plan~A & 2 & \placeholder{} & \placeholder{} \\
appendix.tex:199:Table~\ref{tab:cross_vla} reports results. The $\pi_{0.5}$ baseline already achieves $81.5 \pm 0.5$\% on Object and $84.2 \pm 1.0$\% on Spatial---substantially above SmolVLA's $11.0$\% / $29.4$\%---leaving limited headroom for post-hoc correction. Plan~A results are pending (\placeholder{}).
main.tex:15:\newcommand{\placeholder}[1]{---}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "4815af65-9ff2-4b2b-af62-5b62917419bd",
  "tool_use_result": {
    "stdout": "appendix.tex:194:$\\pi_{0.5}$ Plan~A & 2 & \\placeholder{} & \\placeholder{} \\\\\nappendix.tex:199:Table~\\ref{tab:cross_vla} reports results. The $\\pi_{0.5}$ baseline already achieves $81.5 \\pm 0.5$\\% on Object and $84.2 \\pm 1.0$\\% on Spatial---substantially above SmolVLA's $11.0$\\% / $29.4$\\%---leaving limited headroom for post-hoc correction. Plan~A results are pending (\\placeholder{}).\nmain.tex:15:\\newcommand{\\placeholder}[1]{---}",
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

_source line 94_

<details open><summary>🔧 Tool call — Bash · `toolu_01WXA1KBDvHv3SJykHcMusUS`</summary>

```json
{
  "command": "grep -n \"TODO\\|FIXME\\|XXX\\|HACK\\|todo\\|fixme\" *.tex",
  "description": "Find any TODO/FIXME markers"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "2c7df1c0-cb86-4f27-9abe-a6f92ba6f6a8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PioATA5c86dHKzpK2wEdhc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 618,
      "cache_read_input_tokens": 91832,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 618
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

_source line 95 · 2026-05-21T16:51:11.807Z_

<details><summary>↩ Tool result · `toolu_01WXA1KBDvHv3SJykHcMusUS`</summary>

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
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "d42cef68-940d-420f-89d8-bcbc1605b1b9",
  "tool_use_result": {
    "stdout": "",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "returnCodeInterpretation": "No matches found",
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 96_

<details><summary>Logged reasoning block</summary>

```text
Now let me also verify a few more numbers. Let me check:

1. The Plan A trigger rates vs registry
2. The K=1 CRM value (10.3%)
3. The Spatial adaptive K thresholds

And check for the `\placeholder` rendering in the PDF.

Let me also check the adaptive K Spatial results.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "8822c896-ac7a-49dc-af06-186adc265c86",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UXu5zuRxSVKLsi1bK9p35S",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 467,
      "cache_read_input_tokens": 92450,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 467
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

_source line 97_

Now let me verify Plan A trigger rates and a few more numbers, then check for page count compliance.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "be7505a6-3f62-4e9b-ab0b-7dfa531f5700",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UXu5zuRxSVKLsi1bK9p35S",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 467,
      "cache_read_input_tokens": 92450,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 467
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

_source line 98_

<details open><summary>🔧 Tool call — Bash · `toolu_01LCvdzX4E33efn6ZsXuPBmc`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-8-projects-acr-vla-conformal-refinement/88c568e6-6078-4357-af2d-523b754780c6/tool-results/mcp-agent-ml-research-read_registry-1779381957766.txt') as f:\n    data = json.loads(f.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Plan A trigger rates\nfor eid in ['eval-plan-a-object-seed42','eval-plan-a-object-seed43','eval-plan-a-object-seed44','eval-plan-a-spatial-seed42','eval-plan-a-spatial-seed43','eval-plan-a-spatial-seed44']:\n    if eid in exps:\n        m = exps[eid].get('metrics',{})\n        print(f'{eid}: SR={m.get(\\\"success_rate\\\")}, trigger={m.get(\\\"trigger_rate\\\")}')\n\n# K=1 CRM\nfor eid in ['eval-k1-crm-accg-object-seed42','eval-k1-crm-accg-object-seed43','eval-k1-crm-accg-object-seed44','eval-k1-crm-multiscale-object-seed42','eval-k1-crm-multiscale-object-seed43-r2','eval-k1-crm-multiscale-object-seed44-r2']:\n    if eid in exps:\n        m = exps[eid].get('metrics',{})\n        sr = m.get('overall_success_rate') or m.get('success_rate')\n        print(f'{eid}: SR={sr}')\n\n# Adaptive Spatial  \nfor eid in sorted([k for k in exps if 'adaptive-k-spatial' in k]):\n    m = exps[eid].get('metrics',{})\n    sr = m.get('success_rate') or m.get('overall_success_rate')\n    print(f'{eid}: SR={sr}, status={exps[eid].get(\\\"status\\\")}')\n\" 2>&1",
  "description": "Verify Plan A trigger rates and K=1 CRM data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88c568e6-6078-4357-af2d-523b754780c6",
  "uuid": "81977ca9-873f-44aa-8f6e-0132d4e7df67",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UXu5zuRxSVKLsi1bK9p35S",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 467,
      "cache_read_input_tokens": 92450,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 467
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
