#!/bin/bash
#SBATCH --job-name=medrag-sns-e5-index
#SBATCH --cpus-per-task=8
#SBATCH --nodes=1
#SBATCH --ntasks-per-node=1
#SBATCH --time=03:00:00
#SBATCH --mem=64GB
#SBATCH --gres=gpu:1
#SBATCH --output=experiments/slurm_logs/sns1064_e5_indexing_%j.log
#SBATCH --error=experiments/slurm_logs/sns1064_e5_indexing_%j.err
#SBATCH --mail-type=END,FAIL
#SBATCH --mail-user=igutierrez134@ikasle.ehu.eus

set -euo pipefail

source /home/igutierrez134/envs/med_rag_thesis/bin/activate

export HF_HOME="/home/igutierrez134/.cache/huggingface"
export TRANSFORMERS_CACHE="/home/igutierrez134/.cache/huggingface"
export HF_HUB_CACHE="/home/igutierrez134/.cache/huggingface"
export TOKENIZERS_PARALLELISM=false

mkdir -p experiments/slurm_logs

echo "SNS1064 e5 indexing started on $(hostname)"
echo "Date: $(date)"
echo "SLURM_JOB_ID=${SLURM_JOB_ID:-}"
echo "CUDA_VISIBLE_DEVICES=${CUDA_VISIBLE_DEVICES:-}"
export CUDA_VISIBLE_DEVICES=${CUDA_VISIBLE_DEVICES:-0}
nvidia-smi || true

python scripts/build_retrieval_index.py \
  --input data/processed/sns1064/train.jsonl \
         data/processed/sns1064/dev.jsonl \
         data/processed/sns1064/test.jsonl \
  --output-dir models/retrieval/sns1064_train_multilingual_e5_large \
  --backend dense \
  --model intfloat/multilingual-e5-large \
  --batch-size 16

echo "SNS1064 e5 indexing finished at $(date)"
