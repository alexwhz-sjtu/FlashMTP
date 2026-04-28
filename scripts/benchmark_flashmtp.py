#!/usr/bin/env python3
"""FlashMTP 吞吐/接收长度评测，流程与 NIPS26/dflash/benchmark.py 对齐。"""

from __future__ import annotations

import argparse
import os
import random
import sys
import time
import warnings
from itertools import chain
from pathlib import Path
from types import SimpleNamespace

import numpy as np
import torch
from tqdm import tqdm
from transformers import AutoModelForCausalLM, AutoTokenizer, DynamicCache

FLASHMTP_ROOT = Path(__file__).resolve().parent.parent
DFLASH_ROOT = FLASHMTP_ROOT.parent / "dflash"
if str(FLASHMTP_ROOT) not in sys.path:
    sys.path.insert(0, str(FLASHMTP_ROOT))
if DFLASH_ROOT.is_dir() and str(DFLASH_ROOT) not in sys.path:
    sys.path.insert(0, str(DFLASH_ROOT))

from model import load_and_process_dataset  # noqa: E402
import distributed as dist  # noqa: E402

from specforge.modeling.draft.flashmtp import (  # noqa: E402
    FlashMTPDraftModel,
    extract_stacked_chs,
    sample,
)


def cuda_time() -> float:
    torch.cuda.synchronize()
    return time.perf_counter()


@torch.inference_mode()
def autoregressive_generate(
    target: AutoModelForCausalLM,
    input_ids: torch.Tensor,
    mask_token_id: int,
    max_new_tokens: int,
    block_size: int,
    stop_token_ids: list[int],
    temperature: float,
) -> SimpleNamespace:
    """block_size=1 基线，与 dflash/benchmark.py 中 dflash_generate(bs=1) 一致。"""
    num_input_tokens = input_ids.shape[1]
    max_length = num_input_tokens + max_new_tokens
    dev = input_ids.device

    output_ids = torch.full(
        (1, max_length + block_size),
        mask_token_id,
        dtype=torch.long,
        device=dev,
    )
    position_ids = torch.arange(output_ids.shape[1], device=dev).unsqueeze(0)
    past_key_values_target = DynamicCache()

    prefill_start = cuda_time()
    output = target(
        input_ids,
        position_ids=position_ids[:, :num_input_tokens],
        past_key_values=past_key_values_target,
        use_cache=True,
        logits_to_keep=1,
        output_hidden_states=False,
    )
    output_ids[:, :num_input_tokens] = input_ids
    output_ids[:, num_input_tokens : num_input_tokens + 1] = sample(
        output.logits, temperature
    )
    time_to_first_token = cuda_time() - prefill_start

    decode_start = cuda_time()
    start = input_ids.shape[1]
    acceptance_lengths = []

    while start < max_length:
        block_output_ids = output_ids[:, start : start + block_size].clone()
        block_position_ids = position_ids[:, start : start + block_size]

        output = target(
            block_output_ids,
            position_ids=block_position_ids,
            past_key_values=past_key_values_target,
            use_cache=True,
            output_hidden_states=False,
        )
        posterior = sample(output.logits, temperature)
        acceptance_length = (
            (block_output_ids[:, 1:] == posterior[:, :-1])
            .cumprod(dim=1)
            .sum(dim=1)[0]
            .item()
        )
        output_ids[:, start : start + acceptance_length + 1] = block_output_ids[
            :, : acceptance_length + 1
        ]
        output_ids[:, start + acceptance_length + 1] = posterior[:, acceptance_length]
        acceptance_lengths.append(acceptance_length + 1)
        start += acceptance_length + 1
        past_key_values_target.crop(start)

        if stop_token_ids is not None and any(
            stop_token_id in output_ids[:, num_input_tokens:]
            for stop_token_id in stop_token_ids
        ):
            break

    output_ids = output_ids[:, :max_length]
    output_ids = output_ids[:, output_ids[0] != mask_token_id]
    if stop_token_ids is not None:
        stop_tensor = torch.tensor(stop_token_ids, device=output_ids.device)
        stop_token_indices = torch.isin(
            output_ids[0][num_input_tokens:], stop_tensor
        ).nonzero(as_tuple=True)[0]
        if stop_token_indices.numel() > 0:
            output_ids = output_ids[
                :, : num_input_tokens + stop_token_indices[0] + 1
            ]

    num_output_tokens = output_ids.shape[1] - num_input_tokens
    total_decode_time = cuda_time() - decode_start
    time_per_output_token = total_decode_time / max(num_output_tokens, 1)

    return SimpleNamespace(
        output_ids=output_ids,
        num_input_tokens=num_input_tokens,
        num_output_tokens=num_output_tokens,
        time_to_first_token=time_to_first_token,
        time_per_output_token=time_per_output_token,
        acceptance_lengths=acceptance_lengths,
    )


@torch.inference_mode()
def flashmtp_spec_generate(
    draft: FlashMTPDraftModel,
    target: AutoModelForCausalLM,
    input_ids: torch.Tensor,
    max_new_tokens: int,
    stop_token_ids: list[int],
    temperature: float,
) -> SimpleNamespace:
    """与 specforge FlashMTP spec_generate 一致，并统计耗时（与 dflash 相同指标）。"""
    draft.eval()
    mask_token_id = draft.mask_token_id
    if mask_token_id is None:
        raise ValueError("draft.mask_token_id is None")
    block_size = draft.block_size
    dev = input_ids.device
    num_input_tokens = input_ids.shape[1]
    max_length = num_input_tokens + max_new_tokens

    output_ids = torch.full(
        (1, max_length + block_size),
        mask_token_id,
        dtype=torch.long,
        device=dev,
    )
    position_ids = torch.arange(output_ids.shape[1], device=dev).unsqueeze(0)
    past_key_values_target = DynamicCache()

    prefill_start = cuda_time()
    output = target(
        input_ids,
        position_ids=position_ids[:, :num_input_tokens],
        past_key_values=past_key_values_target,
        use_cache=True,
        logits_to_keep=1,
        output_hidden_states=True,
    )
    output_ids[:, :num_input_tokens] = input_ids
    output_ids[:, num_input_tokens : num_input_tokens + 1] = sample(
        output.logits, temperature
    )
    pre_idx = (num_input_tokens - 1) * torch.ones(1, 1, device=dev, dtype=torch.long)
    pre_idx = pre_idx.clamp(min=0)
    target_hidden = extract_stacked_chs(output.hidden_states, pre_idx)
    time_to_first_token = cuda_time() - prefill_start

    decode_start = cuda_time()
    acceptance_lengths: list[int] = []
    start = input_ids.shape[1]
    draft_prefill = True

    while start < max_length:
        block_output_ids = output_ids[:, start : start + block_size].clone()
        block_position_ids = position_ids[:, start : start + block_size]
        noise_embedding = target.model.embed_tokens(block_output_ids)
        block_position_ids_for_draft = position_ids[:, start : start + block_size]
        draft_logits = target.lm_head(
            draft(
                target_hidden=target_hidden,
                noise_embedding=noise_embedding,
                position_ids=block_position_ids_for_draft,
                past_key_values=None,
                use_cache=False,
                is_causal=False,
            )[:, -block_size + 1 :, :]
        )
        block_output_ids[:, 1:] = sample(draft_logits)
        if draft_prefill:
            draft_prefill = False
            decode_start = cuda_time()

        output = target(
            block_output_ids,
            position_ids=block_position_ids,
            past_key_values=past_key_values_target,
            use_cache=True,
            output_hidden_states=True,
        )
        posterior = sample(output.logits, temperature)
        acceptance_length = (
            (block_output_ids[:, 1:] == posterior[:, :-1])
            .cumprod(dim=1)
            .sum(dim=1)[0]
            .item()
        )
        accept_len_report = int(acceptance_length) + 1
        acceptance_lengths.append(accept_len_report)
        output_ids[:, start : start + acceptance_length + 1] = block_output_ids[
            :, : acceptance_length + 1
        ]
        output_ids[:, start + acceptance_length + 1] = posterior[:, acceptance_length]
        start += acceptance_length + 1
        past_key_values_target.crop(start)
        hs_len = output.hidden_states[0].shape[1]
        last_chunk_idx = min(int(acceptance_length), hs_len - 1)
        last_chunk_idx = max(last_chunk_idx, 0)
        target_hidden = extract_stacked_chs(
            output.hidden_states,
            torch.tensor([[last_chunk_idx]], device=dev, dtype=torch.long),
        )
        if stop_token_ids is not None and any(
            stop_token_id in output_ids[:, num_input_tokens:]
            for stop_token_id in stop_token_ids
        ):
            break

    output_ids = output_ids[:, :max_length]
    output_ids = output_ids[:, output_ids[0] != mask_token_id]
    if stop_token_ids is not None:
        stop_tensor = torch.tensor(stop_token_ids, device=output_ids.device)
        stop_token_indices = torch.isin(
            output_ids[0][num_input_tokens:], stop_tensor
        ).nonzero(as_tuple=True)[0]
        if stop_token_indices.numel() > 0:
            output_ids = output_ids[
                :, : num_input_tokens + stop_token_indices[0] + 1
            ]

    num_output_tokens = output_ids.shape[1] - num_input_tokens
    total_decode_time = cuda_time() - decode_start
    time_per_output_token = total_decode_time / max(num_output_tokens, 1)

    return SimpleNamespace(
        output_ids=output_ids,
        num_input_tokens=num_input_tokens,
        num_output_tokens=num_output_tokens,
        time_to_first_token=time_to_first_token,
        time_per_output_token=time_per_output_token,
        acceptance_lengths=acceptance_lengths,
    )


def main() -> None:
    parser = argparse.ArgumentParser(
        description="FlashMTP benchmark（数据集与输出格式同 dflash/benchmark.py）"
    )
    parser.add_argument(
        "--model-name-or-path",
        type=str,
        default="/share/public/public_models/Qwen3-8B",
    )
    parser.add_argument(
        "--draft-name-or-path",
        type=str,
        default=str(
            FLASHMTP_ROOT
            / "cache/models/FlashMTP_v1.4_sample_400000_think_on_qwen3_8b_maxlen4096_epochs12_nnodes4"
        ),
    )
    parser.add_argument("--block-size", type=int, default=None)
    parser.add_argument("--dataset", type=str, required=True)
    parser.add_argument("--max-samples", type=int, default=None)
    parser.add_argument("--max-new-tokens", type=int, default=2048)
    parser.add_argument("--temperature", type=float, default=0.0)
    args = parser.parse_args()

    random.seed(0)
    np.random.seed(0)
    torch.manual_seed(0)
    torch.cuda.manual_seed_all(0)
    torch.backends.cudnn.deterministic = True
    torch.backends.cudnn.benchmark = False

    dist.init()
    if "RANK" in os.environ:
        torch.cuda.set_device(dist.local_rank())
        device = torch.device(f"cuda:{dist.local_rank()}")
    else:
        if "CUDA_VISIBLE_DEVICES" not in os.environ:
            os.environ["CUDA_VISIBLE_DEVICES"] = "0"
        device = torch.device("cuda:0")

    if not DFLASH_ROOT.is_dir():
        raise FileNotFoundError(
            f"需要同级目录 dflash 以加载数据集: 期望 {DFLASH_ROOT}"
        )

    target = AutoModelForCausalLM.from_pretrained(
        args.model_name_or_path,
        dtype=torch.bfloat16,
        trust_remote_code=True,
    ).to(device).eval()

    draft_model = FlashMTPDraftModel.from_pretrained(
        args.draft_name_or_path,
        dtype=torch.bfloat16,
        trust_remote_code=True,
    ).to(device).eval()

    block_size = (
        args.block_size if args.block_size is not None else draft_model.block_size
    )
    if block_size != draft_model.block_size:
        warnings.warn(
            f"--block-size={block_size} 与草稿 config block_size={draft_model.block_size} "
            f"不一致，投机分支将使用草稿的 {draft_model.block_size}。"
        )
        block_size = draft_model.block_size

    tokenizer = AutoTokenizer.from_pretrained(
        args.model_name_or_path, trust_remote_code=True
    )
    dataset = load_and_process_dataset(args.dataset)

    if args.max_samples is not None and len(dataset) > args.max_samples:
        dataset = dataset.shuffle(seed=0).select(range(args.max_samples))

    benchmark_start = cuda_time()
    responses: list[dict] = []
    indices = range(dist.rank(), len(dataset), max(dist.size(), 1))
    for idx in tqdm(indices, disable=not dist.is_main()):
        instance = dataset[idx]
        messages: list[dict] = []
        for turn_index, user_content in enumerate(instance["turns"]):
            messages.append({"role": "user", "content": user_content})
            input_text = tokenizer.apply_chat_template(
                messages,
                tokenize=False,
                add_generation_prompt=True,
                enable_thinking=True,
            )
            input_ids = tokenizer.encode(input_text, return_tensors="pt").to(device)

            response: dict = {}
            for bs in [1, block_size]:
                if bs == 1:
                    response[bs] = autoregressive_generate(
                        target=target,
                        input_ids=input_ids,
                        mask_token_id=draft_model.mask_token_id,
                        max_new_tokens=args.max_new_tokens,
                        block_size=1,
                        stop_token_ids=[tokenizer.eos_token_id],
                        temperature=args.temperature,
                    )
                else:
                    response[bs] = flashmtp_spec_generate(
                        draft=draft_model,
                        target=target,
                        input_ids=input_ids,
                        max_new_tokens=args.max_new_tokens,
                        stop_token_ids=[tokenizer.eos_token_id],
                        temperature=args.temperature,
                    )

            spec_response = response[block_size]
            acceptance_lengths_text = ", ".join(
                f"{position}:{length}"
                for position, length in enumerate(spec_response.acceptance_lengths)
            )
            avg_acceptance_length = float(np.mean(spec_response.acceptance_lengths))
            print(
                f"[Sample {idx} | Turn {turn_index}] Acceptance lengths (position:length): "
                f"{acceptance_lengths_text}"
            )
            print(
                f"[Sample {idx} | Turn {turn_index}] Average acceptance length: "
                f"{avg_acceptance_length:.2f}"
            )

            generated_ids = spec_response.output_ids[0, spec_response.num_input_tokens :]
            output_text = tokenizer.decode(generated_ids, skip_special_tokens=True)
            messages.append({"role": "assistant", "content": output_text})
            responses.append(response)

    if dist.size() > 1:
        gathered = dist.gather(responses, dst=0)
        if not dist.is_main():
            return
        responses = list(chain(*gathered))

    t1 = np.mean([r[1].time_per_output_token for r in responses])
    tb = np.mean([r[block_size].time_per_output_token for r in responses])
    print(f"Decoding speedup: {t1 / tb:.2f}")

    tau = np.mean(
        [np.mean(r[block_size].acceptance_lengths) for r in responses]
    )
    print(f"Average Acceptance length: {tau:.2f}")

    acceptance_lengths = list(
        chain(*[r[block_size].acceptance_lengths for r in responses])
    )
    histogram = [
        acceptance_lengths.count(b) / len(acceptance_lengths)
        for b in range(block_size + 1)
    ]
    print(f"Acceptance length histogram: {[f'{x * 100:.1f}%' for x in histogram]}")

    total_elapsed_time = cuda_time() - benchmark_start
    print(f"Total elapsed time: {total_elapsed_time:.2f}s")


if __name__ == "__main__":
    main()
