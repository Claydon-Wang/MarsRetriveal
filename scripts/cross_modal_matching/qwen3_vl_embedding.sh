#!/usr/bin/env bash
# Usage: bash scripts/cross_modal_matching/qwen3_vl_embedding.sh 0,1 (or export CUDA_VISIBLE_DEVICES beforehand)
export CUDA_VISIBLE_DEVICES=${1:-${CUDA_VISIBLE_DEVICES:-0}}
export PATH=~/.conda/envs/retrieval/bin:$PATH

# Hugging Face mirrors/caches (adjust to your environment)
export HF_ENDPOINT=https://hf-mirror.com
export HF_HOME=/mnt/sharedata/ssd_large/common/VLMs/
export HF_DATASETS_CACHE=/mnt/sharedata/ssd_large/common/VLMs/datasets/

TASK_CONFIG=CrossModalMatching
MODEL_CONFIG=Qwen3VLEmbedding
EXP_NAME=main_exp

MODEL_NAME=Qwen/Qwen3-VL-Embedding-8B
PRETRAINED=qwen3_vl_embedding
IMAGE_ENCODER_TYPE=qwen3_vl_embedding
TEXT_ENCODER_TYPE=qwen3_vl_embedding

python main.py \
  --task_config "${TASK_CONFIG}" \
  --model_config "${MODEL_CONFIG}" \
  --exp_name "${EXP_NAME}" \
  --query_mode "text" \
  --model_name "${MODEL_NAME}" \
  --pretrained "${PRETRAINED}" \
  --image_encoder_type "${IMAGE_ENCODER_TYPE}" \
  --text_encoder_type "${TEXT_ENCODER_TYPE}"
