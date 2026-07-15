# Copyright 2024 Bytedance Ltd. and/or its affiliates
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
import json
import logging
import os
from pprint import pprint

import hydra
import ray
from omegaconf import DictConfig, OmegaConf, open_dict
from ray._private.runtime_env.constants import RAY_JOB_CONFIG_JSON_ENV_VAR

from verl.trainer.constants_ppo import get_ppo_ray_runtime_env
from verl.trainer.ppo.utils import need_critic, need_reference_policy
from verl.utils.config import validate_config
from verl.utils.device import auto_set_device, is_cuda_available
from verl.utils.import_utils import load_class_from_fqn

logger = logging.getLogger(__name__)
logger.setLevel(os.getenv("VERL_LOGGING_LEVEL", "INFO"))


def _job_runtime_env_var_keys() -> set[str]:
    """Env var keys already supplied by `ray job submit --runtime-env`.

    Ray rejects duplicate env var keys between the Job runtime env and the
    Driver's `ray.init(runtime_env=...)`, even if the values are identical.
    """
    try:
        job_config = json.loads(os.environ.get(RAY_JOB_CONFIG_JSON_ENV_VAR, "{}"))
    except json.JSONDecodeError:
        return set()
    env_vars = job_config.get("runtime_env", {}).get("env_vars", {})
    return set(env_vars) if isinstance(env_vars, dict) else set()


def _should_forward_runtime_env_var(key: str) -> bool:
    return key.startswith(("VERL_TQ_", "VERL_TRAIN_MEM_")) or key in {
        "VERL_ROLLOUT_NODE_RESOURCE",
        "VERL_TRAIN_NODE_RESOURCE",
    }


# Define a function to run the PPO-like training process
def run_ppo(config, task_runner_class) -> None:
    """Initialize Ray cluster and run distributed PPO training process.

    Args:
        config: Training configuration object containing all necessary parameters
                for distributed PPO training including Ray initialization settings,
                model paths, and training hyperparameters.
        task_runner_class: For recipe to change TaskRunner.
    """
    # Propagate determinism env vars from config before ray.init() so
    # get_ppo_ray_runtime_env() forwards them to all Ray actors.
    rollout_cfg = config.actor_rollout_ref.rollout
    rm_rollout_cfg = config.reward.reward_model.rollout
    if rollout_cfg.full_determinism or (config.reward.reward_model.enable and rm_rollout_cfg.full_determinism):
        os.environ["VERL_FULL_DETERMINISM"] = "1"
        os.environ["VLLM_BATCH_INVARIANT"] = "1"
        os.environ["PYTHONHASHSEED"] = str(rollout_cfg.seed)

    # Check if Ray is not initialized
    if not ray.is_initialized():
        # Initialize Ray with a local cluster configuration
        # Set environment variables in the runtime environment to control tokenizer parallelism,
        # NCCL debug level, VLLM logging level, and allow runtime LoRA updating
        # `num_cpus` specifies the number of CPU cores Ray can use, obtained from the configuration
        default_runtime_env = get_ppo_ray_runtime_env()
        ray_init_kwargs = config.ray_kwargs.get("ray_init", {})
        runtime_env_kwargs = ray_init_kwargs.get("runtime_env", {})

        if config.transfer_queue.enable:
            # Add runtime environment variables for transfer queue
            runtime_env_vars = runtime_env_kwargs.get("env_vars", {})
            if isinstance(runtime_env_vars, DictConfig):
                with open_dict(runtime_env_vars):
                    runtime_env_vars["TRANSFER_QUEUE_ENABLE"] = "1"
            else:
                runtime_env_vars["TRANSFER_QUEUE_ENABLE"] = "1"
            runtime_env_kwargs["env_vars"] = runtime_env_vars

        # `ray job submit --runtime-env=...` applies env vars to the driver and Ray
        # merges that Job runtime_env into child actors. Only forward placement/TQ
        # vars that came from the launch shell rather than the Job runtime_env;
        # otherwise ray.init fails with duplicate env-var conflicts.
        job_runtime_env_keys = _job_runtime_env_var_keys()
        runtime_env_vars = runtime_env_kwargs.get("env_vars", {})
        if isinstance(runtime_env_vars, DictConfig):
            with open_dict(runtime_env_vars):
                for key, value in os.environ.items():
                    if key in job_runtime_env_keys:
                        continue
                    if _should_forward_runtime_env_var(key):
                        runtime_env_vars[key] = value
        else:
            for key, value in os.environ.items():
                if key in job_runtime_env_keys:
                    continue
                if _should_forward_runtime_env_var(key):
                    runtime_env_vars[key] = value
        runtime_env_kwargs["env_vars"] = runtime_env_vars

        runtime_env = OmegaConf.merge(default_runtime_env, runtime_env_kwargs)
        ray_init_kwargs = OmegaConf.create({**ray_init_kwargs, "runtime_env": runtime_env})
        print(f"ray init kwargs: {ray_init_kwargs}")
        ray.init(**OmegaConf.to_container(ray_init_kwargs))

    # Create a remote instance of the TaskRunner class, and
    # Execute the `run` method of the TaskRunner instance remotely and wait for it to complete
    if (
        is_cuda_available
        and config.global_profiler.tool == "nsys"
        and config.global_profiler.get("steps") is not None
        and len(config.global_profiler.get("steps", [])) > 0
    ):
        from verl.utils.import_utils import is_nvtx_available

        assert is_nvtx_available(), "nvtx is not available in CUDA platform. Please 'pip3 install nvtx'"
        nsight_options = OmegaConf.to_container(
            config.global_profiler.global_tool_config.nsys.controller_nsight_options
        )
        runner = task_runner_class.options(runtime_env={"nsight": nsight_options}).remote()
    else:
        runner = task_runner_class.remote()
    ray.get(runner.run.remote(config))

    # [Optional] get the path of the timeline trace file from the configuration, default to None
    # This file is used for performance analysis
    timeline_json_file = config.ray_kwargs.get("timeline_json_file", None)
    if timeline_json_file:
        ray.timeline(filename=timeline_json_file)


@ray.remote
class TaskRunnerV1:
    """V1 TaskRunner for PPO training."""

    def __init__(self):
        self.config = None
        self.trainer = None
        self.agent_loop_manager = None

    def init_agent_loop_manager(self):
        """Initialize the agent loop manager to generate sequences.

        NOTE: User can customize their own agent loop manager, the only requirement is:
        1. implement `generate_sequences` method
        2. put agent loop outputs into TransferQueue
        """
        from verl.trainer.ppo.v1 import AgentLoopManagerTQ

        manager_class_fqn = self.config.actor_rollout_ref.rollout.get("agent", {}).get("agent_loop_manager_class")
        if manager_class_fqn:
            agent_loop_manager_cls = load_class_from_fqn(manager_class_fqn, "AgentLoopManager")
        else:
            agent_loop_manager_cls = AgentLoopManagerTQ

        self.agent_loop_manager = agent_loop_manager_cls.create(
            config=self.config,
            llm_client=self.trainer.get_llm_client(),
            teacher_client=self.trainer.get_teacher_client(),
            reward_loop_worker_handles=self.trainer.get_reward_handles(),
        )

    def run(self, config: DictConfig):
        """Run the PPO training process."""
        import transfer_queue as tq

        from verl.trainer.ppo.v1 import get_trainer_cls
        from verl.utils.transferqueue_placement import patch_transfer_queue_simple_storage_placement

        trainer_cls = get_trainer_cls(config.trainer.v1.trainer_mode)

        config.transfer_queue.enable = True
        pprint(OmegaConf.to_container(config, resolve=True))
        OmegaConf.resolve(config)
        self.config = config

        # initialize transfer queue
        patch_transfer_queue_simple_storage_placement()
        tq.init(config.transfer_queue)
        try:
            self.trainer = trainer_cls(config=config)
            self.trainer.init()
            self.init_agent_loop_manager()
            self.trainer.fit(self.agent_loop_manager)
        finally:
            tq.close()


@hydra.main(config_path="config", config_name="ppo_trainer", version_base=None)
def main(config):
    """Main entry point for PPO training with Hydra configuration management.

    Args:
        config: Hydra configuration dictionary containing training parameters.
    """
    # Automatically set `config.trainer.device = npu` when running on Ascend NPU.
    auto_set_device(config)

    # validate config
    validate_config(
        config=config,
        use_reference_policy=need_reference_policy(config),
        use_critic=need_critic(config),
    )

    if config.trainer.use_v1:
        run_ppo(config, task_runner_class=TaskRunnerV1)
    else:
        from verl.trainer.main_ppo_v0 import TaskRunner

        logger.warning(
            "Legacy trainer `main_ppo_v0.py` is deprecated, and wil be removed in v0.9.0."
            "Please set `trainer.use_v1=True` in config to use V1 trainer."
        )
        run_ppo(config, task_runner_class=TaskRunner)


if __name__ == "__main__":
    main()
