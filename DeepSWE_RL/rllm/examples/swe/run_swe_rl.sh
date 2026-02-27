set -x

export VLLM_ATTENTION_BACKEND=FLASH_ATTN
export PYTORCH_CUDA_ALLOC_CONF="expandable_segments:False"
export VLLM_USE_V1=1
export VLLM_ALLOW_LONG_MAX_MODEL_LEN=1
export VLLM_ENGINE_ITERATION_TIMEOUT_S=100000000000

export WANDB_MODE=online


# Find the directory where rllm package is located
RLLM_DIR=$(python3 -c "import rllm; import os; print(os.path.dirname(os.path.dirname(rllm.__file__)))")
echo ${RLLM_DIR}
echo "Python executable:"
python3 -c "import sys; print(sys.executable)"

echo "Python version:"
python3 -c "import sys; print(sys.version)"

echo "Pip version and location:"
python3 -m pip --version

echo "Installed packages:"
python3 -m pip list

echo "========"


export HYDRA_FULL_ERROR=1

# 设置项目名和实验名称
PROJECT_NAME="YOUR_PROJECT_NAME"
EXPERIMENT_NAME="YOUR_EXPERIMENT_NAME"

TS=$(date +"%Y-%m-%d_%H-%M-%S")   # 增加时间后缀
EXPERIMENT_NAME="${EXPERIMENT_NAME}_${TS}"

echo "Project: ${PROJECT_NAME}"
echo "Experiment: ${EXPERIMENT_NAME}"

# 设置输出路径
DEFAULT_LOCAL_DIR="DeepSWE_RLDeepSWE_RL/rllm/train_output/${PROJECT_NAME}/${EXPERIMENT_NAME}"
ROLLOUT_DATA_DIR="DeepSWE_RLDeepSWE_RL/rllm/train_output_rollout/${PROJECT_NAME}/${EXPERIMENT_NAME}"

mkdir -p "${DEFAULT_LOCAL_DIR}" "${ROLLOUT_DATA_DIR}"


echo "DEFAULT_LOCAL_DIR: ${DEFAULT_LOCAL_DIR}"
echo "ROLLOUT_DATA_DIR: ${ROLLOUT_DATA_DIR}"


python3 -m rllm.trainer.verl.train_agent_ppo \
    algorithm.adv_estimator=loop \
    data.train_files="YOUR_TRAIN_FILE_PATH" \
    data.val_files=None \
    data.train_batch_size=32 \
    data.val_batch_size=512 \
    data.max_prompt_length=8192 \
    data.max_response_length=102400 \
    data.filter_overlong_prompts=True \
    data.filter_overlong_prompts_workers=32 \
    actor_rollout_ref.model.path="YOUR_MODEL_PATH" \
    actor_rollout_ref.hybrid_engine=True \
    actor_rollout_ref.actor.optim.lr=1e-6 \
    actor_rollout_ref.model.use_remove_padding=True \
    actor_rollout_ref.actor.loss_agg_mode=seq-mean-token-sum \
    actor_rollout_ref.actor.ppo_mini_batch_size=16 \
    actor_rollout_ref.actor.use_dynamic_bsz=False \
    actor_rollout_ref.actor.ppo_micro_batch_size_per_gpu=1 \
    actor_rollout_ref.rollout.log_prob_use_dynamic_bsz=True \
    actor_rollout_ref.rollout.log_prob_micro_batch_size_per_gpu=1 \
    actor_rollout_ref.actor.ppo_max_token_len_per_gpu=14000 \
    actor_rollout_ref.actor.use_kl_loss=False \
    actor_rollout_ref.actor.clip_ratio_high=0.28 \
    actor_rollout_ref.actor.kl_loss_coef=0.0 \
    actor_rollout_ref.actor.kl_loss_type=low_var_kl \
    actor_rollout_ref.actor.ulysses_sequence_parallel_size=8 \
    actor_rollout_ref.actor.ppo_micro_batch_size_per_gpu=1 \
    actor_rollout_ref.model.enable_gradient_checkpointing=True \
    actor_rollout_ref.actor.fsdp_config.param_offload=True \
    actor_rollout_ref.actor.fsdp_config.optimizer_offload=True \
    actor_rollout_ref.rollout.tensor_model_parallel_size=4 \
    actor_rollout_ref.rollout.name=vllm \
    actor_rollout_ref.rollout.mode="async" \
    actor_rollout_ref.rollout.chat_scheduler=verl.schedulers.completions_scheduler.CompletionsScheduler \
    actor_rollout_ref.rollout.enforce_eager=False \
    actor_rollout_ref.rollout.temperature=1.0 \
    actor_rollout_ref.rollout.gpu_memory_utilization=0.6 \
    actor_rollout_ref.rollout.n=4 \
    actor_rollout_ref.rollout.val_kwargs.n=1 \
    actor_rollout_ref.rollout.val_kwargs.temperature=0 \
    actor_rollout_ref.ref.fsdp_config.param_offload=True \
    actor_rollout_ref.actor.entropy_coeff=0.0 \
    algorithm.kl_ctrl.kl_coef=0.0 \
    algorithm.mask_truncated_samples=False \
    algorithm.clip_advantages=False \
    trainer.critic_warmup=0 \
    trainer.logger=['console','tensorboard'] \
    trainer.project_name=$PROJECT_NAME \
    trainer.experiment_name=$EXPERIMENT_NAME \
    trainer.default_local_dir=$DEFAULT_LOCAL_DIR \
    trainer.rollout_data_dir=$ROLLOUT_DATA_DIR \
    trainer.val_before_train=False \
    trainer.n_gpus_per_node=8 \
    trainer.nnodes=8 \
    trainer.save_freq=3 \
    trainer.max_actor_ckpt_to_keep=2 \
    trainer.max_critic_ckpt_to_keep=2 \
    trainer.test_freq=-1 \
    trainer.default_hdfs_dir=null \
    env.name=swe_sim \
    +env.env_args.backend="simulated" \
    +env.env_args.simulator_yaml="swe_world/src/simulation/models_yaml/example_world_models.yaml" \
    +env.env_args.sim_reward_max_workers=4 \
    +env.env_args.delete_image=False \
    +env.env_args.scaffold="openhands" \
    agent.name=sweagent \
    agent.max_steps=120 \
    agent.overlong_filter=True \
    agent.async_engine=True \
    +agent.agent_args.scaffold="openhands" \
    trainer.total_epochs=1000