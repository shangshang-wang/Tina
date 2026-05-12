# Copyright 2025 The HuggingFace Team. All rights reserved.
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

from dataclasses import dataclass, field
from typing import Optional

from transformers import TrainingArguments


@dataclass
class GRPOConfig(TrainingArguments):
    r"""
    Configuration class for the [`GRPOTrainer`].

    Only the parameters specific to GRPO training are listed here. For details on other parameters, refer to the
    [`~transformers.TrainingArguments`] documentation.

    Using [`~transformers.HfArgumentParser`] we can turn this class into
    [argparse](https://docs.python.org/3/library/argparse#module-argparse) arguments that can be specified on the
    command line.

    Parameters:
        > Parameters that control the model and reference model

        model_init_kwargs (`dict[str, Any]` or `None`, *optional*, defaults to `None`):
            Keyword arguments for [`~transformers.AutoModelForCausalLM.from_pretrained`], used when the `model`
            argument of the [`GRPOTrainer`] is provided as a string.

        > Parameters that control the data preprocessing

        remove_unused_columns (`bool`, *optional*, defaults to `False`):
            Whether to only keep the column `"prompt"` in the dataset. If you use a custom reward function that
            requires any column other than `"prompts"` and `"completions"`, you should keep this to `False`.
        max_prompt_length (`int` or `None`, *optional*, defaults to `512`):
            Maximum length of the prompt. If the prompt is longer than this value, it will be truncated left.
        num_generations (`int` or `None`, *optional*, defaults to `8`):
            Number of generations per prompt to sample. The global batch size (num_processes * per_device_batch_size)
            must be divisible by this value.
        temperature (`float`, *optional*, defaults to `0.9`):
            Temperature for sampling. The higher the temperature, the more random the completions.
        max_completion_length (`int` or `None`, *optional*, defaults to `256`):
            Maximum length of the generated completion.
        ds3_gather_for_generation (`bool`, *optional*, defaults to `True`):
            This setting applies to DeepSpeed ZeRO-3. If enabled, the policy model weights are gathered for generation,
            improving generation speed. However, disabling this option allows training models that exceed the VRAM
            capacity of a single GPU, albeit at the cost of slower generation. Disabling this option is not compatible
            with vLLM generation.

        > Parameters that control generation acceleration powered by vLLM

        use_vllm (`bool`, *optional*, defaults to `False`):
            Whether to use vLLM for generating completions. If set to `True`, ensure that a GPU is kept unused for
            training, as vLLM will require one for generation. vLLM must be installed (`pip install vllm`).
        vllm_device (`str`, *optional*, defaults to `"auto"`):
            Device where vLLM generation will run, e.g. `"cuda:1"`. If set to `"auto"` (default), the system will
            automatically select the next available GPU after the last one used for training. This assumes that
            training has not already occupied all available GPUs. If only one device is available, the device will be
            shared between both training and vLLM.
        vllm_gpu_memory_utilization (`float`, *optional*, defaults to `0.9`):
            Ratio (between 0 and 1) of GPU memory to reserve for the model weights, activations, and KV cache on the
            device dedicated to generation powered by vLLM. Higher values will increase the KV cache size and thus
            improve the model's throughput. However, if the value is too high, it may cause out-of-memory (OOM) errors
            during initialization.
        vllm_dtype (`str`, *optional*, defaults to `"auto"`):
            Data type to use for vLLM generation. If set to `"auto"`, the data type will be automatically determined
            based on the model configuration. Find the supported values in the vLLM documentation.
        vllm_max_model_len (`int` or `None`, *optional*, defaults to `None`):
            If set, the `max_model_len` to use for vLLM. This could be useful when running with reduced
            `vllm_gpu_memory_utilization`, leading to a reduced KV cache size. If not set, vLLM will use the model
            context size, which might be much larger than the KV cache, leading to inefficiencies.

        > Parameters that control the training

        learning_rate (`float`, *optional*, defaults to `1e-6`):
            Initial learning rate for [`AdamW`] optimizer. The default value replaces that of
            [`~transformers.TrainingArguments`].
        beta (`float`, *optional*, defaults to `0.04`):
            KL coefficient.
        reward_weights (`list[float]` or `None`, *optional*, defaults to `None`):
            Weights for each reward function. Must match the number of reward functions. If `None`, all rewards are
            weighted equally with weight `1.0`.
        token_loss_mask (`str`, *optional*, defaults to `"full"`):
            Token-level loss mask strategy. `"full"` keeps the original GRPO objective. `"plan_prefix"` applies the
            policy-gradient and KL loss only to an early prefix of reasoning tokens plus short formatting and answer
            anchors.
        plan_prefix_ratio (`float`, *optional*, defaults to `1.0`):
            Fraction of the reasoning span to train when `token_loss_mask="plan_prefix"`.
        format_anchor_width (`int`, *optional*, defaults to `8`):
            Number of tokens to keep before and after the `</think>` tag for format anchoring.
        answer_anchor_width (`int`, *optional*, defaults to `32`):
            Number of tokens to keep near the answer span when `token_loss_mask="plan_prefix"`.
        use_plan_scaffold (`bool`, *optional*, defaults to `False`):
            Whether to enable PlanScope-GRPO phase weighting for completions that use <plan>...</plan>.
        plan_rl_weight (`float`, *optional*, defaults to `1.0`):
            Policy-gradient weight for tokens inside the <plan>...</plan> span.
        execute_rl_weight (`float`, *optional*, defaults to `0.25`):
            Policy-gradient weight for execution tokens after </plan> and before the final answer span.
        answer_rl_weight (`float`, *optional*, defaults to `1.0`):
            Policy-gradient weight for final-answer tokens.
        plan_min_tokens (`int`, *optional*, defaults to `8`):
            Minimum plan length used for PlanScope logging.
        plan_max_tokens (`int`, *optional*, defaults to `128`):
            Maximum plan length used for PlanScope logging.
        use_advantage_aware_phase_weight (`bool`, *optional*, defaults to `False`):
            Whether to use different phase weights for positive and negative advantages.
        kl_all_tokens (`bool`, *optional*, defaults to `False`):
            Keep KL on all completion tokens even when the policy-gradient term is token-masked. This must be `True`
            for PlanScope-GRPO.
        sync_ref_model (`bool`, *optional*, defaults to `False`):
            Whether to synchronize the reference model with the active model every `ref_model_sync_steps` steps, using
            the `ref_model_mixup_alpha` parameter. This synchronization originites from the
            [TR-DPO](https://huggingface.co/papers/2404.09656) paper.
        ref_model_mixup_alpha (`float`, *optional*, defaults to `0.9`):
            α parameter from the [TR-DPO](https://huggingface.co/papers/2404.09656) paper, which controls the mix
            between the current policy and the previous reference policy during updates. The reference policy is
            updated according to the equation: `π_ref = α * π_θ + (1 - α) * π_ref_prev`. To use this parameter, you
            must set `sync_ref_model=True`.
        ref_model_sync_steps (`int`, *optional*, defaults to `64`):
            τ parameter from the [TR-DPO](https://huggingface.co/papers/2404.09656) paper, which determines how
            frequently the current policy is synchronized with the reference policy. To use this parameter, you must
            set `sync_ref_model=True`.

        > Parameters that control the logging

        log_completions (`bool`, *optional*, defaults to `False`):
            Whether to log the completions during training.
    """

    # Parameters that control the model and reference model
    model_init_kwargs: Optional[dict] = field(
        default=None,
        metadata={
            "help": "Keyword arguments for `transformers.AutoModelForCausalLM.from_pretrained`, used when the `model` "
            "argument of the `GRPOTrainer` is provided as a string."
        },
    )

    # Parameters that control the data preprocessing
    # The default value remove_unused_columns is overwritten from the parent class, because in GRPO we usually rely on
    # additional columns to compute the reward
    remove_unused_columns: Optional[bool] = field(
        default=False,
        metadata={
            "help": "Whether to only keep the column 'prompt' in the dataset. If you use a custom reward function "
            "that requires any column other than 'prompts' and 'completions', you should keep this to `False`."
        },
    )
    max_prompt_length: Optional[int] = field(
        default=512,
        metadata={
            "help": "Maximum length of the prompt. If the prompt is longer than this value, it will be truncated left."
        },
    )
    num_generations: Optional[int] = field(
        default=8,
        metadata={
            "help": "Number of generations to sample. The global batch size (num_processes * per_device_batch_size) "
            "must be divisible by this value."
        },
    )
    temperature: Optional[float] = field(
        default=0.9,
        metadata={"help": "Temperature for sampling. The higher the temperature, the more random the completions."},
    )
    max_completion_length: Optional[int] = field(
        default=256,
        metadata={"help": "Maximum length of the generated completion."},
    )
    ds3_gather_for_generation: bool = field(
        default=True,
        metadata={
            "help": "This setting applies to DeepSpeed ZeRO-3. If enabled, the policy model weights are gathered for "
            "generation, improving generation speed. However, disabling this option allows training models that "
            "exceed the VRAM capacity of a single GPU, albeit at the cost of slower generation. Disabling this option "
            "is not compatible with vLLM generation."
        },
    )

    # Parameters that control generation acceleration powered by vLLM
    use_vllm: Optional[bool] = field(
        default=False,
        metadata={
            "help": "Whether to use vLLM for generating completions. If set to `True`, ensure that a GPU is kept "
            "unused for training, as vLLM will require one for generation. vLLM must be installed "
            "(`pip install vllm`)."
        },
    )
    vllm_device: Optional[str] = field(
        default="auto",
        metadata={
            "help": "Device where vLLM generation will run, e.g. 'cuda:1'. If set to 'auto' (default), the system "
            "will automatically select the next available GPU after the last one used for training. This assumes "
            "that training has not already occupied all available GPUs."
        },
    )
    vllm_gpu_memory_utilization: float = field(
        default=0.9,
        metadata={
            "help": "Ratio (between 0 and 1) of GPU memory to reserve for the model weights, activations, and KV "
            "cache on the device dedicated to generation powered by vLLM. Higher values will increase the KV cache "
            "size and thus improve the model's throughput. However, if the value is too high, it may cause "
            "out-of-memory (OOM) errors during initialization."
        },
    )
    vllm_dtype: Optional[str] = field(
        default="auto",
        metadata={
            "help": "Data type to use for vLLM generation. If set to 'auto', the data type will be automatically "
            "determined based on the model configuration. Find the supported values in the vLLM documentation."
        },
    )
    vllm_max_model_len: Optional[int] = field(
        default=None,
        metadata={
            "help": "If set, the `max_model_len` to use for vLLM. This could be useful when running with reduced "
            "`vllm_gpu_memory_utilization`, leading to a reduced KV cache size. If not set, vLLM will use the model "
            "context size, which might be much larger than the KV cache, leading to inefficiencies."
        },
    )

    # Parameters that control the training
    learning_rate: float = field(
        default=1e-6,
        metadata={
            "help": "Initial learning rate for `AdamW` optimizer. The default value replaces that of "
            "`transformers.TrainingArguments`."
        },
    )
    beta: float = field(
        default=0.04,
        metadata={"help": "KL coefficient."},
    )
    token_loss_mask_type: str = field(
        default="none",
        metadata={
            "help": "Token-level loss mask to apply on top of the completion mask. Use 'none' for the original "
            "full-token GRPO loss, or 'plan_prefix' to train only an early reasoning prefix plus format/answer "
            "anchor tokens."
        },
    )
    plan_prefix_ratio: float = field(
        default=0.25,
        metadata={
            "help": "Fraction of reasoning tokens before the first </think> tag to keep when "
            "token_loss_mask_type='plan_prefix'. Recommended ablations: 0.25 and 0.35."
        },
    )
    plan_format_anchor_radius: int = field(
        default=4,
        metadata={
            "help": "Number of tokens to keep on each side of the detected </think> tag when using the plan-prefix "
            "loss mask."
        },
    )
    plan_answer_anchor_tokens: int = field(
        default=32,
        metadata={
            "help": "Number of final valid completion tokens to keep as an answer/format anchor when using the "
            "plan-prefix loss mask."
        },
    )
    use_plan_scaffold: bool = field(
        default=False,
        metadata={
            "help": "If True, add a <plan>...</plan> instruction scaffold to the training prompt and enable "
            "PlanScope phase weighting for the policy-gradient term."
        },
    )
    plan_rl_weight: float = field(
        default=1.0,
        metadata={"help": "Policy-gradient weight for tokens in the <plan>...</plan> phase."},
    )
    execute_rl_weight: float = field(
        default=1.0,
        metadata={"help": "Policy-gradient weight for execute tokens after </plan> and before the answer phase."},
    )
    answer_rl_weight: float = field(
        default=1.0,
        metadata={"help": "Policy-gradient weight for final-answer tokens."},
    )
    plan_min_tokens: int = field(
        default=4,
        metadata={"help": "Minimum token length for a valid <plan>...</plan> block."},
    )
    plan_max_tokens: int = field(
        default=96,
        metadata={"help": "Maximum token length for a valid <plan>...</plan> block."},
    )
    use_advantage_aware_phase_weight: bool = field(
        default=False,
        metadata={
            "help": "If True, use advantage-aware PlanScope weights: positive advantages use "
            "plan=1.0/execute=0.2/answer=1.0; negative advantages use plan=0.5/execute=0.5/answer=1.0."
        },
    )
    kl_all_tokens: bool = field(
        default=False,
        metadata={
            "help": "If True, compute the KL term over all completion tokens even when policy-gradient token masks "
            "or PlanScope phase weights are active."
        },
    )
    scale_rewards: bool = field(
        default=True,
        metadata={
            "help": "Whether to scale the rewards by dividing them by their standard deviation. If `True` (default), "
            "the rewards are normalized by the standard deviation, ensuring they have unit variance. If `False`, no "
            "scaling is applied. The Dr. GRPO paper recommends not scaling the rewards, as scaling by the standard "
            "deviation introduces a question-level difficulty bias."
        },
    )
    reward_weights: Optional[list[float]] = field(
        default=None,
        metadata={
            "help": "Weights for each reward function. Must match the number of reward functions. If `None`, all "
            "rewards are weighted equally with weight `1.0`."
        },
    )
    token_loss_mask: str = field(
        default="full",
        metadata={
            "help": "Backward-compatible alias for token_loss_mask_type. 'full' maps to 'none'; 'plan_prefix' maps "
            "to 'plan_prefix'. Prefer token_loss_mask_type in new recipes."
        },
    )
    format_anchor_width: int = field(
        default=4,
        metadata={"help": "Backward-compatible alias for plan_format_anchor_radius."},
    )
    answer_anchor_width: int = field(
        default=32,
        metadata={"help": "Backward-compatible alias for plan_answer_anchor_tokens."},
    )
    sync_ref_model: bool = field(
        default=False,
        metadata={
            "help": "Whether to synchronize the reference model with the active model every `ref_model_sync_steps` "
            "steps, using the `ref_model_mixup_alpha` parameter."
        },
    )
    ref_model_mixup_alpha: float = field(
        default=0.9,
        metadata={
            "help": "α parameter from the TR-DPO paper, which controls the mix between the current policy and the "
            "previous reference policy during updates. The reference policy is updated according to the equation: "
            "`π_ref = α * π_θ + (1 - α) * π_ref_prev`. To use this parameter, you must set `sync_ref_model=True`."
        },
    )
    ref_model_sync_steps: int = field(
        default=64,
        metadata={
            "help": "τ parameter from the TR-DPO paper, which determines how frequently the current policy is "
            "synchronized with the reference policy. To use this parameter, you must set `sync_ref_model=True`."
        },
    )

    # Parameters that control the logging
    log_completions: bool = field(
        default=False,
        metadata={"help": "Whether to log the completions during training."},
    )
