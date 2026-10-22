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

import contextvars
import functools
import os
from functools import cache as run_once
from typing import Any

import torch

from vllm_torchtpu.logger import init_logger

logger = init_logger(__name__)

# Opt-in DiT torch.compile with the torch_tpu "tpu" dynamo backend:
# "0" (default, eager), "regional" (each repeated block) or "full" (whole DiT).
OMNI_COMPILE_ENV = "VLLM_TORCHTPU_OMNI_COMPILE"
OMNI_COMPILE_MODES = ("0", "regional", "full")
# Opt-in: run each regionally compiled block as one torch_tpu SPMD-safe region,
# so its sequence-parallel collectives stay inside the compiled program.
OMNI_COMPILE_SPMD_SAFE_ENV = "VLLM_TORCHTPU_OMNI_COMPILE_SPMD_SAFE"
SPMD_SAFE_CACHE_TAG = "spmd-safe-regions-v1"
# DiTs whose repeated blocks issue the same TPU ops and collectives, in the
# same order and with the same shapes, on every sequence-parallel rank.
_SPMD_SAFE_DIT_CLASSES = frozenset({"WanTransformer3DModel"})


def omni_compile_mode() -> str:
    """The VLLM_TORCHTPU_OMNI_COMPILE mode: "0", "regional" or "full"."""
    mode = os.environ.get(OMNI_COMPILE_ENV, "0").strip().lower() or "0"
    if mode not in OMNI_COMPILE_MODES:
        raise ValueError(
            f"{OMNI_COMPILE_ENV}={mode!r} is not one of {OMNI_COMPILE_MODES}."
        )
    return mode


def omni_compile_spmd_safe() -> bool:
    return os.environ.get(OMNI_COMPILE_SPMD_SAFE_ENV, "0").strip() == "1"


def set_compile_cache_tag(tag: str, prefix: str | None = None) -> None:
    """Add ``tag`` to torch.compiler.config.cache_key_tag ('|'-joined).

    Idempotent. With ``prefix``, entries starting with it are replaced, so a
    second call with updated inputs keeps one entry per kind.
    """
    import torch.compiler.config as compiler_config

    existing = [t for t in str(compiler_config.cache_key_tag or "").split("|") if t]
    if prefix is not None:
        existing = [t for t in existing if t == tag or not t.startswith(prefix)]
    if tag not in existing:
        existing.append(tag)
    compiler_config.cache_key_tag = "|".join(existing)


# The DiffusionModelRunner whose load_model is running in this context.
_dit_compile_runner: contextvars.ContextVar[Any] = contextvars.ContextVar(
    "vllm_torchtpu_dit_compile_runner", default=None
)


def dit_compile_gate_open() -> bool:
    """Whether OmniTpuPlatform.supports_torch_inductor() reports True.

    vLLM-Omni uses supports_torch_inductor() as its DiT compile gate
    (DiffusionModelRunner.load_model), but VoxCPM2 and the Qwen3-TTS code
    predictor also read it and then torch.compile with Inductor, which TPU
    cannot run. The gate is therefore open only while a DiffusionModelRunner
    loads a pipeline that takes the generic _compile_transformer path (which
    _patch_dit_compile routes to the "tpu" backend), and only with
    VLLM_TORCHTPU_OMNI_COMPILE set.
    """
    runner = _dit_compile_runner.get()
    pipeline = getattr(runner, "pipeline", None) if runner is not None else None
    if pipeline is None:
        return False
    if omni_compile_mode() == "0":
        return False
    if hasattr(pipeline, "setup_compile"):
        # Pipeline-specific setup_compile() compiles with Inductor options.
        logger.warning_once(
            "%s is set, but %s compiles through its own setup_compile(); "
            "keeping it eager on TPU.",
            OMNI_COMPILE_ENV,
            type(pipeline).__name__,
        )
        return False
    return True


def _patch_dit_compile() -> None:
    # -------------------------------------------------------------------------
    # Opt-in (VLLM_TORCHTPU_OMNI_COMPILE=regional|full, Omni enforce_eager=False).
    #
    # DiffusionModelRunner._compile_transformer builds its torch.compile kwargs
    # locally with no backend (Inductor) and dynamic=od_config.
    # diffusion_compile_dynamic (default True). The torch_tpu dynamo backend
    # "tpu" compiles static shapes only, so on TPU the DiT is compiled with
    # backend="tpu", dynamic=False instead. load_model is wrapped to scope
    # dit_compile_gate_open() (OmniTpuPlatform.supports_torch_inductor) to the
    # DiT compile decision.
    # -------------------------------------------------------------------------
    from vllm_omni.diffusion.worker.diffusion_model_runner import (
        DiffusionModelRunner,
    )

    if hasattr(DiffusionModelRunner, "_tpu_orig_compile_transformer"):
        return
    DiffusionModelRunner._tpu_orig_compile_transformer = (
        DiffusionModelRunner._compile_transformer
    )
    orig_load_model = DiffusionModelRunner.load_model
    DiffusionModelRunner._tpu_orig_load_model = orig_load_model

    @functools.wraps(orig_load_model)
    def _load_model(self: Any, *args: Any, **kwargs: Any) -> Any:
        token = _dit_compile_runner.set(self)
        try:
            return orig_load_model(self, *args, **kwargs)
        finally:
            _dit_compile_runner.reset(token)

    def _compile_transformer(self: Any, attr_name: str) -> None:
        tpu_compile_transformer(self, attr_name)

    DiffusionModelRunner.load_model = _load_model
    DiffusionModelRunner._compile_transformer = _compile_transformer
    logger.info(
        "Applied TPU patch: DiT torch.compile with backend='tpu' (%s=%s).",
        OMNI_COMPILE_ENV,
        omni_compile_mode(),
    )


def tpu_compile_transformer(runner: Any, attr_name: str) -> None:
    """DiffusionModelRunner._compile_transformer for the torch_tpu backend."""
    from vllm_omni.diffusion.worker.diffusion_model_runner import regionally_compile

    model = getattr(runner.pipeline, attr_name, None)
    if model is None:
        return
    mode = omni_compile_mode()
    if mode == "0":
        return
    upstream_granularity = getattr(
        runner.od_config, "diffusion_compile_granularity", mode
    )
    if upstream_granularity != mode:
        logger.info(
            "%s=%s overrides diffusion_compile_granularity=%s on TPU.",
            OMNI_COMPILE_ENV,
            mode,
            upstream_granularity,
        )
    _register_tpu_dynamo_backend()
    _build_dit_ops_eagerly()
    # The torch_tpu backend compiles static shapes only (dynamic=False).
    compile_kwargs: dict[str, Any] = {"backend": "tpu", "dynamic": False}
    spmd_regions: list[tuple[torch.nn.Module, str, bool, Any]] = []
    try:
        if mode == "full":
            if omni_compile_spmd_safe():
                logger.warning_once(
                    "%s=1 applies to regional compile only; ignored for %s=full.",
                    OMNI_COMPILE_SPMD_SAFE_ENV,
                    OMNI_COMPILE_ENV,
                )
            model.compile(**compile_kwargs)
            compiled_model = model
        else:
            spmd_regions = _wrap_spmd_safe_regions(model)
            compiled_model = regionally_compile(model, **compile_kwargs)
            _feed_offset0_inputs(spmd_regions)
        setattr(runner.pipeline, attr_name, compiled_model)
    except Exception as e:
        _unwrap_regions(spmd_regions)
        logger.warning(
            "TPU %s torch.compile setup for %s failed: %s. Continuing with the "
            "uncompiled model.",
            mode,
            attr_name,
            e,
        )
        return
    logger.info(
        "Model runner: %s configured for lazy %s torch.compile (backend='tpu', "
        "dynamic=False, spmd_safe regions=%d).",
        attr_name,
        mode,
        len(spmd_regions),
    )


def _register_tpu_dynamo_backend() -> None:
    try:
        # Registers the "tpu" dynamo backend (torch_tpu/_internal/compile).
        import torch_tpu._internal.compile  # noqa: F401
    except ImportError as e:
        logger.warning("Could not import torch_tpu._internal.compile: %s", e)


def _build_dit_ops_eagerly() -> None:
    # Build the Pallas custom ops the DiT patches call before the first
    # compiled forward: building one while Dynamo traces is a graph break.
    from vllm_torchtpu.omni.rope import _qk_norm_rope_op

    for build in (_optimization_barrier_op, _qk_norm_rope_op):
        try:
            build()
        except Exception as e:
            logger.warning("Could not prebuild %s: %s", build.__name__, e)


def _region_forward_attr(block: torch.nn.Module) -> str:
    # regionally_compile compiles _omni_original_forward when a HookRegistry
    # wraps forward, else forward.
    if getattr(block, "_omni_original_forward", None) is not None:
        return "_omni_original_forward"
    return "forward"


def _wrap_spmd_safe_regions(
    model: torch.nn.Module,
) -> list[tuple[torch.nn.Module, str, bool, Any]]:
    """Wrap each repeated block's forward in torch_tpu's spmd_safe.

    Returns (block, attribute, had instance attribute, original) entries.
    """
    if not omni_compile_spmd_safe():
        return []
    model_cls = type(model).__name__
    if model_cls not in _SPMD_SAFE_DIT_CLASSES:
        logger.warning_once(
            "%s=1 is ignored for %s: only %s are allow-listed.",
            OMNI_COMPILE_SPMD_SAFE_ENV,
            model_cls,
            sorted(_SPMD_SAFE_DIT_CLASSES),
        )
        return []
    repeated_blocks = set(getattr(model, "_repeated_blocks", None) or ())
    if not repeated_blocks:
        return []
    from torch_tpu._internal.distributed.spmd_util import spmd_safe

    # The region annotation is not part of the compile cache key; keep
    # persisted executables of the two region policies apart.
    set_compile_cache_tag(SPMD_SAFE_CACHE_TAG)
    wrapped = []
    for _, block in model.named_modules():
        if type(block).__name__ not in repeated_blocks:
            continue
        attr = _region_forward_attr(block)
        had_instance_attr = attr in block.__dict__
        orig = getattr(block, attr)
        _set_region_forward(block, attr, spmd_safe(orig))
        wrapped.append((block, attr, had_instance_attr, orig))
    return wrapped


def _set_region_forward(block: torch.nn.Module, attr: str, fn: Any) -> None:
    old = getattr(block, attr)
    setattr(block, attr, fn)
    if attr != "_omni_original_forward":
        return
    # Hooks such as MagCache keep their own reference to the original
    # callable; regionally_compile retargets those that match it.
    registry = getattr(block, "_hook_registry", None)
    for hook in getattr(registry, "_hooks", {}).values():
        fn_ref = getattr(hook, "fn_ref", None)
        if fn_ref is not None and fn_ref.original_forward is old:
            fn_ref.original_forward = fn


def _unwrap_regions(regions: list[tuple[torch.nn.Module, str, bool, Any]]) -> None:
    for block, attr, had_instance_attr, orig in regions:
        if had_instance_attr:
            _set_region_forward(block, attr, orig)
        else:
            block.__dict__.pop(attr, None)


def _offset0(x: Any) -> Any:
    if isinstance(x, torch.Tensor) and x.storage_offset() != 0:
        return x.clone(memory_format=torch.contiguous_format)
    return x


def _offset0_inputs(fn: Any) -> Any:
    """Call ``fn`` with tensors that start at storage offset 0.

    vLLM-Omni's sequence-parallel split hook hands Wan rank-dependent
    ``Tensor.chunk`` views (storage offset ``rank * shard numel`` on ranks
    1..sp-1), and torch_tpu keys compiled executables on input storage
    offsets. Fresh copies let every rank run the same block program.
    """
    from torch.utils import _pytree

    @functools.wraps(fn)
    def wrapper(*args: Any, **kwargs: Any) -> Any:
        args, kwargs = _pytree.tree_map(_offset0, (args, kwargs))
        return fn(*args, **kwargs)

    return wrapper


def _feed_offset0_inputs(regions: list[tuple[torch.nn.Module, str, bool, Any]]) -> None:
    # Outside the compiled callable: Dynamo guards on the caller's tensors.
    for block, attr, _, _ in regions:
        _set_region_forward(block, attr, _offset0_inputs(getattr(block, attr)))


_optimization_barrier: Any = None


def _optimization_barrier_op() -> Any:
    # Not functools.cache: Dynamo ignores that wrapper and re-traces the op
    # builder inside compiled DiT forwards (a graph break). After the first
    # eager call, Dynamo reads the built op from this global.
    global _optimization_barrier
    if _optimization_barrier is None:
        from vllm_torchtpu.layers.adapter.custom_ops.optimization_barrier_op import (
            optimization_barrier_op,
        )

        _optimization_barrier = optimization_barrier_op()
    return _optimization_barrier


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
        return apply_split_rotary_half_swap(x, cos, sin, head_dim)

    setattr(_cached_rope_forward, _SPLIT_ROPE_PATCHED, True)
    rope_cls.forward = _cached_rope_forward
    ltx2_transformer.apply_split_rotary_emb = _apply_split_rotary_emb
    logger.info("Applied TPU patch: cached LTX-2 split RoPE on the q/k layout.")
