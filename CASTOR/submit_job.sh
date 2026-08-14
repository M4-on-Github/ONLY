#!/bin/bash
# ─────────────────────────────────────────────────────────────────────────────
# CASTOR — SLURM batch job for pleiades (AART Lab, head1.condo.cs.cmu.edu)
#
# Do NOT call this file directly with sbatch — use CASTOR/submit.sh instead.
# submit.sh creates /data/$USER/logs/ before sbatch opens the log file.
#
# Submit from ~/ONLY/:
#   bash CASTOR/submit.sh                                          # → answers_baseline.jsonl
#   bash CASTOR/submit.sh --use-only                              # → answers_only.jsonl
#   bash CASTOR/submit.sh --use-only --run-name layer2_g025       # → answers_only_layer2_g025.jsonl
#
# Monitor:
#   squeue -u $USER
#   tail -f /data/$USER/logs/castor_<JOBID>.out
#
# Interactive debug:
#   srun -p pleiades --time=1:00:00 --cpus-per-task=4 --gres=gpu:1 --mem=40G --constraint=RTX6000ADA --pty bash
#   cd ~/ONLY
#   apptainer exec --containall --nv \
#       --bind /data/$USER:/data/$USER --bind ~/ONLY:~/ONLY --bind ~/ONLY:/ONLY --bind /tmp:/tmp \
#       /data/$USER/castor_ONLY.sif /opt/conda/bin/python3 CASTOR/run_inference.py --use-only
# ─────────────────────────────────────────────────────────────────────────────
#SBATCH -p pleiades
#SBATCH --gres=gpu:1
#SBATCH --cpus-per-task=4
#SBATCH --mem=40G
#SBATCH --time=12:00:00
#SBATCH -J castor_only
#SBATCH --constraint=RTX6000ADA
# NOTE: --output and --error are set by CASTOR/submit.sh to /data/$USER/logs/

set -e

# ── Locate the shared path library ───────────────────────────────────────────
# SLURM copies this script to a spool directory before executing it, so $0 can
# point at /var/spool/... rather than the repo. Try the script's own directory
# (direct execution) before the submission directory (SLURM batch).
_bb_lib=""
for _c in "$(dirname "$0")/benchybench_paths.sh" \
          "${SLURM_SUBMIT_DIR:-}/CASTOR/benchybench_paths.sh" \
          "${SLURM_SUBMIT_DIR:-}/benchybench_paths.sh" \
          "${BENCHYBENCH_ROOT:-}/ONLY/CASTOR/benchybench_paths.sh"; do
    [[ -f "$_c" ]] && { _bb_lib="$_c"; break; }
done
if [[ -z "$_bb_lib" ]]; then
    echo "ERROR: cannot find CASTOR/benchybench_paths.sh" >&2
    echo "       Submit from the repo root, or set BENCHYBENCH_ROOT." >&2
    exit 1
fi
source "$_bb_lib"

# Resolve the layout once and export it, so prepare_dataset.py, run_inference.py
# and any nested submission all agree on which tree they are reading.
# bb_resolve_root probes each candidate and fails rather than guessing; this
# previously trusted SLURM_SUBMIT_DIR blindly and could run against the wrong
# image set without any error.
BENCHYBENCH_ROOT="$(bb_resolve_root)" || exit 1
export BENCHYBENCH_ROOT
REPO="$(cd "$(dirname "$_bb_lib")/.." && pwd)"
cd "$REPO"
mkdir -p "/data/$USER/logs"

JOB_START=$SECONDS

echo "=========================================="
echo " Job ID   : $SLURM_JOB_ID"
echo " Node     : $(hostname)"
echo " Started  : $(date)"
echo " Args     : $@"
echo " User     : $USER"
echo " Repo     : $REPO"
# Record the resolved layout in every job log. Without this, a run against a
# stale image copy leaves no evidence of which tree it actually read.
bb_report | sed 's/^/ /'
echo "=========================================="

nvidia-smi --query-gpu=name,memory.total,driver_version --format=csv,noheader || true

# ── All user-writable paths live under /data/$USER/ ──────────────────────────
DATA_DIR="/data/$USER"
export HF_HOME="$DATA_DIR/.cache/huggingface"
export TRANSFORMERS_CACHE="$DATA_DIR/.cache/huggingface"
export TORCH_HOME="$DATA_DIR/.cache/torch"
mkdir -p "$HF_HOME" "$TORCH_HOME"

# Container is built by build_container.sh before this array job starts.
# submit.sh chains the two jobs with --dependency=afterok.
SIF="$DATA_DIR/castor_ONLY.sif"
if [ ! -f "$SIF" ]; then
    echo "ERROR: $SIF not found — was the build job (build_container.sh) successful?" >&2
    exit 1
fi
echo "[$(date)] Container: $SIF"

# --containall stops the cluster's apptainer.conf from bind-mounting the host
# /opt over the container's /opt/conda. We then add back only what's needed.
# --bind $REPO:/ONLY makes the repo available at /ONLY so the container's
# PYTHONPATH=/ONLY/transformers/src (set in %environment) resolves at runtime.
APPTAINER_BASE="apptainer exec --containall --nv \
    --pwd $REPO \
    --env USER=$USER \
    --env HOME=$HOME \
    --env HF_HOME=$HF_HOME \
    --env TRANSFORMERS_CACHE=$TRANSFORMERS_CACHE \
    --env TORCH_HOME=$TORCH_HOME \
    --bind /tmp:/tmp \
    --bind $REPO:$REPO \
    --bind $REPO:/ONLY \
    --bind $DATA_DIR:$DATA_DIR"
PYTHON=/opt/conda/bin/python3

echo "[$(date)] Container Python: $PYTHON"

# ── Select prompt and mode for this array task ───────────────────────────────
# submit.sh uses interleaved task IDs:
#   both modes (default) → even task ID = baseline, odd = ONLY (same prompt)
#   one mode specified   → task ID maps directly to prompt index
PROMPTS_DIR="$REPO/CASTOR/prompts"
IMAGE_DIR="$(bb_images_dir)" || exit 1

PROMPT_FILES=( "$PROMPTS_DIR"/*.txt )
N_PROMPTS=${#PROMPT_FILES[@]}

# ── Parse "$@" in one pass ────────────────────────────────────────────────────
USER_RUN_NAME=""
HAS_USE_ONLY=false
HAS_NO_ONLY=false
PASSTHROUGH=()
_args=("$@"); _i=0
while [[ $_i -lt ${#_args[@]} ]]; do
    case "${_args[$_i]}" in
        --run-name)  _i=$((_i+1)); USER_RUN_NAME="${_args[$_i]}" ;;
        --run-name=*) USER_RUN_NAME="${_args[$_i]#--run-name=}" ;;
        --use-only)  HAS_USE_ONLY=true ;;
        --no-only)   HAS_NO_ONLY=true  ;;
        *)           PASSTHROUGH+=("${_args[$_i]}") ;;
    esac
    _i=$((_i+1))
done
unset _args _i

# ── Resolve prompt file and mode from task ID ─────────────────────────────────
if $HAS_USE_ONLY; then
    PROMPT_IDX=$SLURM_ARRAY_TASK_ID
    MODE_FLAG="--use-only"
elif $HAS_NO_ONLY; then
    PROMPT_IDX=$SLURM_ARRAY_TASK_ID
    MODE_FLAG="--no-only"
else
    # Both modes: even task → baseline, odd task → ONLY (pairs share a prompt)
    PROMPT_IDX=$(( SLURM_ARRAY_TASK_ID / 2 ))
    if (( SLURM_ARRAY_TASK_ID % 2 == 0 )); then
        MODE_FLAG="--no-only"
    else
        MODE_FLAG="--use-only"
    fi
fi

PROMPT_FILE="${PROMPT_FILES[$PROMPT_IDX]}"
STEM=$(basename "$PROMPT_FILE" .txt)

# ── Build run name ────────────────────────────────────────────────────────────
# Pattern: [user_tag_]{stem}_j{ArrayJobID}
if [[ -n "$USER_RUN_NAME" ]]; then
    RUN_NAME="${USER_RUN_NAME}_${STEM}_j${SLURM_ARRAY_JOB_ID}"
else
    RUN_NAME="${STEM}_j${SLURM_ARRAY_JOB_ID}"
fi

QUESTIONS_FILE="$DATA_DIR/castor_results/questions_${RUN_NAME}.jsonl"
mkdir -p "$DATA_DIR/castor_results"

echo "=========================================="
echo " Array task  : $SLURM_ARRAY_TASK_ID  (job $SLURM_ARRAY_JOB_ID)"
echo " Mode        : $MODE_FLAG"
echo " Prompt file : $PROMPT_FILE"
echo " Run name    : $RUN_NAME"
echo " Questions   : $QUESTIONS_FILE"
echo "=========================================="

# ── Prepare dataset with this prompt ─────────────────────────────────────────
$APPTAINER_BASE "$SIF" $PYTHON "$REPO/CASTOR/prepare_dataset.py" \
    --image-dir   "$IMAGE_DIR" \
    --output      "$QUESTIONS_FILE" \
    --prompt-file "$PROMPT_FILE"

# ── Run inference ─────────────────────────────────────────────────────────────
# --image-folder is passed explicitly so config.json's relative
# "../shipwreck_wiki_images" is never consulted; that path resolved against the
# current working directory and so depended on where the job was launched.
# It precedes "${PASSTHROUGH[@]}" so a user-supplied --image-folder still wins.
time $APPTAINER_BASE "$SIF" $PYTHON "$REPO/CASTOR/run_inference.py" \
    --image-folder  "$IMAGE_DIR" \
    "${PASSTHROUGH[@]}" \
    --question-file "$QUESTIONS_FILE" \
    --run-name      "$RUN_NAME" \
    "$MODE_FLAG"

ELAPSED=$(( SECONDS - JOB_START ))
echo "=========================================="
echo " Finished     : $(date)"
echo " Job wall time: $(( ELAPSED/3600 ))h $(( (ELAPSED%3600)/60 ))m $(( ELAPSED%60 ))s"
echo "=========================================="
