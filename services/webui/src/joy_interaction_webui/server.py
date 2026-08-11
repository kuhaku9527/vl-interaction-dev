# SPDX-FileCopyrightText: Copyright (c) 2025 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
# SPDX-License-Identifier: Apache-2.0
"""
WebRTC Joy VL Interaction Server
Main server that handles WebRTC connections and serves the web interface
"""

import asyncio
import base64
import copy
import io
import json
import logging
import os as _os_for_accesslog  # access log path
import time as _time_for_accesslog

_access_logger = logging.getLogger("joyai.access")
if not _access_logger.handlers:
    # Default: write one JSONL per line to logs/webui-access-<UTC>.log (rotated daily
    # by launcher path). No-op if logs/ cannot be created. Format: one JSON
    # object per request with ts, method, path, status, latency_ms.
    _log_dir = _os_for_accesslog.path.join(
        _os_for_accesslog.path.dirname(_os_for_accesslog.path.abspath(__file__)),
        "..",
        "..",
        "..",
        "logs",
    )
    try:
        _os_for_accesslog.makedirs(_log_dir, exist_ok=True)
        _ts = _os_for_accesslog.path.join(
            _log_dir,
            (
                "webui-access-"
                + _time_for_accesslog.strftime("%Y-%m-%d", _time_for_accesslog.gmtime())
                + ".log"
            ),
        )
        _fh = logging.FileHandler(_ts, encoding="utf-8")
        _fh.setFormatter(logging.Formatter("%(message)s"))
        _access_logger.addHandler(_fh)
        _access_logger.setLevel(logging.INFO)
    except OSError:
        pass  # access log is best-effort; do not break the webui if logs/ is unwritable
import datetime  # noqa: E402
import os  # noqa: E402
import subprocess  # noqa: E402
import sys  # noqa: E402
import time  # noqa: E402
import uuid  # noqa: E402

# Fix double-module-load bug: when run via `python -m joy_interaction_webui.server`,
# Python executes this file as __main__ and *also* registers a separate module
# instance under the dotted name when jarvis_session.py does
# `from .server import notify_session_llm_reply`. Those two instances have
# *independent globals* (separate session_websockets, websockets, ...), so
# websocket_handler writes to one dict while notify_session_llm_reply reads
# from the other, silently dropping every LLM reply.
# Aliasing __main__ under the dotted name makes downstream `from .server import ...`
# resolve to the SAME module instance. See doc/subsystems/jarvis-mode.md changelog v3.22.
if __name__ == "__main__":
    sys.modules.setdefault("joy_interaction_webui.server", sys.modules["__main__"])
from collections import defaultdict  # noqa: E402

import aiohttp  # noqa: E402
from aiohttp import web  # noqa: E402
from aiortc import RTCConfiguration, RTCPeerConnection, RTCSessionDescription  # noqa: E402
from aiortc.contrib.media import MediaRelay  # noqa: E402

from . import asr as asr_module  # noqa: E402
from .asr import setup_asr_routes  # noqa: E402
from .audio_processor import MicAudioTrack  # noqa: E402
from .background_model import BackgroundModelService  # noqa: E402
from .jarvis_mode import JarvisState, asr_model_display_name  # noqa: E402
from .jarvis_routes import bind_audio, setup_jarvis_routes  # noqa: E402
from .jarvis_session import JarvisSessionManager  # noqa: E402
from .local_file_server import setup_local_file_routes  # noqa: E402
from .tts import setup_tts_routes  # noqa: E402
from .vlm_service import VLMService  # noqa: E402

# Background task registry: keep strong refs to fire-and-forget tasks so they
# are not garbage-collected before completion (satisfies ruff RUF006).
_BACKGROUND_TASKS: set[asyncio.Task] = set()


def _spawn_bg(coro):
    task = asyncio.create_task(coro)
    _BACKGROUND_TASKS.add(task)
    task.add_done_callback(_BACKGROUND_TASKS.discard)
    return task


logging.basicConfig(
    level=logging.INFO, format="%(asctime)s - %(name)s - %(levelname)s - %(message)s"
)
logger = logging.getLogger(__name__)

relay = MediaRelay()
pcs = set()
vlm_service = None
websockets = set()
rtsp_tracks = {}

default_vlm_config = {}
sessions = {}
session_websockets = defaultdict(set)
ws_to_session = {}
session_peer_connections = defaultdict(set)

# send_to_session must actually run the WS send coroutine. The previous
# implementation used asyncio.create_task(ws.send_str(message)) directly,
# which silently drops the message on real aiohttp WebSocketResponse
# (send_str awaits internally and the surrounding coroutine returns
# before the scheduler runs the task). See
# tests/test_send_to_session_actually_awaits.py for the regression test.


async def _safe_send_str(ws, message, session_id):
    try:
        await ws.send_str(message)
    except Exception as exc:
        logger.warning("send_to_session: WS send failed for %s: %s", session_id, exc)


def send_to_session(session_id, message):
    targets = list(session_websockets.get(session_id, set()))
    if not targets:
        # Common during early LLM startup before browser WS reconnects, log at INFO.
        logger.info(
            "send_to_session: no WS targets for session %s (total sessions in dict: %d). Message DROPPED: %s",
            session_id,
            len(session_websockets),
            message[:200],
        )
        return
    for ws in targets:
        try:
            _spawn_bg(_safe_send_str(ws, message, session_id))
        except RuntimeError as exc:
            logger.error("send_to_session: schedule failed for %s: %s", session_id, exc)


def notify_session_json(session_id, payload):
    handle_background_handoff_for_interaction(session_id, payload)
    send_to_session(session_id, json.dumps(payload, ensure_ascii=False))


def notify_session_llm_reply(session_id, text, source="jarvis"):
    payload = {
        "type": "llm_reply",
        "text": text or "",
        "source": source or "jarvis",
        "ts": time.time(),
    }
    send_to_session(session_id, json.dumps(payload, ensure_ascii=False))


def notify_session_pilot_utterance(session_id, text, source="asr"):
    payload = {
        "type": "pilot_utterance",
        "text": text or "",
        "source": source or "asr",
        "ts": time.time(),
    }
    send_to_session(session_id, json.dumps(payload, ensure_ascii=False))


def notify_session_asr_partial(session_id, text, is_final=False):
    payload = {
        "type": "asr_partial",
        "text": text or "",
        "is_final": bool(is_final),
        "ts": time.time(),
    }
    send_to_session(session_id, json.dumps(payload, ensure_ascii=False))


def handle_background_handoff_for_interaction(session_id, payload):
    if not isinstance(payload, dict) or payload.get("type") != "background_result_ready":
        return
    session = sessions.get(session_id)
    if not session or not session.get("vlm_service"):
        return


def get_session_callback(session_id):
    def callback(text, metrics, frame_seq=None):
        session = sessions.get(session_id)
        display_text = text
        if session and session.get("background_service"):
            display_text = session["background_service"].handle_foreground_response(
                text, metrics=metrics
            )
        sh = metrics.get("summarizer_history") if isinstance(metrics, dict) else None
        summarizer_timing = sh.get("summarizer_timing") if isinstance(sh, dict) else None
        out = {"type": "vlm_response", "text": display_text, "metrics": metrics}
        if summarizer_timing:
            out["summarizer_timing"] = summarizer_timing
        if frame_seq is not None:
            out["frame_seq"] = frame_seq
        send_to_session(session_id, json.dumps(out, ensure_ascii=False))

    return callback


async def _safe_send_str_all(ws, message):
    try:
        await ws.send_str(message)
    except Exception as exc:
        logger.warning("broadcast_text_update: WS send failed: %s", exc)


def broadcast_text_update(text, metrics):
    if not websockets:
        return
    message = json.dumps({"type": "vlm_response", "text": text, "metrics": metrics})
    for ws in list(websockets):
        try:
            _spawn_bg(_safe_send_str_all(ws, message))
        except RuntimeError as exc:
            logger.error("broadcast_text_update: schedule failed: %s", exc)


async def websocket_handler(request):
    ws = web.WebSocketResponse()
    await ws.prepare(request)
    session_id = request.query.get("session_id", "").strip() or str(uuid.uuid4())
    ws_to_session[ws] = session_id
    session_websockets[session_id].add(ws)
    websockets.add(ws)
    logger.info(
        "WebSocket client connected. session_id=%s, total clients: %d", session_id, len(websockets)
    )
    session = get_or_create_session(session_id)
    svc = session["vlm_service"]
    # Jarvis session manager (holds the shared JarvisConfig; used for the
    # ASR-promotion runtime toggle and to advertise the ASR model name).
    manager = request.app.get("jarvis_manager")
    bg_svc = session.get("background_service")
    background_service = bg_svc
    try:
        await ws.send_json(
            {
                "type": "status",
                "text": "Connected to server",
                "status": "Ready",
                "session_id": session_id,
            }
        )
        from .video_processor import VideoProcessorTrack as _VPT

        await ws.send_json(
            {
                "type": "server_config",
                "model": svc.model,
                "api_base": svc.api_base,
                "prompt": svc.prompt,
                "process_interval": _VPT.process_interval_seconds,
                "frames_per_batch": _VPT.frames_per_batch,
                "background_model": (
                    background_service.get_config() if background_service else None
                ),
                "asr_promotion_enabled": (
                    bool(manager.config.asr_promotion_enabled) if manager else False
                ),
                "asr_model_name": (
                    asr_model_display_name(manager.config)
                    if manager
                    else "sherpa-onnx local paraformer (unknown)"
                ),
                "session_id": session_id,
            }
        )
        async for msg in ws:
            if msg.type == web.WSMsgType.TEXT:
                try:
                    data = json.loads(msg.data)
                except json.JSONDecodeError:
                    continue
                try:
                    t = data.get("type")
                    if t == "update_prompt":
                        svc.update_prompt(data.get("prompt", ""))
                        await ws.send_json(
                            {"type": "prompt_updated", "prompt": data.get("prompt", "")}
                        )
                    elif t == "update_model":
                        if svc.set_model(data.get("model", "")):
                            await ws.send_json(
                                {"type": "model_updated", "model": data.get("model", "")}
                            )
                    elif t == "update_process_interval":
                        from .video_processor import VideoProcessorTrack

                        VideoProcessorTrack.process_interval_seconds = float(
                            data.get("process_interval", 1.0)
                        )
                        await ws.send_json(
                            {
                                "type": "processing_updated",
                                "process_interval": VideoProcessorTrack.process_interval_seconds,
                            }
                        )
                    elif t == "update_frames_per_batch":
                        from .video_processor import VideoProcessorTrack

                        await ws.send_json(
                            {
                                "type": "frames_per_batch_updated",
                                "frames_per_batch": VideoProcessorTrack.frames_per_batch,
                            }
                        )
                    elif t == "frame":
                        # Screen capture frames shipped via WebSocket (parallel to WebRTC).
                        # Decode base64 JPEG -> PIL Image -> vlm_service.process_frame, then broadcast the
                        # resulting text exactly like VideoProcessorTrack does for webcam/RTSP streams.
                        payload = data.get("data") or ""
                        if not isinstance(payload, str) or not payload:
                            logger.warning("frame: empty data")
                        else:
                            try:
                                from PIL import Image as _PILImage

                                t_arrive = time.perf_counter()
                                raw = base64.b64decode(payload)
                                img = _PILImage.open(io.BytesIO(raw)).convert("RGB")
                                t_decoded = time.perf_counter()
                                meta = {
                                    "source": data.get("source") or "screen",
                                    "format": data.get("format") or "jpeg",
                                    "width": data.get("width"),
                                    "height": data.get("height"),
                                    "timestamp": data.get("timestamp"),
                                }
                                await svc.process_frame(img, frame_metadata=meta)
                                response, _ = svc.get_current_response()
                                t_processed = time.perf_counter()
                                metrics = svc.get_metrics()
                                if response:
                                    get_session_callback(session_id)(
                                        response, metrics, data.get("frame_seq")
                                    )
                                logger.info(
                                    "latency[transport+infer-screen]: arrive->processed_ms=%.1f decode_ms=%.1f seq=%s",
                                    (t_processed - t_arrive) * 1000,
                                    (t_decoded - t_arrive) * 1000,
                                    data.get("frame_seq"),
                                )
                            except Exception as frame_exc:
                                logger.warning("frame decode/process failed: %s", frame_exc)
                    elif t == "background_request":
                        if background_service and data.get("question"):
                            try:
                                task_id = background_service.handle_background_request(
                                    data["question"], session_id=session_id
                                )
                                await ws.send_json(
                                    {
                                        "type": "background_request_accepted",
                                        "task_id": task_id,
                                        "session_id": session_id,
                                    }
                                )
                            except Exception as exc:
                                await ws.send_json(
                                    {
                                        "type": "background_result_error",
                                        "task_id": "",
                                        "error": str(exc),
                                    }
                                )
                    elif t == "update_asr_promotion":
                        # Runtime toggle for the local paraformer ASR
                        # promotion (recall booster). The frontend sends
                        # {type:"update_asr_promotion", enabled: bool}. The
                        # change propagates to every live Jarvis session via
                        # the shared JarvisConfig (same asyncio event loop).
                        raw = data.get("enabled")
                        if isinstance(raw, str):
                            enabled = raw.strip().lower() in {"1", "true", "yes", "on"}
                        else:
                            enabled = bool(raw)
                        if manager is None:
                            logger.warning("update_asr_promotion: jarvis_manager unavailable")
                            await ws.send_json(
                                {
                                    "type": "asr_promotion_updated",
                                    "enabled": False,
                                    "asr_model_name": "sherpa-onnx local paraformer (unknown)",
                                    "error": "jarvis_manager unavailable",
                                }
                            )
                        else:
                            manager.set_asr_promotion_enabled(enabled)
                            await ws.send_json(
                                {
                                    "type": "asr_promotion_updated",
                                    "enabled": bool(enabled),
                                    "asr_model_name": asr_model_display_name(manager.config),
                                }
                            )
                except Exception as e:
                    logger.error("Error handling client message: %s", e)
            elif msg.type == web.WSMsgType.ERROR:
                logger.error("WebSocket error: %s", ws.exception())
    finally:
        s = session_websockets.get(session_id)
        if s is not None:
            s.discard(ws)
            if not s:
                session_websockets.pop(session_id, None)
        ws_to_session.pop(ws, None)
        websockets.discard(ws)
        logger.info(
            "WebSocket client disconnected. session_id=%s, total clients: %d",
            session_id,
            len(websockets),
        )
    return ws


def _probe_llm(llm_api_url):
    import httpx

    try:
        with httpx.Client(timeout=2.0) as client:
            resp = client.get(llm_api_url.rstrip("/") + "/models")
        if resp.status_code == 200:
            try:
                data = resp.json()
                models = data.get("data") or []
                return {
                    "status": "ok",
                    "models": [m.get("id", "") for m in models if isinstance(m, dict)],
                }
            except Exception as exc:
                return {"status": "degraded", "reason": "parse: %s" % exc}
        return {"status": "error", "reason": "http %d" % resp.status_code}
    except Exception as exc:
        return {"status": "error", "reason": str(exc)[:120]}


def _probe_tts(tts_api_url):
    # Probe the voice_clone_api ``/health`` endpoint first; if absent,
    # fall back to a GET on ``/v1/synthesize`` (POST-only, so 405 also
    # counts as "endpoint present"). Two short-lived clients per probe
    # to avoid any keep-alive edge cases.
    from urllib.parse import urlsplit, urlunsplit

    import httpx

    parsed = urlsplit(tts_api_url.rstrip("/"))
    service_root = urlunsplit((parsed.scheme, parsed.netloc, "", "", ""))
    health_url = service_root + "/health" if service_root else None
    synth_url = tts_api_url.rstrip("/")
    for url in (h for h in (health_url, synth_url) if h):
        try:
            with httpx.Client(timeout=3.0) as client:
                resp = client.get(url)
        except Exception as exc:
            logger.warning("TTS health check failed for %s: %s", url, exc)
            continue
        if resp.status_code == 200:
            return {"status": "ok", "endpoint": url, "code": 200}
        if "synthesize" in url and resp.status_code in (405, 422):
            return {"status": "ok", "endpoint": url, "code": resp.status_code, "note": "POST-only"}
    return {"status": "error", "reason": "unreachable"}


def _probe_kws(kws_model_dir):
    from pathlib import Path

    p = Path(kws_model_dir)
    if not p.exists():
        return {"status": "missing", "reason": "dir not found: %s" % kws_model_dir}
    matches = list(p.glob("encoder*chunk-*.onnx"))
    if not matches and all(
        (p / name).exists() for name in ("encoder.onnx", "decoder.onnx", "joiner.onnx")
    ):
        matches = [p / "encoder.onnx"]
    if not matches:
        return {"status": "missing", "reason": "no encoder*.onnx in %s" % kws_model_dir}
    return {"status": "ok", "model": matches[0].name}


_LLM_PROBE_CACHE = {"payload": None, "ts": 0.0}
_LLM_PROBE_TTL_S = 5.0


def _now():
    return time.time()


def _resolve_service_targets(app):
    from .jarvis_mode import JarvisConfig

    cfg = JarvisConfig.from_env()
    return cfg.llm_api_url, cfg.tts_api_url


async def llm_status(request):
    llm_url, tts_url = _resolve_service_targets(request.app)
    kws_dir = os.environ.get("JARVIS_KWS_MODEL_DIR", "D:/AI/models/sherpa-onnx/models/kws/bt-en")
    now = _now()
    cached = _LLM_PROBE_CACHE
    if cached["payload"] is not None and (now - cached["ts"]) < _LLM_PROBE_TTL_S:
        llm_payload = dict(cached["payload"])
    else:
        llm_payload = _probe_llm(llm_url)
        cached["payload"] = llm_payload
        cached["ts"] = now
    loop = asyncio.get_running_loop()
    tts_future = loop.run_in_executor(None, _probe_tts, tts_url)
    kws_future = loop.run_in_executor(None, _probe_kws, kws_dir) if kws_dir else None
    tts_payload, kws_payload = await asyncio.gather(
        tts_future,
        kws_future
        if kws_future is not None
        else asyncio.sleep(
            0, result={"status": "missing", "reason": "kws_model_dir not configured"}
        ),
    )
    overall = "ok"
    for p in (llm_payload, tts_payload, kws_payload):
        if p.get("status") in ("error", "missing"):
            overall = "error"
            break
        if p.get("status") == "degraded" and overall == "ok":
            overall = "degraded"
    return web.json_response(
        {
            "ts": now,
            "overall": overall,
            "llm": {"url": llm_url, **llm_payload},
            "tts": {"url": tts_url, **tts_payload},
            "kws": {"model_dir": kws_dir, **kws_payload},
        }
    )


async def tts_health(request):
    _llm_url, tts_url = _resolve_service_targets(request.app)
    payload = await asyncio.get_running_loop().run_in_executor(None, _probe_tts, tts_url)
    return web.json_response({"ts": _now(), "url": tts_url, **payload})


def _wav_chunk_header(sample_rate: int, channels: int, bits_per_sample: int = 16) -> bytes:
    """Return a 44-byte canonical PCM WAV header for the given format."""
    riff = b"RIFF"
    wave = b"WAVE"
    fmt_ = b"fmt "
    data = b"data"
    audio_format = 1  # PCM
    byte_rate = sample_rate * channels * bits_per_sample // 8
    block_align = channels * bits_per_sample // 8
    fmt_chunk_size = 16
    return (
        riff
        + b"\x00\x00\x00\x00"  # placeholder; caller fills RIFF size after data
        + wave
        + fmt_
        + fmt_chunk_size.to_bytes(4, "little")
        + audio_format.to_bytes(2, "little")
        + channels.to_bytes(2, "little")
        + sample_rate.to_bytes(4, "little")
        + byte_rate.to_bytes(4, "little")
        + block_align.to_bytes(2, "little")
        + bits_per_sample.to_bytes(2, "little")
        + data
        + b"\x00\x00\x00\x00"  # placeholder; caller fills data size after data
    )


def build_tts_synthesize_payload(upstream_json: dict) -> bytes:
    """Wrap a voice_clone_api /v1/synthesize response in a playable WAV blob.

    The upstream returns ``{"pcm16_base64": "...", "sample_rate": 24000, ...}``;
    browsers need a RIFF/WAVE container to play it via HTML5 ``<audio>``.
    Defaults: sample_rate=24000, channels=1 (MiniMax ``speech-2.8-hd`` shape).
    """
    import base64 as _b64

    pcm_b64 = upstream_json.get("pcm16_base64")
    if not pcm_b64:
        raise ValueError(
            "upstream /v1/synthesize response missing pcm16_base64; "
            f"keys={list(upstream_json.keys())}"
        )
    pcm = _b64.b64decode(pcm_b64)
    sample_rate = int(upstream_json.get("sample_rate") or 24000)
    channels = int(upstream_json.get("channels") or 1)
    header = _wav_chunk_header(sample_rate, channels)
    out = bytearray(header)
    out[4:8] = (len(out) + len(pcm) - 8).to_bytes(4, "little")
    out[40:44] = len(pcm).to_bytes(4, "little")
    out.extend(pcm)
    return bytes(out)


async def _tts_synthesize_handler(request):
    """POST /api/tts/synthesize -- wrap voice_clone_api into playable WAV.

    Body: ``{"text": "..."}`` (voice_id is read from ``JARVIS_TTS_VOICE_ID``).
    Returns ``audio/wav`` bytes on 200; 400 on empty text; 502 on upstream error.
    """
    import httpx as _httpx

    try:
        data = await request.json()
    except Exception:
        return web.json_response({"error": "invalid json"}, status=400)
    text = (data.get("text") or "").strip()
    if not text:
        return web.json_response({"error": "text is required"}, status=400)
    # Reuse the same JARVIS_TTS_* env that jarvis_mode.py uses, so behavior
    # stays in sync with the audio path used by the WebRTC speaker track.
    tts_api_url = os.environ.get("JARVIS_TTS_API_URL", "http://127.0.0.1:8985/v1/synthesize")
    voice_id = os.environ.get("JARVIS_TTS_VOICE_ID", "minimax_man_33333")
    body = {
        "text": text,
        "voice_id": voice_id,
        "model": os.environ.get("MINIMAX_DEFAULT_MODEL", "speech-2.8-hd"),
        "language_boost": os.environ.get("MINIMAX_LANGUAGE_BOOST", "Chinese"),
        "streaming": False,
    }
    try:
        async with _httpx.AsyncClient(timeout=30.0) as client:
            resp = await client.post(tts_api_url, json=body)
    except Exception as exc:
        logger.warning("tts_synthesize: upstream unreachable: %s", exc)
        return web.json_response(
            {"error": "upstream unreachable", "reason": str(exc)[:120]}, status=502
        )
    if resp.status_code >= 500:
        return web.json_response(
            {"error": "upstream error", "status": resp.status_code}, status=502
        )
    try:
        upstream_json = resp.json()
    except Exception as exc:
        return web.json_response(
            {"error": "upstream non-json", "reason": str(exc)[:120]}, status=502
        )
    try:
        wav = build_tts_synthesize_payload(upstream_json)
    except ValueError as exc:
        return web.json_response(
            {"error": "upstream payload invalid", "reason": str(exc)[:120]}, status=502
        )
    return web.Response(body=wav, content_type="audio/wav")


async def llm_message(request):
    try:
        data = await request.json()
    except Exception:
        return web.json_response({"error": "invalid json"}, status=400)
    session_id = (data.get("session_id") or "").strip()
    text = (data.get("text") or "").strip()
    if not session_id or not text:
        return web.json_response({"error": "missing session_id or text"}, status=400)
    app = request.app
    manager = app.get("jarvis_manager")
    if manager is None:
        return web.json_response({"error": "jarvis_manager not initialised"}, status=503)
    jarvis_session = await manager.create_session(session_id)
    sm = jarvis_session.state_machine
    if sm.state != JarvisState.DIALOG_ACTIVE:
        sm.state = JarvisState.DIALOG_ACTIVE
    try:
        sm._init_asr()
    except Exception as exc:
        logger.debug("LLM-message: ASR init skipped (%s)", exc)
    # v3.35: optional multimodal frame from the browser paper-plane. When
    # present, jarvis_mode._send_to_llm shapes the user message as a
    # content array (text + image_url) so 7060 llama.cpp (with --mmproj)
    # can describe what is currently on the captured screen.
    image_b64 = data.get("image_b64")
    if isinstance(image_b64, str):
        image_b64 = image_b64.strip() or None
    else:
        image_b64 = None
    # Cap payload at ~3 MB base64 to keep a single request bounded.
    if image_b64 and len(image_b64) > 3 * 1024 * 1024:
        logger.warning("LLM-message: image_b64 too large (%d bytes), dropped", len(image_b64))
        image_b64 = None
    task = asyncio.create_task(
        sm._send_to_llm(text, stream_tts=False, image_b64=image_b64, interaction_mode="call")
    )
    app.setdefault("_llm_tasks", set()).add(task)
    task.add_done_callback(app["_llm_tasks"].discard)
    return web.json_response(
        {
            "session_id": session_id,
            "queued": True,
            "text_chars": len(text),
            "image_attached": bool(image_b64),
        }
    )


def get_or_create_session(session_id):
    api_base = default_vlm_config.get("api_base", "http://127.0.0.1:8070/v1")
    model_name = default_vlm_config.get("model", "streaming-infer-adapter")
    prompt = default_vlm_config.get("prompt")
    vlm = VLMService(api_base=api_base, model=model_name, prompt=prompt)
    sessions[session_id] = {
        "vlm_service": vlm,
        "background_service": BackgroundModelService(
            session_id=session_id,
            notify_callback=lambda payload, sid=session_id: notify_session_json(sid, payload),
            summarizer_api_base=api_base,
        ),
        "show_request_payload": False,
    }
    logger.info("Created new session: %s", session_id)
    return sessions[session_id]


async def session_cleanup(request):
    session_id = request.query.get("session_id", "").strip()
    if not session_id:
        return web.json_response({"error": "missing session_id"}, status=400)
    logger.info("[%s] Cleaning up session", session_id)
    session_sockets = list(session_websockets.pop(session_id, set()))
    for ws in session_sockets:
        try:
            await ws.close()
        except Exception as e:
            logger.warning("[%s] Error closing websocket: %s", session_id, e)
        finally:
            websockets.discard(ws)
            ws_to_session.pop(ws, None)
    if session_id in rtsp_tracks:
        rtsp_track, _processor_track, frame_task = rtsp_tracks.pop(session_id)
        try:
            rtsp_track.stop()
        except Exception as e:
            logger.warning("[%s] Error stopping RTSP track: %s", session_id, e)
        try:
            await frame_task
        except Exception as e:
            logger.warning("[%s] Frame task error: %s", session_id, e)
    pcs_for_session = list(session_peer_connections.pop(session_id, set()))
    for pc in pcs_for_session:
        try:
            await pc.close()
        except Exception as e:
            logger.warning("[%s] Error closing peer connection: %s", session_id, e)
        finally:
            pcs.discard(pc)
    cancelled_vlm_tasks = 0
    cancelled_background_tasks = 0
    session = sessions.pop(session_id, None)
    if session:
        vlm = session.get("vlm_service")
        if vlm:
            try:
                tasks = getattr(vlm, "tasks", set())
                cancelled_vlm_tasks = len(tasks)
                for task in tasks:
                    task.cancel()
            except Exception as e:
                logger.warning("[%s] Error cancelling VLM tasks: %s", session_id, e)
        bg_svc = session.get("background_service")
        if bg_svc:
            try:
                await bg_svc.close(cancel_requests=False)
            except Exception as e:
                logger.warning("[%s] Error closing background service: %s", session_id, e)
    logger.info("[%s] Session cleanup complete", session_id)
    return web.json_response(
        {
            "session_id": session_id,
            "removed": bool(session),
            "websockets_closed": len(session_sockets),
            "peer_connections_closed": len(pcs_for_session),
            "cancelled_vlm_tasks": cancelled_vlm_tasks,
            "cancelled_background_tasks": cancelled_background_tasks,
        }
    )


async def _drain_mic_audio_track(mic_track, session_id):
    """Continuously consume browser mic frames and feed Jarvis.

    aiortc remote tracks only produce frames when something awaits recv().
    MicAudioTrack.recv() does the resample + Jarvis feed, so this task is the
    bridge that makes the always-on KWS listener real.
    """
    try:
        while True:
            await mic_track.recv()
    except asyncio.CancelledError:
        raise
    except Exception as exc:
        logger.info("Jarvis mic audio consumer ended for %s: %s", session_id, exc)
    finally:
        try:
            mic_track.stop()
        except Exception as exc:
            logger.warning("mic track stop failed for %s: %s", session_id, exc)


def _start_mic_audio_consumer(mic_track, session_id):
    return asyncio.create_task(_drain_mic_audio_track(mic_track, session_id))


async def bind_jarvis_audio_for_peer(pc, session_id, manager):
    """Wire a WebRTC peer connection into the Jarvis listening chain."""
    session = await manager.create_session(session_id)
    speaker_track = bind_audio(session_id, manager)
    pc.addTrack(speaker_track)
    mic_tasks = set()

    @pc.on("track")
    def on_track(track):
        if getattr(track, "kind", None) != "audio":
            return
        mic_track = MicAudioTrack(track, session)
        task = _start_mic_audio_consumer(mic_track, session_id)
        mic_tasks.add(task)
        task.add_done_callback(mic_tasks.discard)
        logger.info("Jarvis mic track bound for session %s", session_id)

    return {"session": session, "speaker_track": speaker_track, "mic_tasks": mic_tasks}


def _offer_has_jarvis_audio(params):
    if params.get("jarvis_audio") is True:
        return True
    sdp = params.get("sdp") or ""
    return "m=audio" in sdp


async def offer(request):
    params = await request.json()
    offer_sdp = RTCSessionDescription(sdp=params["sdp"], type=params["type"])
    session_id = params.get("session_id", "default")
    pc = RTCPeerConnection(configuration=RTCConfiguration(iceServers=[]))
    pcs.add(pc)
    session_peer_connections[session_id].add(pc)
    if _offer_has_jarvis_audio(params):
        manager = request.app.get("jarvis_manager")
        if manager is None:
            return web.json_response({"error": "jarvis_manager not initialised"}, status=503)
        await bind_jarvis_audio_for_peer(pc, session_id, manager)
    await pc.setRemoteDescription(offer_sdp)
    answer = await pc.createAnswer()
    await pc.setLocalDescription(answer)
    return web.Response(
        content_type="application/json",
        text=json.dumps(
            {
                "sdp": pc.localDescription.sdp,
                "type": pc.localDescription.type,
                "session_id": session_id,
            }
        ),
    )


async def on_startup(app):
    import asyncio
    import os
    import sys

    here = os.path.dirname(__file__)
    repo_root = os.path.abspath(os.path.join(here, "..", "..", "..", ".."))
    if repo_root not in sys.path:
        sys.path.insert(0, repo_root)
    from .jarvis_mode import JarvisConfig

    cfg = JarvisConfig.from_env()
    if os.environ.get("JARVIS_ASR_MODEL_DIR"):
        cfg.asr_model_dir = os.environ["JARVIS_ASR_MODEL_DIR"]
    app["jarvis_manager"] = JarvisSessionManager(config=cfg)

    async def warm_browser_asr():
        try:
            from .asr import _get_inproc_asr

            if asr_module.get_asr_url():
                return
            await asyncio.to_thread(_get_inproc_asr)
            logger.info("Browser ASR in-process fallback warmed")
        except Exception as exc:
            logger.warning("Browser ASR warm-up skipped: %s", exc)

    app["browser_asr_warmup_task"] = asyncio.create_task(warm_browser_asr())
    logger.info(
        "Jarvis session manager initialised (KWS=%s, ASR=%s)", cfg.kws_model_dir, cfg.asr_model_dir
    )


async def on_shutdown(app):
    for ws in list(websockets):
        try:
            await ws.close()
        except Exception as exc:
            logger.warning("error closing websocket during shutdown: %s", exc)
    for _session_id, session in list(sessions.items()):
        bg_svc = session.get("background_service")
        if bg_svc:
            try:
                await bg_svc.close(cancel_requests=False)
            except Exception as exc:
                logger.warning("error closing background service during shutdown: %s", exc)
    for pc in list(pcs):
        try:
            await pc.close()
        except Exception as exc:
            logger.warning("error closing peer connection during shutdown: %s", exc)


# Default in-memory services config. This is the base layer; any persisted
# file (``config/services.json``) is deep-merged ON TOP of these at startup
# (see ``_merge_services_config_file``) so the file only needs to override what
# differs from the defaults. Kept as a separate constant so a "restart" can be
# simulated by resetting to it and re-applying the file.
_SERVICES_CONFIG_DEFAULTS: dict = {
    "llm": {
        "api_base": "http://127.0.0.1:8070/v1",
        "model": "streaming-infer-adapter",
        "api_key": "",
    },
    "summary": {"api_base": "https://api.minimaxi.com/v1", "model": "MiniMax-VL-01", "api_key": ""},
    "tts": {"api_base": "http://127.0.0.1:8985/v1/synthesize", "model": "", "api_key": ""},
    "asr": {
        "api_base": "",
        "model": "D:/AI/models/sherpa-onnx/models/asr/streaming-paraformer-bilingual-zh-en",
        "api_key": "",
    },
}

# Live, mutable services config — the single source of truth the webui owns.
_services_config: dict = copy.deepcopy(_SERVICES_CONFIG_DEFAULTS)


def _default_services_config_path() -> str:
    """Absolute path of the persisted services config (repo-root ``config/``)."""
    repo_root = os.path.dirname(
        os.path.dirname(os.path.dirname(os.path.dirname(os.path.abspath(__file__))))
    )
    return os.path.join(repo_root, "config", "services.json")


# Overridable in tests (monkeypatch before the PUT handler runs) so persistence
# can be exercised against a tmp_path instead of the real repo config dir.
_SERVICES_CONFIG_PATH = _default_services_config_path()


def _merge_services_config_file(target: dict, path: str) -> bool:
    """Deep-merge the on-disk ``services.json`` over ``target`` (in place).

    Only the known slots (``llm`` / ``summary`` / ``tts`` / ``asr``) and known
    fields (``api_base`` / ``model`` / ``api_key``) are merged; anything else
    is ignored so a partially-written or hand-edited file can never inject
    unexpected keys into the runtime config.

    Returns
    -------
    bool
        ``True`` if the file existed and parsed (even if empty / partial);
        ``False`` if it was absent.

    Notes
    -----
    Raises nothing — a missing or corrupt file must not abort webui startup;
    it simply falls back to the in-memory defaults (logging the reason). This
    is the load path, not the validation gate; PUT-time validation lives in
    ``_validate_and_apply_slot``.
    """
    if not os.path.exists(path):
        return False
    try:
        with open(path, encoding="utf-8") as fh:
            data = json.load(fh)
    except Exception as exc:
        logger.warning("could not read services config file %s: %s", path, exc)
        return False
    if not isinstance(data, dict):
        logger.warning("services config file %s is not a JSON object; ignoring", path)
        return False
    for slot, slot_cfg in data.items():
        if slot not in ("llm", "summary", "tts", "asr"):
            continue
        if not isinstance(slot_cfg, dict):
            continue
        dst = target.setdefault(slot, {})
        for key in ("api_base", "model", "api_key"):
            val = slot_cfg.get(key)
            if isinstance(val, str):
                dst[key] = val
    return True


def _reload_services_config_from_file() -> None:
    """Reset to defaults and re-apply the persisted file.

    Used to simulate a webui restart in tests, and if ever needed, to force a
    re-read of ``config/services.json`` without a full process restart.
    """
    _services_config.clear()
    _services_config.update(copy.deepcopy(_SERVICES_CONFIG_DEFAULTS))
    _merge_services_config_file(_services_config, _SERVICES_CONFIG_PATH)


def _persist_services_config() -> None:
    """Atomically write the current ``_services_config`` to ``services.json``.

    Writes to a temp file in the same directory then ``os.replace`` so a reader
    never observes a half-written file. The file is ``chmod 0600`` (local-only,
    gitignored) because it may carry ``api_key`` plaintext — see the api_key
    persistence tradeoff recorded in the issue. Raises on directory creation /
    write failure: persistence is a hard requirement of a successful PUT, not a
    best-effort nicety.
    """
    path = os.path.abspath(_SERVICES_CONFIG_PATH)
    directory = os.path.dirname(path)
    os.makedirs(directory, exist_ok=True)
    tmp_path = path + ".tmp"
    with open(tmp_path, "w", encoding="utf-8") as fh:
        json.dump(_services_config, fh, ensure_ascii=False, indent=2)
        fh.flush()
        os.fsync(fh.fileno())
    os.replace(tmp_path, path)
    os.chmod(path, 0o600)


def _validate_api_base(api_base: str) -> str | None:
    """Validate the ``api_base`` format.

    Returns ``None`` when the value is acceptable (empty string, meaning
    "use default / local", or a syntactically valid http(s) / ws(s) URL).
    Returns a human-readable reason string when the value must be rejected
    (HTTP 400).

    ws(s):// is allowed because the external ASR may be a websocket bridge
    (e.g. ``asr_adapter.py`` exposing ``/ws/asr``); the webui connects to it
    via ``aiohttp.ws_connect`` (see asr.connect_asr).
    """
    if not isinstance(api_base, str):
        return "api_base must be a string"
    if api_base != api_base.strip():
        return "api_base must not have leading/trailing whitespace"
    if not api_base:
        return None
    from urllib.parse import urlsplit

    parsed = urlsplit(api_base)
    if parsed.scheme not in ("http", "https"):
        return "api_base must be empty or an http(s) URL"
    if not parsed.netloc:
        return "api_base is missing a host"
    return None


def _probe_result_ok(result: object) -> bool:
    """Normalize the heterogeneous probe return shapes into a single bool.

    ``_probe_summary`` / ``_probe_asr`` return ``{"ok": bool, ...}`` while
    ``_probe_llm`` / ``_probe_tts`` return ``{"status": "ok"|"error"|...}``.
    """
    if not isinstance(result, dict):
        return False
    if "ok" in result:
        return bool(result.get("ok"))
    if "status" in result:
        return result.get("status") == "ok"
    return False


def _probe_result_reason(result: object, default: str = "probe failed") -> str:
    """Extract a short, capped reason string from a probe result."""
    if not isinstance(result, dict):
        return default
    reason = result.get("reason") or default
    return str(reason)[:200]


async def _probe_slot(slot: str, proposed: dict, loop: asyncio.AbstractEventLoop) -> dict | None:
    """Run the reachability probe for one slot.

    Returns the probe result dict, or ``None`` when no probe applies (e.g. an
    HTTP slot whose ``api_base`` is empty). ASR is special: it probes either an
    http(s) ``api_base`` OR a local model directory, so it is always probed
    when reachability is in scope.
    """
    api_base = proposed.get("api_base", "")
    if slot == "llm":
        return await loop.run_in_executor(None, _probe_llm, api_base)
    if slot == "summary":
        return await loop.run_in_executor(None, _probe_summary, {"api_base": api_base})
    if slot == "tts":
        return await loop.run_in_executor(None, _probe_tts, api_base)
    if slot == "asr":
        return await loop.run_in_executor(
            None, _probe_asr, {"api_base": api_base, "model": proposed.get("model", "")}
        )
    return None


async def _validate_and_apply_slot(
    slot: str, incoming: dict, loop: asyncio.AbstractEventLoop
) -> tuple[dict | None, bool]:
    """Validate and apply one incoming slot to ``_services_config``.

    Per 约法三章②, invalid config is rejected with an explicit structured body
    and is NEVER silently written. Only the fields the caller actually changes
    are validated / probed — the current persisted state is already trusted, so
    a no-op PUT never triggers a reachability probe.

    Parameters
    ----------
    slot: str
        Service slot (``llm`` / ``summary`` / ``tts`` / ``asr``).
    incoming: dict
        The ``{api_base, model, api_key}`` object for this slot from the PUT.
    loop: asyncio.AbstractEventLoop
        Event loop used to run the (sync) probes off the aiohttp loop.

    Returns
    -------
    tuple[dict | None, bool]
        ``(invalid_entry, applied)``. ``invalid_entry`` is the structured 4xx
        body fragment (including its own ``status``) when the slot is rejected,
        else ``None``. ``applied`` is ``True`` when at least one field was
        committed. Nothing is applied when the slot is rejected.
    """
    cur = _services_config.setdefault(slot, {})
    changing = [
        k for k in ("api_base", "model", "api_key") if k in incoming and incoming[k] != cur.get(k)
    ]
    if not changing:
        return None, False

    # 1) Format gate (before applying): api_base must be empty or a valid
    #    http(s) URL. Reject typos like "htp://" with a 400.
    if "api_base" in changing:
        fmt_err = _validate_api_base(incoming["api_base"])
        if fmt_err is not None:
            return (
                {
                    "error": fmt_err,
                    "slot": slot,
                    "field": "api_base",
                    "reason": fmt_err,
                    "status": 400,
                },
                False,
            )

    # 2) Reachability gate (before applying): probe the new endpoint. Never
    #    silently accept an unreachable service (no local fallback, D-080).
    #    For non-ASR slots an empty api_base means "use default / local" — it
    #    is valid and must NOT be probed.
    #    ASR: the user-facing api_base is an http(s) provider URL. When set we
    #    must bring the internal bridge up BEFORE the probe (and stop it when
    #    the slot reverts to local). Empty api_base = local in-process (no probe).
    proposed_api_base = incoming.get("api_base", cur.get("api_base", ""))
    if slot == "asr" and changing:
        proposed_model = incoming.get("model", cur.get("model", ""))
        proposed_key = incoming.get("api_key", cur.get("api_key", ""))
        # Bridge start/stop is a blocking subprocess op (up to 15s readiness
        # poll). Run it off the aiohttp event loop so saving a cloud ASR config
        # never freezes the whole WebUI. Per code-review BLOCKING fix.
        if proposed_api_base:
            await loop.run_in_executor(
                None, _asr_bridge_ensure, proposed_api_base, proposed_model, proposed_key
            )
        else:
            await loop.run_in_executor(None, _asr_bridge_stop)
    reachability_in_scope = (
        (("api_base" in changing) and bool(proposed_api_base))
        if slot != "asr"
        else bool(proposed_api_base) and proposed_api_base.startswith(("http://", "https://"))
    )
    if reachability_in_scope:
        proposed = {
            "api_base": proposed_api_base,
            "model": incoming.get("model", cur.get("model", "")),
        }
        result = await _probe_slot(slot, proposed, loop)
        if result is not None and not _probe_result_ok(result):
            reason = _probe_result_reason(result, "service unreachable")
            field = "model" if (slot == "asr" and not proposed["api_base"]) else "api_base"
            return (
                {
                    "error": "service unreachable: %s" % reason,
                    "slot": slot,
                    "field": field,
                    "reason": reason,
                    "status": 422,
                },
                False,
            )

    # 3) Valid -> apply the change and audit-log it (ADR-0014 redaction).
    changed_fields = []
    redacted = {}
    for key in ("api_base", "model", "api_key"):
        if key in incoming and incoming[key] != cur.get(key):
            cur[key] = incoming[key]
            changed_fields.append(key)
            if key == "api_key":
                redacted["api_key"] = "***set***" if incoming[key] else "***cleared***"
            else:
                redacted[key] = incoming[key]
    if changed_fields:
        _log_config_change(slot, changed_fields, redacted)
    return None, bool(changed_fields)


if _merge_services_config_file(_services_config, _SERVICES_CONFIG_PATH):
    logger.info("loaded persisted services config from %s", _SERVICES_CONFIG_PATH)
else:
    logger.debug("no persisted services config at %s; using defaults", _SERVICES_CONFIG_PATH)

# Feed the live service config to the ASR module so it can hot-reload the
# external ASR url/api_key without a process restart (see asr.connect_asr).
asr_module.set_asr_config_source(_services_config)

# Last asr subset we propagated, used to detect real changes and avoid
# needless reconnect logging on every PUT. Seeded from the current asr slot
# so the first _propagate_services_to_runtime() call does not false-trigger
# invalidate_asr_client() / reconnect logging.
_last_asr_propagated: dict = {
    "api_base": _services_config.get("asr", {}).get("api_base", ""),
    "api_key": _services_config.get("asr", {}).get("api_key", ""),
    "model": _services_config.get("asr", {}).get("model", ""),
}


# ---------------------------------------------------------------------------
# Internal ASR bridge (WebUI <-> ASR engine)
# ---------------------------------------------------------------------------
# The user-facing ``asr.api_base`` is an http(s) *provider* URL (standard
# OpenAI-compatible contract). The WebUI never connects to it directly; it
# always talks to a fixed internal websocket bridge, which forwards audio to
# the configured upstream. The bridge endpoint is a code constant and is
# NEVER exposed to the user (2026-08-11 contract fix).
ASR_BRIDGE_PORT = int(os.getenv("ASR_ADAPTER_PORT", "8994"))
ASR_BRIDGE_WS = "ws://127.0.0.1:%d/ws/asr" % ASR_BRIDGE_PORT
ASR_BRIDGE_HTTP = "http://127.0.0.1:%d" % ASR_BRIDGE_PORT

_ASR_BRIDGE_PROC: "subprocess.Popen | None" = None
_ASR_BRIDGE_CFG: dict = {}


def _asr_bridge_venv() -> str:
    """Return a python interpreter able to run asr_adapter.py (fastapi/uvicorn)."""
    base = os.path.join(os.path.dirname(os.path.dirname(os.path.abspath(__file__))), ".venv")
    for sub in ("Scripts/python.exe", "bin/python"):
        cand = os.path.join(base, sub)
        if os.path.exists(cand):
            return cand
    return sys.executable


def _asr_bridge_ensure(api_base: str, model: str, api_key: str) -> None:
    """Start (or keep) the ASR bridge pointed at ``api_base``.

    Idempotent on identical config. Raises on launch/readiness failure so the
    caller's reachability gate surfaces it explicitly (no silent fallback).
    """
    global _ASR_BRIDGE_PROC, _ASR_BRIDGE_CFG
    want = {"api_base": api_base, "model": model or "", "api_key": api_key or ""}
    if _ASR_BRIDGE_PROC is not None and _ASR_BRIDGE_PROC.poll() is None and want == _ASR_BRIDGE_CFG:
        return
    _asr_bridge_stop()
    venv_py = _asr_bridge_venv()
    cwd = os.path.join(os.path.dirname(os.path.dirname(os.path.abspath(__file__))), "asr")
    env = dict(os.environ)
    env["ASR_UPSTREAM_URL"] = api_base
    env["ASR_MODEL"] = model or ""
    env["ASR_API_KEY"] = api_key or ""
    env["ASR_ADAPTER_PORT"] = str(ASR_BRIDGE_PORT)
    try:
        proc = subprocess.Popen(
            [
                venv_py,
                "asr_adapter.py",
                "serve",
                "--host",
                "127.0.0.1",
                "--port",
                str(ASR_BRIDGE_PORT),
            ],
            cwd=cwd,
            env=env,
            stdout=subprocess.DEVNULL,
            stderr=subprocess.DEVNULL,
        )
    except Exception as exc:
        logger.error("ASR bridge launch failed: %s", exc)
        raise
    _ASR_BRIDGE_PROC = proc
    _ASR_BRIDGE_CFG = want
    _asr_bridge_wait_ready(15.0)
    logger.info("ASR bridge up: upstream=%s model=%s", api_base, model or "(default)")


def _asr_bridge_stop() -> None:
    global _ASR_BRIDGE_PROC, _ASR_BRIDGE_CFG
    proc = _ASR_BRIDGE_PROC
    if proc is not None:
        try:
            proc.terminate()
            try:
                proc.wait(timeout=5)
            except subprocess.TimeoutExpired:
                proc.kill()
        except Exception as exc:
            logger.warning("ASR bridge stop: %s", exc)
    _ASR_BRIDGE_PROC = None
    _ASR_BRIDGE_CFG = {}


def _asr_bridge_wait_ready(timeout: float) -> None:
    import httpx

    deadline = time.monotonic() + timeout
    last_err = "n/a"
    while time.monotonic() < deadline:
        try:
            with httpx.Client(timeout=1.0) as client:
                resp = client.get(ASR_BRIDGE_HTTP + "/health")
            if resp.status_code == 200:
                return
            last_err = "http %d" % resp.status_code
        except Exception as exc:
            last_err = str(exc)[:120]
        time.sleep(0.5)
    raise RuntimeError("ASR bridge not ready after %.0fs: %s" % (timeout, last_err))


def _asr_bridge_sync() -> None:
    """Reconcile the bridge with the current saved asr config (startup/propagate)."""
    asr_cfg = _services_config.get("asr", {}) or {}
    api_base = asr_cfg.get("api_base", "")
    if api_base:
        _asr_bridge_ensure(api_base, asr_cfg.get("model", ""), asr_cfg.get("api_key", ""))
    else:
        _asr_bridge_stop()


def _probe_summary(summary_cfg):
    """Lightweight reachability probe for the summary model endpoint.
    Mirrors _probe_llm but with a stricter timeout and tolerates non-model
    responses (501 / 404 / etc). Anything that returns JSON is "ok".
    """
    import httpx

    api_base = (summary_cfg or {}).get("api_base", "").rstrip("/")
    if not api_base:
        return {"ok": False, "reason": "api_base empty"}
    try:
        with httpx.Client(timeout=2.0) as client:
            resp = client.get(api_base + "/models")
        if resp.status_code == 200:
            return {"ok": True, "endpoint": api_base + "/models", "code": 200}
        return {"ok": False, "reason": "http %d" % resp.status_code}
    except Exception as exc:
        return {"ok": False, "reason": str(exc)[:120]}


def _probe_asr(asr_cfg):
    """Probe reachability of the ASR slot.

    The user-facing ``api_base`` is an http(s) *provider* URL. The WebUI does
    not connect to it directly; it connects to a fixed internal bridge
    (``ASR_BRIDGE_HTTP``), which the server keeps pointed at the upstream. So:

    - empty api_base  -> local in-process paraformer is the intended primary
                         path; this is a valid state (ok, no probe).
    - http(s)://       -> probe the internal bridge ``/health`` (the WebUI's
                         actual connection target), not the upstream.
    - ws(s)://          -> operator override (ASR_URL env); not probed, treated ok.
    """
    api_base = (asr_cfg or {}).get("api_base", "")
    if not api_base:
        return {"ok": True, "note": "local in-process paraformer"}
    if api_base.startswith("http://") or api_base.startswith("https://"):
        import httpx

        try:
            with httpx.Client(timeout=2.0) as client:
                resp = client.get(ASR_BRIDGE_HTTP + "/health")
            if resp.status_code == 200:
                return {"ok": True, "endpoint": ASR_BRIDGE_HTTP + "/health", "code": 200}
            return {"ok": False, "reason": "http %d (asr bridge)" % resp.status_code}
        except Exception as exc:
            return {"ok": False, "reason": str(exc)[:120]}
    if api_base.startswith("ws://") or api_base.startswith("wss://"):
        return {"ok": True, "endpoint": api_base, "note": "external ws override (not probed)"}
    return {"ok": False, "reason": "api_base must be http(s) or ws override"}


def _log_config_change(slot, changed_fields, redacted_values, events_dir=None):
    """Append one config_change event to the per-service JSONL event stream.

    Aligns with ADR-0014 (``doc/adr/0014-log-event-schema.md``): writes one
    JSON object per line to ``logs/events/webui-<UTC-YYYY-MM-DD>.jsonl`` with
    the four required fields — ``ts`` (ISO-8601 UTC), ``level`` ∈
    {debug,info,warn,error,critical}, ``service`` (``"webui"``) and ``event``
    (kebab-case ``config.services.patch``). The original ``slot`` /
    ``changed_fields`` / ``redacted_values`` are carried inside the optional
    ``extra`` object.

    PII red line (spec S-1 / D-2026-08-01-061): api_key is NEVER written in
    plaintext — the caller already replaces it with ``***set***`` /
    ``***cleared***``, so this helper only persists what it is given.

    Parameters
    ----------
    slot: str
        Service slot that changed (llm / summary / tts / asr).
    changed_fields: list[str]
        Names of the fields that actually changed.
    redacted_values: dict
        Field -> redacted representation. Non-secret fields (api_base, model)
        may carry their plaintext; api_key must be redacted.
    events_dir: str | None
        Override for the events directory (used by tests to redirect output).
        Defaults to ``<repo>/logs/events``.
    """
    try:
        if events_dir is None:
            repo_logs = os.path.join(
                os.path.dirname(os.path.abspath(__file__)),
                "..",
                "..",
                "..",
                "..",
                "logs",
            )
            events_dir = os.path.join(repo_logs, "events")
        os.makedirs(events_dir, exist_ok=True)
        utc_date = datetime.datetime.now(datetime.timezone.utc).strftime("%Y-%m-%d")
        log_path = os.path.join(events_dir, "webui-%s.jsonl" % utc_date)
        record = {
            "ts": datetime.datetime.now(datetime.timezone.utc).isoformat(),
            "level": "info",
            "service": "webui",
            "event": "config.services.patch",
            "extra": {
                "slot": slot,
                "changed_fields": list(changed_fields),
                "redacted_values": dict(redacted_values),
            },
        }
        with open(log_path, "a", encoding="utf-8") as fh:
            fh.write(json.dumps(record, ensure_ascii=False) + "\n")
    except Exception as exc:
        logger.warning("failed to append config-change event: %s", exc)


async def _services_config_handler(request):
    if request.method == "GET":
        return web.json_response(dict(_services_config))
    if request.method == "PUT":
        try:
            payload = await request.json()
        except Exception as exc:
            return web.json_response({"error": "bad json: %s" % exc}, status=400)
        if not isinstance(payload, dict):
            return web.json_response({"error": "payload must be a JSON object"}, status=400)

        loop = asyncio.get_running_loop()
        invalid: list[dict] = []
        applied_any = False
        for slot in ("llm", "summary", "tts", "asr"):
            incoming = payload.get(slot)
            if not isinstance(incoming, dict):
                continue
            entry, applied = await _validate_and_apply_slot(slot, incoming, loop)
            if entry is not None:
                invalid.append(entry)
            if applied:
                applied_any = True

        # Persist + propagate only when at least one valid change landed.
        # Invalid slots were rejected above (never persisted) — the validation
        # gate guarantees we never silently store an invalid config.
        if applied_any:
            try:
                _persist_services_config()
            except OSError as exc:
                logger.error("failed to persist services config: %s", exc)
                return web.json_response(
                    {
                        "error": "persist failed: %s" % exc,
                        "slot": None,
                        "field": None,
                        "reason": str(exc)[:200],
                    },
                    status=500,
                )
            await _propagate_services_to_runtime()

        if invalid:
            # 约法三章②: invalid config MUST surface an explicit 4xx, never a
            # silent 200. Valid slots (if any) were already applied + persisted.
            first = invalid[0]
            logger.warning(
                "PUT /api/services/config rejected slot=%s field=%s: %s",
                first["slot"],
                first["field"],
                first["reason"],
            )
            return web.json_response(
                {
                    "error": first["error"],
                    "slot": first["slot"],
                    "field": first["field"],
                    "reason": first["reason"],
                },
                status=first["status"],
            )
        return web.json_response(dict(_services_config))
    return web.json_response({"error": "method not allowed"}, status=405)


async def _services_status_handler(request):
    """Normalize the 4 probe results into {ok, reason, endpoint} so the
    UI can read a single shape (item.ok ? "OK" : "ERR", reason tooltip).
    """
    llm_cfg = _services_config.get("llm", {})
    summary_cfg = _services_config.get("summary", {})
    tts_cfg = _services_config.get("tts", {})
    asr_cfg = _services_config.get("asr", {})
    tts_url = tts_cfg.get("api_base") or os.environ.get(
        "JARVIS_TTS_API_URL", "http://127.0.0.1:8985/v1/synthesize"
    )
    # Each probe uses sync httpx with a 2-3s timeout; running them inline
    # would block the aiohttp event loop for up to ~9s. Dispatch them to
    # the default executor and gather so the worst case is the slowest probe.
    loop = asyncio.get_running_loop()
    llm_future = loop.run_in_executor(
        None, _probe_llm, llm_cfg.get("api_base", "http://127.0.0.1:8070/v1")
    )
    summary_future = loop.run_in_executor(None, _probe_summary, summary_cfg)
    tts_future = loop.run_in_executor(None, _probe_tts, tts_url)
    asr_future = loop.run_in_executor(None, _probe_asr, asr_cfg)
    llm_raw, summary_raw, tts_raw, asr_raw = await asyncio.gather(
        llm_future, summary_future, tts_future, asr_future
    )
    return web.json_response(
        {
            "llm": {
                "ok": llm_raw.get("status") == "ok",
                "reason": llm_raw.get("reason", ""),
                "endpoint": llm_cfg.get("api_base", "") + "/models",
            },
            "summary": summary_raw,
            "tts": {
                "ok": tts_raw.get("status") == "ok",
                "reason": tts_raw.get("reason", ""),
                "endpoint": tts_raw.get("endpoint", tts_url),
            },
            "asr": asr_raw,
        }
    )


# -- [Local Wiki] frontend gateway endpoints (ADR-0012, task F4) ----------
# The webui is the single SPA entry point. It proxies the whitelisted /v1/*
# wiki endpoints to the memory-store service. Provider health (B3) and
# network settings (B4) are owned by the backend (#36); this gateway only
# forwards the F4 knowledge-base surface (namespaces / sync / ingest).

# v0.3 (2026-07-29): in-code default flipped from 8996 (empty shell) to 8997
# (real bge-m3 backend, D-L4-001). JOYAI_MEMORY_STORE_URL env still wins, so the
# run-windows.ps1 launcher can override per-deploy. Operators hitting the legacy
# 8996 shell (e.g. a sandboxed dev box) only need to set the env explicitly.
MEMORY_STORE_URL = os.environ.get("JOYAI_MEMORY_STORE_URL", "http://127.0.0.1:8997").rstrip("/")

# Issue #43 (final piece): persist browser-reported screen-frame send→render
# latency samples to a server-side JSONL ring file so the data survives a page
# refresh / webui process restart. Previously the samples only lived in the
# browser console + an in-memory ring (lost on refresh).
SCREEN_LATENCY_LOG = os.path.join(
    os.path.dirname(os.path.abspath(__file__)),
    "..",
    "..",
    "..",
    "..",
    "logs",
    "screen_latency.jsonl",
)
SCREEN_LATENCY_RING_CAP = 2000
# Ensure the repo-root logs/ dir exists at startup. A genuinely unwritable
# logs/ is a real deployment error (project standard: raise, do not silently
# degrade), so this is intentionally run WITHOUT a try/except guard.
os.makedirs(os.path.dirname(SCREEN_LATENCY_LOG), exist_ok=True)


def _append_screen_latency(record: dict) -> None:
    """Append one screen-latency sample as a JSON line and trim the ring.

    Parameters
    ----------
    record: dict
        Serializable sample (seq, send_to_render_ms, ts, text_len, received_at).

    Notes
    -----
    When the file exceeds ``SCREEN_LATENCY_RING_CAP`` lines it is rewritten
    keeping only the most recent entries. Volume is low and the webui runs
    single-process, so this simple full-rewrite trim is acceptable.
    """
    os.makedirs(os.path.dirname(SCREEN_LATENCY_LOG), exist_ok=True)
    with open(SCREEN_LATENCY_LOG, "a", encoding="utf-8") as f:
        f.write(json.dumps(record, ensure_ascii=False) + "\n")
    # lightweight trim (low volume; single-process aiohttp is fine)
    try:
        with open(SCREEN_LATENCY_LOG, encoding="utf-8") as f:
            lines = f.readlines()
        if len(lines) > SCREEN_LATENCY_RING_CAP:
            with open(SCREEN_LATENCY_LOG, "w", encoding="utf-8") as f:
                f.writelines(lines[-SCREEN_LATENCY_RING_CAP:])
    except OSError as exc:
        logger.error("[screen-latency] trim failed: %s", exc)


async def _screen_latency_handler(request: web.Request) -> web.Response:
    """Persist one browser screen-frame send→render latency sample.

    Expects a JSON body with ``send_to_render_ms`` (number) and ``seq``
    (required). On success a JSONL record is appended to ``SCREEN_LATENCY_LOG``
    and ``204`` is returned. Malformed / invalid input returns ``4xx`` with a
    warning log; a write failure returns ``500``.
    """
    try:
        payload = await request.json()
    except Exception:
        logger.warning("[screen-latency] bad JSON body")
        return web.json_response({"ok": False, "error": "bad_json"}, status=400)
    s2r = payload.get("send_to_render_ms")
    seq = payload.get("seq")
    if not isinstance(s2r, (int, float)) or seq is None:
        logger.warning("[screen-latency] missing/invalid fields seq=%r s2r=%r", seq, s2r)
        return web.json_response({"ok": False, "error": "invalid_fields"}, status=400)
    record = {
        "seq": seq,
        "send_to_render_ms": round(float(s2r), 2),
        "ts": payload.get("ts"),
        "text_len": payload.get("text_len"),
        "received_at": datetime.datetime.now(datetime.timezone.utc).isoformat(),
    }
    try:
        _append_screen_latency(record)
    except OSError as exc:
        logger.error("[screen-latency] append failed: %s", exc)
        return web.json_response({"ok": False, "error": "write_failed"}, status=500)
    logger.debug("[screen-latency] sample seq=%s s2r=%s", seq, record["send_to_render_ms"])
    # RFC 7231: 204 MUST NOT include a message body, so return an empty response.
    return web.Response(status=204)


async def _proxy_to_memory_store(request: web.Request) -> web.Response:
    """Forward whitelisted [Local Wiki] /v1/* endpoints to memory-store.

    Only the three UI-facing wiki endpoints are proxied; memory-store's
    internal /v1/blocks/* surface is intentionally NOT exposed to the SPA.
    """
    target = MEMORY_STORE_URL + request.path
    if request.query_string:
        target += "?" + request.query_string
    try:
        body = await request.read()
        headers = {
            k: v for k, v in request.headers.items() if k.lower() not in ("host", "content-length")
        }
        async with (
            aiohttp.ClientSession(timeout=aiohttp.ClientTimeout(total=30)) as session,
            session.request(request.method, target, data=body or None, headers=headers) as resp,
        ):
            resp_body = await resp.read()
            # Strip any "; charset=..." — aiohttp's content_type arg rejects it
            # (it adds charset itself), and FastAPI/memory-store send it.
            ct = resp.headers.get("Content-Type", "application/json")
            ct = ct.split(";", 1)[0].strip() or "application/json"
            return web.Response(
                status=resp.status,
                body=resp_body,
                content_type=ct,
            )
    except Exception as exc:
        logger.warning("memory-store proxy %s failed: %s", request.path, exc)
        return web.json_response(
            {"error": "memory-store unreachable", "reason": str(exc)[:160]}, status=502
        )


async def extended_status(request: web.Request) -> web.Response:
    """Aggregate Memory-store + [Local Wiki] status for the header badges (#46).

    Three visual states per service:
      - enabled=False            -> gray  "未启用"  (opt-in flag off)
      - enabled=True & !reachable -> gray  "离线"    (probe failed)
      - enabled=True & reachable & ok=False -> red "异常" (health error)
      - enabled=True & reachable & ok=True  -> green "在线"
    Wiki recall (``WIKI_RECALL_ENABLED``) is configured in webinfer, but its
    corpus backend IS memory-store, so wiki reachability/health reuses the same
    probe. Probe failures are reported explicitly (never a silent 500).
    """
    memory_enabled = os.environ.get("JOYAI_ENABLE_MEMORY_STORE") == "1"
    wiki_enabled = os.environ.get("WIKI_RECALL_ENABLED") == "1"
    ok: bool | None = None
    reachable = False
    reason = ""
    latency_ms = None
    try:
        async with (
            aiohttp.ClientSession(timeout=aiohttp.ClientTimeout(total=2)) as session,
            session.get(MEMORY_STORE_URL + "/health") as resp,
        ):
            if resp.status == 200:
                data = await resp.json()
                ok = bool(data.get("ok"))
                reachable = True
                latency_ms = data.get("latency_ms")
                if not ok:
                    reason = str(data.get("error") or data.get("hint") or "health reported not ok")
            else:
                reason = f"memory-store /health HTTP {resp.status}"
    except Exception as exc:
        reachable = False
        ok = None
        reason = str(exc)
        logger.warning("extended_status: memory-store probe failed: %s", exc)
    payload = {
        "memory": {
            "enabled": memory_enabled,
            "ok": ok,
            "reachable": reachable,
            "reason": reason,
            "latency_ms": latency_ms,
        },
        "wiki": {
            "enabled": wiki_enabled,
            "ok": ok,
            "reachable": reachable,
            "reason": reason,
            "latency_ms": latency_ms,
        },
    }
    return web.json_response(payload)


async def _ingest_text_handler(request: web.Request) -> web.Response:
    """POST /v1/external/ingest-text (F4 pasted-markdown entry).

    The browser cannot write files, so the webui gateway accepts raw markdown
    text, stages it as a single .md under a temp dir, and forwards to the
    memory-store sync endpoint (the single ingest path). The temp dir is
    removed after the upstream call resolves.
    """
    try:
        payload = await request.json()
    except Exception as exc:
        return web.json_response({"error": "bad json: %s" % exc}, status=400)
    namespace = (payload.get("namespace") or "").strip()
    text = payload.get("text") or ""
    if not namespace:
        return web.json_response({"error": "namespace required"}, status=422)
    if not text.strip():
        return web.json_response({"error": "text required"}, status=422)
    import tempfile

    tmp = tempfile.mkdtemp(prefix="joyai-wiki-")
    md_path = os.path.join(tmp, "paste.md")
    try:
        with open(md_path, "w", encoding="utf-8") as fh:
            fh.write(text)
        async with (
            aiohttp.ClientSession(timeout=aiohttp.ClientTimeout(total=60)) as session,
            session.post(
                MEMORY_STORE_URL + "/v1/external/sync",
                json={"namespace": namespace, "dir": tmp, "drop_first": False},
            ) as resp,
        ):
            upstream = await resp.json(content_type=None)
            return web.json_response(upstream, status=resp.status)
    except Exception as exc:
        logger.warning("ingest-text failed: %s", exc)
        return web.json_response(
            {"error": "memory-store unreachable", "reason": str(exc)[:160]}, status=502
        )
    finally:
        import shutil

        shutil.rmtree(tmp, ignore_errors=True)


async def _propagate_services_to_runtime():
    """Push the saved llm/summary config into live service instances.

    - LLM: update every session VLMService (api_base + model + api_key).
    - Summary: webinfer owns the summarizer; webui cannot reach into it.
      We log the change so the operator can restart webinfer if needed.
    - TTS / ASR: read on demand by JarvisConfig.from_env(); changes take
      effect for the NEXT session that calls from_env().

    Async because the ASR bridge start/stop (_asr_bridge_sync) is a blocking
    subprocess op (up to 15s readiness poll) that must run off the aiohttp
    event loop. Always invoked from the event loop (PUT handler).
    """
    global _last_asr_propagated
    loop = asyncio.get_running_loop()
    try:
        llm_cfg = _services_config.get("llm", {})
        api_base = llm_cfg.get("api_base")
        model = llm_cfg.get("model")
        api_key = llm_cfg.get("api_key")
        if api_base:
            for _sid, sess in sessions.items():
                vlm = sess.get("vlm_service") if isinstance(sess, dict) else None
                if vlm and hasattr(vlm, "update_api_settings"):
                    vlm.update_api_settings(api_base=api_base, api_key=api_key)
                if vlm and model and hasattr(vlm, "set_model"):
                    vlm.set_model(model)
            default_vlm_config["api_base"] = api_base
            if model:
                default_vlm_config["model"] = model
    except Exception as exc:
        logger.warning("propagate llm config: %s", exc)
    try:
        os.environ["JARVIS_TTS_API_URL"] = _services_config.get("tts", {}).get(
            "api_base", ""
        ) or os.environ.get("JARVIS_TTS_API_URL", "http://127.0.0.1:8985/v1/synthesize")
        asr_cfg = _services_config.get("asr", {})
        # Mirror the model into the env for legacy callers. The authoritative
        # source is asr_cfg["model"] (slot["model"] in asr._asr_cfg()); the
        # ASR_MODEL_DIR env var is only a fallback used when the slot is empty.
        if asr_cfg.get("model"):
            os.environ["ASR_MODEL_DIR"] = asr_cfg["model"]
    except Exception as exc:
        logger.warning("propagate tts/asr config: %s", exc)
    # ASR: connect_asr reads the live config on every new browser session, so
    # hot-reload needs no persistent client. We only bump the invalidation epoch
    # when the asr slot actually changed, to avoid needless reconnect logging.
    # No silent local fallback: an invalid url/key still raises on connect.
    try:
        asr_cfg = _services_config.get("asr", {}) or {}
        # Bridge start/stop is a blocking subprocess op (up to 15s readiness
        # poll); run it off the aiohttp event loop. Per code-review BLOCKING fix.
        await loop.run_in_executor(None, _asr_bridge_sync)
        asr_subset = {
            "api_base": asr_cfg.get("api_base", ""),
            "api_key": asr_cfg.get("api_key", ""),
            "model": asr_cfg.get("model", ""),
        }
        if asr_subset != _last_asr_propagated:
            _last_asr_propagated = dict(asr_subset)
            asr_module.invalidate_asr_client()
            logger.info(
                "ASR config propagated (url set=%s, key set=%s); next ASR session reconnects",
                bool(asr_subset["api_base"]),
                bool(asr_subset["api_key"]),
            )
    except Exception as exc:
        logger.warning("propagate asr config: %s", exc)
    summary_cfg = _services_config.get("summary", {})
    if summary_cfg.get("api_base") or summary_cfg.get("model") or summary_cfg.get("api_key"):
        # Fire-and-forget; the PUT /api/services/config caller does not
        # need to wait for webinfer. If webinfer is down, the warning
        # is logged in the proxy and the saved config is still applied.
        try:
            loop = asyncio.get_running_loop()
        except RuntimeError:
            loop = None
        if loop is not None and loop.is_running():
            loop.create_task(_webinfer_proxy_summarizer_routing(summary_cfg))
        # else: no live event loop here (e.g. unit test sync invocation);
        # the next PUT will retry the propagation.


def _webinfer_base_url() -> str:
    """webinfer base URL for the /v1/summarizer/route proxy.

    Defaults to http://127.0.0.1:8070. Override with WEBINFER_URL env
    var. The webui's own LLM api_base can also point to webinfer (the
    two share the same OpenAI-compatible gateway).
    """
    env = os.environ.get("WEBINFER_URL")
    if env:
        return env.rstrip("/")
    llm_cfg = _services_config.get("llm", {})
    llm_base = llm_cfg.get("api_base", "http://127.0.0.1:8070/v1").rstrip("/")
    if llm_base.endswith("/v1"):
        llm_base = llm_base[:-3]
    return llm_base


async def _webinfer_proxy_summarizer_routing(summary_cfg: dict) -> dict:
    """Push summary config into the running webinfer process.

    The webui never mutates the summarizer directly. It tells webinfer
    to mutate its own state via /v1/summarizer/route, then webinfer
    ships the snapshot back. This is the single-webinfer-main-path
    principle: branches only happen inside webinfer.
    """
    base = _webinfer_base_url()
    payload = {
        "api_base": summary_cfg.get("api_base"),
        "model_name": summary_cfg.get("model"),
        "api_key": summary_cfg.get("api_key"),
    }
    try:
        async with (
            aiohttp.ClientSession(timeout=aiohttp.ClientTimeout(total=5.0)) as session,
            session.post(base + "/v1/summarizer/route", json=payload) as resp,
        ):
            if resp.status >= 400:
                body = await resp.text()
                logger.warning(
                    "webinfer /v1/summarizer/route returned %d: %s", resp.status, body[:200]
                )
                return {"ok": False, "status": resp.status, "body": body[:200]}
            return await resp.json()
    except Exception as exc:
        logger.warning("webinfer /v1/summarizer/route unreachable: %s", exc)
        return {"ok": False, "reason": str(exc)[:200]}


async def _webinfer_summarizer_route_handler(request):
    """GET / POST /api/webinfer/summarizer/route.

    Proxies directly to webinfer. Saves the round-trip through
    /api/services/config -> _propagate_services_to_runtime when the
    UI just wants to read or push the current snapshot synchronously.
    """
    base = _webinfer_base_url()
    method = "POST" if request.method == "POST" else "GET"
    body = None
    if method == "POST":
        try:
            body = await request.json()
        except Exception:
            return web.json_response({"error": "invalid json"}, status=400)
    try:
        async with aiohttp.ClientSession(timeout=aiohttp.ClientTimeout(total=5.0)) as session:
            if method == "GET":
                async with session.get(base + "/v1/summarizer/route") as resp:
                    payload = await resp.json(content_type=None)
                    return web.json_response(payload, status=resp.status)
            else:
                async with session.post(base + "/v1/summarizer/route", json=body) as resp:
                    payload = await resp.json(content_type=None)
                    return web.json_response(payload, status=resp.status)
    except Exception as exc:
        logger.warning("webinfer summarizer route proxy failed: %s", exc)
        return web.json_response(
            {"error": "webinfer unreachable", "reason": str(exc)[:200]}, status=502
        )


def main():
    import argparse

    parser = argparse.ArgumentParser(description="JoyAI VL Interaction WebUI Server")
    parser.add_argument("--host", default="127.0.0.1")
    parser.add_argument("--port", type=int, default=8099)
    parser.add_argument("--no-ssl", action="store_true")
    parser.add_argument("--model", default="streaming-infer-adapter")
    parser.add_argument("--api-base", default="http://127.0.0.1:8070/v1")
    args = parser.parse_args()

    default_vlm_config.update({"api_base": args.api_base, "model": args.model, "prompt": None})

    @web.middleware
    async def security_headers_middleware(request, handler):
        # Apply defensive HTTP headers to every response (static pages, JSON API,
        # WebSocket upgrade). SRI on the CDN <script>/<link> tags plus this CSP
        # is the primary supply-chain / XSS defense-in-depth for the SPA.
        try:
            response = await handler(request)
        except Exception:
            raise
        if response is not None and getattr(response, "headers", None) is not None:
            response.headers["Content-Security-Policy"] = (
                "default-src 'self'; "
                "script-src 'self' 'unsafe-inline' https://cdn.jsdelivr.net https://unpkg.com; "
                "style-src 'self' 'unsafe-inline' https://cdn.jsdelivr.net; "
                "img-src 'self' data: blob:; "
                "font-src 'self' data: https://cdn.jsdelivr.net; "
                "media-src 'self' blob: data:; "
                "connect-src 'self' ws: wss: http://127.0.0.1:* https://127.0.0.1:*; "
                "object-src 'none'; "
                "base-uri 'self'; "
                "frame-ancestors 'none'"
            )
            response.headers["X-Content-Type-Options"] = "nosniff"
            response.headers["Referrer-Policy"] = "no-referrer"
        return response

    @web.middleware
    async def access_log_middleware(request, handler):
        # One JSONL line per HTTP request. PII: do NOT log message bodies,
        # only the path + method + status + latency. WebSocket upgrades are
        # recorded at the upgrade point (status 101) but not per frame.
        t0 = _time_for_accesslog.perf_counter()
        status = 500
        try:
            response = await handler(request)
            status = response.status if response is not None else 500
            return response
        finally:
            try:
                latency_ms = int((time.perf_counter() - t0) * 1000)
                line = json.dumps(
                    {
                        "ts": _time_for_accesslog.strftime(
                            "%Y-%m-%dT%H:%M:%SZ", _time_for_accesslog.gmtime()
                        ),
                        "method": request.method,
                        "path": request.path,
                        "status": status,
                        "latency_ms": latency_ms,
                    },
                    ensure_ascii=False,
                )
                _access_logger.info(line)
            except Exception:  # noqa: S110
                pass  # never let logging fail a request

    async def _health_handler(request):
        # Liveness probe for the drift-gate-runtime CI job (Drift Gate v2.1 阶段A)
        return web.json_response({"status": "ok"})

    app = web.Application(middlewares=[access_log_middleware, security_headers_middleware])
    app.router.add_get("/", _index_handler)
    app.router.add_get("/health", _health_handler)
    app.router.add_get("/models", _models_handler)
    app.router.add_get("/detect-services", _detect_services_handler)
    app.router.add_get("/api/services/config", _services_config_handler)
    app.router.add_put("/api/services/config", _services_config_handler)
    app.router.add_get("/api/services/status", _services_status_handler)
    # [Local Wiki] frontend gateway (ADR-0012, tasks F1-F4). Provider health
    # (B3) and network settings (B4) are OWNED by the backend (#36); this
    # gateway only FORWARDS them to memory-store — no business logic here.
    app.router.add_get("/v1/providers/health", _proxy_to_memory_store)
    app.router.add_get("/v1/settings/network", _proxy_to_memory_store)
    app.router.add_put("/v1/settings/network", _proxy_to_memory_store)
    app.router.add_get("/v1/namespaces", _proxy_to_memory_store)
    app.router.add_post("/v1/external/sync", _proxy_to_memory_store)
    app.router.add_post("/v1/external/ingest-text", _ingest_text_handler)
    app.router.add_delete("/v1/namespaces/{namespace}", _proxy_to_memory_store)
    app.router.add_get("/api/webinfer/summarizer/route", _webinfer_summarizer_route_handler)
    app.router.add_post("/api/webinfer/summarizer/route", _webinfer_summarizer_route_handler)

    app.router.add_get("/ws", websocket_handler)
    setup_asr_routes(app)
    setup_tts_routes(app)
    setup_local_file_routes(app)
    setup_jarvis_routes(app)
    app.router.add_post("/offer", offer)
    app.router.add_post("/api/session/cleanup", session_cleanup)
    app.router.add_get("/api/llm/status", llm_status)
    app.router.add_get("/api/services/extended-status", extended_status)
    app.router.add_get("/api/tts/health", tts_health)
    app.router.add_post("/api/llm/message", llm_message)
    app.router.add_post("/api/tts/synthesize", _tts_synthesize_handler)
    # Issue #43: persist browser screen-frame send→render latency samples
    # (POSTed from the SPA) to the server-side JSONL ring file.
    app.router.add_post("/api/screen-latency", _screen_latency_handler)
    app.router.add_post("/api/rtsp/start", _rtsp_start_stub)
    app.router.add_post("/api/rtsp/stop", _rtsp_stop_stub)
    app.router.add_get("/api/rtsp/status", _rtsp_status_stub)
    images_dir = os.path.join(os.path.dirname(__file__), "static", "images")
    images_dir = os.path.abspath(images_dir)
    if os.path.exists(images_dir):
        app.router.add_static("/images", images_dir, name="images")
        logger.info("Serving static files from: %s", images_dir)
    else:
        logger.warning("static images directory missing: %s", images_dir)
    favicon_dir = os.path.join(os.path.dirname(__file__), "static", "favicon")
    favicon_dir = os.path.abspath(favicon_dir)
    if os.path.exists(favicon_dir):
        app.router.add_static("/favicon", favicon_dir, name="favicon")
        logger.info("Serving favicon files from: %s", favicon_dir)
    else:
        logger.warning("favicon directory missing: %s", favicon_dir)
    # v3.27 missed this: serve the entire static dir at "/" so /screen_capture.js
    # (loaded by index.html line 3650 <script src="./screen_capture.js">) returns
    # 200 instead of 404. Without it the browser never registers
    # window.startScreenCapture / stopScreenCapture and the video frame pipeline
    # stays empty. Static add is registered AFTER explicit routes, so
    # /, /ws, /api/* keep their handlers; only undeclared GETs fall through here.
    static_root_dir = os.path.abspath(os.path.join(os.path.dirname(__file__), "static"))
    if os.path.exists(static_root_dir):
        app.router.add_static(
            "/", static_root_dir, name="static-root", show_index=False, append_version=False
        )
        logger.info("Serving static root files from: %s", static_root_dir)
    else:
        logger.warning("static root directory missing: %s", static_root_dir)
    test_mode = os.environ.get("JOYAI_TEST_MODE") == "1"
    if not test_mode:
        app.on_startup.append(on_startup)
        app.on_shutdown.append(on_shutdown)
    if args.no_ssl:
        logger.warning("SSL disabled with --no-ssl flag")
        ssl_context = None
    else:
        ssl_context = _build_ssl_context()
    logger.info("Initialized VLM service: model=%s, api_base=%s", args.model, args.api_base)
    print("\n======== Running on http://%s:%d ========" % (args.host, args.port))
    print("(Press CTRL+C to quit)")
    web.run_app(app, host=args.host, port=args.port, ssl_context=ssl_context)


def _build_ssl_context():
    import ssl

    cert = os.path.join(os.path.dirname(__file__), "static", "favicon", "cert.pem")
    key = os.path.join(os.path.dirname(__file__), "static", "favicon", "key.pem")
    if os.path.exists(cert) and os.path.exists(key):
        return ssl.create_default_context(ssl.Purpose.CLIENT_AUTH, cafile=cert)
    return None


async def _index_handler(request):
    from pathlib import Path

    static_dir = Path(os.path.dirname(__file__)) / "static"
    idx = static_dir / "index.html"
    if idx.exists():
        return web.Response(text=idx.read_text(encoding="utf-8"), content_type="text/html")
    return web.Response(text="webui running", content_type="text/plain")


async def _models_handler(request):
    return web.json_response({"models": ["joyai-vl-interaction-preview"]})


async def _detect_services_handler(request):
    return web.json_response(
        {
            "llm": {"url": default_vlm_config.get("api_base")},
            "tts": {
                "url": os.environ.get("JARVIS_TTS_API_URL", "http://127.0.0.1:8985/v1/synthesize")
            },
            "kws": {
                "model_dir": os.environ.get(
                    "JARVIS_KWS_MODEL_DIR", "D:/AI/models/sherpa-onnx/models/kws/bt-en"
                )
            },
        }
    )


async def _rtsp_start_stub(request):
    return web.json_response({"error": "RTSP not implemented"}, status=501)


async def _rtsp_stop_stub(request):
    return web.json_response({"error": "RTSP not implemented"}, status=501)


async def _rtsp_status_stub(request):
    return web.json_response({"error": "RTSP not implemented"}, status=501)


if __name__ == "__main__":
    main()
