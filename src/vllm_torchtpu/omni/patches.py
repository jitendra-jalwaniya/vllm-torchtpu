# Copyright 2026 Google LLC
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
"""TPU runtime patches for vLLM-Omni diffusion models.

vLLM-Omni diffusion workers run in separate worker processes spawned by
vLLM-Omni's DiffusionEngine rather than through TPUWorker's worker_init /
model_load lifecycle stages, so OmniTpuPlatform applies the Omni patches
itself: apply_omni_tpu_patches() when the platform is constructed, and
apply_omni_model_specific_patches() at attention backend selection
(get_diffusion_attn_backend_cls). Tracked in #1862 for unification with
patch_registry.py.
"""

from functools import cache as run_once
from typing import Any

import torch

from vllm_torchtpu.logger import init_logger

logger = init_logger(__name__)


@run_once
def _optimization_barrier_op() -> Any:
    from vllm_torchtpu.layers.adapter.custom_ops.optimization_barrier_op import (
        optimization_barrier_op,
    )

    return optimization_barrier_op()


@run_once
def apply_omni_tpu_patches() -> None:
    """Extend the async output timeout for TPU compilation and execution."""

    # -------------------------------------------------------------------------
    # Upstream torch_tpu Root Cause Tracking:
    # 1. Lazy execution attributes failure to sync point: In PyTorch/XLA
    #    and torch_tpu, forward passes are queued lazily in the computation
    #    graph. diffusion_worker emits COMPUTE_DONE prematurely before the TPU
    #    hardware finishes execution. When the async output background loop
    #    triggers host synchronization (.cpu()), it blocks on multi-step diffusion
    #    graph execution and initial compilation.
    # 2. Recompilation storms & JIT compile latency: Initial JIT/AOT
    #    compilation and weight distribution for large diffusion models (e.g.
    #    Wan 14B) take >600s, exceeding vLLM-Omni's default 600s timeout.
    #
    # REMOVAL / FIX CONDITION:
    # This patch can be removed/reduced once:
    # 1. OmniTpuPlatform.record_device_event() implements hardware
    #    synchronization (torch.accelerator.synchronize()) to ensure execution
    #    completes before COMPUTE_DONE.
    # 2. AOT compilation caching stabilizes startup compile times.
    # -------------------------------------------------------------------------
    import os

    os.environ.setdefault("VLLM_OMNI_ASYNC_OUTPUT_TIMEOUT", "1800.0")
    logger.info("Applied TPU patch: extended VLLM_OMNI_ASYNC_OUTPUT_TIMEOUT to 1800s.")


@run_once
def apply_omni_model_specific_patches() -> None:
    """Apply model-specific runtime patches."""
    _patch_diffusion_ipc_cpu_pack()
    _patch_qwen_image_rope_txt_freqs_clone()
    _patch_wan_pair_swap_rope()
    _patch_wan_ffn_gelu_fence()
    _patch_diffusion_worker_d2h_stream()
    _patch_diffusion_startup_warmup_sync()
    _patch_ltx2_split_rope()
    _patch_wan_fused_qk_norm_rope()
    _patch_wan_fresh_timestep()
    _patch_sdpa_fallback_dispatch()
    _patch_ltx2_vocoder_cpu_init()
    _patch_ltx2_per_batch_timestep()
    _patch_ltx2_guidance_sigma_scalar()
    _patch_ltx2_fast_eager_dispatch()
    _patch_ltx2_video_vae_decode()
    from vllm_torchtpu.omni.ltx2_compile import apply_ltx2_compile_patches

    apply_ltx2_compile_patches()


def _patch_diffusion_ipc_cpu_pack() -> None:
    # -------------------------------------------------------------------------
    # Upstream torch_tpu Root Cause Tracking:
    # 1. Pickling a device tensor aborts process: In torch_tpu, calling
    #    pickle.dumps on a device tensor hits
    #    ABSL_CHECK(tensor.storage().allocator() == nullptr) in
    #    csrc/eager/tensor_to_buffer.cc:260-261, terminating the worker process
    #    with SIGABRT (exit code 134) with no Python traceback.
    # 2. libtpu per-process lockfile prevents cross-process init:
    #    Holding TPU tensors across process boundaries causes the CPU-only
    #    orchestrator process to trigger PJRT backend initialization during
    #    unpickling, colliding with the worker on /tmp/libtpu_lockfile.
    #
    # REMOVAL / FIX CONDITION:
    # This patch can be removed once torch_tpu supports safe inter-process tensor
    # serialization / proxy unpickling without triggering PJRT initialization
    # in host processes that do not own TPU hardware.
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion import ipc

    orig_pack_tensor = ipc._pack_tensor_if_large

    def _safe_pack_tensor_if_large(val: torch.Tensor, *args: Any, **kwargs: Any) -> Any:
        return orig_pack_tensor(val.cpu(), *args, **kwargs)

    ipc._pack_tensor_if_large = _safe_pack_tensor_if_large
    logger.info("Applied TPU patch: safe CPU serialization for diffusion IPC tensors.")


def _patch_qwen_image_rope_txt_freqs_clone() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove this patch once torch_tpu supports torch.real/torch.imag
    # inside torch.inference_mode() on a complex tensor created outside it.
    #
    # Qwen-Image RoPE modules return txt_freqs as a slice of pos_freqs, which
    # is created outside inference mode. The attention blocks take
    # torch.real/torch.imag of that slice inside inference mode, which fails
    # on TPU with "RuntimeError: Cannot set version_counter for inference
    # tensor". vid_freqs comes from torch.cat inside inference mode and is not
    # affected. Cloning txt_freqs once per transformer forward gives the
    # attention blocks an inference tensor of the same values.
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.models.qwen_image import qwen_image_transformer

    for rope_cls in (
        qwen_image_transformer.QwenEmbedRope,
        qwen_image_transformer.QwenEmbedLayer3DRope,
    ):
        rope_cls.forward = _clone_txt_freqs(rope_cls.forward)
    logger.info("Applied TPU patch: Qwen-Image RoPE txt_freqs clone.")


def _clone_txt_freqs(forward: Any) -> Any:
    def _forward(self: Any, *args: Any, **kwargs: Any):
        vid_freqs, txt_freqs = forward(self, *args, **kwargs)
        return vid_freqs, txt_freqs.clone()

    return _forward


def _patch_wan_pair_swap_rope() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove this patch once torch_tpu lowers size-2 minor unflatten/stack
    # without relayouts, or vLLM-Omni's CustomOp gains an out-of-tree dispatch
    # hook (then make this the TPU forward of RotaryEmbeddingWan).
    #
    # RotaryEmbeddingWan.forward_native (the CustomOp path non-CUDA platforms
    # take) rotates interleaved pairs via unflatten(-1, (-1, 2)) / stack(-1).
    # torch_tpu lowers the size-2 minor dimension to sequence-minor layouts
    # plus strided relayout copies around every q/k rotation, costing ~7 ms
    # per Wan2.2-A14B layer at 480p on v7x (~9% of the layer).
    # The replacement computes the same rotation on the (..., head_dim)
    # layout with an exact signed pair-swap matmul (see omni/rope.py). It is
    # installed on the class because CustomOp binds _forward_method at init
    # and the rotary op is constructed before the attention layer that
    # triggers these patches.
    #
    # Complex sliced views crash on TPU under inference mode, which rules
    # out the complex-number RoPE form.
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.layers.rope import RotaryEmbeddingWan

    from vllm_torchtpu.omni.rope import rotary_embedding_wan_forward

    RotaryEmbeddingWan.forward = rotary_embedding_wan_forward
    logger.info("Applied TPU patch: pair-swap matmul RotaryEmbeddingWan.")


def _patch_wan_ffn_gelu_fence() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove this patch once XLA stops duplicating the elementwise producer
    # into the matmul operand fusion here, or torch_tpu exposes a fusion fence.
    #
    # XLA fuses the Wan FFN up-projection's bias add and tanh-GELU into the
    # operand fusion of the down-projection matmul, so the GELU of the
    # (tokens, 13824) activation is recomputed for every output tile of the
    # down-projection instead of once. torch_tpu has no way to stop a
    # producer fusion. An XLA optimization barrier on the GELU output (an
    # identity that fusion passes cannot see through) makes XLA materialize
    # it once, in bf16, which is also the value eager PyTorch produces.
    # Measured on v7x, Wan2.2-I2V-A14B: 72.72 -> 71.39 ms per block at
    # 32,760 tokens on one core; 0.939 -> 0.927 s/step end to end at
    # 480x832x81 on 8 cores (CFG 2 x Ulysses 4).
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.models.wan2_2.wan2_2_transformer import (
        ColumnParallelGELU,
    )

    orig_forward = getattr(
        ColumnParallelGELU, "_tpu_orig_forward", ColumnParallelGELU.forward
    )
    ColumnParallelGELU._tpu_orig_forward = orig_forward

    def _fenced_gelu_forward(self: Any, x: torch.Tensor) -> torch.Tensor:
        return _optimization_barrier_op()(orig_forward(self, x))

    ColumnParallelGELU.forward = _fenced_gelu_forward
    logger.info("Applied TPU patch: fusion fence after Wan FFN GELU.")


_D2H_STREAM_PATCHED = "_tpu_d2h_stream_patched"


def _patch_diffusion_worker_d2h_stream() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove once vLLM-Omni creates the D2H stream of
    # WorkerProc._async_output_loop (vllm_omni/diffusion/worker/diffusion_worker.py)
    # on the current device index instead of
    # torch.device(torch.accelerator.current_accelerator().type, self.gpu_id).
    #
    # Problem: WorkerProc._async_output_loop creates its D2H stream on device
    #   index self.gpu_id. On TPU, OmniTpuPlatform.set_device selects device
    #   index 0 in every worker process, so a worker with gpu_id >= 1 asks for
    #   a stream on a device index that its process did not select.
    # Fix: run the loop with a proxy as self whose gpu_id is the current
    #   device index; other attribute reads and writes go to the worker.
    # Effect: the output thread of a worker with gpu_id >= 1 gets its stream
    #   instead of failing at startup.
    # Scope: the proxy is live for the whole output-thread lifetime, not only
    #   while the stream is created. Only attribute reads/writes are
    #   forwarded, so identity/type checks on self inside the loop would see
    #   the proxy (the upstream loop does none).
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.worker.diffusion_worker import WorkerProc

    orig_async_output_loop = WorkerProc._async_output_loop
    if getattr(orig_async_output_loop, _D2H_STREAM_PATCHED, False):
        return

    def _tpu_async_output_loop(self: Any) -> None:
        orig_async_output_loop(_CurrentDeviceWorkerProxy(self))

    setattr(_tpu_async_output_loop, _D2H_STREAM_PATCHED, True)
    WorkerProc._async_output_loop = _tpu_async_output_loop
    logger.info("Applied TPU patch: diffusion D2H stream on the current device.")


class _CurrentDeviceWorkerProxy:
    """Forward attribute access to a worker, reporting the current device as
    ``gpu_id``."""

    def __init__(self, worker: Any) -> None:
        object.__setattr__(self, "_worker", worker)

    def __getattr__(self, name: str) -> Any:
        if name == "gpu_id":
            return torch.accelerator.current_device_index()
        return getattr(self._worker, name)

    def __setattr__(self, name: str, value: Any) -> None:
        setattr(self._worker, name, value)


# TODO: Remove once vLLM-Omni synchronizes the device at the end of its
# startup warmup (e.g. self.executor.collective_rpc("synchronize_device") in
# _dummy_run).
def _patch_diffusion_startup_warmup_sync() -> None:
    """Synchronize the device after vLLM-Omni's diffusion startup warmup.

    Root cause: ``DiffusionEngine._dummy_run`` (startup warmup) drops its output
    without a host sync. Under torch_tpu DEFER_AND_FUSE the warmup's tail ops
    (VAE decode) stay pending in torch_tpu's process-global deferred-op queue and
    are materialized together with the first real request, which then gets cut
    into different fused programs than later identical requests (those start
    from an empty queue because the previous output's ``.cpu()`` flushed it).
    The first request after startup therefore differs numerically from later
    same-seed requests.

    Scope: this only takes effect when the engine runs its worker in-process
    (the uniproc executor, the single-device default). With the mp executor,
    only the worker processes install this patch, and they never call
    run_startup_warmup.
    """
    from vllm_omni.diffusion.diffusion_engine import DiffusionEngine

    orig_run_startup_warmup = DiffusionEngine.run_startup_warmup

    def _synced_run_startup_warmup(self: Any) -> None:
        orig_run_startup_warmup(self)
        # TODO: Once the vllm-omni pin is >= 0.30, sync every worker with
        # self.executor.collective_rpc("synchronize_device") and install this
        # patch at platform init, so that mp engines are covered too.
        torch.accelerator.synchronize()

    DiffusionEngine.run_startup_warmup = _synced_run_startup_warmup
    logger.info("Applied TPU patch: device sync after diffusion startup warmup.")


def _patch_wan_fused_qk_norm_rope() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove this patch once XLA fuses the q/k RMSNorm and RoPE into one
    # pass at HBM bandwidth, or vLLM-Omni's CustomOp gains an out-of-tree dispatch
    # hook for a fused q/k norm + RoPE op.
    #
    # WanSelfAttention normalizes q and k (RMSNorm over all heads) and then
    # rotates them. XLA splits this into a row-reduction fusion for the norm
    # statistics, an apply fusion and the RoPE fusion, each streaming the
    # (tokens, 5120) q and k through HBM; the row reduction also runs well
    # below HBM bandwidth. Together ~0.78 ms per block at 8190 tokens per
    # core on v7x. A Pallas kernel that reads q and k once and writes them
    # once takes 0.23 ms and is closer to an f64 reference (single rounding).
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.models.wan2_2.wan2_2_transformer import (
        WanSelfAttention,
    )

    from vllm_torchtpu.omni.rope import (
        can_fuse_qk_norm_rope,
        wan_self_attention_fused,
    )

    if hasattr(WanSelfAttention, "_tpu_orig_forward"):
        return
    WanSelfAttention._tpu_orig_forward = WanSelfAttention.forward

    def _fused_self_attention_forward(
        self: Any,
        hidden_states: torch.Tensor,
        rotary_emb: Any = None,
        attn_metadata: Any = None,
    ) -> torch.Tensor:
        if not can_fuse_qk_norm_rope(self, hidden_states, rotary_emb):
            return WanSelfAttention._tpu_orig_forward(
                self, hidden_states, rotary_emb, attn_metadata
            )
        return wan_self_attention_fused(self, hidden_states, rotary_emb, attn_metadata)

    WanSelfAttention.forward = _fused_self_attention_forward
    logger.info("Applied TPU patch: fused q/k RMSNorm + RoPE for Wan attention.")


def _patch_wan_fresh_timestep() -> None:
    # Wan: give the transformer its own copy of the timestep.
    #
    # Problem: Wan pipelines pass `t.expand(batch)`, a view into
    #   scheduler.timesteps. torch_tpu bakes a view's offset into every graph
    #   that reads it, so the transformer recompiles at every denoising step.
    # Fix: clone the timestep on entry and flush the clone right away, so only
    #   a tiny copy graph sees the view.
    # Effect (v7x, 480x832x81, 8 cores): first 12-step request 53.0 s -> 26.9 s
    #   (warm: 15.3 s); output is bit-identical.
    # Scope: WanTransformer3DModel (T2V, I2V, TI2V, both A14B experts),
    #   WanVACETransformer3DModel (overrides forward) and
    #   WanS2VTransformer3DModel (separate class). The numbers above are T2V;
    #   the VACE and S2V classes are covered but not measured on TPU.
    # TODO: remove once torch_tpu passes view offsets as runtime inputs.
    from vllm_omni.diffusion.models.wan2_2.wan2_2_s2v_transformer import (
        WanS2VTransformer3DModel,
    )
    from vllm_omni.diffusion.models.wan2_2.wan2_2_transformer import (
        WanTransformer3DModel,
    )
    from vllm_omni.diffusion.models.wan2_2.wan2_2_vace_transformer import (
        WanVACETransformer3DModel,
    )

    for cls in (
        WanTransformer3DModel,
        WanVACETransformer3DModel,
        WanS2VTransformer3DModel,
    ):
        _wrap_fresh_timestep(cls)
    logger.info(
        "Applied TPU patch: fresh timestep buffer for WanTransformer3DModel, "
        "WanVACETransformer3DModel and WanS2VTransformer3DModel."
    )


_FRESH_TIMESTEP_PATCHED = "_tpu_fresh_timestep_patched"


def _wrap_fresh_timestep(cls: type) -> None:
    # The flag lives on the forward function, not the class:
    # WanVACETransformer3DModel subclasses WanTransformer3DModel but has its
    # own forward, which still needs the wrapper.
    if getattr(cls.forward, _FRESH_TIMESTEP_PATCHED, False):
        return
    forward = cls.forward

    def _fresh_timestep_forward(
        self: Any, hidden_states: Any, timestep: Any, *args: Any, **kwargs: Any
    ) -> Any:
        if isinstance(timestep, torch.Tensor):
            from vllm_torchtpu.utils import synchronize_tensors

            timestep = timestep.clone()
            synchronize_tensors(timestep, wait=False)
        return forward(self, hidden_states, timestep, *args, **kwargs)

    setattr(_fresh_timestep_forward, _FRESH_TIMESTEP_PATCHED, True)
    cls.forward = _fresh_timestep_forward


_SDPA_FALLBACK_PATCHED = "_tpu_sdpa_fallback_patched"


def _patch_sdpa_fallback_dispatch() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove once vLLM-Omni's AttentionImpl.forward dispatches
    # out-of-tree platforms instead of raising NotImplementedError.
    #
    # Problem: Attention builds `sdpa_fallback` from vLLM-Omni's SDPAImpl,
    #   whatever the selected backend. AttentionImpl.forward picks
    #   forward_cuda/_npu/... from the platform and raises NotImplementedError
    #   on TPU, so every sdpa_fallback call fails there.
    # Fix: SDPAImpl.forward is replaced by TpuSDPAImpl.forward, which runs
    #   SDPAImpl._forward_impl with broadcast key masks, as forward_cuda does.
    # Effect: sdpa_fallback calls run on TPU instead of raising
    #   NotImplementedError. LTX-2's _LTX2ParallelAttention sends masked calls
    #   to sdpa_fallback: with sequence parallelism the audio latents are
    #   padded to a multiple of the SP size, so audio self-attention and
    #   audio-to-video cross-attention carry a key-padding mask. SANA-Video,
    #   LingBot-Video and SenseNova-U1 also call sdpa_fallback.
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.attention.backends.sdpa import SDPAImpl

    from vllm_torchtpu.omni.attention import TpuSDPAImpl

    if getattr(SDPAImpl.forward, _SDPA_FALLBACK_PATCHED, False):
        return
    # The flag lands on TpuSDPAImpl.forward, the function shared by both classes.
    setattr(TpuSDPAImpl.forward, _SDPA_FALLBACK_PATCHED, True)
    SDPAImpl.forward = TpuSDPAImpl.forward
    logger.info("Applied TPU patch: SDPAImpl.forward routes to TpuSDPAImpl.")


_VOCODER_CPU_INIT_PATCHED = "_tpu_vocoder_cpu_init_patched"


def _patch_ltx2_vocoder_cpu_init() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove once torch_tpu implements kaiser_window and sinc, or
    # vLLM-Omni builds the vocoder and runs
    # ltx2_runtime._restore_ltx_bwe_resampler_filter on CPU.
    #
    # Problem: DiffusersPipelineLoader._init_from_load_format constructs the
    #   pipeline under a `with torch.device("tpu:N"):` context. LTX-2.3 and
    #   LTX-2.5 use Diffusers LTX2VocoderWithBWE (`act_fn="snakebeta"`,
    #   `antialias=True`), whose __init__ builds AntiAliasAct1d -> UpSample1d
    #   -> kaiser_sinc_filter1d and calls torch.kaiser_window(...) on the
    #   active default device before weights are loaded, failing on TPU with
    #   `DispatchStub: missing kernel for tpu`. At decode,
    #   ltx2_runtime._restore_ltx_bwe_resampler_filter rebuilds the BWE
    #   resampler's FP32 Hann filter with torch.sinc on the filter's device,
    #   failing on TPU with `operator 'aten::sinc.out' is not implemented`.
    # Fix: Constructing the vocoder on CPU (matching text_encoder and
    #   latent_upsampler in ltx2_components.py) builds the filter buffers on
    #   the host before _place_aux_components moves the module to
    #   pipeline.device. The restore helper runs upstream's rebuild on a CPU
    #   stand-in filter and moves the result to the filter's device, so later
    #   decodes hit upstream's identity check and skip the rebuild.
    # Effect: LTX-2.3 loads and decodes on TPU.
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.models.ltx2 import ltx2_components, ltx2_runtime

    _wrap_ltx2_bwe_filter_restore(ltx2_runtime)
    if getattr(ltx2_components._load_component, _VOCODER_CPU_INIT_PATCHED, False):
        return
    orig_load_component = ltx2_components._load_component

    def _cpu_vocoder_load_component(
        component_cls: Any,
        model: str,
        subfolder: str,
        *args: Any,
        **kwargs: Any,
    ) -> Any:
        if subfolder == "vocoder":
            with torch.device("cpu"):
                return orig_load_component(
                    component_cls, model, subfolder, *args, **kwargs
                )
        return orig_load_component(component_cls, model, subfolder, *args, **kwargs)

    setattr(_cpu_vocoder_load_component, _VOCODER_CPU_INIT_PATCHED, True)
    ltx2_components._load_component = _cpu_vocoder_load_component
    logger.info("Applied TPU patch: CPU-context init for LTX-2 vocoder.")


_BWE_FILTER_CPU_RESTORE_PATCHED = "_tpu_bwe_filter_cpu_restore_patched"


def _wrap_ltx2_bwe_filter_restore(ltx2_runtime: Any) -> None:
    # _run_ltx_vocoder resolves the helper as an ltx2_runtime global at call
    # time, so replacing the module attribute covers every caller.
    restore = ltx2_runtime._restore_ltx_bwe_resampler_filter
    if getattr(restore, _BWE_FILTER_CPU_RESTORE_PATCHED, False):
        return

    def _cpu_restore_ltx_bwe_resampler_filter(vocoder: Any) -> None:
        resampler: Any = getattr(vocoder, "resampler", None)
        current: Any = getattr(resampler, "filter", None)
        previous = getattr(resampler, "_ltx_restored_filter", None)
        if (
            not isinstance(current, torch.Tensor)
            or current.device.type == "cpu"
            or current is previous
        ):
            return restore(vocoder)
        # Upstream reads only the filter's device, never its values.
        resampler.filter = torch.empty_like(current, device="cpu")
        try:
            restore(vocoder)
        finally:
            rebuilt: Any = getattr(resampler, "_ltx_restored_filter", None)
            if rebuilt is previous or resampler.filter is not rebuilt:
                resampler.filter = current
            else:
                rebuilt = rebuilt.to(current.device)
                resampler.filter = rebuilt
                resampler._ltx_restored_filter = rebuilt

    setattr(
        _cpu_restore_ltx_bwe_resampler_filter, _BWE_FILTER_CPU_RESTORE_PATCHED, True
    )
    ltx2_runtime._restore_ltx_bwe_resampler_filter = (
        _cpu_restore_ltx_bwe_resampler_filter
    )
    logger.info("Applied TPU patch: CPU rebuild of the LTX-2 BWE resampler filter.")


_SPLIT_ROPE_PATCHED = "_tpu_split_rope_patched"


def _patch_ltx2_split_rope() -> None:
    # -------------------------------------------------------------------------
    # TODO: Remove this patch once vLLM-Omni's LTX-2 split RoPE rotates q and
    # k in their (B, T, H * D) layout instead of reshaping them per head.
    #
    # Problem: LTX2AudioVideoRotaryPosEmbed builds split-RoPE tables as
    #   (B, H, T, D/2), so apply_split_rotary_emb transposes every (B, T, H * D)
    #   q and k to (B, H, T, D) and back in each attention layer. The pipeline
    #   passes the same coords tensor at every denoising step, and the rope
    #   modules rebuild the tables each time.
    # Fix: the rope module returns the tables in the layout of q and k,
    #   (B, 1, T, H * D) with the sign of each half folded into sin
    #   (split_rope_natural_tables), and apply_split_rotary_emb rotates them
    #   elementwise. Each rope module keeps the tables of its last split-RoPE
    #   call and returns them while the key matches, until a call with
    #   another key replaces them.
    # Effect: LTX-2 T2V 704x1280x121, 40 steps, on TPU v7x: 0.770 -> 0.482
    #   s/step (-37%).
    # Scope:
    #   - T stays at dim 2, where the split-RoPE sequence-parallel (SP) plan
    #     shards the tables.
    #   - TP: _slice_rope_for_tp slices 4-D tables by heads on dim 1 and so
    #     passes these (B, 1, T, H * D) tables through whole; the rotation
    #     takes the lanes of the local heads.
    #   - Cache key: the storage of coords (its data pointer; Tensor.is_set_to
    #     is not implemented for TPU), the layout of coords on it (storage
    #     offset, shape, stride), its dtype, device and version counter, and
    #     the device and out_dtype arguments. Fresh views with the same layout,
    #     such as the cross-attention ropes' coords[:, 0:1, :] each step, hit
    #     in and out of inference mode. The cache holds the coords view, which
    #     keeps the storage alive, so its address is not reused while cached.
    #     Inference tensors have no version counter, so in-place edits of
    #     coords in inference mode are not seen (vLLM-Omni does not edit
    #     coords after building them).
    #   - Interleaved RoPE and (B, H, T, D/2) tables use the original
    #     functions.
    #   - synchronize_tensors materializes the cached tables once.
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.models.ltx2 import ltx2_transformer

    from vllm_torchtpu.omni.rope import (
        apply_split_rotary_half_swap,
        split_rope_natural_tables,
    )
    from vllm_torchtpu.utils import synchronize_tensors

    rope_cls = ltx2_transformer.LTX2AudioVideoRotaryPosEmbed
    if getattr(rope_cls.forward, _SPLIT_ROPE_PATCHED, False):
        return
    orig_rope_forward = rope_cls.forward
    orig_apply_split_rotary_emb = ltx2_transformer.apply_split_rotary_emb

    def _cached_rope_forward(
        self: Any,
        coords: torch.Tensor,
        device: str | torch.device | None = None,
        out_dtype: torch.dtype | None = None,
    ) -> tuple[torch.Tensor, torch.Tensor]:
        if self.rope_type != "split":
            return orig_rope_forward(self, coords, device, out_dtype)
        storage = coords.untyped_storage().data_ptr()
        version = None if coords.is_inference() else coords._version
        key = (
            version,
            coords.storage_offset(),
            tuple(coords.shape),
            coords.stride(),
            coords.dtype,
            coords.device,
            device,
            out_dtype,
        )
        cached = getattr(self, "_tpu_split_rope_cache", None)
        if (
            cached is not None
            and storage != 0
            and cached[0].untyped_storage().data_ptr() == storage
            and cached[1] == key
        ):
            return cached[2]
        tables = orig_rope_forward(self, coords, device, out_dtype)
        if tables[0].ndim != 4:
            return tables
        tables = split_rope_natural_tables(*tables)
        synchronize_tensors(list(tables), wait=False)
        self._tpu_split_rope_cache = (coords, key, tables)
        return tables

    shard_cache: dict[
        tuple[Any, ...],
        tuple[torch.Tensor, torch.Tensor, tuple[torch.Tensor, torch.Tensor]],
    ] = {}

    def _apply_split_rotary_emb(
        x: torch.Tensor,
        freqs: tuple[torch.Tensor, torch.Tensor],
        *,
        head_dim: int,
    ) -> torch.Tensor:
        cos, sin = freqs
        if cos.ndim != 4 or cos.shape[1] != 1 or cos.shape[-1] == head_dim // 2:
            return orig_apply_split_rotary_emb(x, freqs, head_dim=head_dim)
        width = x.shape[-1]
        if cos.shape[-1] != width:
            tp_size = ltx2_transformer.get_tensor_model_parallel_world_size()
            if cos.shape[-1] != width * tp_size:
                raise ValueError(
                    f"LTX-2 split RoPE tables of width {cos.shape[-1]} do not "
                    f"match q/k of width {width} on {tp_size} tensor-parallel "
                    "ranks; the tables must cover all heads of all ranks."
                )
            start = ltx2_transformer.get_tensor_model_parallel_rank() * width
            cos = cos[..., start : start + width]
            sin = sin[..., start : start + width]
        if not torch.compiler.is_compiling():
            cos_ptr = cos.untyped_storage().data_ptr()
            sin_ptr = sin.untyped_storage().data_ptr()
        else:
            cos_ptr = 0
            sin_ptr = 0
        if cos_ptr != 0 and sin_ptr != 0:
            shard_key = (
                cos_ptr,
                cos.storage_offset(),
                tuple(cos.shape),
                cos.stride(),
                sin_ptr,
                sin.storage_offset(),
                tuple(sin.shape),
                sin.stride(),
                cos.dtype,
                cos.device,
            )
            entry = shard_cache.get(shard_key)
            if (
                entry is not None
                and entry[0].untyped_storage().data_ptr() == cos_ptr
                and entry[1].untyped_storage().data_ptr() == sin_ptr
            ):
                cos, sin = entry[2]
            else:
                cos_local = torch.empty(
                    cos.shape, dtype=cos.dtype, device=cos.device
                )
                cos_local.copy_(cos)
                sin_local = torch.empty(
                    sin.shape, dtype=sin.dtype, device=sin.device
                )
                sin_local.copy_(sin)
                synchronize_tensors([cos_local, sin_local], wait=False)
                if len(shard_cache) >= 8:
                    shard_cache.clear()
                shard_cache[shard_key] = (cos, sin, (cos_local, sin_local))
                cos, sin = cos_local, sin_local
        return apply_split_rotary_half_swap(x, cos, sin, head_dim)

    setattr(_cached_rope_forward, _SPLIT_ROPE_PATCHED, True)
    rope_cls.forward = _cached_rope_forward
    ltx2_transformer.apply_split_rotary_emb = _apply_split_rotary_emb
    logger.info("Applied TPU patch: cached LTX-2 split RoPE on the q/k layout.")


_LTX2_PER_BATCH_TIMESTEP_PATCHED = "_tpu_ltx2_per_batch_timestep_patched"


def _patch_ltx2_per_batch_timestep() -> None:
    """Keep LTX-2 T2V timestep per-batch under sequence parallelism.

    Upstream LTXRuntime._denoise_timestep_kwargs always passes
    expand_for_sequence_parallel=True, expanding the scalar timestep to
    (B, T_video) and (B, T_audio). Under c2u4 this projects and materializes
    bf16[3072, 36864] -> [2, 1536, 9, 4096] (226 MB) and [2, 1536, 4, 4096]
    (96 MB) in every block (19.7% of the step). For T2V (and I2V when
    conditioning_mask is None), every token has the same timestep; passing it
    per-batch (B,) keeps temb at (B, 1, 9, D) (144 KB) and broadcasts into
    each block's norm modulation. When I2V has a conditioning_mask,
    LTXConditioningMixin._denoise_timestep_kwargs still overrides video
    timestep with the 2-D masked tensor.
    """
    from vllm_omni.diffusion.models.ltx2.ltx2_runtime import LTXRuntime

    if getattr(
        LTXRuntime._denoise_timestep_kwargs,
        _LTX2_PER_BATCH_TIMESTEP_PATCHED,
        False,
    ):
        return

    def _per_batch_denoise_timestep_kwargs(
        self: Any,
        ts: torch.Tensor,
        forward_ctx: Any,
        denoise_ctx: Any,
        *,
        video_token_count: int,
        audio_token_count: int,
    ) -> dict[str, torch.Tensor]:
        del forward_ctx, denoise_ctx
        return self.guidance_executor.timestep_kwargs(
            ts,
            video_token_count,
            audio_token_count,
            expand_for_sequence_parallel=False,
        )

    setattr(
        _per_batch_denoise_timestep_kwargs,
        _LTX2_PER_BATCH_TIMESTEP_PATCHED,
        True,
    )
    LTXRuntime._denoise_timestep_kwargs = _per_batch_denoise_timestep_kwargs
    logger.info("Applied TPU patch: per-batch LTX-2 T2V timestep under SP.")


_LTX2_GUIDANCE_SIGMA_SCALAR_PATCHED = "_tpu_ltx2_guidance_sigma_scalar_patched"


def _patch_ltx2_guidance_sigma_scalar() -> None:
    """Pre-materialize LTX-2 scheduler sigmas on CPU to avoid per-step D2H syncs.

    Upstream LTXGuidanceExecutor.predict_parallel_guidance and predict_noise
    call self._guide_modality(..., sigma=scheduler.sigmas[index]) twice per
    denoise step (video and audio) without passing sigma_scalar, so
    velocity_from_x0 executes sigma.to(torch.float32).item() on a TPU tensor
    twice every step. In TorchTPU DEFER_AND_FUSE mode, each .item() triggers a
    blocking PJRT_Buffer_ToHostBuffer (TransferFromDevice) that drains the
    in-flight execution queue (180.3 ms in step 1 + 18-26 ms/step in steps
    2..40) and creates a ~14 ms/step TensorCore starvation bubble at the start
    of the next step. Pre-caching scheduler.sigmas on CPU once per phase and
    supplying sigma_scalar to _guide_modality / velocity_from_x0 (matching
    ltx2_audio_runtime.py:513,609) eliminates all 80 D2H host syncs across the
    40-step denoise loop while keeping the exact same IEEE-754 float32 scalar.
    """
    from vllm_omni.diffusion.models.ltx2 import ltx2_denoise, ltx2_guidance

    executor_cls = ltx2_guidance.LTXGuidanceExecutor
    if getattr(
        executor_cls.predict_noise,
        _LTX2_GUIDANCE_SIGMA_SCALAR_PATCHED,
        False,
    ):
        return

    orig_prepare_scheduler_stage = ltx2_denoise.prepare_scheduler_stage
    orig_predict_noise = executor_cls.predict_noise
    orig_guide_modality = executor_cls._guide_modality
    active_step_sigma_map: dict[int, float | None] = {}

    def _ensure_sigma_scalars(scheduler: Any) -> tuple[float, ...] | None:
        sigmas_t = getattr(scheduler, "sigmas", None)
        if not isinstance(sigmas_t, torch.Tensor):
            return None
        ptr = sigmas_t.untyped_storage().data_ptr()
        cached_ptr = getattr(scheduler, "_tpu_sigma_scalars_ptr", None)
        cached_scalars = getattr(scheduler, "_tpu_sigma_scalars", None)
        if cached_scalars is not None and cached_ptr == ptr and ptr != 0:
            return cached_scalars
        scalars = tuple(
            float(x)
            for x in sigmas_t.detach().to(device="cpu", dtype=torch.float32).tolist()
        )
        scheduler._tpu_sigma_scalars = scalars
        scheduler._tpu_sigma_scalars_ptr = ptr
        return scalars

    def _cached_prepare_scheduler_stage(
        pipeline: Any,
        request_inputs: Any,
        *args: Any,
        **kwargs: Any,
    ) -> tuple[Any, Any, torch.Tensor]:
        audio_scheduler, video_audio_step_adapter, timesteps_tensor = (
            orig_prepare_scheduler_stage(pipeline, request_inputs, *args, **kwargs)
        )
        if not torch.compiler.is_compiling():
            _ensure_sigma_scalars(getattr(pipeline, "scheduler", None))
            _ensure_sigma_scalars(audio_scheduler)
        return audio_scheduler, video_audio_step_adapter, timesteps_tensor

    def _predict_noise_with_cached_sigma(
        self: Any,
        pipeline: Any,
        plan: Any,
        index: int,
        timestep: torch.Tensor,
        state: Any,
        forward_ctx: Any,
        denoise_ctx: Any,
        preserve_positive_velocity: bool = False,
    ) -> tuple[torch.Tensor, torch.Tensor]:
        if not torch.compiler.is_compiling():
            v_scalars = _ensure_sigma_scalars(getattr(pipeline, "scheduler", None))
            a_scalars = _ensure_sigma_scalars(
                getattr(forward_ctx, "audio_scheduler", None)
            )
            active_step_sigma_map[id(state.video)] = (
                v_scalars[index]
                if v_scalars is not None and 0 <= index < len(v_scalars)
                else None
            )
            active_step_sigma_map[id(state.audio)] = (
                a_scalars[index]
                if a_scalars is not None and 0 <= index < len(a_scalars)
                else None
            )
        try:
            return orig_predict_noise(
                self,
                pipeline,
                plan,
                index,
                timestep,
                state,
                forward_ctx,
                denoise_ctx,
                preserve_positive_velocity=preserve_positive_velocity,
            )
        finally:
            active_step_sigma_map.clear()

    @staticmethod
    def _guide_modality_with_cached_sigma(
        sample: torch.Tensor,
        splits: dict[str, torch.Tensor],
        sigma: torch.Tensor,
        guidance: Any,
        *,
        model_sigma: torch.Tensor | None = None,
        sigma_scalar: float | None = None,
        preserve_positive_velocity: bool = False,
        rescale_token_count: int | None = None,
    ) -> torch.Tensor:
        if sigma_scalar is None:
            sigma_scalar = active_step_sigma_map.get(id(sample))
        return orig_guide_modality(
            sample,
            splits,
            sigma,
            guidance,
            model_sigma=model_sigma,
            sigma_scalar=sigma_scalar,
            preserve_positive_velocity=preserve_positive_velocity,
            rescale_token_count=rescale_token_count,
        )

    setattr(
        _predict_noise_with_cached_sigma,
        _LTX2_GUIDANCE_SIGMA_SCALAR_PATCHED,
        True,
    )
    ltx2_denoise.prepare_scheduler_stage = _cached_prepare_scheduler_stage
    executor_cls.predict_noise = _predict_noise_with_cached_sigma
    executor_cls._guide_modality = _guide_modality_with_cached_sigma
    logger.info(
        "Applied TPU patch: pre-materialized LTX-2 guidance sigma scalars on CPU."
    )


_LTX2_FAST_EAGER_DISPATCH_PATCHED = "_tpu_ltx2_fast_eager_dispatch_patched"


def _patch_ltx2_fast_eager_dispatch() -> None:
    """Eliminate Python reflection and wrapper overhead in LTX-2 block dispatch.

    XProf host-timeline analysis (A1 rank2.pkl, 184,321 Python events/step)
    showed three pure-Python dispatch hotspots inside each 48-block denoise
    step:
    1. LTX2Attention.forward calls inspect.signature(self.processor.__call__)
       on all 288 attention calls/step (11,520 calls/gen = 29.02 ms/step =
       1.16 s/gen). Fast-pathing the standard 6-arg call eliminates all
       per-call inspect.signature reflection.
    2. BasevLLMParameter defines a no-op Python __torch_function__ classmethod
       that forces C++ torch._C._nn.linear to bounce into Python 1,632
       times/step (65,280 calls/gen = 19.69 ms/step = 0.79 s/gen). Restoring
       torch.Tensor.__torch_function__ re-enables the C++ fast path.
    3. SeqAllToAll4D.apply goes through torch.autograd.Function.apply 288
       times/step under torch.no_grad() and performs a double transpose in
       scatter_idx=1, gather_idx=2. Calling all_to_all_4D directly with a
       single permute removes autograd boxing and redundant reshape/transpose
       calls.
    """
    import inspect

    from vllm.model_executor.parameter import BasevLLMParameter
    from vllm_omni.diffusion.distributed import comm
    from vllm_omni.diffusion.models.ltx2 import (
        ltx2_sequence_parallel,
        ltx2_transformer,
    )
    from vllm_omni.diffusion.models.ltx2.ltx2_transformer import LTX2Attention

    if getattr(
        LTX2Attention.forward,
        _LTX2_FAST_EAGER_DISPATCH_PATCHED,
        False,
    ):
        return

    if hasattr(BasevLLMParameter, "__torch_function__"):
        BasevLLMParameter.__torch_function__ = torch.Tensor.__torch_function__

    sig_cache: dict[type, frozenset[str]] = {}

    def _fast_ltx2_attention_forward(
        self: Any,
        hidden_states: torch.Tensor,
        encoder_hidden_states: torch.Tensor | None = None,
        attention_mask: torch.Tensor | None = None,
        query_rotary_emb: tuple[torch.Tensor, torch.Tensor] | None = None,
        key_rotary_emb: tuple[torch.Tensor, torch.Tensor] | None = None,
        perturbation_mask: torch.Tensor | None = None,
        **kwargs: Any,
    ) -> torch.Tensor:
        if not kwargs:
            return self.processor(
                self,
                hidden_states,
                encoder_hidden_states,
                attention_mask,
                query_rotary_emb,
                key_rotary_emb,
                perturbation_mask=perturbation_mask,
            )
        proc_cls = type(self.processor)
        attn_parameters = sig_cache.get(proc_cls)
        if attn_parameters is None:
            attn_parameters = frozenset(
                inspect.signature(self.processor.__call__).parameters.keys()
            )
            sig_cache[proc_cls] = attn_parameters
        filtered = {k: v for k, v in kwargs.items() if k in attn_parameters}
        if perturbation_mask is not None and "perturbation_mask" in attn_parameters:
            filtered["perturbation_mask"] = perturbation_mask
        return self.processor(
            self,
            hidden_states,
            encoder_hidden_states,
            attention_mask,
            query_rotary_emb,
            key_rotary_emb,
            **filtered,
        )

    orig_all_to_all_4d = comm.all_to_all_4D

    def _fast_all_to_all_4d(
        input_t: torch.Tensor,
        scatter_idx: int = 2,
        gather_idx: int = 1,
        group: Any = None,
        use_sync: bool = False,
        *,
        _output_destination: torch.Tensor | None = None,
    ) -> torch.Tensor:
        if _output_destination is not None:
            return orig_all_to_all_4d(
                input_t,
                scatter_idx,
                gather_idx,
                group=group,
                use_sync=use_sync,
                _output_destination=_output_destination,
            )
        seq_world_size = torch.distributed.get_world_size(group)
        if seq_world_size <= 1:
            return input_t
        if scatter_idx == 2 and gather_idx == 1:
            bs, shard_seqlen, hc, hs = input_t.shape
            seqlen = shard_seqlen * seq_world_size
            shard_hc = hc // seq_world_size
            send_buf = (
                input_t.reshape(bs, shard_seqlen, seq_world_size, shard_hc, hs)
                .permute(2, 1, 0, 3, 4)
                .contiguous()
            )
            recv_buf = torch.empty_like(send_buf)
            torch.distributed.all_to_all_single(recv_buf, send_buf, group=group)
            return (
                recv_buf.reshape(seqlen, bs, shard_hc, hs)
                .transpose(0, 1)
                .contiguous()
            )
        if scatter_idx == 1 and gather_idx == 2:
            bs, seqlen, shard_hc, hs = input_t.shape
            hc = shard_hc * seq_world_size
            shard_seqlen = seqlen // seq_world_size
            send_buf = (
                input_t.reshape(bs, seq_world_size, shard_seqlen, shard_hc, hs)
                .permute(1, 3, 2, 0, 4)
                .contiguous()
            )
            recv_buf = torch.empty_like(send_buf)
            torch.distributed.all_to_all_single(recv_buf, send_buf, group=group)
            return (
                recv_buf.reshape(hc, shard_seqlen, bs, hs)
                .permute(2, 1, 0, 3)
                .contiguous()
            )
        return orig_all_to_all_4d(
            input_t,
            scatter_idx,
            gather_idx,
            group=group,
            use_sync=use_sync,
        )

    def _fast_seq_all_to_all_4d_apply(
        group: Any,
        input_t: torch.Tensor,
        scatter_idx: int,
        gather_idx: int,
        use_sync: bool = False,
    ) -> torch.Tensor:
        return _fast_all_to_all_4d(
            input_t,
            scatter_idx,
            gather_idx,
            group=group,
            use_sync=use_sync,
        )

    setattr(
        _fast_ltx2_attention_forward,
        _LTX2_FAST_EAGER_DISPATCH_PATCHED,
        True,
    )
    LTX2Attention.forward = _fast_ltx2_attention_forward
    comm.all_to_all_4D = _fast_all_to_all_4d
    comm.SeqAllToAll4D.apply = staticmethod(_fast_seq_all_to_all_4d_apply)
    ltx2_sequence_parallel.SeqAllToAll4D.apply = staticmethod(
        _fast_seq_all_to_all_4d_apply
    )
    logger.info(
        "Applied TPU patch: fast LTX-2 attention dispatch, parameter torch_function bypass, and direct all_to_all_4D."
    )


_LTX2_VIDEO_VAE_DECODE_PATCHED = "_tpu_ltx2_video_vae_decode_patched"


def _patch_ltx2_video_vae_decode() -> None:
    """Optimize and compile LTX-2 Video VAE 3D decoder on TPU.

    Upstream LTX2VideoUpsampler3d.forward separately permutes and 3x-flattens
    the 8-D residual tensor, calls .repeat(1, 4, 1, 1, 1) (materializing a 4x
    larger 761 MB tensor in up_blocks[2]), and adds it after a second 8-D
    permute of conv_out. Because addition commutes with permutation and
    slicing, adding the unrepeated residual via broadcast before the 8-D
    permute eliminates the second 8-D permute, the 4x .repeat() allocation, and
    the post-permute 761 MB add while remaining bit-exact. Combining this with
    rsqrt PerChannelRMSNorm, single-reshape unpatchify, and full-graph
    torch.compile(backend="tpu", dynamic=False) on LTX2VideoDecoder3d fuses the
    ResNet3D/upsampler stages on rank 0.
    """
    import os

    from diffusers.models.autoencoders import autoencoder_kl_ltx2

    decoder_cls = autoencoder_kl_ltx2.LTX2VideoDecoder3d
    upsampler_cls = autoencoder_kl_ltx2.LTX2VideoUpsampler3d
    rms_norm_cls = autoencoder_kl_ltx2.PerChannelRMSNorm
    if getattr(decoder_cls.forward, _LTX2_VIDEO_VAE_DECODE_PATCHED, False):
        return

    def _per_channel_rms_norm_forward(
        self: Any,
        x: torch.Tensor,
        channel_dim: int | None = None,
    ) -> torch.Tensor:
        dim = self.channel_dim if channel_dim is None else channel_dim
        mean_sq = torch.mean(x * x, dim=dim, keepdim=True)
        return x * torch.rsqrt(mean_sq + self.eps)

    def _upsampler_forward(
        self: Any,
        hidden_states: torch.Tensor,
        causal: bool = True,
    ) -> torch.Tensor:
        batch_size, _, num_frames, height, width = hidden_states.shape
        s0, s1, s2 = self.stride
        conv_out = self.conv(hidden_states, causal=causal)
        if self.residual:
            repeats = (s0 * s1 * s2) // self.upscale_factor
            c_base = hidden_states.shape[1] // (s0 * s1 * s2)
            conv_out = (
                conv_out.reshape(
                    batch_size,
                    repeats,
                    c_base,
                    s0,
                    s1,
                    s2,
                    num_frames,
                    height,
                    width,
                )
                + hidden_states.reshape(
                    batch_size,
                    1,
                    c_base,
                    s0,
                    s1,
                    s2,
                    num_frames,
                    height,
                    width,
                )
            ).reshape(
                batch_size,
                repeats * c_base,
                s0,
                s1,
                s2,
                num_frames,
                height,
                width,
            )
        else:
            conv_out = conv_out.reshape(
                batch_size, -1, s0, s1, s2, num_frames, height, width
            )
        hidden_states = conv_out.permute(0, 1, 5, 2, 6, 3, 7, 4).reshape(
            batch_size, -1, num_frames * s0, height * s1, width * s2
        )[:, :, s0 - 1 :]
        return hidden_states

    def _decoder_forward_impl(
        self: Any,
        hidden_states: torch.Tensor,
        temb: torch.Tensor | None = None,
        causal: bool | None = None,
    ) -> torch.Tensor:
        causal_flag = bool(causal or self.is_causal)
        hidden_states = self.conv_in(hidden_states, causal=causal_flag)
        if self.timestep_scale_multiplier is not None and temb is not None:
            temb = temb * self.timestep_scale_multiplier
        hidden_states = self.mid_block(hidden_states, temb, causal=causal_flag)
        for up_block in self.up_blocks:
            hidden_states = up_block(hidden_states, temb, causal=causal_flag)
        hidden_states = self.norm_out(hidden_states)
        if self.time_embedder is not None and temb is not None:
            temb = self.time_embedder(
                timestep=temb.flatten(),
                resolution=None,
                aspect_ratio=None,
                batch_size=hidden_states.size(0),
                hidden_dtype=hidden_states.dtype,
            )
            temb = temb.view(hidden_states.size(0), -1, 1, 1, 1).unflatten(
                1, (2, -1)
            )
            temb = temb + self.scale_shift_table[None, ..., None, None, None]
            shift, scale = temb.unbind(dim=1)
            hidden_states = hidden_states * (1 + scale) + shift
        hidden_states = self.conv_act(hidden_states)
        hidden_states = self.conv_out(hidden_states, causal=causal_flag)
        p = self.patch_size
        p_t = self.patch_size_t
        batch_size, _, num_frames, height, width = hidden_states.shape
        hidden_states = hidden_states.reshape(
            batch_size, -1, p_t, p, p, num_frames, height, width
        )
        hidden_states = hidden_states.permute(0, 1, 5, 2, 6, 4, 7, 3).reshape(
            batch_size, -1, num_frames * p_t, height * p, width * p
        )
        return hidden_states

    def _decoder_forward(
        self: Any,
        hidden_states: torch.Tensor,
        temb: torch.Tensor | None = None,
        causal: bool | None = None,
    ) -> torch.Tensor:
        if (
            os.environ.get("VLLM_TORCHTPU_COMPILE_VAE_DECODER", "1") != "0"
            and not torch.compiler.is_compiling()
        ):
            compiled = getattr(self, "_tpu_compiled_decoder_fn", None)
            if compiled is None:
                compiled = torch.compile(
                    _decoder_forward_impl,
                    backend="tpu",
                    dynamic=False,
                )
                self._tpu_compiled_decoder_fn = compiled
            return compiled(self, hidden_states, temb, causal)
        return _decoder_forward_impl(self, hidden_states, temb, causal)

    setattr(_decoder_forward, _LTX2_VIDEO_VAE_DECODE_PATCHED, True)
    rms_norm_cls.forward = _per_channel_rms_norm_forward
    upsampler_cls.forward = _upsampler_forward
    decoder_cls.forward = _decoder_forward
    logger.info(
        "Applied TPU patch: pre-permute LTX-2 VAE upsampler residual and compiled decoder."
    )
