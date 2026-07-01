#!/usr/bin/env bash
# EXP-R1c (2026-06-11): cumulative (sample-scoped) dead-slot judge on the P11
# chunk512 base. Identical to launch_expR1_deadslot_reset.sh EXCEPT it adds:
#   + --dead_slot_criterion cumulative
# i.e. a slot is "dead" only if it was NEVER selected over the WHOLE sample so
# far (_cum_usage==0), not merely silent for the last `interval` chunks
# (_recycle_usage==0, the R1 "window" judge). Motivation: R1's window judge
# mistook long-range memory slots (stored an early fact, queried much later)
# for dead and recycle_reset overwrote their content → BABILong 8k-32k collapsed
# ~3x. The cumulative judge spares any slot that has ever been selected, so it
# recycles strictly fewer slots and never erases a long-range memory slot.
# See gp-73 EXP-R1c.
#
# Runs on the B200 .188 node (8x L20A 183GB, CEPH=wzc1, NOT shared with diskA).
set -euo pipefail
PROJECT_ROOT="${PROJECT_ROOT:-/apdcephfs_wzc1/share_304376610/pighzliu_code/Mixture-of-Memory}"
cd "$PROJECT_ROOT"
export WANDB_API_KEY="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"
export WANDB_MODE="offline"
export http_proxy="http://hy-proxy.woa.com:3128"
export https_proxy="http://hy-proxy.woa.com:3128"
export all_proxy="http://hy-proxy.woa.com:3128"
export no_proxy="mirrors.cloud.tencent.com,tlinux-mirror.tencent-cloud.com,localhost,127.0.0.1,.oa.com,.woa.com,.local"
export HF_HOME="$PROJECT_ROOT/.hf_cache"
export HF_DATASETS_CACHE="$PROJECT_ROOT/.hf_cache/datasets"
export HF_HUB_OFFLINE=1
export HF_DATASETS_OFFLINE=1
export PYTHONPATH="$PROJECT_ROOT/third_party/babilong-pkg:$PROJECT_ROOT:${PYTHONPATH:-}"
export PYTHONUNBUFFERED=1
PYBIN="${PYTHON_BIN:-$PROJECT_ROOT/.venv/bin/python}"
RUN="expR1cN192b_cum_slots192"
# L20A chunk512: physical bs4 x grad_accum1 x 8gpu = eff_batch 32 (same as P11).
setsid bash -c "CUDA_VISIBLE_DEVICES=0,1,2,3,4,5,6,7 $PYBIN -m torch.distributed.run --nproc_per_node=8 --master_port=29863 \
  scripts/train_mem_space_dolmino_cpt.py \
  --model_path models/Meta-Llama-3-8B \
  --per_doc_data --dolmino_path MemLong/data/processed/dolmino_per_doc/train \
  --output_dir outputs/$RUN --total_steps 1000 --lr 1e-4 --warmup_steps 100 \
  --chunk_size 512 --batch_size 4 --num_slots 192 --top_k 16 --selector_dim 128 \
  --selector_temperature 40 --load_balance_weight 0.0 --entropy_aux_weight 0.0 \
  --use_loss_free_balance --loss_free_update_rate 0.001 --num_global_slots 4 \
  --key_repulsion_weight 1.0 --key_repulsion_threshold 0.3 --slot_value_norm_cap 5.0 \
  --use_delta_rule_writeback --normalize_readout \
  --slot_init strided_token --slot_init_noise 0.0 --writeback_gate_max 1.0 \
  --unfreeze_hidden_to_slot --use_dual_gate --forget_bias_init 2.0 --input_bias_init 0.0 \
  --dual_gate_tanh_new --use_l3_summary --l3_n_summary 64 --l3_n_layers 2 --l3_n_heads 8 \
  --shared_memory_bank --gradient_checkpointing --gradient_accumulation_steps 1 \
  --curriculum 0:3 --bptt_window 2 --no_detach_slots_in_selector \
  --no_slot_delta_clip --inject_gate_bias_init -2.0 --routing_pool_mode slot_query \
  --multi_query_tau 1.0 --l3_diversity_weight 0.0 --l3_diversity_threshold 0.5 \
  --l_recon_weight 0.0 --route_aux_weight 1.0 \
  --use_memory_xattn --memory_xattn_gate_init 0.4 \
  --dead_slot_reset_interval 8 --dead_slot_grace_chunks 1 --dead_slot_reset_mode strided_current \
  --dead_slot_criterion cumulative \
  --save_interval 500 --eval_interval 0 --eval_samples 30 --log_interval 5 \
  --grad_clip 1.0 --proj_grad_clip 0.1 --wandb_project mixture-of-memory \
  --wandb_run_name $RUN --dtype bfloat16 --attn_impl sdpa --seed 1234" \
  </dev/null >logs/$RUN.log 2>&1 &
echo "launched $RUN pid=$!"
