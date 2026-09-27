"""
[AI_DIRECTIVE]
ROL: VLM (Vision-Language Model) pipeline for image processing and prompt preparation
OBJETIVO: Preparar prompts VLM con imágenes, aplicar chat templates, y sincronizar Metal
ENTRADAS: processor, config, messages con image_url, tools, enable_thinking
SALIDAS: (input_ids, pixel_values, mask, vlm_kwargs) para generación
REGLAS INVIOLABLES:
- No scrubbing del prompt formateado — la canonicalización es del caller
- Metal sync (torch.mps.synchronize + mx.eval) antes de generación para evitar colisiones
- Fallback a get_chat_template si HuggingFace template falla
SSoT: Este módulo es la única fuente de preparación de inputs VLM
"""
from __future__ import annotations

from typing import Any, Dict, List, Optional, Tuple

# ── VLM dependencies (optional — None when mlx-vlm not installed) ────────────
try:
    from mlx_vlm.utils import prepare_inputs as vlm_prepare_inputs
    from mlx_vlm.prompt_utils import get_chat_template
except ImportError:
    vlm_prepare_inputs = None
    get_chat_template = None


# ── Module-level state (set via init()) ──────────────────────────────────────
_feature_preserve_thinking: bool = True


def init(*, feature_preserve_thinking: bool) -> None:
    """Initialize VLM pipeline with shared config from server2."""
    global _feature_preserve_thinking
    _feature_preserve_thinking = feature_preserve_thinking


def vlm_prompt_and_inputs(
    processor_any,
    config: Dict[str, Any],
    messages: List[Dict[str, Any]],
    images: List[Any],
    tools: Optional[Any] = None,
    enable_thinking: Optional[bool] = None,
    **kwargs: Any,
) -> Tuple[Any, Any, Any, Any]:
    """
    Build formatted prompt and run prepare_inputs for VLM using native chat templates.
    Returns (input_ids, pixel_values, mask, vlm_kwargs) where input_ids is mx.array; mask may be None.
    """
    template_kwargs = dict(kwargs)
    if tools is not None:
        template_kwargs["tools"] = tools
    if enable_thinking is not None:
        template_kwargs["enable_thinking"] = enable_thinking
    template_kwargs["preserve_thinking"] = _feature_preserve_thinking

    template_processor = None
    if processor_any is not None and hasattr(processor_any, "apply_chat_template"):
        if getattr(processor_any, "chat_template", None) is not None:
            template_processor = processor_any
    if (
        template_processor is None
        and getattr(processor_any, "tokenizer", None) is not None
    ):
        tok = processor_any.tokenizer
        if (
            hasattr(tok, "apply_chat_template")
            and getattr(tok, "chat_template", None) is not None
        ):
            template_processor = tok

    formatted = ""
    if template_processor is not None:
        try:
            formatted = template_processor.apply_chat_template(
                messages,
                tokenize=False,
                add_generation_prompt=True,
                **template_kwargs,
            )
            if isinstance(formatted, list):
                formatted = formatted[0] if formatted else ""
            formatted = str(formatted)
        except Exception:
            formatted = ""

    # Fallback to mlx_vlm's get_chat_template if HF template fails/is missing
    if not formatted:
        out = get_chat_template(
            processor_any,
            messages,
            add_generation_prompt=True,
            tokenize=False,
            **template_kwargs,
        )
        if isinstance(out, list):
            out = out[0].get("content", "") if out else ""
        formatted = str(out) if out else ""

    # NOTE: do NOT scrub the formatted string here — this is the model input.
    # Post-render scrubbing for the cache key is applied in do_POST on the
    # cache_prompt_raw string (canonical pipeline), never on the model input.

    inputs = vlm_prepare_inputs(
        processor_any,
        images=images if images else None,
        prompts=formatted,
        add_special_tokens=True,
        return_tensors="mlx",
    )

    input_ids = inputs.get("input_ids")
    pixel_values = inputs.get("pixel_values")
    mask = inputs.get("attention_mask")
    vlm_kwargs = {
        k: v
        for k, v in inputs.items()
        if k not in ["input_ids", "pixel_values", "attention_mask"]
    }

    return input_ids, pixel_values, mask, vlm_kwargs


def vlm_sync_before_generation(pixel_values: Any, mask: Any) -> None:
    """
    Flush Metal work before VLM generation to prevent PyTorch and MLX from colliding.
    """
    try:
        import torch

        if hasattr(torch, "mps") and torch.backends.mps.is_available():
            torch.mps.synchronize()
            torch.mps.empty_cache()  # CRITICAL: Force PyTorch to release all Metal encoders
    except Exception:
        pass

    to_eval = []
    if pixel_values is not None and hasattr(pixel_values, "shape"):
        to_eval.append(pixel_values)
    if mask is not None and hasattr(mask, "shape"):
        to_eval.append(mask)
    if to_eval:
        try:
            import mlx.core as mx

            mx.eval(*to_eval)
        except Exception:
            pass
