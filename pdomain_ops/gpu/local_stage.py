"""LocalStageDispatcher — in-process stage registry for local mode."""

from __future__ import annotations

import asyncio
import time
import warnings
from typing import TYPE_CHECKING, Any

from pdomain_ops.gpu.device import canonical_execution_device, pick_device, pick_doctr_batch_sizes
from pdomain_ops.gpu.types import OcrBatchRequest, StageResult

if TYPE_CHECKING:
    from collections.abc import Callable

_VALID_DEVICES = frozenset({"local", "mps", "cpu", "modal", "shared_container"})


def _is_valid_device(device: str) -> bool:
    """Return True if *device* is a recognised compute-target identifier."""
    if device in _VALID_DEVICES:
        return True
    # Accept cuda:N (e.g. cuda:0, cuda:1)
    return device.startswith("cuda:") and device[5:].isdigit()


class UnknownStageError(KeyError):
    """Raised when a stage_id is not registered in the local registry."""


class LocalStageDispatcher:
    """In-process stage dispatcher.

    The registry is intentionally empty in Phase 1 — pgdp-prep's STAGE_IMPL
    migrates in plan #7.

    Registry keys are (stage_id, device) tuples.
    Impl signature: async def impl(page_id: str, device: str, **kwargs) -> dict
    """

    def __init__(
        self,
        registry: dict[tuple[str, str], Callable[..., Any]] | None = None,
        *,
        device_resolver: Callable[[], str] | None = None,
    ) -> None:
        self._registry: dict[tuple[str, str], Callable[..., Any]] = dict(registry or {})
        self._device_resolver = device_resolver

    def register_stage(self, stage_id: str, device: str, impl: Callable[..., Any]) -> None:
        """Register a stage implementation. Warns if replacing an existing entry."""
        if not _is_valid_device(device):
            raise ValueError(
                f"device {device!r} is not valid. Allowed: {sorted(_VALID_DEVICES)} or cuda:N"
            )
        key = (stage_id, device)
        if key in self._registry:
            warnings.warn(
                f"Replacing existing stage impl for ({stage_id!r}, {device!r})",
                UserWarning,
                stacklevel=2,
            )
        self._registry[key] = impl

    def unregister_stage(self, stage_id: str, device: str) -> None:
        """Remove a stage implementation."""
        self._registry.pop((stage_id, device), None)

    async def run_stage(
        self,
        stage_id: str,
        page_id: str,
        *,
        device: str | None = None,
        **kwargs: Any,
    ) -> StageResult:
        """Dispatch a stage call to the registered implementation.

        When *device* is given (e.g. a user CPU/GPU choice), it overrides
        auto-detection. Otherwise pick_device() chooses.
        Fallthrough order: requested/detected device -> "cpu" (if not in registry).

        Every candidate is canonicalized to registry vocabulary before lookup
        (e.g. "cuda:0" -> "local") -- the registry only ever holds cpu/local/mps
        keys, so an uncanonicalized display id would silently miss and fall
        through to cpu.
        """
        device = (
            canonical_execution_device(device)
            or (
                canonical_execution_device(self._device_resolver())
                if self._device_resolver
                else None
            )
            or pick_device()
        )

        # Try preferred device first, fall through to cpu
        impl = self._registry.get((stage_id, device))
        if impl is None and device != "cpu":
            impl = self._registry.get((stage_id, "cpu"))
            if impl is not None:
                device = "cpu"

        if impl is None:
            raise UnknownStageError(
                f"No implementation registered for stage {stage_id!r} "
                f"(tried device={device!r} and fallback cpu)"
            )

        start_ns = time.monotonic_ns()
        result_dict = await impl(page_id=page_id, device=device, **kwargs)
        duration_ms = (time.monotonic_ns() - start_ns) // 1_000_000

        return StageResult(
            stage_id=stage_id,
            page_id=page_id,
            device=device,
            duration_ms=duration_ms,
            metadata=result_dict or {},
        )

    async def run_ocr_batch(self, req: OcrBatchRequest) -> list[dict[str, object]]:
        """Run batched OCR on multiple pages.

        Accepts image bytes (not paths) so the same interface works remotely
        in Wave 5.  Delegates to :func:`~pdomain_ops.gpu.doctr_batch.run_doctr_batch`
        with a sized predictor fetched from / stored in the module-level
        predictor cache in :mod:`pdomain_ops.gpu.default_stages`.

        The ``build_smaller`` callback closes over the cache so that OOM
        backoff can rebuild a predictor at reduced batch sizes and store it
        back under its own cache key.
        """
        from pdomain_ops.gpu.default_stages import (
            _predictor_cache,  # pyright: ignore[reportPrivateUsage]  # deliberate gpu-package-internal shared cache
        )
        from pdomain_ops.gpu.doctr_batch import run_doctr_batch

        device = (
            canonical_execution_device(req.device)
            or (
                canonical_execution_device(self._device_resolver())
                if self._device_resolver
                else None
            )
            or pick_device()
        )
        det_bs, reco_bs = pick_doctr_batch_sizes(device, len(req.images))

        def _get_or_build_predictor(d_bs: int, r_bs: int) -> Any:
            """Fetch from cache or build a predictor for the given batch sizes."""
            try:
                from pdomain_book_tools.hf import resolve_ocr_models
                from pdomain_book_tools.ocr.doctr_support import (
                    get_finetuned_torch_doctr_predictor,
                )
            except ImportError:
                return None  # No finetuned models available; run_doctr_batch will use CPU

            det_path, reco_path = resolve_ocr_models()
            cache_key = (str(det_path), str(reco_path), d_bs, r_bs)
            predictor = _predictor_cache.get(cache_key)
            if predictor is None:
                predictor = get_finetuned_torch_doctr_predictor(
                    str(det_path),
                    str(reco_path),
                    det_bs=d_bs,
                    reco_bs=r_bs,
                )
                _predictor_cache[cache_key] = predictor
            return predictor

        predictor = _get_or_build_predictor(det_bs, reco_bs)

        def build_smaller(d_bs: int, r_bs: int) -> Any:
            return _get_or_build_predictor(d_bs, r_bs)

        loop = asyncio.get_event_loop()
        # The worker returns book-tools Page objects; serialize to dicts here
        # at the dispatcher's transport boundary (a remote backend would
        # serialize identically before sending results over the wire).
        pages = await loop.run_in_executor(
            None,
            lambda: run_doctr_batch(
                req.images,
                predictor=predictor,
                device=device,
                build_smaller=build_smaller,
                source_identifiers=req.source_identifiers,
            ),
        )
        return [p.to_dict() for p in pages]
