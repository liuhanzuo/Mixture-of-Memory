#!/bin/bash
# Experiment H10: Aggressive NIAH (H6b-like) + Contrastive Retrieval
#
# Tests if contrastive loss helps even with aggressive NIAH training.
# H6b had mix=0.50, lambda=2.0 but still 0% NIAH accuracy.
# Adding contrastive should provide direct slot supervision.
#
# Changes vs H6b:
#   - contrastive_weight: 0.0 → 1.0
#   - save_interval: 1000 → 500

set -e
cd /apdcephfs_wzc1/share_303098609/pighzliu_code/Mixture-of-Memory

export PYTHONPATH="/apdcephfs_wzc1/share_303098609/pighzliu_code/Mixture-of-Memory:$PYTHONPATH"
export PYTHONUNBUFFERED=1

LOGDIR=logs
mkdir -p $LOGDIR
LOGFILE=$LOGDIR/experiment_h10_aggressive_contrastive_$(date +%Y%m%d_%H%M).log

echo "============================================"
echo "Experiment H10: Aggressive NIAH + Contrastive"
echo "  NIAH: lambda=2.0, mix=0.50, warmup=100"
echo "  CONTRASTIVE WEIGHT: 1.0 (NEW!)"
echo "Output: outputs/experiment_h10_aggressive_contrastive"
echo "Log:    $LOGFILE"
echo "============================================"

torchrun \
    --nproc_per_node=8 \
    --nnodes=1 \
    --node_rank=0 \
    --rdzv_backend=c10d \
    --rdzv_endpoint=localhost:29500 \
    scripts/train_cross_attn_memory.py \
    --model /apdcephfs_wzc1/share_303098609/pighzliu_code/models/Llama--Llama3-8b \
    --shard_dir /apdcephfs_wzc1/share_303098609/pighzliu_code/data/dolmino-mix-1124-llama3 \
    --output_dir /apdcephfs_wzc1/share_303098609/pighzliu_code/Mixture-of-Memory/outputs/experiment_h10_aggressive_contrastive \
    --wikitext_path /apdcephfs_wzc1/share_303098609/pighzliu_code/Mixture-of-Memory/data/wikitext_chunks_llama3_4096.npy \
    --niah_data /apdcephfs_wzc1/share_303098609/pighzliu_code/Mixture-of-Memory/data/pg19_chunks_llama3.npy \
    --slot_forward \
    --middle_layer_memory \
    --memory_write_layer 16 \
    --memory_read_layers 18,22,26,30 \
    --memory_init strided \
    --use_dual_gate \
    --forget_bias_init 1.0 \
    --input_bias_init 0.0 \
    --niah_mix_fraction 0.50 \
    --niah_max_N 2 \
    --niah_warmup_steps 100 \
    --lambda_retrieve 2.0 \
    --contrastive_weight 1.0 \
    --contrastive_temperature 0.1 \
    --num_shards 25 \
    --seq_len 4096 \
    --chunks_per_doc 32 \
    --num_slots 64 \
    --full_finetune \
    --use_memory \
    --gradient_checkpointing \
    --gradient_accumulation_steps 4 \
    --lr 5e-6 \
    --min_lr 1e-6 \
    --warmup_steps 200 \
    --max_steps 5000 \
    --eval_interval 200 \
    --save_interval 500 \
    --weight_decay 0.01 \
    --max_grad_norm 1.0 \
    2>&1 | tee $LOGFILE
