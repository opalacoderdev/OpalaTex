"""The ``local_onnx`` route: a Piper-format voice run in this process.

A Piper voice is a VITS model exported to ONNX plus a JSON config that carries
its phoneme table, sample rate and inference defaults. Both are permissively
licensed (``rhasspy/piper-voices`` is MIT) and one voice is ~63 MB, so a host
can download a voice and read text aloud with no network at all -- which is what
makes speech synthesis reachable for an offline-first application rather than a
feature that implies a paid endpoint.

Nothing about this is provider-specific, so it lives beside the HTTP adapter
rather than above it: the block, the caller and the UI are unchanged, and the
route is selected by name. That is what the adapter registry is for.

Two things this module is careful about:

* **It never blocks the caller's event loop.** ONNX inference is synchronous and
  CPU-bound, so the adapter hands the whole load-phonemize-infer sequence to a
  worker thread. A host that runs one event loop for everything (as OpalaTex
  does) would otherwise stall on every request.
* **It caches sessions by path and mtime.** Re-reading 63 MB per utterance would
  dominate the cost of speaking a sentence.
"""

from __future__ import annotations

import asyncio
import io
import json
import os
import threading
import wave
from pathlib import Path
from typing import Any

from agenticblocks.blocks.speech.phonemes import PhonemizerError, phonemize
from agenticblocks.blocks.speech.types import SpeechArtifact, SpeechSynthesisError

# Piper's sentinel symbols. Every phoneme is followed by the pad symbol, which
# is how the model was trained; dropping the interleave produces audio that is
# recognisably wrong rather than merely worse.
_BOS = "^"
_EOS = "$"
_PAD = "_"

# Silence inserted between clauses, in seconds. Without it a multi-sentence
# excerpt runs together.
_CLAUSE_GAP = 0.20

# How many voices to keep loaded. Small on purpose: each session holds its
# model's weights, and a reader uses one voice at a time.
_MAX_CACHED = 2

_cache: "dict[str, tuple[float, Any, dict]]" = {}
_cache_lock = threading.Lock()


def _load_config(model_path: Path) -> dict:
    # Piper ships the config as "<model>.onnx.json"; some mirrors drop the
    # ".onnx". Both are accepted, and a missing config is reported as such
    # rather than surfacing later as a confusing phoneme-table error.
    for candidate in (
        model_path.with_name(model_path.name + ".json"),
        model_path.with_suffix(".json"),
    ):
        if candidate.is_file():
            try:
                return json.loads(candidate.read_text(encoding="utf-8"))
            except (OSError, ValueError) as exc:
                raise SpeechSynthesisError(
                    f"The voice config '{candidate.name}' could not be read: {exc}",
                    kind="bad_request",
                ) from exc
    raise SpeechSynthesisError(
        f"No config found next to '{model_path.name}'. A Piper voice needs its "
        f"'{model_path.name}.json' alongside the model file.",
        kind="not_configured",
    )


def load_voice(model_path: str | os.PathLike) -> tuple[Any, dict]:
    """Return a cached ``(onnx session, config)`` pair for *model_path*."""
    path = Path(model_path)
    if not path.is_file():
        raise SpeechSynthesisError(
            f"The voice file '{path}' does not exist.", kind="not_configured"
        )

    key = str(path.resolve())
    try:
        mtime = path.stat().st_mtime
    except OSError:
        mtime = 0.0

    with _cache_lock:
        cached = _cache.get(key)
        if cached and cached[0] == mtime:
            return cached[1], cached[2]

    try:
        import onnxruntime
    except ImportError as exc:
        raise SpeechSynthesisError(
            "onnxruntime is required to run a local voice but is not installed.",
            kind="not_configured",
        ) from exc

    config = _load_config(path)
    options = onnxruntime.SessionOptions()
    # The host is an interactive application, not a batch job: a synthesis that
    # saturates every core makes the rest of the UI stutter for the half second
    # it runs.
    options.inter_op_num_threads = 1
    options.intra_op_num_threads = max(1, min(4, (os.cpu_count() or 2) // 2))
    try:
        session = onnxruntime.InferenceSession(
            str(path), sess_options=options, providers=["CPUExecutionProvider"]
        )
    except Exception as exc:  # noqa: BLE001 - surfaced as a classified error
        raise SpeechSynthesisError(
            f"The voice '{path.name}' could not be loaded: {exc}", kind="bad_request"
        ) from exc

    with _cache_lock:
        _cache[key] = (mtime, session, config)
        while len(_cache) > _MAX_CACHED:
            _cache.pop(next(iter(_cache)))

    return session, config


def clear_cache() -> None:
    """Drop every loaded voice. Used when a voice file is replaced or removed."""
    with _cache_lock:
        _cache.clear()


def phoneme_ids(phonemes: str, id_map: dict[str, list[int]], terminator: str = "") -> list[int]:
    """Map IPA *phonemes* onto the voice's ids, in Piper's interleaved layout.

    A phoneme the voice does not know is skipped rather than substituted: the
    id table is the model's vocabulary, and inventing an entry produces a sound
    the voice was never trained to make.
    """
    ids: list[int] = list(id_map.get(_BOS, []))
    ids += id_map.get(_PAD, [])
    for symbol in phonemes:
        mapped = id_map.get(symbol)
        if not mapped:
            continue
        ids += mapped
        ids += id_map.get(_PAD, [])
    if terminator:
        mapped = id_map.get(terminator)
        if mapped:
            ids += mapped
            ids += id_map.get(_PAD, [])
    ids += id_map.get(_EOS, [])
    return ids


def _encode_wav(samples, sample_rate: int) -> bytes:
    import numpy as np

    if samples.size == 0:
        raise SpeechSynthesisError(
            "The voice produced no audio for this text.", kind="empty"
        )
    peak = float(np.max(np.abs(samples)))
    # Piper's own normalisation. The floor keeps a near-silent clause from being
    # amplified into noise.
    scaled = samples * (32767.0 / max(0.01, peak))
    pcm = np.clip(scaled, -32768, 32767).astype("<i2")

    buffer = io.BytesIO()
    with wave.open(buffer, "wb") as handle:
        handle.setnchannels(1)
        handle.setsampwidth(2)
        handle.setframerate(sample_rate)
        handle.writeframes(pcm.tobytes())
    return buffer.getvalue()


def synthesize_wav(
    model_path: str | os.PathLike,
    text: str,
    speaker_id: int | None = None,
    length_scale: float | None = None,
    noise_scale: float | None = None,
    noise_w: float | None = None,
) -> tuple[bytes, int]:
    """Synthesize *text* with the voice at *model_path*; return ``(wav, rate)``.

    Synchronous and CPU-bound: call it from a worker thread.
    """
    import numpy as np

    session, config = load_voice(model_path)
    id_map = config.get("phoneme_id_map") or {}
    if not id_map:
        raise SpeechSynthesisError(
            "This voice config carries no phoneme table.", kind="bad_request"
        )

    espeak_voice = str((config.get("espeak") or {}).get("voice") or "").strip()
    inference = config.get("inference") or {}
    sample_rate = int((config.get("audio") or {}).get("sample_rate") or 22050)

    try:
        clauses = phonemize(text, espeak_voice)
    except PhonemizerError as exc:
        # The distinction matters: "espeak-ng is not installed" is something the
        # user fixes in a minute, and must not read as "synthesis failed".
        raise SpeechSynthesisError(
            str(exc),
            kind="not_configured" if exc.kind == "not_installed" else "bad_request",
        ) from exc

    if not clauses:
        raise SpeechSynthesisError(
            "This text produced no pronounceable phonemes.", kind="bad_request"
        )

    scales = np.array([
        float(noise_scale if noise_scale is not None else inference.get("noise_scale", 0.667)),
        float(length_scale if length_scale is not None else inference.get("length_scale", 1.0)),
        float(noise_w if noise_w is not None else inference.get("noise_w", 0.8)),
    ], dtype=np.float32)

    input_names = {i.name for i in session.get_inputs()}
    gap = np.zeros(int(sample_rate * _CLAUSE_GAP), dtype=np.float32)

    parts: list[Any] = []
    for index, clause in enumerate(clauses):
        ids = phoneme_ids(clause.phonemes, id_map, clause.terminator)
        if len(ids) <= 2:
            continue
        feeds = {
            "input": np.array([ids], dtype=np.int64),
            "input_lengths": np.array([len(ids)], dtype=np.int64),
            "scales": scales,
        }
        # Multi-speaker voices carry a speaker id; single-speaker ones have no
        # such input and reject it.
        if "sid" in input_names:
            feeds["sid"] = np.array([int(speaker_id or 0)], dtype=np.int64)

        try:
            audio = session.run(None, feeds)[0]
        except Exception as exc:  # noqa: BLE001 - surfaced as a classified error
            raise SpeechSynthesisError(
                f"The voice failed to synthesize this text: {exc}", kind="unknown"
            ) from exc

        if index:
            parts.append(gap)
        parts.append(np.asarray(audio, dtype=np.float32).reshape(-1))

    if not parts:
        raise SpeechSynthesisError(
            "This text produced no pronounceable phonemes.", kind="bad_request"
        )

    return _encode_wav(np.concatenate(parts), sample_rate), sample_rate


async def local_onnx_adapter(
    model: str,
    request: Any,
    model_kwargs: dict[str, Any],
) -> SpeechArtifact:
    """Adapter for a locally installed Piper-format voice.

    ``model_kwargs["model_path"]`` points at the ``.onnx`` file; ``model`` is
    only a label here, since nothing is dispatched over a network.
    """
    model_path = str((model_kwargs or {}).get("model_path") or "").strip()
    if not model_path:
        raise SpeechSynthesisError(
            "No local voice is selected. Download one and pick it in the "
            "pronunciation settings.",
            kind="not_configured",
        )

    # Piper's length_scale is duration, so it runs opposite to "speed": a
    # request for 2x faster is a length scale of 0.5.
    speed = getattr(request, "speed", None)
    length_scale = None
    if speed:
        try:
            value = float(speed)
            if value > 0:
                length_scale = 1.0 / value
        except (TypeError, ValueError):
            length_scale = None

    speaker_id = (model_kwargs or {}).get("speaker_id")

    # The event loop must stay free: this is the one adapter that does its work
    # in-process rather than waiting on a socket.
    wav, _rate = await asyncio.to_thread(
        synthesize_wav,
        model_path,
        getattr(request, "text", ""),
        speaker_id,
        length_scale,
    )

    import base64

    return SpeechArtifact(
        data_b64=base64.b64encode(wav).decode("ascii"),
        mime="audio/wav",
        voice=Path(model_path).stem,
        model=model or Path(model_path).stem,
    )
