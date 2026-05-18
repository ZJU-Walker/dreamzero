#!/bin/bash
# DreamZero YAM Sanity-Check Training Script
#
# Runs 20 steps on 1 GPU with batch size 1 to verify the data + model pipeline
# end-to-end before committing real GPU hours. Mirrors yam_training.sh, with
# overrides for the smallest possible run:
#   - max_steps=20
#   - save_steps=20
#   - per_device_train_batch_size=1
#   - NUM_GPUS=1 (default)
#   - dataloader_num_workers=0
#   - report_to=none  (skip wandb)
#
# Usage:
#   YAM_DATA_ROOT=/iris/u/kewalk/dataset/plate_task_0505_lerobot \
#       bash scripts/train/yam_sanity.sh
#
# Prerequisites (~73 GB):
#   - ./checkpoints/Wan2.1-I2V-14B-480P
#   - ./checkpoints/umt5-xxl
#   - ./checkpoints/DreamZero-AgiBot

export HYDRA_FULL_ERROR=1

# ============ CONFIG ============
YAM_DATA_ROOT=${YAM_DATA_ROOT:-"/iris/u/kewalk/dataset/plate_task_0505_lerobot"}
OUTPUT_DIR=${OUTPUT_DIR:-"./checkpoints/yam_sanity"}

if [ -z "${NUM_GPUS}" ]; then
  NUM_GPUS=$(nvidia-smi -L 2>/dev/null | wc -l)
fi
NUM_GPUS=${NUM_GPUS:-1}

WAN_CKPT_DIR=${WAN_CKPT_DIR:-"./checkpoints/Wan2.1-I2V-14B-480P"}
TOKENIZER_DIR=${TOKENIZER_DIR:-"./checkpoints/umt5-xxl"}
# ================================

# Auto-download weights if missing
if [ ! -d "$WAN_CKPT_DIR" ] || [ -z "$(ls -A "$WAN_CKPT_DIR" 2>/dev/null)" ]; then
    echo "Wan2.1-I2V-14B-480P not found at $WAN_CKPT_DIR. Downloading..."
    huggingface-cli download Wan-AI/Wan2.1-I2V-14B-480P --local-dir "$WAN_CKPT_DIR"
fi

if [ ! -d "$TOKENIZER_DIR" ] || [ -z "$(ls -A "$TOKENIZER_DIR" 2>/dev/null)" ]; then
    echo "umt5-xxl not found at $TOKENIZER_DIR. Downloading..."
    huggingface-cli download google/umt5-xxl --local-dir "$TOKENIZER_DIR"
fi

if [ ! -d "$YAM_DATA_ROOT" ]; then
    echo "ERROR: YAM dataset not found at $YAM_DATA_ROOT"
    exit 1
fi
if [ ! -f "$YAM_DATA_ROOT/meta/embodiment.json" ]; then
    echo "ERROR: $YAM_DATA_ROOT/meta/embodiment.json missing — run convert_lerobot_to_gear.py first"
    exit 1
fi

torchrun --nproc_per_node $NUM_GPUS --standalone groot/vla/experiment/experiment.py \
    report_to=none \
    data=dreamzero/yam_relative \
    train_architecture=lora \
    num_frames=33 \
    action_horizon=24 \
    num_views=3 \
    model=dreamzero/vla \
    model/dreamzero/action_head=wan_flow_matching_action_tf \
    model/dreamzero/transform=dreamzero_cotrain \
    num_frame_per_block=2 \
    num_action_per_block=24 \
    num_state_per_block=1 \
    seed=42 \
    training_args.learning_rate=1e-5 \
    training_args.deepspeed="groot/vla/configs/deepspeed/zero2.json" \
    save_steps=20 \
    training_args.warmup_ratio=0.05 \
    output_dir=$OUTPUT_DIR \
    per_device_train_batch_size=1 \
    max_steps=40 \
    weight_decay=1e-5 \
    save_total_limit=5 \
    upload_checkpoints=false \
    bf16=true \
    tf32=true \
    eval_bf16=true \
    dataloader_pin_memory=false \
    dataloader_num_workers=0 \
    image_resolution_width=320 \
    image_resolution_height=176 \
    save_lora_only=true \
    max_chunk_size=4 \
    frame_seqlen=880 \
    save_strategy=steps \
    yam_data_root=$YAM_DATA_ROOT \
    dit_version=$WAN_CKPT_DIR \
    text_encoder_pretrained_path=$WAN_CKPT_DIR/models_t5_umt5-xxl-enc-bf16.pth \
    image_encoder_pretrained_path=$WAN_CKPT_DIR/models_clip_open-clip-xlm-roberta-large-vit-huge-14.pth \
    vae_pretrained_path=$WAN_CKPT_DIR/Wan2.1_VAE.pth \
    tokenizer_path=$TOKENIZER_DIR \
    pretrained_model_path=./checkpoints/DreamZero-AgiBot \
    ++action_head_cfg.config.skip_component_loading=true \
    ++action_head_cfg.config.defer_lora_injection=true
