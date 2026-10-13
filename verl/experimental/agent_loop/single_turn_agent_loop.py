import logging
import os
from typing import Any
from uuid import uuid4
from verl.experimental.agent_loop.agent_loop import (
    AgentLoopBase,
    AgentLoopOutput,
    register,
)
from verl.tools.utils.tool_registry import initialize_tools_from_config
from verl.utils.profiler import simple_timer

logger = logging.getLogger(__file__)
logger.setLevel(os.getenv("VERL_LOGGING_LEVEL", "WARN"))


@register("single_turn_agent")
class SingleTurnAgentLoop(AgentLoopBase):

    def __init__(self, *args, **kwargs):
        super().__init__(*args, **kwargs)
        self.prompt_length = self.config.actor_rollout_ref.rollout.prompt_length
        self.response_length = self.config.actor_rollout_ref.rollout.response_length
        tool_config_path = self.config.data.tool_config_path
        tool_list = (
            initialize_tools_from_config(tool_config_path) if tool_config_path else []
        )
        self.tool_schemas = [
            tool.tool_schema.model_dump(exclude_unset=True, exclude_none=True)
            for tool in tool_list
        ]

    async def run(self, sampling_params: dict[str, Any], **kwargs) -> AgentLoopOutput:
        messages = list(kwargs["raw_prompt"])
        multi_modal_data = await self.process_vision_info(messages)
        images = multi_modal_data.get("images")
        videos = multi_modal_data.get("videos")
        prompt_ids = await self.apply_chat_template(
            messages, tools=self.tool_schemas, images=images, videos=videos
        )
        generation_prompt_ids = prompt_ids
        scaffold_metrics = {}
        scaffold = self.config.trainer.get("ruscarl", {})
        if (
            scaffold.get("enabled", False)
            and "training_step" in kwargs
            and not kwargs.get("_is_validation", False)
        ):
            from rubric_rl.ruscarl import scaffold_prompt

            generation_prompt_ids, scaffold_metrics = scaffold_prompt(
                self.tokenizer,
                prompt_ids,
                kwargs.get("reward_model"),
                sample_index=int(kwargs["rollout_index"]),
                group_size=int(self.config.actor_rollout_ref.rollout.n),
                step=int(kwargs["training_step"]),
                total_steps=int(self.config.trainer.total_training_steps),
                start=float(scaffold.get("start", 0.2)),
                steepness=float(scaffold.get("steepness", 125.0)),
            )
            if (
                len(generation_prompt_ids) + self.response_length
                > self.config.actor_rollout_ref.rollout.max_model_len
            ):
                raise ValueError(
                    "RuscaRL scaffold exceeds configured context; increase model_length"
                )
        metrics = {}
        with simple_timer("generate_sequences", metrics):
            output = await self.server_manager.generate(
                request_id=uuid4().hex,
                prompt_ids=generation_prompt_ids,
                sampling_params=sampling_params,
                image_data=images,
                video_data=videos,
            )
        metrics.update(
            {"ruscarl/" + key: value for key, value in scaffold_metrics.items()}
        )
        response_mask = [1] * len(output.token_ids)
        output = AgentLoopOutput(
            prompt_ids=prompt_ids,
            response_ids=output.token_ids[: self.response_length],
            response_mask=response_mask[: self.response_length],
            response_logprobs=(
                output.log_probs[: self.response_length] if output.log_probs else None
            ),
            routed_experts=(
                output.routed_experts[: len(prompt_ids) + self.response_length]
                if output.routed_experts is not None
                else None
            ),
            multi_modal_data=multi_modal_data,
            num_turns=2,
            metrics=metrics,
        )
        return output
