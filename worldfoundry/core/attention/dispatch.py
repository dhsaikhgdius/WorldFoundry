"""Dispatching attention wrapper for model code that uses flexible QKV layouts."""

import math
import os
import threading
import warnings
from collections import deque
from functools import lru_cache

import torch
from einops import rearrange

from worldfoundry.core.attention.backends import (
    attention_backend_from_env,
    gpu_supports_flash_attention,
    probe_attention_backends,
    resolve_attention_backend,
)
from worldfoundry.core.attention.native import (
    native_sdpa_priority,
)
from worldfoundry.core.attention.native import (
    scaled_dot_product_attention as _worldfoundry_scaled_dot_product_attention,
)


def initialize_attention_priority():
    # Keep the user's preference (usually ``auto``) unresolved until a tensor
    # device is known. Resolving at import time can permanently select CPU SDPA
    # before a worker calls torch.cuda.set_device().
    return attention_backend_from_env()


ATTENTION_IMPLEMENTATION = initialize_attention_priority()

# CC-07: capability probing calls ``torch.cuda.get_device_capability`` which
# lazily creates a CUDA context. Doing that at import time breaks fork-based
# workers and pins a context on GPU 0 before ``torch.cuda.set_device``.
# ``_CAPABILITIES`` and the ``*_AVAILABLE`` flags are therefore resolved on
# first attribute access instead of at import, and are never frozen into
# module globals (``probe_attention_backends`` already caches per runtime
# signature).
_LAZY_CAPABILITY_EXPORTS = {
    "FLASH_ATTN_3_AVAILABLE": "flash_attention_3",
    "FLASH_ATTN_2_AVAILABLE": "flash_attention_2",
    "SAGE_ATTN_AVAILABLE": "sage_attention",
    "XFORMERS_AVAILABLE": "xformers",
}


def __getattr__(name: str):
    if name == "_CAPABILITIES":
        return probe_attention_backends()
    backend_name = _LAZY_CAPABILITY_EXPORTS.get(name)
    if backend_name is not None:
        return probe_attention_backends()[backend_name].available
    raise AttributeError(f"module {__name__!r} has no attribute {name!r}")


def _gpu_supports_flash_attention():
    return gpu_supports_flash_attention()


def rearrange_qkv(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    required_in_pattern="b n s d",
    dims=None,
):
    dims = {} if dims is None else dims
    if q_pattern != required_in_pattern:
        q = rearrange(q, f"{q_pattern} -> {required_in_pattern}", **dims)
    if k_pattern != required_in_pattern:
        k = rearrange(k, f"{k_pattern} -> {required_in_pattern}", **dims)
    if v_pattern != required_in_pattern:
        v = rearrange(v, f"{v_pattern} -> {required_in_pattern}", **dims)
    return q, k, v


def rearrange_out(out: torch.Tensor, out_pattern="b n s d", required_out_pattern="b n s d", dims=None):
    dims = {} if dims is None else dims
    if out_pattern != required_out_pattern:
        out = rearrange(out, f"{required_out_pattern} -> {out_pattern}", **dims)
    return out


def torch_sdpa(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    out_pattern="b n s d",
    dims=None,
    attn_mask=None,
    scale=None,
):
    required_in_pattern, required_out_pattern = "b n s d", "b n s d"
    q, k, v = rearrange_qkv(q, k, v, q_pattern, k_pattern, v_pattern, required_in_pattern, dims)
    # The core helper already supplies a math implementation when PyTorch does
    # not expose SDPA. Runtime failures from an available implementation must
    # propagate: retrying with an explicit O(S^2) score tensor can amplify OOM.
    out = _worldfoundry_scaled_dot_product_attention(
        q,
        k,
        v,
        attn_mask,
        scale=scale,
        enable_gqa=q.shape[1] != k.shape[1],
        backends=native_sdpa_priority(q.device, has_mask=attn_mask is not None),
    )
    out = rearrange_out(out, out_pattern, required_out_pattern, dims)
    return out


def flash_attention_3(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    out_pattern="b n s d",
    dims=None,
    scale=None,
):
    import flash_attn_interface

    required_in_pattern, required_out_pattern = "b s n d", "b s n d"
    q, k, v = rearrange_qkv(q, k, v, q_pattern, k_pattern, v_pattern, required_in_pattern, dims)
    out = flash_attn_interface.flash_attn_func(q, k, v, softmax_scale=scale)
    if isinstance(out, tuple):
        out = out[0]
    out = rearrange_out(out, out_pattern, required_out_pattern, dims)
    return out


def flash_attention_2(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    out_pattern="b n s d",
    dims=None,
    scale=None,
):
    import flash_attn

    required_in_pattern, required_out_pattern = "b s n d", "b s n d"
    q, k, v = rearrange_qkv(q, k, v, q_pattern, k_pattern, v_pattern, required_in_pattern, dims)
    out = flash_attn.flash_attn_func(q, k, v, softmax_scale=scale)
    out = rearrange_out(out, out_pattern, required_out_pattern, dims)
    return out


def sage_attention(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    out_pattern="b n s d",
    dims=None,
    scale=None,
):
    from sageattention import sageattn

    required_in_pattern, required_out_pattern = "b n s d", "b n s d"
    q, k, v = rearrange_qkv(q, k, v, q_pattern, k_pattern, v_pattern, required_in_pattern, dims)
    out = sageattn(q, k, v, sm_scale=scale)
    out = rearrange_out(out, out_pattern, required_out_pattern, dims)
    return out


def sage_attention_3(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    out_pattern="b n s d",
    dims=None,
    scale=None,
):
    """Run an explicitly requested Blackwell FP4 provider when it is built."""

    from sageattn3 import sageattn3_blackwell

    required_in_pattern, required_out_pattern = "b n s d", "b n s d"
    q, k, v = rearrange_qkv(q, k, v, q_pattern, k_pattern, v_pattern, required_in_pattern, dims)
    if q.shape[1] != k.shape[1] or k.shape[1] != v.shape[1]:
        raise RuntimeError("SageAttention 3 does not support GQA/MQA head layouts")
    default_scale = q.shape[-1] ** -0.5
    if scale is not None and not math.isclose(float(scale), default_scale, rel_tol=1e-6, abs_tol=1e-8):
        raise RuntimeError("SageAttention 3 does not support a custom softmax scale")
    out = sageattn3_blackwell(q, k, v)
    return rearrange_out(out, out_pattern, required_out_pattern, dims)


def xformers_attention(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    out_pattern="b n s d",
    dims=None,
    scale=None,
):
    import xformers.ops as xops

    required_in_pattern, required_out_pattern = "b s n d", "b s n d"
    q, k, v = rearrange_qkv(q, k, v, q_pattern, k_pattern, v_pattern, required_in_pattern, dims)
    out = xops.memory_efficient_attention(q, k, v, scale=scale)
    out = rearrange_out(out, out_pattern, required_out_pattern, dims)
    return out


def attention_forward(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern="b n s d",
    k_pattern="b n s d",
    v_pattern="b n s d",
    out_pattern="b n s d",
    dims=None,
    attn_mask=None,
    scale=None,
    compatibility_mode=False,
):
    """Dispatch Q/K/V attention across qualified exact backends.

    Tensor layouts are described by einops-style patterns and normalized
    before execution. Automatic mode tries only providers that are available
    for the current device, dtype, and shape, remembers unsupported workload
    signatures, and always retains the in-tree PyTorch SDPA path as the exact
    fallback.

    Args:
        q: Query tensor in ``q_pattern`` layout.
        k: Key tensor in ``k_pattern`` layout.
        v: Value tensor in ``v_pattern`` layout.
        q_pattern: Layout pattern for ``q``.
        k_pattern: Layout pattern for ``k``.
        v_pattern: Layout pattern for ``v``.
        out_pattern: Requested output layout.
        dims: Named dimensions needed to expand grouped pattern terms such as
            ``(n d)``.
        attn_mask: Optional boolean or additive attention mask. A mask forces
            the PyTorch compatibility path because optional fused providers do
            not share one mask contract.
        scale: Optional softmax scale; ``None`` uses the backend default.
        compatibility_mode: Skip optional providers and execute PyTorch SDPA
            directly.

    Returns:
        Attention output rearranged into ``out_pattern``.

    Raises:
        RuntimeError: The selected provider fails for a reason other than an
            unsupported kernel or optional-library availability problem.

    Notes:
        Backend choice can be inspected with ``attention_dispatch_report``.
        Use ``clear_attention_dispatch_cache`` after changing provider
        availability inside a long-lived process.
    """
    if compatibility_mode or (attn_mask is not None):
        return torch_sdpa(q, k, v, q_pattern, k_pattern, v_pattern, out_pattern, dims, attn_mask=attn_mask, scale=scale)
    signature = _attention_signature(q, k, v, q_pattern, k_pattern, v_pattern, dims)
    candidates = _select_attention_backends_cached(
        ATTENTION_IMPLEMENTATION,
        str(q.device),
        str(q.dtype),
        signature,
        _short_attention_threshold(q.device),
        tuple(sorted(_UNAVAILABLE_ATTENTION_BACKENDS)),
    )
    for selected in candidates:
        if selected == "torch":
            break
        failure_key = (selected, str(q.device), str(q.dtype), signature)
        if failure_key in _FAILED_ATTENTION_SIGNATURES:
            continue
        try:
            if selected == "flash_attention_3":
                return flash_attention_3(q, k, v, q_pattern, k_pattern, v_pattern, out_pattern, dims, scale=scale)
            if selected == "flash_attention_2":
                return flash_attention_2(q, k, v, q_pattern, k_pattern, v_pattern, out_pattern, dims, scale=scale)
            if selected == "sage_attention":
                return sage_attention(q, k, v, q_pattern, k_pattern, v_pattern, out_pattern, dims, scale=scale)
            if selected == "sage_attention_3":
                return sage_attention_3(q, k, v, q_pattern, k_pattern, v_pattern, out_pattern, dims, scale=scale)
            if selected == "xformers":
                return xformers_attention(q, k, v, q_pattern, k_pattern, v_pattern, out_pattern, dims, scale=scale)
        except (ImportError, OSError) as exc:
            if not _is_backend_load_error(selected, exc):
                raise
            _UNAVAILABLE_ATTENTION_BACKENDS.add(selected)
            _warn_backend_fallback(selected, exc)
        except RuntimeError as exc:
            if not _is_unsupported_kernel_error(exc):
                raise
            _remember_failed_attention_signature(failure_key)
            _warn_backend_fallback(selected, exc)
    return torch_sdpa(q, k, v, q_pattern, k_pattern, v_pattern, out_pattern, dims, scale=scale)


_FAILED_ATTENTION_SIGNATURE_LIMIT = 1024
_FAILED_ATTENTION_SIGNATURES: set[tuple[object, ...]] = set()
_FAILED_ATTENTION_SIGNATURE_ORDER: deque[tuple[object, ...]] = deque()
_FAILED_ATTENTION_SIGNATURE_LOCK = threading.Lock()
_UNAVAILABLE_ATTENTION_BACKENDS: set[str] = set()


def _short_attention_threshold(device: torch.device | str | None = None) -> int:
    try:
        configured = os.getenv("WORLDFOUNDRY_ATTENTION_MIN_FUSED_SEQUENCE")
        if configured is not None:
            return max(int(configured or "0"), 0)
    except ValueError:
        return 128
    capability = _device_compute_capability(device)
    if capability is not None and capability[0] == 7:
        return 256
    if capability is not None and capability[0] == 9:
        return 64
    return 128


def _device_compute_capability(device: torch.device | str | None = None) -> tuple[int, int] | None:
    """Return a validated NVIDIA compute capability for ``device``.

    HIP exposes a CUDA-compatible PyTorch device API, so checking only
    ``torch.cuda.is_available()`` can accidentally classify an AMD GPU as an
    NVIDIA architecture. Unknown and non-CUDA devices deliberately return
    ``None`` and use the exact PyTorch SDPA path.
    """

    if getattr(torch.version, "hip", None) is not None or not torch.cuda.is_available():
        return None
    try:
        resolved = torch.device("cuda", torch.cuda.current_device()) if device is None else torch.device(device)
        if resolved.type != "cuda":
            return None
        major, minor = torch.cuda.get_device_capability(resolved)
        return int(major), int(minor)
    except (AssertionError, RuntimeError, TypeError, ValueError):
        return None


def _auto_attention_backends(device: torch.device | str | None) -> tuple[str, ...]:
    """Use the in-tree exact PyTorch provider for automatic dispatch.

    External FlashAttention/xFormers packages and approximate SageAttention
    remain explicit opt-ins. PyTorch SDPA already dispatches to its bundled
    Flash/cuDNN kernels and preserves WorldFoundry's no-external-repo contract.
    """

    del device
    return ()


def _tensor_layout_shape(tensor: torch.Tensor, pattern: str, dims: dict | None) -> tuple[int, int, int] | None:
    """Return ``(sequence, heads, head_dim)`` for common dispatcher layouts."""

    normalized = " ".join(str(pattern).split())
    if tensor.ndim == 4 and normalized == "b n s d":
        return int(tensor.shape[2]), int(tensor.shape[1]), int(tensor.shape[3])
    if tensor.ndim == 4 and normalized == "b s n d":
        return int(tensor.shape[1]), int(tensor.shape[2]), int(tensor.shape[3])
    if tensor.ndim == 3 and normalized in {"b s (n d)", "b s (h d)"}:
        names = {} if dims is None else dims
        heads = int(names.get("n") or names.get("h") or 0)
        if heads > 0 and tensor.shape[-1] % heads == 0:
            return int(tensor.shape[1]), heads, int(tensor.shape[-1] // heads)
    return None


def _attention_signature(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    q_pattern: str,
    k_pattern: str,
    v_pattern: str,
    dims: dict | None,
) -> tuple[object, ...]:
    q_shape = _tensor_layout_shape(q, q_pattern, dims)
    k_shape = _tensor_layout_shape(k, k_pattern, dims)
    v_shape = _tensor_layout_shape(v, v_pattern, dims)
    if q_shape is None or k_shape is None or v_shape is None:
        return ("unknown", q.ndim, k.ndim, v.ndim, q.shape[-1], k.shape[-1], v.shape[-1])
    q_seq, q_heads, head_dim = q_shape
    k_seq, k_heads, k_dim = k_shape
    v_seq, v_heads, v_dim = v_shape
    return (
        "known",
        q_seq,
        k_seq,
        v_seq,
        q_heads,
        k_heads,
        v_heads,
        head_dim,
        k_dim,
        v_dim,
        str(k.dtype),
        str(v.dtype),
        str(k.device),
        str(v.device),
    )


@lru_cache(maxsize=2048)
def _select_attention_backends_cached(
    preferred: str,
    device: str,
    dtype: str,
    signature: tuple[object, ...],
    short_threshold: int,
    unavailable: tuple[str, ...],
) -> tuple[str, ...]:
    """Return usable backends in priority order for one workload signature."""

    if dtype not in {"torch.float16", "torch.bfloat16"}:
        return ("torch",)
    if preferred == "auto" and signature[0] == "known":
        q_seq, k_seq = int(signature[1]), int(signature[2])
        if max(q_seq, k_seq) < short_threshold:
            return ("torch",)

    capabilities = probe_attention_backends(device)
    if preferred == "auto":
        requested = _auto_attention_backends(device)
    elif preferred == "flash_attention":
        requested = ("flash_attention_3", "flash_attention_2")
    else:
        resolved = resolve_attention_backend(preferred, device)
        requested = () if resolved == "torch" else (resolved,)

    blocked = set(unavailable)
    selected = tuple(
        candidate
        for candidate in requested
        if candidate not in blocked
        and capabilities.get(candidate) is not None
        and capabilities[candidate].usable
        and _attention_backend_shape_eligible(candidate, device, dtype, signature)
    )
    return (*selected, "torch")


def _attention_backend_shape_eligible(
    selected: str,
    device: str,
    dtype: str,
    signature: tuple[object, ...],
) -> bool:
    if signature[0] != "known":
        return True

    (
        _,
        _q_seq,
        k_seq,
        v_seq,
        q_heads,
        k_heads,
        v_heads,
        head_dim,
        k_dim,
        v_dim,
        k_dtype,
        v_dtype,
        k_device,
        v_device,
    ) = signature
    if k_seq != v_seq:
        return False
    if k_dtype != dtype or v_dtype != dtype or k_device != device or v_device != device:
        return False
    if k_heads != v_heads or head_dim != k_dim or head_dim != v_dim:
        return False
    if k_heads <= 0 or q_heads % k_heads:
        return False
    if selected in {"flash_attention_2", "flash_attention_3"}:
        if int(head_dim) <= 0 or int(head_dim) > 256 or int(head_dim) % 8:
            return False
    if selected == "sage_attention" and int(head_dim) not in {64, 128}:
        return False
    if selected == "sage_attention_3":
        if int(head_dim) not in {64, 128}:
            return False
        if q_heads != k_heads or k_heads != v_heads:
            return False
        if max(int(_q_seq), int(k_seq)) < 512:
            return False
    if selected == "xformers" and (q_heads != k_heads or k_heads != v_heads):
        # Common xFormers releases require explicit 5D grouped layout for
        # GQA/MQA. Until that layout is built here, keep the safe MHA path.
        return False
    return True


def _remember_failed_attention_signature(key: tuple[object, ...]) -> None:
    with _FAILED_ATTENTION_SIGNATURE_LOCK:
        if key in _FAILED_ATTENTION_SIGNATURES:
            return
        if len(_FAILED_ATTENTION_SIGNATURE_ORDER) >= _FAILED_ATTENTION_SIGNATURE_LIMIT:
            expired = _FAILED_ATTENTION_SIGNATURE_ORDER.popleft()
            _FAILED_ATTENTION_SIGNATURES.discard(expired)
        _FAILED_ATTENTION_SIGNATURE_ORDER.append(key)
        _FAILED_ATTENTION_SIGNATURES.add(key)


def attention_dispatch_report() -> dict[str, object]:
    """Return lightweight operator-selection and quarantine state."""

    if torch.cuda.is_available():
        try:
            device = torch.device("cuda", torch.cuda.current_device())
        except (AssertionError, RuntimeError, ValueError):
            device = torch.device("cpu")
    else:
        device = torch.device("cpu")
    capability = _device_compute_capability(device)
    return {
        "requested": ATTENTION_IMPLEMENTATION,
        "device": str(device),
        "compute_capability": capability,
        "auto_priority": list(_auto_attention_backends(device)) or ["torch"],
        "native_sdpa_priority": list(native_sdpa_priority(device)) or ["pytorch-auto"],
        "selection_cache": _select_attention_backends_cached.cache_info()._asdict(),
        "unavailable_backends": sorted(_UNAVAILABLE_ATTENTION_BACKENDS),
        "failed_signatures": len(_FAILED_ATTENTION_SIGNATURES),
        "min_fused_sequence": _short_attention_threshold(device),
    }


def clear_attention_dispatch_cache() -> None:
    """Clear workload decisions and runtime failure quarantine."""

    _select_attention_backends_cached.cache_clear()
    with _FAILED_ATTENTION_SIGNATURE_LOCK:
        _FAILED_ATTENTION_SIGNATURES.clear()
        _FAILED_ATTENTION_SIGNATURE_ORDER.clear()
    _UNAVAILABLE_ATTENTION_BACKENDS.clear()


_UNSUPPORTED_KERNEL_MARKERS = (
    "not supported",
    "unsupported",
    "only supports",
    "requires sm",
    "no kernel image is available",
    "invalid device function",
    "not compiled with",
)

_BACKEND_IMPORT_ROOTS = {
    "flash_attention_3": ("flash_attn_interface",),
    "flash_attention_2": ("flash_attn", "flash_attn_2_cuda"),
    "sage_attention": ("sageattention",),
    "sage_attention_3": ("sageattn3",),
    "xformers": ("xformers",),
}
_DYNAMIC_LIBRARY_ERROR_MARKERS = (
    "cannot open shared object file",
    "dll load failed",
    "image not found",
    "undefined symbol",
    "symbol not found",
    "library not loaded",
)


def _is_backend_load_error(selected: str, exc: ImportError | OSError) -> bool:
    """Classify only optional-package or dynamic-loader availability errors."""

    roots = _BACKEND_IMPORT_ROOTS.get(selected, ())
    if isinstance(exc, ImportError):
        # Once execution is inside a selected optional provider, a missing
        # transitive Python/CUDA module is a provider availability failure too.
        return bool(roots)
    message = str(exc).lower()
    if not any(marker in message for marker in _DYNAMIC_LIBRARY_ERROR_MARKERS):
        return False
    # Loader errors commonly mention only a transitive dependency such as
    # libcudart/libtorch rather than the importing backend module.
    return True


def _is_unsupported_kernel_error(exc: RuntimeError) -> bool:
    """Return True only for explicit kernel-availability failures."""

    message = str(exc).lower()
    if "out of memory" in message or "alloc_failed" in message:
        return False
    return any(marker in message for marker in _UNSUPPORTED_KERNEL_MARKERS)


def _warn_backend_fallback(selected: str, exc: BaseException) -> None:
    warnings.warn(
        f"Attention backend {selected!r} is unavailable for this workload; "
        f"trying the next eligible backend: {exc}",
        RuntimeWarning,
        stacklevel=3,
    )


def packed_sequence_attention(
    q: torch.Tensor, k: torch.Tensor, v: torch.Tensor, num_heads: int, compatibility_mode=False, scale=None
):
    """Apply the shared dispatcher to flattened packed-sequence Q/K/V.

    Args:
        q: Query tensor shaped ``(batch, sequence, heads * head_dim)``.
        k: Key tensor with the same flattened-head convention.
        v: Value tensor with the same flattened-head convention.
        num_heads: Head count used to split the final dimension.
        compatibility_mode: Force the exact PyTorch SDPA path.
        scale: Optional attention softmax scale.

    Returns:
        Tensor shaped ``(batch, query_sequence, heads * value_head_dim)``.

    Notes:
        This adapter is appropriate when the model already packs heads into
        the hidden dimension. Use ``attention_forward`` directly for custom
        layouts or explicit masks.
    """
    return attention_forward(
        q,
        k,
        v,
        q_pattern="b s (n d)",
        k_pattern="b s (n d)",
        v_pattern="b s (n d)",
        out_pattern="b s (n d)",
        dims={"n": num_heads},
        scale=scale,
        compatibility_mode=compatibility_mode,
    )


__all__ = [
    "ATTENTION_IMPLEMENTATION",
    "attention_dispatch_report",
    "attention_forward",
    "clear_attention_dispatch_cache",
    "flash_attention_2",
    "flash_attention_3",
    "initialize_attention_priority",
    "packed_sequence_attention",
    "rearrange_out",
    "rearrange_qkv",
    "sage_attention",
    "sage_attention_3",
    "torch_sdpa",
    "xformers_attention",
]
