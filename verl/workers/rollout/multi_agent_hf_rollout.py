# Copyright 2025
#
# Multi-agent HuggingFace rollout that selects actor/ref per sample based on agent_id.
# This is a minimal extension of HFRollout that groups samples by agent_id and
# runs generation with the corresponding model. It assumes agent_id is present in
# prompts.batch["agent_id"]. Context chaining across turns should be handled upstream.

from __future__ import annotations

import contextlib
from collections import defaultdict

import torch
from tensordict import TensorDict
from torch import nn
from torch.distributed.fsdp import FullyShardedDataParallel as FSDP
from transformers import GenerationConfig

from verl import DataProto
from verl.utils.device import get_device_name, get_torch_device
from verl.utils.torch_functional import get_response_mask

from .base import BaseRollout

__all__ = ["MultiAgentHFRollout"]


class MultiAgentHFRollout(BaseRollout):
    """
    A multi-agent variant of HFRollout. It keeps a dict of modules keyed by agent_id.
    Prompts must carry `agent_id` tensor (bs, 1). For each distinct agent_id, we run
    generation independently and stitch outputs back to the original order.
    """

    def __init__(self, modules: dict[int, nn.Module], config):
        super().__init__()
        self.config = config
        self.modules = modules  # {agent_id: model}

    async def resume(self, tags: list[str]):
        return None

    async def update_weights(
        self,
        weights,
        **kwargs,
    ):
        return None

    async def release(self):
        return None

    def generate_sequences(self, prompts: DataProto) -> DataProto:
        assert "agent_id" in prompts.batch, "prompts must carry agent_id"
        agent_ids = prompts.batch["agent_id"].squeeze(-1).tolist()
        buckets = defaultdict(list)
        for idx, aid in enumerate(agent_ids):
            buckets[int(aid)].append(idx)

        outputs: dict[int, DataProto] = {}
        for aid, indices in buckets.items():
            sub = prompts[indices]
            module = self.modules.get(aid)
            if module is None:
                raise ValueError(f"No module loaded for agent_id={aid}")
            outputs[aid] = self._generate_minibatch(sub, module)

        # stitch back
        ordered_batches = []
        for idx, aid in enumerate(agent_ids):
            ordered_batches.append(outputs[int(aid)][[0]])  # keep DataProto for concat
        return DataProto.concat(ordered_batches)

    @torch.no_grad()
    def _generate_minibatch(self, prompts: DataProto, module: nn.Module) -> DataProto:
        do_sample = prompts.meta_info.get("do_sample", self.config.do_sample)
        is_validate = prompts.meta_info.get("validate", False)

        temperature = prompts.meta_info.get("temperature", self.config.temperature)
        response_length = prompts.meta_info.get("response_length", self.config.response_length)
        top_p = prompts.meta_info.get("top_p", self.config.get("top_p", 1.0))
        top_k = max(0, prompts.meta_info.get("top_k", self.config.get("top_k", 0)))

        if not do_sample:
            kwargs = {"do_sample": False, "num_beams": 1}
        elif is_validate:
            kwargs = {
                "do_sample": True,
                "num_beams": 1,
                "top_k": max(0, self.config.val_kwargs.top_k),
                "top_p": self.config.val_kwargs.top_p,
                "temperature": self.config.val_kwargs.temperature,
                "num_return_sequences": 1,
            }
        else:
            kwargs = {
                "do_sample": True,
                "num_beams": 1,
                "top_p": top_p,
                "top_k": top_k,
                "temperature": temperature,
                "num_return_sequences": self.config.n,
            }

        generation_config = GenerationConfig(**kwargs)

        idx = prompts.batch["input_ids"]
        prompt_length = idx.size(1)
        attention_mask = prompts.batch["attention_mask"]
        position_ids = prompts.batch["position_ids"]
        eos_token_id = prompts.meta_info["eos_token_id"]
        pad_token_id = prompts.meta_info["pad_token_id"]

        module.eval()
        param_ctx = contextlib.nullcontext()
        if isinstance(module, FSDP):
            param_ctx = FSDP.summon_full_params(module, writeback=False, recurse=False)
        with param_ctx, torch.autocast(device_type=get_device_name(), dtype=torch.bfloat16):
            output = module.generate(
                input_ids=idx,
                attention_mask=attention_mask,
                position_ids=position_ids,
                do_sample=do_sample,
                max_new_tokens=response_length,
                eos_token_id=eos_token_id,
                pad_token_id=pad_token_id,
                generation_config=generation_config,
                output_scores=False,
                return_dict_in_generate=True,
                use_cache=True,
            )

        seq = output.sequences
        generated_batch_size = seq.size(0)

        sequence_length = prompt_length + self.config.response_length
        delta_length = sequence_length - seq.shape[1]
        if delta_length > 0:
            delta_tokens = torch.ones(size=(generated_batch_size, delta_length), device=seq.device, dtype=seq.dtype)
            delta_tokens = pad_token_id * delta_tokens
            seq = torch.cat((seq, delta_tokens), dim=1)
        assert seq.shape[1] == sequence_length

        num_return_sequences = kwargs.get("num_return_sequences", 1)
        if num_return_sequences > 1:
            position_ids = position_ids.repeat_interleave(num_return_sequences, dim=0)
            attention_mask = attention_mask.repeat_interleave(num_return_sequences, dim=0)

        prompt = seq[:, :prompt_length]
        response = seq[:, prompt_length:]

        response_length = response.size(1)
        delta_position_id = torch.arange(1, response_length + 1, device=position_ids.device)
        delta_position_id = delta_position_id.unsqueeze(0).repeat(generated_batch_size, 1)

        response_position_ids = position_ids[:, -1:] + delta_position_id
        position_ids = torch.cat([position_ids, response_position_ids], dim=-1)

        response_attention_mask = get_response_mask(
            response_id=response, eos_token=eos_token_id, dtype=attention_mask.dtype
        )
        attention_mask = torch.cat((attention_mask, response_attention_mask), dim=-1)

        batch = TensorDict(
            {
                "prompts": prompt,
                "responses": response,
                "input_ids": seq,
                "attention_mask": attention_mask,
                "position_ids": position_ids,
            },
            batch_size=generated_batch_size,
        )

        get_torch_device().empty_cache()
        module.train()
        return DataProto(batch=batch)
