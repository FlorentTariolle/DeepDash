#!/bin/bash
#SBATCH -J "train_ppo_20k"
#SBATCH -o slurm/logs/train_ppo_%j.out
#SBATCH -e slurm/logs/train_ppo_%j.err
#SBATCH -p ar_a100
#SBATCH --gres=gpu:a100:1
#SBATCH -n 1
#SBATCH --cpus-per-gpu 8
#SBATCH --mem 64G
#SBATCH --time=08:00:00
#SBATCH --exclude=c23hpda2
#SBATCH --signal=B:USR1@300

# Auto-resubmit on timeout: SIGUSR1 is sent 5 minutes before the time limit.
cleanup_and_resubmit() {
    echo "$(date): Caught signal, saving and resubmitting..."
    sbatch "$0"
    exit 0
}
trap cleanup_and_resubmit USR1

module purge
module load aidl/pytorch/2.6.0-cuda12.6
export PATH="$HOME/.local/bin:$PATH"
pip install --user wandb 2>/dev/null

echo "=== Train Controller (PPO, constant LR, auto-resume) ==="
echo "$(date): Starting on $(hostname), Job ID: $SLURM_JOB_ID"

# First run: fresh from BC. Subsequent runs: resume.
if [ -f checkpoints/controller_ppo_latest.pt ]; then
    echo "Resuming from latest checkpoint"
    RESUME_FLAG="--resume"
else
    echo "Starting fresh from BC checkpoint"
    RESUME_FLAG=""
fi

python -u scripts/train_controller_ppo.py \
    --transformer-checkpoint checkpoints/transformer_best.pt \
    --pretrained checkpoints/controller_bc_best.pt \
    $RESUME_FLAG \
    --config configs/v6.yaml \
    --checkpoint-dir checkpoints \
    --seed 42 &

# Wait for training process (needed for signal handling)
wait $!
echo "$(date): Training finished normally"
