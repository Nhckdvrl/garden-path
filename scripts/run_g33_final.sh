#!/usr/bin/env bash
# Usage: bash scripts/run_g33_final.sh <GPU index> <model tag> [item limit]
set -euo pipefail
cd /home/xiang/garden-path
export PATH=/home/xiang/miniconda3/envs/verl-clean/bin:$PATH
export HF_HUB_OFFLINE=1
export CUDA_DEVICE_ORDER=PCI_BUS_ID
export VLLM_LOGGING_LEVEL=WARNING
export TOKENIZERS_PARALLELISM=false
export VLLM_USE_FLASHINFER_SAMPLER=0
export VLLM_WORKER_MULTIPROC_METHOD=spawn
PY=/home/xiang/miniconda3/envs/verl-clean/bin/python
HUB=/home/xiang/.cache/huggingface/hub
GPU=${1:?GPU index required}
TAG=${2:?model tag required}
LIMIT=${3:-}
case "$TAG" in
  qwen3-8b) MODEL=$HUB/models--Qwen--Qwen3-8B/snapshots/b968826d9c46dd6066d109eabc6255188de91218 ;;
  gemma3-12b) MODEL=$HUB/models--google--gemma-3-12b-it/snapshots/96b6f1eccf38110c56df3a15bffe176da04bfd80 ;;
  mistral-small-24b) MODEL=${G33_MISTRAL_MODEL:-data/mistral_small_24b_hf} ;;
  *) echo "unknown model tag: $TAG" >&2; exit 2 ;;
esac
test -d "$MODEL"
ARGS=(--resume --gpu-frac "${G33_GPU_FRAC:-0.64}")
if [[ -n "${G33_CASE_START:-}" ]]; then ARGS+=(--case-start "$G33_CASE_START"); fi
if [[ -n "${G33_CASE_END:-}" ]]; then ARGS+=(--case-end "$G33_CASE_END"); fi
if [[ -n "${G33_ITEMS:-}" ]]; then ARGS+=(--items "$G33_ITEMS"); fi
if [[ "$TAG" == "mistral-small-24b" ]]; then ARGS+=(--tokenizer data/external/g33_mistral_tokenizer); fi
if [[ -n "$LIMIT" ]]; then ARGS+=(--limit "$LIMIT"); fi
CUDA_VISIBLE_DEVICES="$GPU" "$PY" scripts/run_g33_final.py \
  --model "$MODEL" --tag "$TAG" --out "${G33_OUTPUT:-results/raw/${TAG}_g33_final_v1${LIMIT:+_smoke}.jsonl}" "${ARGS[@]}"
