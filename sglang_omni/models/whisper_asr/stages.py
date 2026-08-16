# SPDX-License-Identifier: Apache-2.0
"""Stage factory for SGLang-backed Whisper ASR inference."""

from __future__ import annotations

from typing import Any


def create_sglang_whisper_asr_executor(
    model_path: str,
    *,
    device: str = "cuda:0",
    dtype: str = "float16",
    max_running_requests: int = 16,
    max_new_tokens: int = 256,
    mem_fraction_static: float = 0.85,
    enable_encoder_cuda_graph: bool = False,
    encoder_graph_batch_buckets: list[int] | None = None,
    enable_encoder_torch_compile: bool = False,
    encoder_torch_compile_mode: str | None = None,
    quantization_scope: str = "all",
    request_build_max_workers: int = 2,
    request_build_max_pending: int | None = 16,
    prefill_coalesce_requests: int = 2,
    prefill_coalesce_wait_ms: float = 6.0,
    prefill_coalesce_when_idle: bool = True,
    prefill_coalesce_requires_pending_builds: bool = True,
    prefill_coalesce_after_builds_during_decode: bool = False,
    enable_speculative: bool = False,
    speculative_draft_model_path: str | None = None,
    speculative_num_steps: int = 3,
    speculative_num_draft_tokens: int = 4,
    speculative_cuda_graph: bool = False,
    speculative_draft_cuda_graph: bool = False,
    speculative_share_encoder: bool = True,
    server_args_overrides: dict[str, Any] | None = None,
):
    from sglang_omni.models.whisper_asr.engine_builder import WhisperASREngineBuilder

    return WhisperASREngineBuilder(
        max_running_requests=max_running_requests,
        mem_fraction_static=mem_fraction_static,
        max_new_tokens=max_new_tokens,
        enable_encoder_cuda_graph=enable_encoder_cuda_graph,
        encoder_graph_batch_buckets=encoder_graph_batch_buckets,
        enable_encoder_torch_compile=enable_encoder_torch_compile,
        encoder_torch_compile_mode=encoder_torch_compile_mode,
        quantization_scope=quantization_scope,
        request_build_max_workers=request_build_max_workers,
        request_build_max_pending=request_build_max_pending,
        prefill_coalesce_requests=prefill_coalesce_requests,
        prefill_coalesce_wait_ms=prefill_coalesce_wait_ms,
        prefill_coalesce_when_idle=prefill_coalesce_when_idle,
        prefill_coalesce_requires_pending_builds=(
            prefill_coalesce_requires_pending_builds
        ),
        prefill_coalesce_after_builds_during_decode=(
            prefill_coalesce_after_builds_during_decode
        ),
        enable_speculative=enable_speculative,
        speculative_draft_model_path=speculative_draft_model_path,
        speculative_num_steps=speculative_num_steps,
        speculative_num_draft_tokens=speculative_num_draft_tokens,
        speculative_cuda_graph=speculative_cuda_graph,
        speculative_draft_cuda_graph=speculative_draft_cuda_graph,
        speculative_share_encoder=speculative_share_encoder,
    ).build(
        model_path,
        device=device,
        dtype=dtype,
        server_args_overrides=server_args_overrides,
    )


def create_whisper_asr_executor(*args, **kwargs):
    return create_sglang_whisper_asr_executor(*args, **kwargs)


__all__ = ["create_sglang_whisper_asr_executor", "create_whisper_asr_executor"]
