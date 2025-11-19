#!/usr/bin/env python3
"""
FastAPI Web Interface for IndexTTS vLLM v2
A single-file FastAPI application that combines webui_with_presets.py functionality
with the API structure from deploy_vllm_indextts.py, using IndexTTS vLLM v2 as backend.

Features:
- IndexTTS vLLM v2 backend for ultra-fast inference
- Speaker preset management with persistent storage
- API compatibility for external integrations
- Modern web interface with Chinese support
- Parallel chunk processing for long texts
- MP3 output support
- Advanced translate/edit mode with segment editing and selective regeneration
- Gemini model selection (Flash vs Pro) with optional API key override
- Translation/transcription toggle with custom prompt support
- Per-segment generation control for efficient audio processing
"""

from __future__ import annotations

import os
import sys
import asyncio
import time
import tempfile
import traceback
import uuid
from pathlib import Path
from typing import Any, List, Dict, Optional, Literal, Tuple, Set, Callable, Awaitable
from contextlib import asynccontextmanager
from io import BytesIO
import base64
import functools
import json
import math
import re
import shutil
import subprocess
import urllib.request
import hashlib
from concurrent.futures import ThreadPoolExecutor
import copy
from dataclasses import dataclass, field


# Audio processing
import numpy as np
import soundfile as sf
from pydub import AudioSegment

try:
    from clearvoice import ClearVoice  # type: ignore[import]
except ImportError:
    ClearVoice = None

try:
    from google import genai  # type: ignore[import]
    from google.genai import types  # type: ignore[import]
except ImportError:
    genai = None
    types = None


# FastAPI and web interface
from fastapi import FastAPI, File, UploadFile, Form, Request, BackgroundTasks, HTTPException, Depends
from fastapi.responses import HTMLResponse, FileResponse, JSONResponse, Response, StreamingResponse
from pydantic import BaseModel, Field, validator
from urllib.parse import quote

# IndexTTS v2 and speaker management
current_dir = os.path.dirname(os.path.abspath(__file__))
sys.path.insert(0, current_dir)
sys.path.insert(0, os.path.join(current_dir, "indextts"))

from indextts.infer_vllm_v2 import IndexTTS2
from speaker_preset_manager import SpeakerPresetManager, initialize_preset_manager

# Configuration
import argparse

# Global thread executor for blocking operations
# Use CPU count for parallel audio processing, but cap at 8 to avoid excessive context switching
_executor_workers = min(8, max(4, (os.cpu_count() or 4)))
executor = ThreadPoolExecutor(max_workers=_executor_workers, thread_name_prefix="fastapi_async")

# Global ClearVoice models (initialized lazily and reused)
_enhancement_model: Optional[Any] = None
_super_res_model: Optional[Any] = None

# Gemini configuration
GEMINI_API_KEY_ENV_VAR = "GEMINI_API_KEY"
GOOGLE_API_KEY_ENV_VAR = "GOOGLE_API_KEY"
GEMINI_MODEL_ENV_VAR = "GEMINI_MODEL_NAME"
DEFAULT_GEMINI_MODEL_NAME = "gemini-2.5-pro"
JSON_FENCE_PATTERN = re.compile(r"```(?:json)?\s*(.*?)```", re.DOTALL)
COERCE_SPEAKER_SEGMENTS_PATTERN = re.compile(
    r'^\s*(\[[\s\S]*?\])\s*,\s*"segments"\s*:\s*(\[[\s\S]*\])\s*$',
    re.DOTALL,
)
TRANSLATION_PROMPT_TEMPLATE = (
    "You are a professional interpreter and diarization analyst. "
    "Transcribe the speech from the provided audio and translate it into {dest_language} using natural, conversational wording. "
    "{non_speech_instruction}"
    "CRITICAL: Conversations may contain rapid handoffs without pauses. Detect every speaker change by listening for voice characteristics (pitch, timbre, accent, cadence) and never merge two speakers into one segment. "
    "Return JSON with exactly two top-level keys: \"speakers\" and \"segments\". "
    "\"speakers\" must be an array ordered by first appearance where every entry has "
    "\"id\" (deterministic labels \"speaker1\", \"speaker2\", ...), "
    "and \"description\" (≤12 words highlighting gender, approximate age range, and personality or tone). "
    "\"segments\" must be an array where each item represents a contiguous utterance with the keys "
    "\"start\" (timestamp mm:ss or mm:ss.xxx), "
    "\"end\" (same format), "
    "\"speaker\" (one of the ids from the speakers list), "
    "\"source_text\" (original-language transcript), "
    "\"translated_text\" (translation in {dest_language}). "
    "Ensure timestamps align with the audio, keep segments coherent, and add a new speaker entry whenever a new voice appears. "
    "Respond with JSON only—no explanations, markdown, or additional prose."
)
TRANSCRIPTION_PROMPT_TEMPLATE = (
    "You are a meticulous transcription and diarization expert. "
    "Transcribe the provided speech audio in its original language without translating it. "
    "{non_speech_instruction}"
    "CRITICAL: Conversations may contain rapid speaker transitions without pauses. Detect every speaker change by voice characteristics and never mix two speakers in one segment. "
    "Return JSON with the top-level keys \"speakers\" and \"segments\". "
    "\"speakers\" is an ordered array of objects containing "
    "\"id\" (speaker1, speaker2, ... in order of first appearance) "
    "and \"description\" (short summary focusing on gender, approximate age, and personality/tone). "
    "\"segments\" is an array where each entry contains "
    "\"start\" (timestamp mm:ss or mm:ss.xxx), "
    "\"end\" (same), "
    "\"speaker\" (speaker id), "
    "\"source_text\" (transcript in the original language), "
    "\"translated_text\" (use empty string \"\" because no translation is requested). "
    "Make sure timestamps are accurate and segments remain speaker-homogeneous. "
    "Respond with JSON only—no markdown or commentary."
)
IGNORE_NON_SPEECH_PROMPT_SUFFIX = (
    "Ignore non-speech vocalizations (laughter, shouts, chants, or crowd noise) and any background voices that are not clear speech; only capture spoken dialogue."
)
NON_SPEECH_PROMPT_PLACEHOLDER = "{non_speech_instruction}"
DEFAULT_GEMINI_TEMPERATURE = 0.2
DEFAULT_GEMINI_TOP_P = 0.9
TRANSLATE_DEFAULT_OUTPUT_FORMAT = "mp3"
TRANSLATE_DEFAULT_BITRATE = "128k"
AUDIO_GENERATION_MARGIN_MS = 20
TRANSLATION_TTS_CONCURRENCY = 20
MIN_SPEECH_DURATION_MS = 3000
MAX_MERGE_INTERVAL_MS = 0
DEFAULT_GENERATED_VOLUME_PERCENT = 100.0
MIN_GENERATED_VOLUME_PERCENT = 10.0
MAX_GENERATED_VOLUME_PERCENT = 300.0
DEFAULT_EMOTION_WEIGHT = 0.6
ALLOWED_GEMINI_MODELS = {"gemini-flash-latest", "gemini-2.5-pro"}
GEMINI_AUDIO_EXPORT_BITRATE = "128k"
SPEAKER_PREVIEW_DIR = Path("speaker_presets") / "previews"
SPEAKER_PREVIEW_BITRATE = "128k"
CHUNK_SPLIT_DEFAULT_MIN_MINUTES = 5.0
CHUNK_SPLIT_DEFAULT_MAX_MINUTES = 10.0
CHUNK_SPLIT_MIN_MINUTES = 1.0
CHUNK_SPLIT_MAX_MINUTES = 45.0
CHUNK_SPLIT_MIN_SILENCE_MS = 1500
CHUNK_SPLIT_SILENCE_THRESHOLD_DB = -42.0
CHUNK_SPLIT_MAX_CHUNKS = 64
CHUNK_SPLIT_SILENCE_GRACE_MS = 45000
CHUNK_SPLIT_MIN_CHUNK_MS = 1000
CHUNK_BATCH_GENERATE_DELAY_SECONDS = 60


async def _run_blocking(func: Callable, *args, **kwargs):
    loop = asyncio.get_event_loop()
    return await loop.run_in_executor(executor, functools.partial(func, *args, **kwargs))


def _normalize_gemini_model_name(gemini_model_value: Optional[str]) -> str:
    sanitized = (gemini_model_value or "").strip()
    if sanitized and sanitized not in ALLOWED_GEMINI_MODELS:
        return _get_gemini_model_name()
    return sanitized or _get_gemini_model_name()


def _coerce_merge_backing_flag(
    requested: bool,
    apply_enhancement: bool,
    alternate_backing_available: bool = False,
) -> bool:
    if not requested:
        return False
    if apply_enhancement or alternate_backing_available:
        return True
    print("⚠️ Merge-back requested without MossFormer2_SE_48K enhancement or custom/reused backing; ignoring request.")
    return False


def _resolve_final_prompt(
    prompt_override: Optional[str],
    dest_language: str,
    translate_enabled: bool,
    ignore_non_speech_flag: bool,
) -> str:
    non_speech_instruction_text = f"{IGNORE_NON_SPEECH_PROMPT_SUFFIX} " if ignore_non_speech_flag else ""
    final_prompt = (prompt_override or "").strip()
    if not final_prompt:
        if translate_enabled:
            final_prompt = TRANSLATION_PROMPT_TEMPLATE.format(
                dest_language=dest_language,
                non_speech_instruction=non_speech_instruction_text,
            )
        else:
            final_prompt = TRANSCRIPTION_PROMPT_TEMPLATE.format(
                non_speech_instruction=non_speech_instruction_text,
            )
        return final_prompt.strip()

    placeholder_present = NON_SPEECH_PROMPT_PLACEHOLDER in final_prompt
    final_prompt = final_prompt.replace(
        NON_SPEECH_PROMPT_PLACEHOLDER,
        non_speech_instruction_text,
    ).strip()
    if ignore_non_speech_flag and not placeholder_present:
        final_prompt = f"{final_prompt.rstrip()} {IGNORE_NON_SPEECH_PROMPT_SUFFIX}".strip()
    return final_prompt


def _decode_audio_segment_sync(audio_bytes: bytes, audio_format: Optional[str]) -> AudioSegment:
    audio_buffer = BytesIO(audio_bytes)
    if audio_format:
        return AudioSegment.from_file(audio_buffer, format=audio_format)
    return AudioSegment.from_file(audio_buffer)


async def _decode_audio_segment(audio_bytes: bytes, audio_format: Optional[str]) -> AudioSegment:
    return await _run_blocking(_decode_audio_segment_sync, audio_bytes, audio_format)


def _export_audio_segment_bytes_sync(audio: AudioSegment, fmt: str = "mp3", bitrate: Optional[str] = None) -> bytes:
    with BytesIO() as buffer:
        export_kwargs: Dict[str, Any] = {"format": fmt}
        if bitrate and fmt in {"mp3", "ogg", "opus", "aac"}:
            export_kwargs["bitrate"] = bitrate
        audio.export(buffer, **export_kwargs)
        return buffer.getvalue()


async def _export_audio_segment_bytes(audio: AudioSegment, fmt: str = "mp3", bitrate: Optional[str] = None) -> bytes:
    return await _run_blocking(_export_audio_segment_bytes_sync, audio, fmt, bitrate)


def _export_audio_segment_to_tempfile_sync(audio: AudioSegment, suffix: str = ".wav") -> str:
    with tempfile.NamedTemporaryFile(suffix=suffix, delete=False) as tmp_file:
        audio.export(tmp_file.name, format="wav")
        return tmp_file.name


async def _export_audio_segment_to_tempfile(audio: AudioSegment, suffix: str = ".wav") -> str:
    return await _run_blocking(_export_audio_segment_to_tempfile_sync, audio, suffix)


def _load_audio_segment_from_path_sync(path: str) -> AudioSegment:
    """Load audio segment from file path, auto-detecting format from extension."""
    ext = os.path.splitext(path)[1].lstrip(".").lower()
    if ext == "mp3":
        return AudioSegment.from_file(path, format="mp3")
    elif ext == "wav":
        return AudioSegment.from_file(path, format="wav")
    else:
        return AudioSegment.from_file(path)


async def _load_audio_segment_from_path(path: str) -> AudioSegment:
    return await _run_blocking(_load_audio_segment_from_path_sync, path)


async def _run_clearvoice_pipeline(
    original_audio: AudioSegment,
    *,
    apply_enhancement: bool,
    apply_super_resolution: bool,
    pre_clearvoice_mix_audio: Optional[AudioSegment],
    emit_status: Optional[Callable[..., Awaitable[None]]],
    source_audio_path: Optional[str] = None,
) -> Tuple[AudioSegment, Optional[AudioSegment]]:
    if not (apply_enhancement or apply_super_resolution):
        return original_audio, None
    if ClearVoice is None:
        raise TranslateWorkflowHttpError(
            500,
            {
                "status": "error",
                "message": "ClearVoice package is required for enhancement or super-resolution.",
            },
        )

    processed_paths: Set[str] = set()
    try:
        if emit_status:
            action = "Applying MossFormer2_SE_48K enhancement..."
            if apply_super_resolution and not apply_enhancement:
                action = "Applying MossFormer2_SR_48K super-resolution..."
            elif apply_super_resolution and apply_enhancement:
                action = "Applying MossFormer2_SE_48K enhancement + SR_48K super-resolution..."
            await emit_status(stage="enhancement", message=action)

        wav_input_path: Optional[str] = None
        if source_audio_path:
            wav_input_path, created_temp = await _ensure_clearvoice_input_path(source_audio_path)
            if created_temp and wav_input_path:
                processed_paths.add(wav_input_path)
                temp_input_path = wav_input_path
            else:
                temp_input_path = wav_input_path or source_audio_path
        else:
            temp_input_path = await _export_audio_segment_to_tempfile(original_audio)
            processed_paths.add(temp_input_path)

        cache_hash = _compute_file_md5(temp_input_path)
        cache_dir = os.path.join(CLEARVOICE_CACHE_DIR, cache_hash)
        os.makedirs(cache_dir, exist_ok=True)
        cached_enhanced_path = os.path.join(cache_dir, "mossformer2_se.mp3")
        cached_sr_path = os.path.join(cache_dir, "mossformer2_sr.mp3")
        cached_backing_path = os.path.join(cache_dir, "backing_track.mp3")
        use_cached_enhancement = apply_enhancement and os.path.exists(cached_enhanced_path)
        use_cached_sr = apply_super_resolution and os.path.exists(cached_sr_path)
        clearvoice_paths: List[str] = []

        final_processed_path: Optional[str] = None
        enhancement_output_path: Optional[str] = None

        if apply_super_resolution:
            if use_cached_sr and (not apply_enhancement or use_cached_enhancement):
                final_processed_path = cached_sr_path
                enhancement_output_path = cached_enhanced_path if apply_enhancement else None
                print(f"♻️ ClearVoice: Reusing cached MossFormer2_SR_48K output for {cache_hash}.")
        elif apply_enhancement and use_cached_enhancement:
            final_processed_path = cached_enhanced_path
            enhancement_output_path = cached_enhanced_path
            print(f"♻️ ClearVoice: Reusing cached MossFormer2_SE_48K output for {cache_hash}.")

        if final_processed_path is None:
            final_processed_local_path, clearvoice_paths, enhancement_output_local = await apply_clearvoice_processing(
                temp_input_path,
                apply_enhancement,
                apply_super_resolution,
            )
            processed_paths.update(clearvoice_paths)
            processed_paths.add(final_processed_local_path)
            final_processed_path = final_processed_local_path
            enhancement_output_path = enhancement_output_local

            if apply_enhancement and enhancement_output_local:
                enhancement_output_path = await _normalize_audio_to_cached(
                    enhancement_output_local,
                    cached_enhanced_path,
                    delete_source=True,
                )
                print(f"💾 ClearVoice: Cached MossFormer2_SE_48K output for {cache_hash}.")

            if apply_super_resolution:
                final_processed_path = await _normalize_audio_to_cached(
                    final_processed_local_path,
                    cached_sr_path,
                    delete_source=True,
                )
                print(f"💾 ClearVoice: Cached MossFormer2_SR_48K output for {cache_hash}.")
            elif apply_enhancement and enhancement_output_path is not None:
                final_processed_path = enhancement_output_path
            else:
                final_processed_path = await _normalize_audio_to_cached(
                    final_processed_local_path,
                    cached_enhanced_path,
                    delete_source=True,
                )
        else:
            # Ensure enhancement path is set when reusing cache
            if apply_enhancement and enhancement_output_path is None and os.path.exists(cached_enhanced_path):
                enhancement_output_path = cached_enhanced_path

        processed_audio = await _load_audio_segment_from_path(final_processed_path)

        backing_track_audio: Optional[AudioSegment] = None
        if os.path.exists(cached_backing_path):
            try:
                backing_track_audio = AudioSegment.from_file(cached_backing_path, format="mp3")
                print(
                    "♻️ ClearVoice: Reusing cached backing track for %s (%.2fs)"
                    % (cache_hash, len(backing_track_audio) / 1000.0)
                )
            except Exception as backing_exc:
                print(f"⚠️ Failed to load cached backing track for {cache_hash}: {backing_exc}")
                backing_track_audio = None
        if apply_enhancement and pre_clearvoice_mix_audio is not None:
            enhancement_audio: Optional[AudioSegment] = None
            if backing_track_audio is None:
                if enhancement_output_path is None:
                    print("⚠️ Enhancement output path not available, cannot extract backing track.")
                else:
                    try:
                        enhancement_audio = await _load_audio_segment_from_path(enhancement_output_path)
                    except Exception as enhancement_load_error:
                        print(f"⚠️ Failed to load ClearVoice enhancement output: {enhancement_load_error}")
                if enhancement_audio is None:
                    print("⚠️ Cannot extract backing track: enhancement audio not available.")
                else:
                    backing_track_audio = _extract_backing_track_from_vocals(
                        pre_clearvoice_mix_audio,
                        enhancement_audio,
                    )
                    if backing_track_audio is not None:
                        backing_dbfs = backing_track_audio.dBFS
                        if math.isinf(backing_dbfs):
                            backing_dbfs = -120.0
                        print(
                            "🎼 Extracted backing track %.2fs @ %d Hz (%d ch, %.1f dBFS)"
                            % (
                                len(backing_track_audio) / 1000.0,
                                backing_track_audio.frame_rate,
                                backing_track_audio.channels,
                                backing_dbfs,
                            )
                        )
                        try:
                            backing_track_audio.export(cached_backing_path, format="mp3")
                            print(f"💾 ClearVoice: Cached backing track for {cache_hash}.")
                        except Exception as cache_exc:
                            print(f"⚠️ Failed to cache backing track for {cache_hash}: {cache_exc}")
                    if backing_track_audio is not None and emit_status:
                        sr_note = " (super-resolution applied after extraction)" if apply_super_resolution else ""
                        await emit_status(
                            stage="enhancement",
                            message=f"Extracted instrumental backing track via MossFormer2_SE_48K{sr_note}.",
                        )

        if backing_track_audio is not None:
            reference_audio = pre_clearvoice_mix_audio or processed_audio
            reference_ms = len(reference_audio)
            backing_ms = len(backing_track_audio)
            if abs(backing_ms - reference_ms) > 1000:
                print(
                    f"⚠️ Backing track duration mismatch (backing={backing_ms} ms vs reference={reference_ms} ms) for cache {cache_hash}."
                )
        if emit_status:
            await emit_status(stage="enhancement", message="ClearVoice enhancement complete.")
        return processed_audio, backing_track_audio
    except TranslateWorkflowHttpError:
        raise
    except Exception as exc:
        raise TranslateWorkflowHttpError(
            500,
            {"status": "error", "message": f"ClearVoice processing failed: {str(exc)}"},
        ) from exc
    finally:
        for path in processed_paths:
            try:
                os.remove(path)
            except Exception:
                pass


async def _prepare_audio_assets(
    *,
    reuse_source_session: Optional[TranslateSessionData],
    audio_file: Optional[UploadFile],
    audio_reference: Optional[str],
    preloaded_audio_bytes: Optional[bytes] = None,
    source_audio_filename: Optional[str] = None,
    audio_mime_type_value: Optional[str],
    apply_enhancement: bool,
    apply_super_resolution: bool,
    requested_merge_backing: bool,
    custom_backing_audio_file: Optional[UploadFile] = None,
    custom_backing_audio_reference: Optional[str] = None,
    custom_backing_mime_type_value: Optional[str] = None,
    emit_status: Optional[Callable[..., Awaitable[None]]] = None,
) -> Tuple[AudioSegment, str, bytes, str, Optional[AudioSegment], bool, str]:
    source_audio_temp_path: Optional[str] = None
    custom_backing_audio: Optional[AudioSegment] = None
    backing_track_source = "none"
    custom_backing_ref = (custom_backing_audio_reference or "").strip()
    custom_backing_requested = bool(custom_backing_audio_file) or bool(custom_backing_ref)
    if custom_backing_requested:
        if emit_status:
            await emit_status(stage="backing", message="Loading custom backing track...")
        custom_audio_io = await load_audio_bytes_from_request(custom_backing_audio_file, custom_backing_audio_reference)
        if custom_audio_io is None:
            raise TranslateWorkflowHttpError(
                400,
                {"status": "error", "message": "Custom backing track not provided."},
            )
        custom_audio_bytes = custom_audio_io.read()
        if not custom_audio_bytes:
            raise TranslateWorkflowHttpError(
                400,
                {"status": "error", "message": "Custom backing track data is empty."},
            )
        custom_mime_type = (
            custom_backing_mime_type_value
            or (custom_backing_audio_file.content_type if custom_backing_audio_file else None)
            or "audio/wav"
        )
        custom_audio_format = _guess_audio_format_from_mime(custom_mime_type)
        try:
            custom_backing_audio = await _decode_audio_segment(custom_audio_bytes, custom_audio_format)
        except Exception as exc:
            raise TranslateWorkflowHttpError(
                400,
                {"status": "error", "message": f"Failed to decode custom backing track: {str(exc)}"},
            ) from exc
        backing_track_source = "custom"
        if emit_status:
            await emit_status(stage="backing", message="Custom backing track loaded.")

    if reuse_source_session is not None:
        try:
            original_audio = _get_session_original_audio(reuse_source_session)
        except RuntimeError:
            raise TranslateWorkflowHttpError(
                404,
                {
                    "status": "error",
                    "message": "Reusable session is missing separated vocals. Please re-upload the audio.",
                },
            )
        input_mime_type = reuse_source_session.input_mime_type or audio_mime_type_value or "audio/wav"
        if emit_status:
            await emit_status(
                stage="decode",
                message=f"Reusing audio from session {reuse_source_session.session_id}.",
            )
        processed_audio_bytes = await _export_audio_segment_bytes(
            original_audio,
            fmt="mp3",
            bitrate=GEMINI_AUDIO_EXPORT_BITRATE,
        )
        backing_track_audio = custom_backing_audio or _get_session_backing_audio(reuse_source_session)
        if custom_backing_audio is not None:
            backing_track_source = "custom"
        elif backing_track_audio is not None:
            backing_track_source = reuse_source_session.backing_track_source or "reuse"
        else:
            backing_track_source = "none"
        merge_with_backing = requested_merge_backing and backing_track_audio is not None
        if requested_merge_backing and backing_track_audio is None:
            print("⚠️ Unable to merge with backing track because no instrumental was derived.")
        return (
            original_audio,
            input_mime_type,
            processed_audio_bytes,
            "audio/mpeg",
            backing_track_audio,
            merge_with_backing,
            backing_track_source,
        )

    try:
        if preloaded_audio_bytes is not None:
            audio_bytes = preloaded_audio_bytes
        else:
            audio_io = await load_audio_bytes_from_request(audio_file, audio_reference)
            if audio_io is None:
                raise TranslateWorkflowHttpError(
                    400,
                    {"status": "error", "message": "No audio provided for translation."},
                )
            audio_bytes = audio_io.read()
        if not audio_bytes:
            raise TranslateWorkflowHttpError(
                400,
                {"status": "error", "message": "Provided audio data is empty."},
            )
        original_filename = source_audio_filename or (audio_file.filename if audio_file else None)
        normalized_audio_temp_path: Optional[str] = None
        if apply_enhancement or apply_super_resolution:
            upload_temp_path = _persist_audio_upload(audio_bytes, original_filename)
            normalized_audio_temp_path = await _normalize_uploaded_audio(upload_temp_path)
            source_audio_temp_path = normalized_audio_temp_path

        input_mime_type = audio_mime_type_value or (audio_file.content_type if audio_file else None) or "audio/wav"
        audio_format = _guess_audio_format_from_mime(input_mime_type)

        if emit_status:
            await emit_status(stage="decode", message="Decoding audio input...")
        try:
            if normalized_audio_temp_path:
                original_audio = await _load_audio_segment_from_path(normalized_audio_temp_path)
            else:
                original_audio = await _decode_audio_segment(audio_bytes, audio_format)
        except Exception as exc:
            raise TranslateWorkflowHttpError(
                400,
                {"status": "error", "message": f"Failed to decode audio: {str(exc)}"},
            ) from exc
        if emit_status:
            await emit_status(
                stage="decode",
                message=f"Decoded audio ({len(original_audio) / 1000:.1f}s).",
            )

        pre_clearvoice_mix_audio = original_audio if apply_enhancement else None
        processed_audio, backing_track_audio = await _run_clearvoice_pipeline(
            original_audio,
            apply_enhancement=apply_enhancement,
            apply_super_resolution=apply_super_resolution,
            pre_clearvoice_mix_audio=pre_clearvoice_mix_audio,
            emit_status=emit_status,
            source_audio_path=source_audio_temp_path,
        )
        if backing_track_audio is not None:
            backing_track_source = "extracted"
        if custom_backing_audio is not None:
            backing_track_audio = custom_backing_audio
            backing_track_source = "custom"

        processed_audio_bytes = await _export_audio_segment_bytes(
            processed_audio,
            fmt="mp3",
            bitrate=GEMINI_AUDIO_EXPORT_BITRATE,
        )
        merge_with_backing = requested_merge_backing and backing_track_audio is not None
        if requested_merge_backing and backing_track_audio is None:
            print("⚠️ Unable to merge with backing track because no instrumental was derived.")

        if emit_status:
            if apply_super_resolution:
                await emit_status(
                    stage="gemini_prep",
                    message="📤 Sending super-resolved audio (MossFormer2_SR_48K) to Gemini for transcription/translation.",
                )
            elif apply_enhancement:
                await emit_status(
                    stage="gemini_prep",
                    message="📤 Sending enhanced audio (MossFormer2_SE_48K) to Gemini for transcription/translation.",
                )
            else:
                await emit_status(
                    stage="gemini_prep",
                    message="📤 Sending original audio to Gemini for transcription/translation.",
                )

        return (
            processed_audio,
            input_mime_type,
            processed_audio_bytes,
            "audio/mpeg",
            backing_track_audio,
            merge_with_backing,
            backing_track_source,
        )
    finally:
        if source_audio_temp_path:
            try:
                os.remove(source_audio_temp_path)
            except Exception:
                pass


@dataclass
class SegmentBuildResult:
    session: TranslateSessionData
    segments: List[Dict[str, Any]]
    ui_segments: List[Dict[str, Any]]
    gemini_chunks: List[Dict[str, Any]]
    speaker_profiles: List[Dict[str, Any]]
    gemini_raw_text: Optional[str]
    metadata: Dict[str, Any]
    manual_segments_used: bool


async def _build_translation_segments(
    *,
    original_audio: AudioSegment,
    processed_audio_bytes: bytes,
    gemini_mime_type: str,
    dest_language: str,
    final_prompt: str,
    translate_enabled: bool,
    response_format_value: str,
    bitrate_value: str,
    input_mime_type: str,
    apply_enhancement: bool,
    apply_super_resolution: bool,
    ignore_non_speech_flag: bool,
    preserve_silence_audio_flag: bool,
    generated_volume_percent_value: float,
    backing_volume_percent_value: float,
    backing_track_audio: Optional[AudioSegment],
    backing_track_source: str,
    merge_with_backing: bool,
    segments_override_value: Optional[str],
    min_speech_duration: int,
    max_merge_interval: int,
    resolved_gemini_model: str,
    gemini_api_key_value: Optional[str],
    emit_status: Optional[Callable[..., Awaitable[None]]] = None,
    source_chunk_session: Optional[TranslateSessionData] = None,
) -> SegmentBuildResult:
    manual_chunk_data = None
    manual_speaker_profiles: List[Dict[str, Any]] = []
    manual_segments_used = False
    raw_gemini_response_text: Optional[str] = None
    manual_raw_input = (segments_override_value or "").strip() if segments_override_value else None
    if segments_override_value:
        try:
            parsed_override = _parse_manual_segments_input(segments_override_value)
            if parsed_override is not None:
                manual_chunk_data, manual_speaker_profiles = parsed_override
                manual_segments_used = True
                raw_gemini_response_text = manual_raw_input
        except ValueError as exc:
            raise TranslateWorkflowHttpError(
                400,
                {"status": "error", "message": str(exc)},
            ) from exc

    if emit_status:
        await emit_status(
            stage="gemini",
            message=f"Analyzing audio with Gemini model '{resolved_gemini_model}'...",
        )

    speaker_profiles: List[Dict[str, Any]] = []
    if manual_chunk_data is not None:
        gemini_chunks = manual_chunk_data
        speaker_profiles = manual_speaker_profiles or []
    else:
        gemini_chunks, speaker_profiles, raw_gemini_response_text = await _gemini_transcribe_translate(
            processed_audio_bytes,
            gemini_mime_type,
            dest_language,
            final_prompt,
            model_name=resolved_gemini_model,
            api_key_override=gemini_api_key_value,
        )
    if raw_gemini_response_text is None and manual_raw_input:
        raw_gemini_response_text = manual_raw_input

    if emit_status:
        await emit_status(
            stage="segmentation",
            message=f"Received {len(gemini_chunks)} raw segments; preparing timeline...",
        )

    segments = _prepare_translation_segments(
        original_audio,
        gemini_chunks,
        dest_language,
        speaker_profiles=speaker_profiles,
        min_speech_duration_ms=min_speech_duration,
        max_merge_interval_ms=max_merge_interval,
    )

    if not translate_enabled:
        for segment in segments:
            if segment.get("type") != "speech":
                continue
            translated_text = (segment.get("translated_text") or "").strip()
            source_text = (segment.get("source_text") or "").strip()
            if not translated_text and source_text:
                segment["translated_text"] = source_text

    session = await _create_translate_session(
        original_audio,
        dest_language,
        final_prompt,
        translate_enabled,
        response_format_value,
        bitrate_value,
        input_mime_type,
        {
            "enhancement": apply_enhancement,
            "super_resolution": apply_super_resolution,
        },
        segments,
        gemini_chunks,
        resolved_gemini_model,
        gemini_api_key_value,
        backing_track_audio=backing_track_audio,
        merge_with_backing=merge_with_backing,
        ignore_non_speech=ignore_non_speech_flag,
        preserve_silence_audio=preserve_silence_audio_flag,
        generated_volume_percent=generated_volume_percent_value,
        backing_volume_percent=backing_volume_percent_value,
        speaker_profiles=speaker_profiles,
        gemini_raw_text=raw_gemini_response_text,
        backing_track_source=backing_track_source,
    )
    if source_chunk_session and source_chunk_session.chunk_parent_id:
        session.chunk_parent_id = source_chunk_session.chunk_parent_id
        session.chunk_index = source_chunk_session.chunk_index
        session.chunk_start_ms = source_chunk_session.chunk_start_ms
        session.chunk_end_ms = source_chunk_session.chunk_end_ms
        session.chunk_cut_reason = source_chunk_session.chunk_cut_reason
        session.chunk_silence_midpoint_ms = source_chunk_session.chunk_silence_midpoint_ms
        session.chunk_source_session_id = source_chunk_session.session_id
    ui_segments = _serialize_segments_for_ui(segments, original_audio)

    metadata = {
        "dest_language": dest_language,
        "segment_count": len(segments),
        "speech_segment_count": sum(1 for seg in segments if seg.get("type") == "speech"),
        "silence_segment_count": sum(1 for seg in segments if seg.get("type") == "silence"),
        "audio_duration_ms": len(original_audio),
        "translate_enabled": translate_enabled,
        "response_format": response_format_value,
        "bitrate": bitrate_value,
        "prompt": final_prompt,
        "gemini_model": resolved_gemini_model,
        "ignore_non_speech": ignore_non_speech_flag,
        "preserve_silence_audio": preserve_silence_audio_flag,
        "generated_volume_percent": generated_volume_percent_value,
        "backing_volume_percent": backing_volume_percent_value,
        "gemini_raw_segments": gemini_chunks,
        "speaker_profiles": copy.deepcopy(speaker_profiles),
        "speaker_overrides": copy.deepcopy(getattr(session, "speaker_overrides", {})),
        "gemini_raw_text": raw_gemini_response_text,
        "clearvoice": {
            "enhancement": apply_enhancement,
            "super_resolution": apply_super_resolution,
        },
        "backing_track": {
            "available": backing_track_audio is not None,
            "requested": merge_with_backing or False,
            "merge_with_backing": merge_with_backing,
            "preview_url": f"/api/translate_backing_track/{session.session_id}"
            if backing_track_audio is not None
            else None,
            "volume_percent": backing_volume_percent_value,
            "source": backing_track_source,
        },
        "segment_rules": {
            "min_speech_ms": min_speech_duration,
            "max_merge_ms": max_merge_interval,
        },
        "manual_segments": manual_segments_used,
    }
    chunk_reference = source_chunk_session if source_chunk_session else (session if session.chunk_parent_id else None)
    if chunk_reference:
        metadata["chunk"] = {
            "session_id": chunk_reference.session_id,
            "chunk_index": chunk_reference.chunk_index,
            "start_ms": chunk_reference.chunk_start_ms,
            "end_ms": chunk_reference.chunk_end_ms,
            "cut_reason": chunk_reference.chunk_cut_reason,
            "batch_id": chunk_reference.chunk_parent_id,
            "silence_midpoint_ms": chunk_reference.chunk_silence_midpoint_ms,
            "start_label": _format_ms_to_timestamp(chunk_reference.chunk_start_ms or 0),
            "end_label": _format_ms_to_timestamp(chunk_reference.chunk_end_ms or 0),
            "duration_label": _format_ms_to_timestamp(
                max(0, (chunk_reference.chunk_end_ms or 0) - (chunk_reference.chunk_start_ms or 0))
            ),
            "backing_available": _session_has_backing_audio(chunk_reference),
            "backing_source": chunk_reference.backing_track_source or "none",
            "audio_url": _chunk_output_url(chunk_reference),
            "output_format": chunk_reference.chunk_output_format,
            "output_filename": chunk_reference.chunk_output_filename,
            "vocals_url": f"/api/translate_vocals/{chunk_reference.session_id}",
            "backing_url": (
                f"/api/translate_backing_track/{chunk_reference.session_id}"
                if _session_has_backing_audio(chunk_reference)
                else None
            ),
        }
    metadata["session_id"] = session.session_id
    metadata["reuse_session_id"] = session.session_id
    separation_info = {
        "vocals_available": True,
        "vocals_url": f"/api/translate_vocals/{session.session_id}",
        "backing_available": backing_track_audio is not None,
        "backing_url": metadata["backing_track"]["preview_url"] if backing_track_audio is not None else None,
        "backing_source": backing_track_source,
        "session_id": session.session_id,
    }
    metadata["separation"] = separation_info

    return SegmentBuildResult(
        session=session,
        segments=segments,
        ui_segments=ui_segments,
        gemini_chunks=gemini_chunks,
        speaker_profiles=speaker_profiles,
        gemini_raw_text=raw_gemini_response_text,
        metadata=metadata,
        manual_segments_used=manual_segments_used,
    )


@dataclass
class TranslateSessionData:
    session_id: str
    original_audio: AudioSegment
    dest_language: str
    prompt: str
    translate_enabled: bool
    response_format: str
    bitrate: str
    input_mime_type: Optional[str]
    clearvoice_settings: Dict[str, bool]
    base_segments: List[Dict[str, Any]]
    gemini_chunks: List[Dict[str, Any]]
    gemini_model: str
    gemini_api_key: Optional[str]
    original_audio_path: Optional[str] = None
    backing_track_audio: Optional[AudioSegment] = None
    backing_track_source: str = "none"
    merge_with_backing: bool = False
    ignore_non_speech: bool = False
    preserve_silence_audio: bool = False
    generated_volume_percent: float = DEFAULT_GENERATED_VOLUME_PERCENT
    backing_volume_percent: float = DEFAULT_GENERATED_VOLUME_PERCENT
    speaker_profiles: List[Dict[str, Any]] = field(default_factory=list)
    speaker_overrides: Dict[str, Dict[str, Any]] = field(default_factory=dict)
    gemini_raw_text: Optional[str] = None
    created_at: float = field(default_factory=lambda: time.time())
    chunk_parent_id: Optional[str] = None
    chunk_index: Optional[int] = None
    chunk_start_ms: Optional[int] = None
    chunk_end_ms: Optional[int] = None
    chunk_generated: bool = False
    chunk_output_path: Optional[str] = None
    chunk_output_filename: Optional[str] = None
    chunk_output_format: Optional[str] = None
    chunk_generated_at: Optional[float] = None
    chunk_cut_reason: Optional[str] = None
    chunk_silence_midpoint_ms: Optional[int] = None
    chunk_source_session_id: Optional[str] = None


ADVANCED_TRANSLATE_SESSIONS: Dict[str, TranslateSessionData] = {}
ADVANCED_TRANSLATE_SESSION_LOCK = asyncio.Lock()
ADVANCED_TRANSLATE_SESSION_TTL_SECONDS = 60 * 60  # 1 hour


def _session_media_path(session_id: str, kind: str, fmt: str = "mp3") -> str:
    safe_kind = "".join(c for c in kind if c.isalnum() or c in {"_", "-"}).strip() or "media"
    return os.path.join(TRANSLATE_SESSION_MEDIA_DIR, f"{session_id}_{safe_kind}.{fmt}")


def _chunk_batch_media_path(batch_id: str, kind: str, fmt: str = "mp3") -> str:
    safe_kind = "".join(c for c in kind if c.isalnum() or c in {"_", "-"}).strip() or kind
    return os.path.join(TRANSLATE_SESSION_MEDIA_DIR, f"{batch_id}_{safe_kind}.{fmt}")


def _compute_file_md5(path: str) -> str:
    hash_md5 = hashlib.md5()
    with open(path, "rb") as infile:
        for chunk in iter(lambda: infile.read(8192), b""):
            hash_md5.update(chunk)
    return hash_md5.hexdigest()


def _persist_session_audio_segment(session_id: str, audio: AudioSegment, kind: str, fmt: str = "mp3") -> str:
    path = _session_media_path(session_id, kind, fmt)
    audio.export(path, format=fmt)
    return path


def _get_session_original_audio(session: TranslateSessionData) -> AudioSegment:
    if session.original_audio is not None:
        return session.original_audio
    if session.original_audio_path and os.path.exists(session.original_audio_path):
        session.original_audio = _load_audio_segment_from_path_sync(session.original_audio_path)
        return session.original_audio
    raise RuntimeError(f"Session {session.session_id} does not have a stored vocal track.")


def _get_session_backing_audio(session: TranslateSessionData) -> Optional[AudioSegment]:
    return session.backing_track_audio


def _session_has_backing_audio(session: TranslateSessionData) -> bool:
    return session.backing_track_audio is not None


def _persist_chunk_batch_media(batch_id: str, audio: AudioSegment, kind: str, fmt: str = "mp3") -> str:
    path = _chunk_batch_media_path(batch_id, kind, fmt)
    audio.export(path, format=fmt)
    return path


def _session_audio_duration_ms(session: TranslateSessionData) -> int:
    audio = _get_session_original_audio(session)
    return len(audio)


class TranslateWorkflowHttpError(Exception):
    def __init__(self, status_code: int, content: Dict[str, Any]):
        super().__init__(content.get("message") or "Translate workflow error")
        self.status_code = status_code
        self.content = content


@functools.lru_cache(maxsize=4)
def _create_gemini_client(api_key: str):
    if genai is None:
        raise RuntimeError(
            "The google-genai package is required for translation. Install it with `pip install google-genai`."
        )
    return genai.Client(api_key=api_key)


def _get_gemini_client(api_key: str):
    return _create_gemini_client(api_key)


def estimate_speech_duration(text: str, language: str = "auto") -> int:
    """
    Estimate speech duration in milliseconds based on text length.
    
    Args:
        text: Input text
        language: Language hint ("zh", "en", or "auto")
    
    Returns:
        Estimated duration in milliseconds
    """
    if not text or not text.strip():
        return 0
    
    # Clean text
    text = text.strip()
    
    # Detect language if auto
    if language == "auto":
        # Simple heuristic: if more than 30% Chinese characters, treat as Chinese
        chinese_chars = sum(1 for c in text if '\u4e00' <= c <= '\u9fff')
        if chinese_chars / max(len(text), 1) > 0.3:
            language = "zh"
        else:
            language = "en"
    
    # Speech rate estimates (characters per second)
    # These are conservative estimates based on typical TTS output
    if language == "zh":
        # Chinese: ~4-5 characters per second
        chars_per_second = 4.5
        char_count = len([c for c in text if '\u4e00' <= c <= '\u9fff' or c.isalnum()])
    else:
        # English: ~12-15 characters per second (including spaces)
        # Or ~150-180 words per minute = 2.5-3 words per second
        chars_per_second = 13.0
        char_count = len(text)
    
    # Calculate base duration
    duration_seconds = char_count / chars_per_second
    
    # Add padding for punctuation pauses (10% extra time)
    punctuation_count = sum(1 for c in text if c in ',.!?;:。，！？；：')
    pause_time = punctuation_count * 0.3  # 300ms per punctuation
    
    total_duration_seconds = duration_seconds + pause_time
    
    # Add 10% buffer for natural speech variations
    total_duration_seconds *= 1.1
    
    # Convert to milliseconds and round up to nearest 100ms
    duration_ms = int(total_duration_seconds * 1000)
    duration_ms = ((duration_ms + 99) // 100) * 100  # Round up to nearest 100ms
    
    return duration_ms

parser = argparse.ArgumentParser(description="IndexTTS vLLM v2 FastAPI WebUI")
parser.add_argument("--verbose", action="store_true", default=False, help="Enable verbose mode")
parser.add_argument("--port", type=int, default=8000, help="Port to run the web API on")
parser.add_argument("--host", type=str, default="0.0.0.0", help="Host to run the web API on")
parser.add_argument("--model_dir", type=str, default="checkpoints", help="Model checkpoints directory")
parser.add_argument("--is_fp16", action="store_true", default=False, help="Fp16 infer")
parser.add_argument("--use_torch_compile", action="store_true", default=False, help="use torch compile")
parser.add_argument("--gpu_memory_utilization", type=float, default=0.25, help="GPU memory utilization")

# Parse args if run as script, otherwise use defaults
try:
    cmd_args = parser.parse_args()
except SystemExit:
    # If running in interactive mode, use defaults
    cmd_args = argparse.Namespace(
        verbose=False,
        port=8000,
        host="0.0.0.0",
        model_dir="checkpoints",
        is_fp16=False,
        use_torch_compile=False,
        gpu_memory_utilization=0.25
    )

# Create directories
os.makedirs("outputs/tasks", exist_ok=True)
os.makedirs("outputs", exist_ok=True)
os.makedirs("prompts", exist_ok=True)
os.makedirs("speaker_presets", exist_ok=True)
TRANSLATE_OUTPUT_DIR = os.path.join("outputs", "translate_results")
os.makedirs(TRANSLATE_OUTPUT_DIR, exist_ok=True)
TRANSLATE_SESSION_MEDIA_DIR = os.path.join("outputs", "translate_session_media")
os.makedirs(TRANSLATE_SESSION_MEDIA_DIR, exist_ok=True)
CLEARVOICE_CACHE_DIR = os.path.join("outputs", "clearvoice_cache")
os.makedirs(CLEARVOICE_CACHE_DIR, exist_ok=True)


def _guess_media_type_from_extension(filename: str) -> str:
    ext = os.path.splitext(filename)[1].lower().lstrip(".")
    mapping = {
        "mp3": "audio/mpeg",
        "wav": "audio/wav",
        "flac": "audio/flac",
        "aac": "audio/aac",
        "opus": "audio/opus",
        "ogg": "audio/ogg",
        "webm": "audio/webm",
    }
    return mapping.get(ext, "application/octet-stream")

# Async wrapper functions for blocking operations
async def async_write_file(file_path: str, data: bytes) -> None:
    """Async wrapper for writing file data"""
    loop = asyncio.get_event_loop()
    await loop.run_in_executor(executor, _write_file_sync, file_path, data)

def _write_file_sync(file_path: str, data: bytes) -> None:
    """Synchronous file write operation"""
    with open(file_path, 'wb') as f:
        f.write(data)

async def async_read_file(file_path: str) -> bytes:
    """Async wrapper for reading file data"""
    loop = asyncio.get_event_loop()
    return await loop.run_in_executor(executor, _read_file_sync, file_path)

def _read_file_sync(file_path: str) -> bytes:
    """Synchronous file read operation"""
    with open(file_path, 'rb') as f:
        return f.read()

async def async_remove_file(file_path: str) -> None:
    """Async wrapper for removing files"""
    loop = asyncio.get_event_loop()
    await loop.run_in_executor(executor, _remove_file_sync, file_path)

def _remove_file_sync(file_path: str) -> None:
    """Synchronous file removal operation"""
    try:
        os.unlink(file_path)
    except Exception:
        pass  # Ignore errors when removing temporary files


def _sanitize_preview_basename(speaker_name: str) -> str:
    sanitized = re.sub(r"[^0-9A-Za-z_-]+", "_", speaker_name.strip())
    sanitized = sanitized.strip("_") or "speaker"
    digest = hashlib.md5(speaker_name.encode("utf-8")).hexdigest()[:8]
    return f"{sanitized}_{digest}"


def _get_speaker_preview_path(speaker_name: str) -> Path:
    return SPEAKER_PREVIEW_DIR / f"{_sanitize_preview_basename(speaker_name)}.mp3"


def _speaker_preview_url(speaker_name: str) -> str:
    return f"/api/speaker_preview/{quote(speaker_name, safe='')}"


def _speaker_preview_exists(speaker_name: str) -> bool:
    return _get_speaker_preview_path(speaker_name).exists()


async def _remove_speaker_preview(speaker_name: str) -> None:
    preview_path = _get_speaker_preview_path(speaker_name)
    if preview_path.exists():
        await async_remove_file(str(preview_path))


async def _create_speaker_preview_mp3(
    source_audio_path: str,
    speaker_name: str,
    *,
    bitrate: str = SPEAKER_PREVIEW_BITRATE,
) -> Optional[str]:
    """Create/overwrite a speaker preview MP3 derived from the processed reference audio."""
    loop = asyncio.get_event_loop()
    preview_path = _get_speaker_preview_path(speaker_name)

    def _export_preview() -> str:
        SPEAKER_PREVIEW_DIR.mkdir(parents=True, exist_ok=True)
        audio = AudioSegment.from_file(source_audio_path)
        audio.export(preview_path, format="mp3", bitrate=bitrate)
        return str(preview_path)

    try:
        return await loop.run_in_executor(executor, _export_preview)
    except Exception as exc:
        print(f"⚠️ Failed to create preview MP3 for speaker '{speaker_name}': {exc}")
        return None


async def async_audio_read(file_path: str):
    """Async wrapper for soundfile.read()"""
    loop = asyncio.get_event_loop()
    return await loop.run_in_executor(executor, sf.read, file_path)

async def async_cut_audio_to_duration(input_path: str, max_duration: float = 10.0):
    """Async wrapper for smart audio cutting at silence intervals"""
    loop = asyncio.get_event_loop()
    return await loop.run_in_executor(executor, _smart_cut_audio_at_silence, input_path, max_duration)

def _detect_silence_intervals(audio_data, sample_rate, min_silence_duration=0.3, silence_threshold=-40):
    """
    Detect silence intervals in audio data.
    
    Args:
        audio_data: Audio samples (mono or stereo)
        sample_rate: Sample rate in Hz
        min_silence_duration: Minimum duration of silence in seconds (default: 0.3s)
        silence_threshold: Silence threshold in dB (default: -40dB)
    
    Returns:
        List of tuples (start_sample, end_sample) for each silence interval
    """
    import numpy as np
    
    # Convert to mono if stereo
    if len(audio_data.shape) > 1:
        audio_mono = np.mean(audio_data, axis=1)
    else:
        audio_mono = audio_data
    
    # Calculate RMS energy in dB
    frame_length = int(0.02 * sample_rate)  # 20ms frames
    hop_length = int(0.01 * sample_rate)    # 10ms hop
    
    # Calculate energy for each frame
    energy_db = []
    for i in range(0, len(audio_mono) - frame_length, hop_length):
        frame = audio_mono[i:i + frame_length]
        rms = np.sqrt(np.mean(frame ** 2))
        db = 20 * np.log10(rms + 1e-10)  # Add small value to avoid log(0)
        energy_db.append(db)
    
    energy_db = np.array(energy_db)
    
    # Find silence regions (below threshold)
    is_silence = energy_db < silence_threshold
    
    # Convert frame indices to sample indices
    min_silence_frames = int(min_silence_duration * sample_rate / hop_length)
    
    # Find continuous silence regions
    silence_intervals = []
    in_silence = False
    silence_start = 0
    
    for i, silent in enumerate(is_silence):
        if silent and not in_silence:
            # Start of silence
            in_silence = True
            silence_start = i
        elif not silent and in_silence:
            # End of silence
            silence_length = i - silence_start
            if silence_length >= min_silence_frames:
                # Convert frame indices to sample indices
                start_sample = silence_start * hop_length
                end_sample = i * hop_length
                silence_intervals.append((start_sample, end_sample))
            in_silence = False
    
    # Check last region
    if in_silence:
        silence_length = len(is_silence) - silence_start
        if silence_length >= min_silence_frames:
            start_sample = silence_start * hop_length
            end_sample = len(audio_mono)
            silence_intervals.append((start_sample, end_sample))
    
    return silence_intervals

def _smart_cut_audio_at_silence(input_path: str, max_duration: float = 10.0):
    """
    Smart audio cutting that uses silence intervals as natural cut points.
    Tries to find a segment between 3s and 15s that ends at a silence.
    
    Args:
        input_path: Path to input audio file
        max_duration: Maximum duration (unused, kept for compatibility)
    
    Returns:
        Path to cut audio file
    """
    try:
        # Load audio data
        audio_data, sample_rate = sf.read(input_path)
        
        total_duration = len(audio_data) / sample_rate
        
        # If audio is shorter than 3 seconds, return original
        if total_duration < 3.0:
            print(f"📏 Audio duration ({total_duration:.1f}s) is too short, keeping original")
            return input_path
        
        # If audio is between 3s and 15s, return original
        if total_duration <= 15.0:
            print(f"📏 Audio duration ({total_duration:.1f}s) is within ideal range (3-15s)")
            return input_path
        
        print(f"🔍 Analyzing audio ({total_duration:.1f}s) for silence intervals...")
        
        # Detect silence intervals
        silence_intervals = _detect_silence_intervals(audio_data, sample_rate)
        
        if not silence_intervals:
            print(f"⚠️ No silence intervals found, cutting at 10 seconds")
            cut_sample = int(10.0 * sample_rate)
            cut_audio = audio_data[:cut_sample]
        else:
            print(f"✓ Found {len(silence_intervals)} silence intervals")
            
            # Find the best cut point
            best_cut_sample = None
            
            for start_silence, end_silence in silence_intervals:
                # Use the middle of the silence interval as cut point
                cut_sample = (start_silence + end_silence) // 2
                cut_duration = cut_sample / sample_rate
                
                # Check if this cut point gives us a good duration (3s to 15s)
                if 3.0 <= cut_duration <= 15.0:
                    best_cut_sample = cut_sample
                    print(f"✓ Found ideal cut point at {cut_duration:.1f}s (at silence interval)")
                    break
            
            # If no ideal cut point found, try to get closest to target
            if best_cut_sample is None:
                # Find the silence interval closest to 10 seconds
                target_sample = int(10.0 * sample_rate)
                closest_silence = min(silence_intervals, 
                                    key=lambda x: abs((x[0] + x[1]) // 2 - target_sample))
                best_cut_sample = (closest_silence[0] + closest_silence[1]) // 2
                cut_duration = best_cut_sample / sample_rate
                print(f"✓ Using closest silence interval at {cut_duration:.1f}s")
            
            cut_audio = audio_data[:best_cut_sample]
        
        # Create output path with _cut suffix
        input_name = os.path.splitext(input_path)[0]
        output_path = f"{input_name}_cut.wav"
        
        # Save cut audio
        sf.write(output_path, cut_audio, sample_rate)
        
        cut_duration = len(cut_audio) / sample_rate
        
        print(f"✂️ Smart cut: {total_duration:.1f}s → {cut_duration:.1f}s (saved to {os.path.basename(output_path)})")
        
        # Remove original file and return cut file path
        try:
            os.remove(input_path)
        except Exception as cleanup_error:
            print(f"⚠️ Could not remove original audio file: {cleanup_error}")
        
        return output_path
        
    except Exception as e:
        print(f"❌ Error cutting audio: {e}")
        # Return original path if cutting fails
        return input_path


def _audio_segment_to_ndarray(audio: AudioSegment) -> Tuple[np.ndarray, int]:
    """Convert a pydub AudioSegment into a normalized numpy array (float32)."""
    if audio is None:
        return np.zeros((0,), dtype=np.float32), 16000
    frame_rate = int(audio.frame_rate or 16000)
    sample_width = max(1, int(audio.sample_width or 2))
    raw_samples = np.array(audio.get_array_of_samples())
    if audio.channels > 1:
        try:
            raw_samples = raw_samples.reshape((-1, audio.channels))
        except ValueError:
            raw_samples = raw_samples.reshape((-1, audio.channels), order="F")
    max_val = float(1 << (8 * sample_width - 1))
    if max_val > 0:
        normalized = raw_samples.astype(np.float32) / max_val
    else:
        normalized = raw_samples.astype(np.float32)
    return normalized, frame_rate


def _detect_silence_midpoints_in_window(
    audio: AudioSegment,
    *,
    min_silence_ms: int,
    silence_threshold_db: float,
    offset_ms: int = 0,
) -> List[int]:
    """
    Detect silence midpoints within a short audio window and return absolute millisecond offsets.
    """
    samples, sample_rate = _audio_segment_to_ndarray(audio)
    silence_seconds = max(min_silence_ms / 1000.0, 0.1)
    silence_intervals = _detect_silence_intervals(
        samples,
        sample_rate,
        min_silence_duration=silence_seconds,
        silence_threshold=silence_threshold_db,
    )
    return [
        offset_ms + int(((start + end) / 2) * 1000 / sample_rate)
        for start, end in silence_intervals
        if end > start
    ]


def _detect_silence_midpoints_parallel(
    audio: AudioSegment,
    *,
    min_silence_ms: int,
    silence_threshold_db: float,
    window_ms: int = 240_000,
) -> Tuple[List[int], int]:
    """
    Split the audio into overlapping windows and detect silence midpoints in parallel.
    Returns (sorted_midpoints, window_count).
    """
    total_duration_ms = len(audio)
    if total_duration_ms <= 0:
        return [], 0

    effective_window = max(window_ms, min_silence_ms * 4, 60_000)
    overlap_ms = max(min_silence_ms * 2, 2_000)
    step_ms = max(10_000, effective_window - overlap_ms)

    futures: List[Any] = []
    start_ms = 0
    while start_ms < total_duration_ms:
        end_ms = min(total_duration_ms, start_ms + effective_window)
        segment = audio[start_ms:end_ms]
        futures.append(
            executor.submit(
                _detect_silence_midpoints_in_window,
                segment,
                min_silence_ms=min_silence_ms,
                silence_threshold_db=silence_threshold_db,
                offset_ms=start_ms,
            )
        )
        if end_ms >= total_duration_ms:
            break
        start_ms += step_ms

    midpoints: List[int] = []
    for future in futures:
        try:
            midpoints.extend(future.result())
        except Exception as exc:
            print(f"⚠️ Silence detection window failed: {exc}")

    return sorted(set(midpoints)), len(futures)


def _plan_chunk_ranges(
    audio: AudioSegment,
    *,
    min_chunk_ms: int,
    max_chunk_ms: int,
    min_silence_ms: int = CHUNK_SPLIT_MIN_SILENCE_MS,
    silence_threshold_db: float = CHUNK_SPLIT_SILENCE_THRESHOLD_DB,
) -> Tuple[List[Dict[str, Any]], Dict[str, Any]]:
    """
    Determine chunk boundaries for long-form audio by opportunistically snapping to nearby silence.
    Returns a list of chunk metadata dictionaries plus diagnostics.
    """
    total_duration_ms = len(audio)
    if total_duration_ms <= 0:
        return [(0, 0)], {"silence_probes": 0}
    min_chunk_ms = max(60_000, int(min_chunk_ms))
    max_chunk_ms = max(min_chunk_ms, int(max_chunk_ms))
    if total_duration_ms <= max_chunk_ms:
        return [(0, total_duration_ms)], {"silence_probes": 0}

    silence_midpoints_ms, probe_windows = _detect_silence_midpoints_parallel(
        audio,
        min_silence_ms=min_silence_ms,
        silence_threshold_db=silence_threshold_db,
        window_ms=max(max_chunk_ms * 2, 240_000),
    )

    chunk_ranges: List[Dict[str, Any]] = []
    current_start = 0
    pointer = 0
    grace_window = min(CHUNK_SPLIT_SILENCE_GRACE_MS, max_chunk_ms // 2 or 15_000)

    while current_start < total_duration_ms and len(chunk_ranges) < CHUNK_SPLIT_MAX_CHUNKS:
        desired_min = current_start + min_chunk_ms
        desired_max = min(current_start + max_chunk_ms, total_duration_ms)
        candidate_cut: Optional[int] = None
        candidate_after_window: Optional[int] = None
        cut_from_silence = False

        while pointer < len(silence_midpoints_ms) and silence_midpoints_ms[pointer] <= current_start:
            pointer += 1

        lookahead = pointer
        while lookahead < len(silence_midpoints_ms):
            point = silence_midpoints_ms[lookahead]
            if point < desired_min:
                lookahead += 1
                continue
            if point <= desired_max:
                candidate_cut = point
                cut_from_silence = True
                pointer = lookahead + 1
                break
            candidate_after_window = point
            pointer = lookahead + 1
            break

        if candidate_cut is None and candidate_after_window is not None:
            if candidate_after_window - desired_max <= grace_window:
                candidate_cut = candidate_after_window
                cut_from_silence = True

        if candidate_cut is None:
            candidate_cut = desired_max
            cut_from_silence = False

        if candidate_cut <= current_start:
            candidate_cut = min(total_duration_ms, max(current_start + min_chunk_ms, current_start + 1000))
            cut_from_silence = False

        chunk_ranges.append(
            {
                "start_ms": current_start,
                "end_ms": candidate_cut,
                "cut_reason": "silence_center" if cut_from_silence else "hard_limit",
                "silence_midpoint_ms": candidate_cut if cut_from_silence else None,
            }
        )
        current_start = candidate_cut

    if chunk_ranges:
        last_range = chunk_ranges[-1]
        if last_range["end_ms"] < total_duration_ms:
            last_range["end_ms"] = total_duration_ms
            if last_range["cut_reason"] != "silence_center":
                last_range["cut_reason"] = "hard_limit"

    merged_ranges: List[Dict[str, Any]] = []
    for entry in chunk_ranges:
        start_ms = entry["start_ms"]
        end_ms = entry["end_ms"]
        duration = end_ms - start_ms
        if merged_ranges and duration < max(10_000, int(0.25 * min_chunk_ms)):
            merged_ranges[-1]["end_ms"] = end_ms
            merged_ranges[-1]["cut_reason"] = entry["cut_reason"]
            merged_ranges[-1]["silence_midpoint_ms"] = entry.get("silence_midpoint_ms")
        else:
            merged_ranges.append(entry)

    return merged_ranges, {"silence_probes": probe_windows, "silence_points": len(silence_midpoints_ms)}


def _append_suffix_to_path(file_path: str, suffix: str) -> str:
    """Create a new path with the given suffix before the extension."""
    path_obj = Path(file_path)
    return str(path_obj.with_name(f"{path_obj.stem}{suffix}{path_obj.suffix}"))


def _persist_audio_upload(bytes_data: bytes, original_filename: Optional[str] = None) -> str:
    """Persist uploaded audio bytes to a temporary file and return its path."""
    suffix = ".tmp"
    if original_filename:
        _, ext = os.path.splitext(original_filename)
        if ext:
            suffix = ext.lower()
    fd, temp_path = tempfile.mkstemp(suffix=suffix)
    try:
        with os.fdopen(fd, "wb") as temp_file:
            temp_file.write(bytes_data)
    except Exception:
        try:
            os.remove(temp_path)
        except Exception:
            pass
        raise
    return temp_path


def _transcode_audio_to_wav(source_path: str) -> str:
    """Transcode an arbitrary audio file to WAV (48 kHz PCM16)."""
    fd, temp_path = tempfile.mkstemp(suffix=".wav")
    os.close(fd)
    cmd = [
        "ffmpeg",
        "-y",
        "-i",
        source_path,
        "-acodec",
        "pcm_s16le",
        "-ar",
        "48000",
        temp_path,
    ]
    try:
        subprocess.run(
            cmd,
            stdout=subprocess.DEVNULL,
            stderr=subprocess.PIPE,
            check=True,
        )
    except subprocess.CalledProcessError as exc:
        try:
            os.remove(temp_path)
        except Exception:
            pass
        stderr_msg = exc.stderr.decode("utf-8", errors="ignore") if exc.stderr else ""
        raise RuntimeError(f"Failed to transcode audio for ClearVoice: {stderr_msg.strip()}") from exc
    return temp_path


async def _normalize_audio_to_cached(
    source_path: str,
    target_path: str,
    *,
    delete_source: bool = False,
) -> str:
    """Convert ClearVoice output to MP3 and save it to cache."""
    # Load the audio from source (WAV from ClearVoice)
    audio = await _load_audio_segment_from_path(source_path)
    # Export as MP3 to cache
    os.makedirs(os.path.dirname(target_path), exist_ok=True)
    audio.export(target_path, format="mp3", bitrate="128k")
    if delete_source and os.path.exists(source_path) and source_path != target_path:
        try:
            os.remove(source_path)
        except Exception as exc:
            print(f"⚠️ Failed to delete temp ClearVoice output {source_path}: {exc}")
    return target_path


async def _normalize_uploaded_audio(source_path: str) -> str:
    """
    Normalize user-uploaded audio to canonical WAV (48 kHz PCM16) before
    ClearVoice processing and backing extraction.
    """
    normalized_path = await _run_blocking(_transcode_audio_to_wav, source_path)
    if os.path.exists(source_path) and source_path != normalized_path:
        try:
            os.remove(source_path)
        except Exception as exc:
            print(f"⚠️ Failed to remove original upload {source_path}: {exc}")
    return normalized_path


async def _ensure_clearvoice_input_path(source_path: str) -> Tuple[str, bool]:
    """
    Ensure the ClearVoice input is a WAV file on disk.
    Returns (path, created_temp_flag).
    """
    if source_path.lower().endswith(".wav"):
        return source_path, False
    temp_wav_path = await _run_blocking(_transcode_audio_to_wav, source_path)
    return temp_wav_path, True


def _chunk_output_url(session: TranslateSessionData) -> Optional[str]:
    if session.chunk_output_filename:
        return f"/api/translate_outputs/{session.chunk_output_filename}"
    return None


def _serialize_chunk_session(session: TranslateSessionData) -> Dict[str, Any]:
    start_ms = max(0, session.chunk_start_ms or 0)
    end_ms = max(start_ms, session.chunk_end_ms or _session_audio_duration_ms(session))
    duration_ms = max(0, end_ms - start_ms)
    audio_url = _chunk_output_url(session)
    backing_available = _session_has_backing_audio(session)
    return {
        "chunk_index": session.chunk_index,
        "session_id": session.session_id,
        "reuse_session_id": session.session_id,
        "start_ms": start_ms,
        "end_ms": end_ms,
        "duration_ms": duration_ms,
        "start_label": _format_ms_to_timestamp(start_ms),
        "end_label": _format_ms_to_timestamp(end_ms),
        "duration_label": _format_ms_to_timestamp(duration_ms),
        "generated": bool(session.chunk_generated),
        "generated_at": session.chunk_generated_at,
        "audio_url": audio_url,
        "output_format": session.chunk_output_format,
        "output_filename": session.chunk_output_filename,
        "backing_available": backing_available,
        "backing_source": session.backing_track_source or "none",
        "vocals_url": f"/api/translate_vocals/{session.session_id}",
        "backing_url": f"/api/translate_backing_track/{session.session_id}" if backing_available else None,
        "batch_id": session.chunk_parent_id,
        "cut_reason": session.chunk_cut_reason or "unknown",
        "silence_midpoint_ms": session.chunk_silence_midpoint_ms,
    }


def _mark_chunk_generated(
    session: TranslateSessionData,
    output_path: str,
    output_filename: str,
    response_format: str,
) -> None:
    session.chunk_generated = True
    session.chunk_output_path = output_path
    session.chunk_output_filename = output_filename
    session.chunk_output_format = response_format
    session.chunk_generated_at = time.time()


async def _generate_chunk_audio_from_session(
    chunk_session: TranslateSessionData,
    *,
    dest_language: str,
    response_format: str,
    bitrate: str,
    gemini_model: str,
    gemini_api_key: Optional[str],
    ignore_non_speech: bool,
    preserve_silence_audio: bool,
    generated_volume_percent: float,
    backing_volume_percent: float,
    merge_backing_track: bool,
) -> Tuple[str, str, Dict[str, Any]]:
    clearvoice_settings = chunk_session.clearvoice_settings or {}
    apply_enhancement = bool(clearvoice_settings.get("enhancement"))
    apply_super_resolution = bool(clearvoice_settings.get("super_resolution"))

    (
        original_audio,
        input_mime_type_value,
        processed_audio_bytes,
        gemini_mime_type,
        backing_track_audio,
        merge_with_backing,
        backing_track_source,
    ) = await _prepare_audio_assets(
        reuse_source_session=chunk_session,
        audio_file=None,
        audio_reference=None,
        preloaded_audio_bytes=None,
        audio_mime_type_value=chunk_session.input_mime_type,
        apply_enhancement=apply_enhancement,
        apply_super_resolution=apply_super_resolution,
        requested_merge_backing=merge_backing_track,
        custom_backing_audio_file=None,
        custom_backing_audio_reference=None,
        custom_backing_mime_type_value=None,
        emit_status=None,
    )

    final_prompt = _resolve_final_prompt(
        chunk_session.prompt,
        dest_language,
        True,
        ignore_non_speech,
    )

    segment_result = await _build_translation_segments(
        original_audio=original_audio,
        processed_audio_bytes=processed_audio_bytes,
        gemini_mime_type=gemini_mime_type,
        dest_language=dest_language,
        final_prompt=final_prompt,
        translate_enabled=True,
        response_format_value=response_format,
        bitrate_value=bitrate,
        input_mime_type=input_mime_type_value,
        apply_enhancement=apply_enhancement,
        apply_super_resolution=apply_super_resolution,
        ignore_non_speech_flag=ignore_non_speech,
        preserve_silence_audio_flag=preserve_silence_audio,
        generated_volume_percent_value=generated_volume_percent,
        backing_volume_percent_value=backing_volume_percent,
        backing_track_audio=backing_track_audio,
        backing_track_source=backing_track_source,
        merge_with_backing=merge_with_backing,
        segments_override_value=None,
        min_speech_duration=MIN_SPEECH_DURATION_MS,
        max_merge_interval=MAX_MERGE_INTERVAL_MS,
        resolved_gemini_model=gemini_model,
        gemini_api_key_value=(gemini_api_key or "").strip() or None,
        emit_status=None,
        source_chunk_session=chunk_session,
    )

    audio_payload, _media_type, synthesis_metadata = await _synthesize_translated_audio(
        original_audio,
        segment_result.segments,
        dest_language,
        response_format=response_format,
        bitrate=bitrate,
        input_mime_type=input_mime_type_value,
        clearvoice_settings=clearvoice_settings,
        backing_track_audio=backing_track_audio,
        backing_track_source=backing_track_source,
        merge_with_backing=merge_with_backing,
        preserve_silence_audio=preserve_silence_audio,
        generated_volume_percent=generated_volume_percent,
        speaker_overrides=chunk_session.speaker_overrides,
        backing_volume_percent=backing_volume_percent,
    )

    metadata = dict(segment_result.metadata)
    metadata.update(synthesis_metadata or {})
    metadata["ignore_non_speech"] = ignore_non_speech
    metadata["preserve_silence_audio"] = preserve_silence_audio
    metadata["generated_volume_percent"] = generated_volume_percent
    metadata["backing_volume_percent"] = backing_volume_percent
    metadata["gemini_model"] = gemini_model

    output_filename = f"translate_chunk_{chunk_session.session_id}_{uuid.uuid4().hex}.{response_format}"
    output_path = os.path.join(TRANSLATE_OUTPUT_DIR, output_filename)
    with open(output_path, "wb") as outfile:
        outfile.write(audio_payload)
    audio_url = f"/api/translate_outputs/{output_filename}"

    _mark_chunk_generated(chunk_session, output_path, output_filename, response_format)
    metadata["chunk"] = _serialize_chunk_session(chunk_session)

    chunk_session.dest_language = dest_language
    chunk_session.ignore_non_speech = ignore_non_speech
    chunk_session.preserve_silence_audio = preserve_silence_audio
    chunk_session.generated_volume_percent = generated_volume_percent
    chunk_session.backing_volume_percent = backing_volume_percent
    chunk_session.gemini_model = gemini_model

    await _update_translate_session_metadata(
        chunk_session.session_id,
        response_format=response_format,
        bitrate=bitrate,
        gemini_model=gemini_model,
        generated_volume_percent=generated_volume_percent,
        backing_volume_percent=backing_volume_percent,
    )
    await _update_translate_session_segments(
        chunk_session.session_id,
        segment_result.ui_segments,
    )

    return audio_url, output_filename, metadata


def _load_chunk_audio_for_merge(session: TranslateSessionData) -> Optional[AudioSegment]:
    if (
        session.chunk_generated
        and session.chunk_output_path
        and os.path.exists(session.chunk_output_path)
    ):
        ext = os.path.splitext(session.chunk_output_path)[1].lstrip(".") or None
        try:
            return AudioSegment.from_file(session.chunk_output_path, format=ext)
        except Exception as exc:
            print(f"⚠️ Failed to load generated chunk audio ({session.session_id}): {exc}")
    try:
        return _get_session_original_audio(session)
    except RuntimeError as exc:
        print(f"⚠️ Chunk session '{session.session_id}' is missing original audio: {exc}")
        return None


def _extract_backing_track_from_vocals(
    original_mix: AudioSegment,
    enhanced_vocals: AudioSegment,
) -> Optional[AudioSegment]:
    """
    Approximate an instrumental backing track by subtracting the ClearVoice
    MossFormer2 vocals estimate from the original mixture.
    """
    if original_mix is None or enhanced_vocals is None:
        return None

    try:
        target_rate = int(original_mix.frame_rate or enhanced_vocals.frame_rate or 44100)
        target_channels = int(original_mix.channels or enhanced_vocals.channels or 1)
        target_sample_width = 2  # work in int16 space for predictable clipping

        mix_aligned = (
            original_mix.set_frame_rate(target_rate)
            .set_channels(target_channels)
            .set_sample_width(target_sample_width)
        )
        vocals_aligned = (
            enhanced_vocals.set_frame_rate(target_rate)
            .set_channels(target_channels)
            .set_sample_width(target_sample_width)
        )

        mix_samples = np.array(mix_aligned.get_array_of_samples(), dtype=np.float32)
        vocal_samples = np.array(vocals_aligned.get_array_of_samples(), dtype=np.float32)

        if target_channels > 1:
            mix_samples = mix_samples.reshape((-1, target_channels))
            vocal_samples = vocal_samples.reshape((-1, target_channels))

        min_len = min(len(mix_samples), len(vocal_samples))
        if min_len == 0:
            return None

        residual = np.copy(mix_samples)
        residual[:min_len] = mix_samples[:min_len] - vocal_samples[:min_len]
        if len(mix_samples) > min_len:
            residual[min_len:] = mix_samples[min_len:]

        clip_min = np.iinfo(np.int16).min
        clip_max = np.iinfo(np.int16).max
        residual = np.clip(residual, clip_min, clip_max).astype(np.int16)

        if target_channels > 1:
            residual = residual.reshape(-1)

        return AudioSegment(
            residual.tobytes(),
            frame_rate=target_rate,
            sample_width=target_sample_width,
            channels=target_channels,
        )
    except Exception as exc:
        print(f"⚠️ Failed to extract backing track from ClearVoice output: {exc}")
        return None


def _apply_clearvoice_processing_sync(
    input_path: str,
    apply_enhancement: bool,
    apply_super_resolution: bool,
) -> Tuple[str, List[str], Optional[str]]:
    """Run ClearVoice enhancement/super-resolution synchronously."""
    global _enhancement_model, _super_res_model
    
    if ClearVoice is None:
        raise RuntimeError("ClearVoice package is not available in the environment.")
    
    generated_paths: List[str] = []
    enhancement_output_path: Optional[str] = None
    current_input = input_path
    final_path = input_path
    
    try:
        if apply_enhancement:
            print("✨ ClearVoice: Applying MossFormer2_SE_48K enhancement...")
            # Initialize enhancement model if not already created
            if _enhancement_model is None:
                print("🔧 Initializing enhancement model (first use)...")
                _enhancement_model = ClearVoice(task="speech_enhancement", model_names=["MossFormer2_SE_48K"])
            enhancement_output = _enhancement_model(input_path=current_input, online_write=False)
            enhanced_path = _append_suffix_to_path(current_input, "_se")
            _enhancement_model.write(enhancement_output, output_path=enhanced_path)
            generated_paths.append(enhanced_path)
            final_path = enhanced_path
            current_input = enhanced_path
            enhancement_output_path = enhanced_path
            print(f"✅ ClearVoice: Enhancement saved to {os.path.basename(enhanced_path)}")
        
        if apply_super_resolution:
            print("🎛️ ClearVoice: Applying MossFormer2_SR_48K super-resolution...")
            # Initialize super-resolution model if not already created
            if _super_res_model is None:
                print("🔧 Initializing super-resolution model (first use)...")
                _super_res_model = ClearVoice(task="speech_super_resolution", model_names=["MossFormer2_SR_48K"])
            super_res_output = _super_res_model(input_path=current_input, online_write=False)
            super_res_path = _append_suffix_to_path(current_input, "_sr")
            _super_res_model.write(super_res_output, output_path=super_res_path)
            generated_paths.append(super_res_path)
            final_path = super_res_path
            print(f"✅ ClearVoice: Super-resolution saved to {os.path.basename(super_res_path)}")
        
        return final_path, generated_paths, enhancement_output_path
    except Exception:
        for created_path in generated_paths:
            try:
                os.remove(created_path)
            except Exception:
                pass
        raise


async def apply_clearvoice_processing(
    input_path: str,
    apply_enhancement: bool,
    apply_super_resolution: bool,
) -> Tuple[str, List[str], Optional[str]]:
    """Async wrapper for ClearVoice processing."""
    if not (apply_enhancement or apply_super_resolution):
        return input_path, []
    
    loop = asyncio.get_event_loop()
    return await loop.run_in_executor(
        executor,
        _apply_clearvoice_processing_sync,
        input_path,
        apply_enhancement,
        apply_super_resolution,
    )

async def convert_audio_to_format(wav_data, sample_rate, output_format="mp3", bitrate="128k"):
    """Convert audio data to specified format (MP3 or WAV)"""
    loop = asyncio.get_event_loop()
    return await loop.run_in_executor(executor, _convert_audio_to_format_sync, wav_data, sample_rate, output_format, bitrate)

def _convert_audio_to_format_sync(wav_data, sample_rate, output_format="mp3", bitrate="128k"):
    """Synchronous audio format conversion"""
    try:
        # Convert numpy array to AudioSegment
        # Ensure wav_data is in the right format
        if wav_data.dtype != 'int16':
            # Convert float to int16
            wav_data = (wav_data * 32767).astype('int16')
        
        # Create AudioSegment from raw audio data
        audio_segment = AudioSegment(
            wav_data.tobytes(),
            frame_rate=sample_rate,
            sample_width=wav_data.dtype.itemsize,
            channels=1 if len(wav_data.shape) == 1 else wav_data.shape[1]
        )
        
        # Export to desired format
        with BytesIO() as output_buffer:
            if output_format.lower() == "mp3":
                audio_segment.export(output_buffer, format="mp3", bitrate=bitrate)
                media_type = "audio/mpeg"
                file_extension = "mp3"
            else:
                audio_segment.export(output_buffer, format="wav")
                media_type = "audio/wav" 
                file_extension = "wav"
            
            return output_buffer.getvalue(), media_type, file_extension
            
    except Exception as e:
        print(f"⚠️ Audio conversion failed, falling back to WAV: {e}")
        # Fallback to original soundfile method
        with BytesIO() as wav_buffer:
            sf.write(wav_buffer, wav_data, sample_rate, format='WAV')
            return wav_buffer.getvalue(), "audio/wav", "wav"


# Gemini translation helpers
def _get_gemini_model_name() -> str:
    return os.getenv(GEMINI_MODEL_ENV_VAR, DEFAULT_GEMINI_MODEL_NAME)


def _strip_code_fences(text: str) -> str:
    if not text:
        return ""
    match = JSON_FENCE_PATTERN.search(text)
    if match:
        return match.group(1).strip()
    text = text.strip()
    if text.startswith("```") and text.endswith("```"):
        return text[3:-3].strip()
    # Fallback: extract JSON array if present
    start = text.find("[")
    end = text.rfind("]")
    if start != -1 and end != -1 and end > start:
        return text[start:end + 1].strip()
    return text


def _coerce_gemini_json_payload(raw: str) -> Optional[str]:
    trimmed = (raw or "").strip()
    if not trimmed:
        return None
    match = COERCE_SPEAKER_SEGMENTS_PATTERN.match(trimmed)
    if match:
        speakers_part, segments_part = match.groups()
        return f'{{"speakers": {speakers_part}, "segments": {segments_part}}}'
    return None


SPEAKER_ID_PATTERN = re.compile(r"^speaker\s*(\d+)$", re.IGNORECASE)


def _canonicalize_speaker_id(raw_value: Any, fallback_index: int) -> str:
    fallback_index = max(1, int(fallback_index))
    if isinstance(raw_value, (int, float)) and raw_value >= 1:
        return f"speaker{int(raw_value)}"
    if isinstance(raw_value, str):
        candidate = raw_value.strip()
        if not candidate:
            return f"speaker{fallback_index}"
        match = SPEAKER_ID_PATTERN.match(candidate)
        if match:
            return f"speaker{int(match.group(1))}"
        digits = re.findall(r"\d+", candidate)
        if digits:
            return f"speaker{int(digits[0])}"
    return f"speaker{fallback_index}"


def _normalize_speaker_profiles(raw_profiles: Any) -> List[Dict[str, Any]]:
    if not isinstance(raw_profiles, list):
        return []
    normalized: List[Dict[str, Any]] = []
    used_ids: Set[str] = set()
    for idx, entry in enumerate(raw_profiles, start=1):
        entry_dict: Dict[str, Any]
        if isinstance(entry, dict):
            entry_dict = entry
        else:
            entry_dict = {"description": str(entry)}
        candidate_id = entry_dict.get("id") or entry_dict.get("speaker") or entry_dict.get("label") or entry_dict.get("name")
        speaker_id = _canonicalize_speaker_id(candidate_id, idx)
        while speaker_id in used_ids:
            idx += 1
            speaker_id = _canonicalize_speaker_id(None, idx)
        used_ids.add(speaker_id)
        description = str(
            entry_dict.get("description")
            or entry_dict.get("summary")
            or entry_dict.get("traits")
            or entry_dict.get("role")
            or ""
        ).strip()
        if not description:
            description = f"{speaker_id.title()} voice"
        display_name = str(entry_dict.get("label") or entry_dict.get("name") or speaker_id.title()).strip()
        normalized.append(
            {
                "id": speaker_id,
                "label": display_name or speaker_id.title(),
                "description": description,
            }
        )
    return normalized


def _normalize_speaker_overrides(
    raw_overrides: Optional[Dict[str, Any]],
    speaker_profiles: Optional[List[Dict[str, Any]]] = None,
) -> Dict[str, Dict[str, Any]]:
    if not isinstance(raw_overrides, dict):
        return {}
    valid_ids = {profile.get("id") for profile in (speaker_profiles or []) if profile.get("id")}
    normalized: Dict[str, Dict[str, Any]] = {}
    for key, value in raw_overrides.items():
        if not isinstance(key, str):
            continue
        speaker_id = _canonicalize_speaker_id(key, fallback_index=1).lower()
        if valid_ids and speaker_id not in valid_ids:
            continue
        if not isinstance(value, dict):
            continue
        preset_name = str(value.get("preset_name") or "").strip()
        volume_value = value.get("volume_percent")
        has_volume_override = volume_value is not None
        if not preset_name and not has_volume_override:
            continue
        entry: Dict[str, Any] = {}
        if preset_name:
            entry["preset_name"] = preset_name
            entry["use_emotion_prompt"] = bool(value.get("use_emotion_prompt"))
            entry["emotion_weight"] = _coerce_emotion_weight(
                value.get("emotion_weight"),
                DEFAULT_EMOTION_WEIGHT,
            )
        if has_volume_override:
            entry["volume_percent"] = _coerce_volume_percent(
                volume_value,
                DEFAULT_GENERATED_VOLUME_PERCENT,
            )
        normalized[speaker_id] = entry
    return normalized


def _parse_gemini_json(text: str) -> Tuple[List[Dict[str, Any]], List[Dict[str, Any]]]:
    cleaned = _strip_code_fences(text)
    try:
        data = json.loads(cleaned)
    except json.JSONDecodeError as exc:
        coerced_payload = _coerce_gemini_json_payload(cleaned)
        if coerced_payload:
            try:
                data = json.loads(coerced_payload)
            except json.JSONDecodeError as coerced_exc:
                preview = cleaned if len(cleaned) <= 4000 else f"{cleaned[:4000]}...<truncated>"
                print("❌ Gemini JSON parse error (after coercion). Raw response preview:\n", preview)
                raise ValueError(f"Gemini returned invalid JSON: {coerced_exc}") from coerced_exc
        else:
            preview = cleaned if len(cleaned) <= 4000 else f"{cleaned[:4000]}...<truncated>"
            print("❌ Gemini JSON parse error. Raw response preview:\n", preview)
            raise ValueError(f"Gemini returned invalid JSON: {exc}") from exc
    if isinstance(data, list):
        return data, []
    if isinstance(data, dict):
        segments = data.get("segments")
        if not isinstance(segments, list):
            raise ValueError("Gemini response must include a 'segments' array.")
        speaker_profiles = _normalize_speaker_profiles(data.get("speakers"))
        return segments, speaker_profiles
    raise ValueError("Gemini response must be a JSON object or array.")


def _extract_text_from_gemini_response(response: Any) -> str:
    if response is None:
        return ""

    for attr in ("text", "output_text", "output_texts"):
        value = getattr(response, attr, None)
        if isinstance(value, str) and value.strip():
            return value.strip()
        if isinstance(value, list) and value:
            concatenated = "\n".join(str(item) for item in value if item)
            if concatenated.strip():
                return concatenated.strip()

    parts_text: List[str] = []

    candidates = getattr(response, "candidates", None)
    if candidates:
        for candidate in candidates:
            content = getattr(candidate, "content", None)
            if content is not None:
                parts = getattr(content, "parts", None)
                if parts:
                    for part in parts:
                        part_text = getattr(part, "text", None)
                        if isinstance(part_text, str) and part_text.strip():
                            parts_text.append(part_text.strip())
            if isinstance(candidate, dict):
                for part in candidate.get("content", {}).get("parts", []):
                    part_text = part.get("text")
                    if isinstance(part_text, str) and part_text.strip():
                        parts_text.append(part_text.strip())

    if not parts_text:
        contents = getattr(response, "contents", None)
        if contents:
            for content in contents:
                parts = getattr(content, "parts", None)
                if parts:
                    for part in parts:
                        part_text = getattr(part, "text", None)
                        if isinstance(part_text, str) and part_text.strip():
                            parts_text.append(part_text.strip())
                elif isinstance(content, dict):
                    for part in content.get("parts", []):
                        part_text = part.get("text")
                        if isinstance(part_text, str) and part_text.strip():
                            parts_text.append(part_text.strip())

    return "\n".join(parts_text).strip()


def _parse_timestamp_to_ms(timestamp_value: Any) -> Optional[int]:
    if timestamp_value is None:
        return None
    if isinstance(timestamp_value, (int, float)):
        # Treat integer millisecond values separately
        if isinstance(timestamp_value, int) and timestamp_value >= 1000:
            return max(0, int(timestamp_value))
        seconds = float(timestamp_value)
        return max(0, int(round(seconds * 1000)))
    value = str(timestamp_value).strip()
    if not value:
        return None
    value = value.replace(",", ".")
    # Try simple numeric parse
    if re.fullmatch(r"\d+(?:\.\d+)?", value):
        seconds = float(value)
        return max(0, int(seconds * 1000))
    # Handle colon-delimited formats (e.g., hh:mm:ss.xxx or mm:ss)
    parts = value.split(":")
    try:
        parts = [p.strip() for p in parts if p.strip()]
        if not parts:
            return None
        total_seconds = 0.0
        multiplier = 1.0
        for part in reversed(parts):
            if "." in part:
                seconds = float(part)
            else:
                seconds = float(int(part))
            total_seconds += seconds * multiplier
            multiplier *= 60.0
        return max(0, int(round(total_seconds * 1000)))
    except ValueError:
        return None


def _format_ms_to_timestamp(milliseconds: int) -> str:
    ms = max(0, int(milliseconds))
    total_seconds = ms / 1000.0
    hours = int(total_seconds // 3600)
    minutes = int((total_seconds % 3600) // 60)
    seconds = total_seconds % 60
    if abs(seconds - round(seconds)) < 1e-3:
        seconds_str = f"{int(round(seconds)):02d}"
    else:
        seconds_str = f"{seconds:06.3f}".rstrip("0").rstrip(".")
        if seconds < 10 and not seconds_str.startswith("0"):
            seconds_str = "0" + seconds_str
    if hours > 0:
        return f"{hours:02d}:{minutes:02d}:{seconds_str}"
    return f"{minutes:02d}:{seconds_str}"


def _find_case_insensitive_key(data: Dict[str, Any], candidates: List[str], ignore: Set[str]) -> Optional[str]:
    lowered = {str(k).lower(): k for k in data.keys()}
    for candidate in candidates:
        candidate_lower = candidate.lower()
        if candidate_lower in lowered:
            if candidate_lower in ignore:
                continue
            return lowered[candidate_lower]
    return None


def _extract_text_fields(entry: Dict[str, Any], dest_language: str) -> Tuple[Optional[str], Optional[str], Optional[str], Optional[str]]:
    ignore_keys = {
        "start",
        "end",
        "start_time",
        "end_time",
        "start_ms",
        "end_ms",
        "duration",
        "duration_ms",
        "timestamp",
        "time",
        "index",
        "type",
        "speaker",
        "language",
        "source_language",
        "target_language",
    }
    lower_dest = dest_language.lower() if dest_language else ""
    translation_candidates = [
        "translated_text",
        "translation",
        "translation_text",
        "target_text",
        "target",
        "output",
        "output_text",
        "translation_result",
        "english",
        "en",
    ]
    if lower_dest:
        translation_candidates.extend([
            lower_dest,
            lower_dest.replace("-", "_"),
            lower_dest.replace(" ", "_"),
        ])
    source_candidates = [
        "source_text",
        "source",
        "original_text",
        "original",
        "transcript",
        "transcription",
        "input_text",
        "utterance",
        "text",
        "chinese",
        "zh",
        "cn",
    ]
    translation_key = _find_case_insensitive_key(entry, translation_candidates, ignore_keys)
    source_key = _find_case_insensitive_key(entry, source_candidates, ignore_keys)

    def _fallback_key(preferred_key: Optional[str]) -> Optional[str]:
        if preferred_key is not None:
            return preferred_key
        for key, value in entry.items():
            key_lower = str(key).lower()
            if key_lower in ignore_keys:
                continue
            if isinstance(value, str) and value.strip():
                return key
        return None

    source_key = _fallback_key(source_key)
    translation_key = _fallback_key(translation_key)

    source_text = entry.get(source_key) if source_key else None
    translated_text = entry.get(translation_key) if translation_key else None
    return source_text, translated_text, source_key, translation_key


def _coerce_to_bool(value: Any) -> bool:
    if isinstance(value, bool):
        return value
    if value is None:
        return False
    if isinstance(value, str):
        return value.strip().lower() in {"1", "true", "yes", "on"}
    return bool(value)


def _coerce_positive_int(
    value: Any,
    default: int,
    *,
    min_value: int = 0,
    max_value: Optional[int] = None,
) -> int:
    if value is None:
        return default
    try:
        parsed = int(value)
    except (TypeError, ValueError):
        return default
    if parsed < min_value:
        return min_value
    if max_value is not None and parsed > max_value:
        return max_value
    return parsed


def _coerce_positive_float(
    value: Any,
    default: float,
    *,
    min_value: float = 0.0,
    max_value: Optional[float] = None,
) -> float:
    if value is None:
        return max(default, min_value)
    try:
        parsed = float(value)
    except (TypeError, ValueError):
        return max(default, min_value)
    if not math.isfinite(parsed):
        return max(default, min_value)
    parsed = max(parsed, min_value)
    if max_value is not None:
        parsed = min(parsed, max_value)
    return parsed


def _coerce_float_range(
    value: Any,
    default: float,
    *,
    min_value: Optional[float] = None,
    max_value: Optional[float] = None,
) -> float:
    if value is None:
        return default
    try:
        parsed = float(value)
    except (TypeError, ValueError):
        return default
    if not math.isfinite(parsed):
        return default
    if min_value is not None and parsed < min_value:
        parsed = min_value
    if max_value is not None and parsed > max_value:
        parsed = max_value
    return parsed


def _coerce_volume_percent(
    value: Any,
    default: float = DEFAULT_GENERATED_VOLUME_PERCENT,
) -> float:
    if value is None:
        return default
    try:
        parsed = float(value)
    except (TypeError, ValueError):
        return default
    if not math.isfinite(parsed):
        return default
    if parsed < MIN_GENERATED_VOLUME_PERCENT:
        return MIN_GENERATED_VOLUME_PERCENT
    if parsed > MAX_GENERATED_VOLUME_PERCENT:
        return MAX_GENERATED_VOLUME_PERCENT
    return parsed


def _coerce_emotion_weight(value: Any, default: float = DEFAULT_EMOTION_WEIGHT) -> float:
    if value is None:
        return default
    try:
        parsed = float(value)
    except (TypeError, ValueError):
        return default
    if not math.isfinite(parsed):
        return default
    if parsed < 0.0:
        return 0.0
    if parsed > 1.0:
        return 1.0
    return parsed


def _parse_manual_segments_input(
    raw: Optional[str],
) -> Optional[Tuple[List[Dict[str, Any]], List[Dict[str, Any]]]]:
    """
    Parse user-supplied Gemini segment JSON.
    Accepts either a JSON array or an object with "segments" and optional "speakers".
    """
    if raw is None:
        return None
    raw_str = str(raw).strip()
    if not raw_str:
        return None
    try:
        parsed = json.loads(raw_str)
    except json.JSONDecodeError as exc:
        raise ValueError(f"segments_json is not valid JSON: {exc}") from exc

    speaker_profiles: List[Dict[str, Any]] = []
    if isinstance(parsed, dict):
        speaker_profiles = _normalize_speaker_profiles(parsed.get("speakers"))
        parsed = parsed.get("segments")

    if not isinstance(parsed, list):
        raise ValueError("segments_json must be a JSON array of segment objects.")
    if not parsed:
        raise ValueError("segments_json array is empty.")

    cleaned: List[Dict[str, Any]] = []
    for idx, entry in enumerate(parsed):
        if not isinstance(entry, dict):
            raise ValueError(f"segments_json[{idx}] is not an object.")
        cleaned.append(entry)
    return cleaned, speaker_profiles


def _merge_short_speech_segments(
    segments: List[Dict[str, Any]],
    min_duration_ms: int,
    max_merge_interval_ms: int = MAX_MERGE_INTERVAL_MS,
) -> List[Dict[str, Any]]:
    max_merge_interval_ms = max(0, int(max_merge_interval_ms))
    if max_merge_interval_ms == 0:
        no_merge_segments: List[Dict[str, Any]] = []
        for idx, segment in enumerate(segments):
            clone = dict(segment)
            clone["index"] = idx
            no_merge_segments.append(clone)
        return no_merge_segments
    merged_segments: List[Dict[str, Any]] = []
    i = 0
    total = len(segments)

    def _concat_text(a: Optional[str], b: Optional[str]) -> str:
        parts = [part.strip() for part in [a or "", b or ""] if part and part.strip()]
        return " ".join(parts)

    while i < total:
        segment = segments[i]
        if segment.get("type") != "speech":
            merged_segments.append(segment)
            i += 1
            continue

        start_ms = int(segment.get("start_ms", 0))
        end_ms = int(segment.get("end_ms", start_ms))
        source_text = segment.get("source_text", "")
        translated_text = segment.get("translated_text", "")
        raw_chunks: List[Any] = [segment.get("raw_chunk")]
        raw_indices: List[Any] = [segment.get("raw_chunk_index")]
        current_speaker = str(segment.get("speaker") or "").strip().lower() or None

        j = i + 1

        # Merge forward with following silence/speech until threshold reached
        # Only merge if silence intervals are short (<= max_merge_interval_ms)
        while end_ms - start_ms < min_duration_ms and j < total:
            next_segment = segments[j]
            seg_type = next_segment.get("type")
            if seg_type == "silence":
                silence_duration = int(next_segment.get("duration_ms", 0))
                # Only merge if silence is short enough
                if silence_duration <= max_merge_interval_ms:
                    end_ms = int(next_segment.get("end_ms", end_ms))
                    j += 1
                    continue
                else:
                    # Silence gap too long, stop merging forward
                    break
            if seg_type == "speech":
                next_speaker = str(next_segment.get("speaker") or "").strip().lower() or None
                if current_speaker and next_speaker and next_speaker != current_speaker:
                    break
                end_ms = int(next_segment.get("end_ms", end_ms))
                source_text = _concat_text(source_text, next_segment.get("source_text"))
                translated_text = _concat_text(translated_text, next_segment.get("translated_text"))
                raw_chunks.append(next_segment.get("raw_chunk"))
                raw_indices.append(next_segment.get("raw_chunk_index"))
                j += 1
                continue
            break

        duration_ms = end_ms - start_ms

        if duration_ms < min_duration_ms and merged_segments:
            # Merge backward with previous speech if forward merge insufficient
            # Find the last speech segment in merged_segments
            prev_speech_idx = len(merged_segments) - 1
            while prev_speech_idx >= 0 and merged_segments[prev_speech_idx].get("type") != "speech":
                prev_speech_idx -= 1
            
            if prev_speech_idx >= 0:
                prev_segment = merged_segments[prev_speech_idx]
                prev_end_ms = int(prev_segment.get("end_ms", 0))
                gap_ms = start_ms - prev_end_ms
                # Only merge backward if gap is short enough
                prev_speaker = str(prev_segment.get("speaker") or "").strip().lower() or None
                if gap_ms <= max_merge_interval_ms and (
                    not current_speaker
                    or not prev_speaker
                    or prev_speaker == current_speaker
                ):
                    prev_segment["end_ms"] = end_ms
                    prev_segment["duration_ms"] = end_ms - int(prev_segment.get("start_ms", start_ms))
                    prev_segment["end"] = _format_ms_to_timestamp(end_ms)
                    prev_segment["source_text"] = _concat_text(prev_segment.get("source_text"), source_text)
                    prev_segment["translated_text"] = _concat_text(prev_segment.get("translated_text"), translated_text)

                    prev_raw = prev_segment.get("raw_chunk")
                    if isinstance(prev_raw, list):
                        prev_raw.extend(raw_chunks)
                    elif prev_raw is None:
                        prev_segment["raw_chunk"] = raw_chunks
                    else:
                        prev_segment["raw_chunk"] = [prev_raw] + raw_chunks

                    prev_indices = prev_segment.get("raw_chunk_index")
                    raw_indices_clean = [idx for idx in raw_indices if idx is not None]
                    if raw_indices_clean:
                        if isinstance(prev_indices, list):
                            prev_indices.extend(raw_indices_clean)
                        elif prev_indices is None:
                            prev_segment["raw_chunk_index"] = raw_indices_clean
                        else:
                            prev_segment["raw_chunk_index"] = [prev_indices] + raw_indices_clean

                    i = j
                    continue

        new_segment = dict(segment)
        new_segment["start_ms"] = start_ms
        new_segment["end_ms"] = end_ms
        new_segment["duration_ms"] = duration_ms
        new_segment["start"] = _format_ms_to_timestamp(start_ms)
        new_segment["end"] = _format_ms_to_timestamp(end_ms)
        new_segment["source_text"] = source_text
        new_segment["translated_text"] = translated_text

        raw_chunks_clean = [chunk for chunk in raw_chunks if chunk is not None]
        if raw_chunks_clean:
            new_segment["raw_chunk"] = raw_chunks_clean if len(raw_chunks_clean) > 1 else raw_chunks_clean[0]
        raw_indices_clean = [idx for idx in raw_indices if idx is not None]
        if raw_indices_clean:
            new_segment["raw_chunk_index"] = raw_indices_clean if len(raw_indices_clean) > 1 else raw_indices_clean[0]

        merged_segments.append(new_segment)
        i = j

    # Reassign indices
    for idx, seg in enumerate(merged_segments):
        seg["index"] = idx

    return merged_segments


def _segment_audio_data_uri(
    audio: AudioSegment,
    start_ms: int,
    end_ms: int,
    fmt: str = "mp3",
    bitrate: str = "128k",
) -> Optional[str]:
    start = max(0, int(start_ms))
    end = max(start, int(end_ms))
    audio_len = len(audio)
    if start >= audio_len or start == end:
        return None
    if end > audio_len:
        end = audio_len
    snippet = audio[start:end]
    if len(snippet) == 0:
        return None
    buffer = BytesIO()
    export_kwargs: Dict[str, Any] = {}
    if fmt == "mp3":
        export_kwargs["bitrate"] = bitrate
        mime_type = "audio/mpeg"
    else:
        mime_type = f"audio/{fmt}"
    snippet.export(buffer, format=fmt, **export_kwargs)
    encoded = base64.b64encode(buffer.getvalue()).decode("ascii")
    return f"data:{mime_type};base64,{encoded}"


def _serialize_segments_for_ui(
    segments: List[Dict[str, Any]],
    audio: AudioSegment,
) -> List[Dict[str, Any]]:
    ui_segments: List[Dict[str, Any]] = []
    for segment in segments:
        seg_type = segment.get("type", "speech")
        start_ms = int(segment.get("start_ms", 0))
        end_ms = int(segment.get("end_ms", start_ms))
        duration_ms = int(segment.get("duration_ms", max(0, end_ms - start_ms)))
        base_payload = {
            "index": segment.get("index"),
            "type": seg_type,
            "start_ms": start_ms,
            "end_ms": end_ms,
            "duration_ms": duration_ms,
            "start": segment.get("start"),
            "end": segment.get("end"),
            "source_text": segment.get("source_text", ""),
            "translated_text": segment.get("translated_text", ""),
            "text_keys": segment.get("text_keys", {}),
            "speaker": segment.get("speaker"),
            "volume_percent": segment.get("volume_percent"),
            "emotion_weight": segment.get("emotion_weight"),
        }
        if seg_type == "speech":
            base_payload["generate"] = True
            preview = _segment_audio_data_uri(audio, start_ms, end_ms)
            if preview:
                base_payload["audio_preview"] = preview
        else:
            base_payload["generate"] = False
        ui_segments.append(base_payload)
    return ui_segments


def _cleanup_expired_translate_sessions_locked(now: Optional[float] = None) -> None:
    if now is None:
        now = time.time()
    expired: List[str] = [
        session_id
        for session_id, session in ADVANCED_TRANSLATE_SESSIONS.items()
        if now - session.created_at > ADVANCED_TRANSLATE_SESSION_TTL_SECONDS
    ]
    for session_id in expired:
        ADVANCED_TRANSLATE_SESSIONS.pop(session_id, None)


async def _create_translate_session(
    original_audio: AudioSegment,
    dest_language: str,
    prompt: str,
    translate_enabled: bool,
    response_format: str,
    bitrate: str,
    input_mime_type: Optional[str],
    clearvoice_settings: Dict[str, bool],
    base_segments: List[Dict[str, Any]],
    gemini_chunks: List[Dict[str, Any]],
    gemini_model: str,
    gemini_api_key: Optional[str],
    backing_track_audio: Optional[AudioSegment] = None,
    backing_track_source: str = "none",
    merge_with_backing: bool = False,
    ignore_non_speech: bool = False,
    preserve_silence_audio: bool = False,
    generated_volume_percent: float = DEFAULT_GENERATED_VOLUME_PERCENT,
    backing_volume_percent: float = DEFAULT_GENERATED_VOLUME_PERCENT,
    speaker_profiles: Optional[List[Dict[str, Any]]] = None,
    speaker_overrides: Optional[Dict[str, Dict[str, Any]]] = None,
    gemini_raw_text: Optional[str] = None,
    chunk_parent_id: Optional[str] = None,
    chunk_index: Optional[int] = None,
    chunk_start_ms: Optional[int] = None,
    chunk_end_ms: Optional[int] = None,
    chunk_cut_reason: Optional[str] = None,
    chunk_silence_midpoint_ms: Optional[int] = None,
    persist_media: bool = False,
    media_format: str = "wav",
) -> TranslateSessionData:
    session_id = uuid.uuid4().hex
    session = TranslateSessionData(
        session_id=session_id,
        original_audio=original_audio,
        dest_language=dest_language,
        prompt=prompt,
        translate_enabled=translate_enabled,
        response_format=response_format,
        bitrate=bitrate,
        input_mime_type=input_mime_type,
        clearvoice_settings=dict(clearvoice_settings or {}),
        base_segments=copy.deepcopy(base_segments),
        gemini_chunks=copy.deepcopy(gemini_chunks),
        gemini_model=gemini_model,
        gemini_api_key=gemini_api_key,
        backing_track_audio=backing_track_audio,
        backing_track_source=backing_track_source or "none",
        merge_with_backing=merge_with_backing,
        ignore_non_speech=ignore_non_speech,
        preserve_silence_audio=preserve_silence_audio,
        generated_volume_percent=generated_volume_percent,
        backing_volume_percent=backing_volume_percent,
        speaker_profiles=copy.deepcopy(speaker_profiles or []),
        speaker_overrides=copy.deepcopy(speaker_overrides or {}),
        gemini_raw_text=gemini_raw_text,
        chunk_parent_id=chunk_parent_id,
        chunk_index=chunk_index,
        chunk_start_ms=chunk_start_ms,
        chunk_end_ms=chunk_end_ms,
        chunk_cut_reason=chunk_cut_reason,
        chunk_silence_midpoint_ms=chunk_silence_midpoint_ms,
    )
    if persist_media:
        session.original_audio_path = _persist_session_audio_segment(session_id, original_audio, "vocals", fmt=media_format)
        session.original_audio = None
    async with ADVANCED_TRANSLATE_SESSION_LOCK:
        _cleanup_expired_translate_sessions_locked()
        ADVANCED_TRANSLATE_SESSIONS[session_id] = session
    return session


async def _get_translate_session(session_id: str) -> Optional[TranslateSessionData]:
    async with ADVANCED_TRANSLATE_SESSION_LOCK:
        _cleanup_expired_translate_sessions_locked()
        session = ADVANCED_TRANSLATE_SESSIONS.get(session_id)
        if session:
            session.created_at = time.time()
        return session


async def _update_translate_session_segments(
    session_id: str, segments: List[Dict[str, Any]]
) -> None:
    async with ADVANCED_TRANSLATE_SESSION_LOCK:
        session = ADVANCED_TRANSLATE_SESSIONS.get(session_id)
        if session:
            session.base_segments = copy.deepcopy(segments)
            session.created_at = time.time()


async def _update_translate_session_speaker_overrides(
    session_id: str, overrides: Dict[str, Dict[str, Any]]
) -> None:
    async with ADVANCED_TRANSLATE_SESSION_LOCK:
        session = ADVANCED_TRANSLATE_SESSIONS.get(session_id)
        if session:
            session.speaker_overrides = copy.deepcopy(overrides)
            session.created_at = time.time()


async def _update_translate_session_metadata(
    session_id: str,
    *,
    response_format: Optional[str] = None,
    bitrate: Optional[str] = None,
    gemini_model: Optional[str] = None,
    generated_volume_percent: Optional[float] = None,
    backing_volume_percent: Optional[float] = None,
) -> None:
    async with ADVANCED_TRANSLATE_SESSION_LOCK:
        session = ADVANCED_TRANSLATE_SESSIONS.get(session_id)
        if session:
            if response_format:
                session.response_format = response_format
            if bitrate:
                session.bitrate = bitrate
            if gemini_model:
                session.gemini_model = gemini_model
            if generated_volume_percent is not None:
                session.generated_volume_percent = generated_volume_percent
        if backing_volume_percent is not None:
            session.backing_volume_percent = backing_volume_percent
            session.created_at = time.time()


async def _list_chunk_sessions(chunk_parent_id: str) -> List[TranslateSessionData]:
    async with ADVANCED_TRANSLATE_SESSION_LOCK:
        _cleanup_expired_translate_sessions_locked()
        return [
            session
            for session in ADVANCED_TRANSLATE_SESSIONS.values()
            if session.chunk_parent_id == chunk_parent_id
        ]


def _guess_audio_format_from_mime(mime_type: Optional[str]) -> Optional[str]:
    if not mime_type:
        return None
    mime = mime_type.lower()
    mapping = {
        "audio/wav": "wav",
        "audio/x-wav": "wav",
        "audio/wave": "wav",
        "audio/mpeg": "mp3",
        "audio/mp3": "mp3",
        "audio/ogg": "ogg",
        "audio/ogg; codecs=opus": "ogg",
        "audio/webm": "webm",
        "audio/opus": "opus",
        "audio/flac": "flac",
        "audio/aac": "aac",
        "audio/mp4": "mp4",
        "audio/m4a": "mp4",
        "audio/x-m4a": "mp4",
        "audio/vnd.wave": "wav",
    }
    return mapping.get(mime)


def _prepare_translation_segments(
    original_audio: AudioSegment,
    chunk_data: List[Dict[str, Any]],
    dest_language: str,
    *,
    speaker_profiles: Optional[List[Dict[str, Any]]] = None,
    min_speech_duration_ms: int = MIN_SPEECH_DURATION_MS,
    max_merge_interval_ms: int = MAX_MERGE_INTERVAL_MS,
) -> List[Dict[str, Any]]:
    total_duration_ms = len(original_audio)
    segments: List[Dict[str, Any]] = []
    current_ms = 0
    normalized_profiles = speaker_profiles or []

    def _get_timestamp(entry: Dict[str, Any], keys: List[str]) -> Optional[int]:
        for key in keys:
            if key in entry:
                parsed = _parse_timestamp_to_ms(entry[key])
                if parsed is not None:
                    return parsed
        return None

    def _ensure_silence(duration_ms: int, position: str) -> Optional[Dict[str, Any]]:
        if duration_ms <= 0:
            return None
        start_ms = current_ms
        end_ms = current_ms + duration_ms
        segment_payload = {
            "type": "silence",
            "start_ms": start_ms,
            "end_ms": end_ms,
            "duration_ms": duration_ms,
            "start": _format_ms_to_timestamp(start_ms),
            "end": _format_ms_to_timestamp(end_ms),
            "position": position,
        }
        return segment_payload

    def _resolve_speaker_label(entry: Dict[str, Any], index: int) -> Optional[str]:
        fallback_index = index + 1
        candidate_keys = ["speaker", "speaker_id", "speaker_label", "voice", "speaker_name"]
        for key in candidate_keys:
            if key in entry and entry[key] not in (None, ""):
                return _canonicalize_speaker_id(entry[key], fallback_index).lower()
        speaker_idx = entry.get("speaker_index")
        if isinstance(speaker_idx, int):
            return f"speaker{max(1, speaker_idx + 1)}"
        if normalized_profiles and index < len(normalized_profiles):
            profile_id = normalized_profiles[index].get("id")
            if profile_id:
                return str(profile_id).strip().lower()
        return None

    if not chunk_data:
        raise ValueError("Gemini returned no transcription segments.")

    for idx, entry in enumerate(chunk_data):
        if not isinstance(entry, dict):
            continue

        start_ms = _get_timestamp(
            entry,
            [
                "start_ms",
                "startMilliseconds",
                "start_milliseconds",
                "start",
                "start_time",
                "begin",
                "from",
            ],
        )
        end_ms = _get_timestamp(
            entry,
            [
                "end_ms",
                "endMilliseconds",
                "end_milliseconds",
                "end",
                "end_time",
                "stop",
                "to",
            ],
        )

        if start_ms is None:
            start_ms = current_ms
        if end_ms is None:
            duration_ms = _get_timestamp(
                entry,
                ["duration_ms", "durationMilliseconds", "duration", "length", "segment_duration"],
            )
            if duration_ms is not None:
                end_ms = start_ms + duration_ms

        if end_ms is None:
            # Fallback: assume contiguous audio up to detected order
            # Use remainder of audio divided equally over remaining segments
            remaining_segments = max(len(chunk_data) - idx, 1)
            remaining_ms = max(total_duration_ms - start_ms, 0)
            avg_duration = remaining_ms // remaining_segments if remaining_segments else remaining_ms
            end_ms = start_ms + avg_duration

        start_ms = max(0, min(start_ms, total_duration_ms))
        end_ms = max(0, min(end_ms, total_duration_ms))
        if start_ms < current_ms:
            start_ms = current_ms
        if end_ms <= start_ms:
            continue

        # Add silence if there is a gap before this segment
        if start_ms > current_ms:
            silence_payload = _ensure_silence(start_ms - current_ms, "leading" if current_ms == 0 else "between")
            if silence_payload:
                silence_payload["index"] = len(segments)
                segments.append(silence_payload)
            current_ms = start_ms

        source_text, translated_text, source_key, translation_key = _extract_text_fields(entry, dest_language)
        if isinstance(source_text, str):
            source_text_value = source_text.strip()
        elif source_text is None:
            source_text_value = ""
        else:
            source_text_value = str(source_text)

        if isinstance(translated_text, str):
            translated_text_value = translated_text.strip()
        elif translated_text is None:
            translated_text_value = ""
        else:
            translated_text_value = str(translated_text)

        segment_payload: Dict[str, Any] = {
            "type": "speech",
            "start_ms": start_ms,
            "end_ms": end_ms,
            "duration_ms": end_ms - start_ms,
            "start": _format_ms_to_timestamp(start_ms),
            "end": _format_ms_to_timestamp(end_ms),
            "source_text": source_text_value,
            "translated_text": translated_text_value,
            "text_keys": {
                "source": source_key,
                "translated": translation_key,
            },
            "raw_chunk_index": idx,
            "raw_chunk": entry,
        }
        speaker_label = _resolve_speaker_label(entry, idx)
        if speaker_label:
            segment_payload["speaker"] = speaker_label
        segment_payload["index"] = len(segments)
        segments.append(segment_payload)
        current_ms = end_ms

    # Add trailing silence if needed
    if current_ms < total_duration_ms:
        remaining = total_duration_ms - current_ms
        silence_payload = _ensure_silence(remaining, "trailing")
        if silence_payload:
            silence_payload["index"] = len(segments)
            segments.append(silence_payload)

    segments = _merge_short_speech_segments(
        segments,
        max(0, int(min_speech_duration_ms)),
        max_merge_interval_ms=max(0, int(max_merge_interval_ms)),
    )

    return segments


def _create_silence_segment(duration_ms: int, frame_rate: int, sample_width: int, channels: int) -> AudioSegment:
    duration_ms = max(0, int(duration_ms))
    silence = AudioSegment.silent(duration=duration_ms, frame_rate=frame_rate)
    silence = silence.set_sample_width(sample_width)
    silence = silence.set_channels(channels)
    return silence


def _match_segment_duration(
    segment: AudioSegment,
    target_ms: int,
    frame_rate: int,
    sample_width: int,
    channels: int,
    *,
    loop_fill: bool = False,
    allow_trim: bool = False,
) -> AudioSegment:
    target_ms = max(0, int(target_ms))
    segment = segment.set_frame_rate(frame_rate)
    segment = segment.set_sample_width(sample_width)
    segment = segment.set_channels(channels)

    if target_ms == 0:
        return _create_silence_segment(0, frame_rate, sample_width, channels)

    current_ms = len(segment)
    tolerance_ms = 100
    diff = target_ms - current_ms
    if diff > 0:
        if loop_fill and current_ms > 0:
            filler = AudioSegment.silent(duration=0, frame_rate=frame_rate)
            filler = filler.set_sample_width(sample_width).set_channels(channels)
            extended = filler
            while len(extended) < target_ms:
                extended += segment
            if len(extended) > target_ms:
                extended = extended[:target_ms]
            return extended
        if diff <= tolerance_ms:
            return segment + _create_silence_segment(diff, frame_rate, sample_width, channels)
        return segment + _create_silence_segment(diff, frame_rate, sample_width, channels)
    if diff < 0 and allow_trim and target_ms >= 0:
        return segment[:target_ms]
    # Never trim segments by default; return original even if longer than target.
    return segment


def _apply_volume_with_ffmpeg(segment: AudioSegment, volume_percent: float) -> AudioSegment:
    """Adjust segment volume using ffmpeg when available, fallback to pydub gain."""
    try:
        volume_percent = float(volume_percent)
    except (TypeError, ValueError):
        volume_percent = DEFAULT_GENERATED_VOLUME_PERCENT
    if abs(volume_percent - DEFAULT_GENERATED_VOLUME_PERCENT) < 0.01:
        return segment

    volume_factor = max(volume_percent, MIN_GENERATED_VOLUME_PERCENT) / 100.0
    if shutil.which("ffmpeg") is None:
        gain_db = 20 * math.log10(volume_factor) if volume_factor > 0 else -120.0
        return segment.apply_gain(gain_db)

    input_path = None
    output_path = None
    try:
        with tempfile.NamedTemporaryFile(suffix=".wav", delete=False) as tmp_input:
            segment.export(tmp_input.name, format="wav")
            input_path = tmp_input.name
        with tempfile.NamedTemporaryFile(suffix=".wav", delete=False) as tmp_output:
            output_path = tmp_output.name

        cmd = [
            "ffmpeg",
            "-y",
            "-loglevel",
            "error",
            "-i",
            input_path,
            "-filter:a",
            f"volume={volume_factor}",
            output_path,
        ]
        process = subprocess.run(cmd, capture_output=True, text=True)
        if process.returncode != 0:
            print(f"⚠️ FFmpeg volume adjustment failed (code {process.returncode}): {process.stderr.strip()}")
            gain_db = 20 * math.log10(volume_factor) if volume_factor > 0 else -120.0
            return segment.apply_gain(gain_db)

        adjusted = AudioSegment.from_file(output_path, format="wav")
        adjusted = adjusted.set_frame_rate(segment.frame_rate)
        adjusted = adjusted.set_sample_width(segment.sample_width)
        adjusted = adjusted.set_channels(segment.channels)
        return adjusted
    except Exception as exc:
        print(f"⚠️ Volume adjustment fallback due to error: {exc}")
        gain_db = 20 * math.log10(volume_factor) if volume_factor > 0 else -120.0
        return segment.apply_gain(gain_db)
    finally:
        for path in (input_path, output_path):
            if path and os.path.exists(path):
                try:
                    os.remove(path)
                except Exception:
                    pass


async def _synthesize_translated_audio(
    original_audio: AudioSegment,
    segments: List[Dict[str, Any]],
    dest_language: str,
    response_format: str = TRANSLATE_DEFAULT_OUTPUT_FORMAT,
    bitrate: str = TRANSLATE_DEFAULT_BITRATE,
    input_mime_type: Optional[str] = None,
    clearvoice_settings: Optional[Dict[str, bool]] = None,
    backing_track_audio: Optional[AudioSegment] = None,
    backing_track_source: str = "none",
    merge_with_backing: bool = False,
    preserve_silence_audio: bool = False,
    generated_volume_percent: float = DEFAULT_GENERATED_VOLUME_PERCENT,
    speaker_overrides: Optional[Dict[str, Dict[str, Any]]] = None,
    backing_volume_percent: float = DEFAULT_GENERATED_VOLUME_PERCENT,
    pad_to_original: bool = True,
) -> Tuple[bytes, str, Dict[str, Any]]:
    tts = tts_manager.get_tts()
    frame_rate = int(original_audio.frame_rate or 22050)
    sample_width = int(original_audio.sample_width or 2)
    channels = int(original_audio.channels or 1)

    combined_audio = _create_silence_segment(0, frame_rate, sample_width, channels)
    generation_log: List[Dict[str, Any]] = []
    semaphore = asyncio.Semaphore(TRANSLATION_TTS_CONCURRENCY)
    override_map: Dict[str, Dict[str, Any]] = {
        str(key).lower(): value for key, value in (speaker_overrides or {}).items()
    }

    async def process_segment(index: int, segment: Dict[str, Any]):
        seg_type = segment.get("type")
        start_ms = int(segment.get("start_ms", 0))
        end_ms = int(segment.get("end_ms", start_ms))
        duration_ms = max(0, int(segment.get("duration_ms", max(0, end_ms - start_ms))))

        if seg_type == "silence":
            if preserve_silence_audio:
                chunk_audio = original_audio[start_ms:end_ms]
                audio_seg = _match_segment_duration(chunk_audio, duration_ms, frame_rate, sample_width, channels)
                log_entry = {
                    "index": index,
                    "type": "silence",
                    "status": "preserved",
                    "duration_ms": duration_ms,
                    "start_ms": start_ms,
                    "end_ms": end_ms,
                }
            else:
                audio_seg = _create_silence_segment(duration_ms, frame_rate, sample_width, channels)
                log_entry = {
                    "index": index,
                    "type": "silence",
                    "duration_ms": duration_ms,
                    "start_ms": start_ms,
                    "end_ms": end_ms,
                }
            return index, audio_seg, log_entry

        translated_text = (segment.get("translated_text") or "").strip()
        source_text = (segment.get("source_text") or "").strip()
        generate_segment = segment.get("generate", True)
        keep_original = segment.get("keep_original", False) or (not generate_segment)

        chunk_audio = original_audio[start_ms:end_ms]
        speaker_label = str(segment.get("speaker") or "").strip().lower()
        override_config = override_map.get(speaker_label) if speaker_label else None
        preset_name = None
        use_emotion_prompt = False
        speaker_emotion_weight = DEFAULT_EMOTION_WEIGHT
        speaker_volume_percent: Optional[float] = None
        if override_config:
            raw_volume = override_config.get("volume_percent")
            if raw_volume is not None:
                speaker_volume_percent = _coerce_volume_percent(
                    raw_volume,
                    DEFAULT_GENERATED_VOLUME_PERCENT,
                )
        if override_config:
            preset_candidate = override_config.get("preset_name")
            if isinstance(preset_candidate, str) and preset_candidate.strip():
                preset_name = preset_candidate.strip()
                use_emotion_prompt = bool(override_config.get("use_emotion_prompt"))
                speaker_emotion_weight = _coerce_emotion_weight(
                    override_config.get("emotion_weight"),
                    DEFAULT_EMOTION_WEIGHT,
                )
        segment_volume_percent: Optional[float] = None
        raw_segment_volume = segment.get("volume_percent")
        if raw_segment_volume is not None:
            segment_volume_percent = _coerce_volume_percent(
                raw_segment_volume,
                DEFAULT_GENERATED_VOLUME_PERCENT,
            )
        segment_emotion_weight: Optional[float] = None
        raw_segment_emotion = segment.get("emotion_weight")
        if raw_segment_emotion is not None:
            segment_emotion_weight = _coerce_emotion_weight(
                raw_segment_emotion,
                DEFAULT_EMOTION_WEIGHT,
            )
        resolved_emotion_weight = (
            segment_emotion_weight
            if segment_emotion_weight is not None
            else speaker_emotion_weight
        )
        resolved_volume_percent = (
            segment_volume_percent
            if segment_volume_percent is not None
            else (
                speaker_volume_percent
                if speaker_volume_percent is not None
                else generated_volume_percent
            )
        )

        if keep_original:
            audio_seg = _match_segment_duration(chunk_audio, duration_ms, frame_rate, sample_width, channels)
            log_entry = {
                "index": index,
                "type": "speech",
                "status": "preserved",
                "duration_ms": duration_ms,
                "source_text": source_text,
                "translated_text": translated_text,
            }
            return index, audio_seg, log_entry

        if not translated_text:
            audio_seg = _create_silence_segment(duration_ms, frame_rate, sample_width, channels)
            log_entry = {
                "index": index,
                "type": "speech",
                "status": "skipped",
                "reason": "empty_translation",
                "source_text": source_text,
                "duration_ms": duration_ms,
            }
            return index, audio_seg, log_entry

        with tempfile.NamedTemporaryFile(suffix=".wav", delete=False) as tmp_chunk:
            chunk_audio.export(tmp_chunk.name, format="wav")
            chunk_path = tmp_chunk.name

        generation_target_ms = max(0, duration_ms - AUDIO_GENERATION_MARGIN_MS)
        generated_path = os.path.join("outputs", f"translate_{uuid.uuid4().hex}.wav")

        status = "success"
        error_message = None
        generated_audio: Optional[AudioSegment] = None
        spk_prompt_value = chunk_path if not preset_name else ""
        emo_prompt_value = chunk_path if preset_name and use_emotion_prompt else None

        try:
            async with semaphore:
                inference_path = await tts.infer(
                    spk_audio_prompt=spk_prompt_value,
                    text=translated_text,
                    output_path=generated_path,
                    interval_silence=0,
                    speech_length=generation_target_ms,
                    diffusion_steps=10,
                    verbose=cmd_args.verbose,
                    speaker_preset=preset_name,
                    emo_audio_prompt=emo_prompt_value,
                    emo_alpha=resolved_emotion_weight,
                )
            generated_audio = AudioSegment.from_file(inference_path)
            if abs(resolved_volume_percent - DEFAULT_GENERATED_VOLUME_PERCENT) >= 0.01:
                generated_audio = _apply_volume_with_ffmpeg(generated_audio, resolved_volume_percent)
            generated_audio = _match_segment_duration(generated_audio, duration_ms, frame_rate, sample_width, channels)
        except Exception as exc:
            status = "error"
            error_message = str(exc)
            print(f"⚠️ Translation synthesis failed for segment {index}: {error_message}")
            generated_audio = _create_silence_segment(duration_ms, frame_rate, sample_width, channels)
        finally:
            if os.path.exists(chunk_path):
                try:
                    os.remove(chunk_path)
                except Exception:
                    pass
            if os.path.exists(generated_path):
                try:
                    await async_remove_file(generated_path)
                except Exception:
                    pass

        log_entry: Dict[str, Any] = {
            "index": index,
            "type": "speech",
            "status": status,
            "duration_ms": duration_ms,
            "source_text": source_text,
            "translated_text": translated_text,
        }
        if speaker_label:
            log_entry["speaker"] = speaker_label
        if preset_name:
            log_entry["speaker_preset"] = preset_name
            log_entry["emotion_prompt"] = use_emotion_prompt
            log_entry["emotion_weight"] = resolved_emotion_weight
        if speaker_volume_percent is not None or segment_volume_percent is not None:
            log_entry["volume_percent"] = resolved_volume_percent
        if status == "error" and error_message:
            log_entry["error"] = error_message

        return index, generated_audio, log_entry

    segment_tasks = [process_segment(idx, segment) for idx, segment in enumerate(segments)]
    results = await asyncio.gather(*segment_tasks)
    results.sort(key=lambda item: item[0])

    for _, audio_segment, log_entry in results:
        combined_audio += audio_segment
        generation_log.append(log_entry)

    original_duration_ms = len(original_audio)
    final_duration_ms = len(combined_audio)
    if pad_to_original and final_duration_ms < original_duration_ms:
        combined_audio += _create_silence_segment(original_duration_ms - final_duration_ms, frame_rate, sample_width, channels)
        final_duration_ms = len(combined_audio)

    backing_applied = False
    if merge_with_backing and backing_track_audio is not None:
        try:
            prepared_backing = (
                backing_track_audio.set_frame_rate(frame_rate)
                .set_sample_width(sample_width)
                .set_channels(channels)
            )
            if abs(backing_volume_percent - DEFAULT_GENERATED_VOLUME_PERCENT) >= 0.01:
                volume_factor = max(backing_volume_percent, MIN_GENERATED_VOLUME_PERCENT) / 100.0
                gain_db = 20 * math.log10(volume_factor) if volume_factor > 0 else -120.0
                prepared_backing = prepared_backing.apply_gain(gain_db)
            prepared_backing = _match_segment_duration(
                prepared_backing,
                len(combined_audio),
                frame_rate,
                sample_width,
                channels,
                loop_fill=backing_track_source == "custom",
                allow_trim=backing_track_source == "custom",
            )
            if backing_track_source == "custom":
                fade_duration = min(2000, len(prepared_backing))
                if fade_duration > 0:
                    prepared_backing = prepared_backing.fade_out(fade_duration)
            combined_audio = prepared_backing.overlay(combined_audio)
            backing_applied = True
        except Exception as merge_error:
            print(f"⚠️ Failed to merge translated audio with backing track: {merge_error}")

    buffer = BytesIO()
    export_kwargs: Dict[str, Any] = {}
    audio_format = (response_format or TRANSLATE_DEFAULT_OUTPUT_FORMAT).lower()
    if audio_format == "mp3" and bitrate:
        export_kwargs["bitrate"] = bitrate
    combined_audio.export(buffer, format=audio_format, **export_kwargs)
    audio_bytes = buffer.getvalue()

    media_type_map = {
        "mp3": "audio/mpeg",
        "wav": "audio/wav",
        "aac": "audio/aac",
        "flac": "audio/flac",
        "opus": "audio/opus",
        "ogg": "audio/ogg",
        "webm": "audio/webm",
    }
    media_type = media_type_map.get(audio_format, f"audio/{audio_format}")

    metadata = {
        "dest_language": dest_language,
        "segment_count": len(segments),
        "speech_segment_count": sum(1 for s in segments if s["type"] == "speech"),
        "silence_segment_count": sum(1 for s in segments if s["type"] == "silence"),
        "original_duration_ms": original_duration_ms,
        "generated_duration_ms": len(combined_audio),
        "generation_log": generation_log,
        "padded_to_original": pad_to_original,
        "backing_volume_percent": backing_volume_percent,
    }
    if input_mime_type:
        metadata["input_mime_type"] = input_mime_type
    if clearvoice_settings:
        metadata["clearvoice"] = clearvoice_settings
    metadata["backing_track"] = {
        "available": backing_track_audio is not None,
        "merged": backing_applied,
        "volume_percent": backing_volume_percent,
        "source": backing_track_source,
    }
    metadata["preserve_silence_audio"] = preserve_silence_audio
    metadata["generated_volume_percent"] = generated_volume_percent

    return audio_bytes, media_type, metadata


async def _gemini_transcribe_translate(
    audio_bytes: bytes,
    mime_type: str,
    dest_language: str,
    prompt_text: Optional[str] = None,
    *,
    model_name: Optional[str] = None,
    api_key_override: Optional[str] = None,
) -> Tuple[List[Dict[str, Any]], List[Dict[str, Any]], str]:
    if genai is None:
        raise RuntimeError(
            "The google-genai package is required for translation. Install it with `pip install google-genai`."
        )

    api_key = (api_key_override or "").strip() or os.getenv(GEMINI_API_KEY_ENV_VAR) or os.getenv(GOOGLE_API_KEY_ENV_VAR)
    if not api_key:
        raise RuntimeError(
            f"Neither {GEMINI_API_KEY_ENV_VAR} nor {GOOGLE_API_KEY_ENV_VAR} environment variables are set."
        )

    prompt = (prompt_text or "").strip() or TRANSLATION_PROMPT_TEMPLATE.format(dest_language=dest_language)
    model_name = (model_name or "").strip() or _get_gemini_model_name()

    if types is None:
        raise RuntimeError(
            "google-genai types module is unavailable. Ensure the `google-genai` package is installed and up to date."
        )

    client = _get_gemini_client(api_key)

    user_content = types.Content(
        role="user",
        parts=[
            types.Part.from_text(text=prompt),
            types.Part.from_bytes(data=audio_bytes, mime_type=mime_type),
        ],
    )

    def _call_gemini() -> str:
        response = client.models.generate_content(
            model=model_name,
            contents=[user_content],
            config=types.GenerateContentConfig(
                response_mime_type="application/json",
                temperature=DEFAULT_GEMINI_TEMPERATURE,
                top_p=DEFAULT_GEMINI_TOP_P,
            ),
        )

        prompt_feedback = getattr(response, "prompt_feedback", None)
        if prompt_feedback is not None:
            block_reason = getattr(prompt_feedback, "block_reason", None)
            if block_reason:
                raise RuntimeError(f"Gemini blocked the prompt: {block_reason}")

        text = _extract_text_from_gemini_response(response)
        if not text:
            raise RuntimeError("Gemini returned an empty response.")
        return text

    loop = asyncio.get_event_loop()
    max_attempts = 10
    retry_delay_seconds = 10
    last_error: Optional[Exception] = None
    for attempt in range(1, max_attempts + 1):
        try:
            raw_text = await loop.run_in_executor(executor, _call_gemini)
            break
        except Exception as exc:
            last_error = exc
            print(
                f"⚠️ Gemini call failed (attempt {attempt}/{max_attempts}): {exc}. "
                f"Retrying in {retry_delay_seconds}s..."
            )
            if attempt < max_attempts:
                await asyncio.sleep(retry_delay_seconds)
    else:
        raise RuntimeError(f"Gemini request failed after {max_attempts} attempts: {last_error}")

    segments, speaker_profiles = _parse_gemini_json(raw_text)
    return segments, speaker_profiles, raw_text

# Global TTS manager
class TTSManager:
    _instance = None
    _initialized = False
    
    def __init__(self):
        self.tts = None
        self.speaker_manager = None
        
    @classmethod
    def get_instance(cls):
        if cls._instance is None:
            cls._instance = cls()
        return cls._instance
    
    async def initialize(self):
        if not self._initialized:
            try:
                print("🚀 Initializing IndexTTS2 vLLM v2...")
                
                # Check model directory
                if not os.path.exists(cmd_args.model_dir):
                    raise FileNotFoundError(f"Model directory {cmd_args.model_dir} does not exist")
                
                # Check required files
                required_files = [
                    "bpe.model",
                    "gpt.pth", 
                    "config.yaml",
                    "s2mel.pth",
                    "wav2vec2bert_stats.pt"
                ]
                
                for file in required_files:
                    file_path = os.path.join(cmd_args.model_dir, file)
                    if not os.path.exists(file_path):
                        raise FileNotFoundError(f"Required file {file_path} does not exist")
                
                # Initialize IndexTTS2
                self.tts = IndexTTS2(
                    model_dir=cmd_args.model_dir,
                    is_fp16=cmd_args.is_fp16,
                    use_torch_compile=cmd_args.use_torch_compile,
                    gpu_memory_utilization=cmd_args.gpu_memory_utilization
                )
                
                # Initialize speaker preset manager
                self.speaker_manager = initialize_preset_manager(self.tts)
                
                # Initialize speaker API wrapper
                global speaker_api
                speaker_api = SpeakerAPIWrapper(self.speaker_manager)
                
                self._initialized = True
                print("✅ IndexTTS2 vLLM v2 initialized successfully!")
                print(f"🎭 Speaker preset manager initialized with {len(self.speaker_manager.list_presets())} existing presets")
                
                return True
                
            except Exception as e:
                print(f"❌ Failed to initialize IndexTTS2: {e}")
                traceback.print_exc()
                self._initialized = False
                return False
        return True
    
    def get_tts(self):
        if not self._initialized or self.tts is None:
            raise Exception("IndexTTS2 not initialized")
        return self.tts
    
    def is_ready(self):
        return self._initialized and self.tts is not None

# Create global TTS manager
tts_manager = TTSManager.get_instance()

# Speaker Management Functions using existing SpeakerPresetManager
class SpeakerAPIWrapper:
    """Wrapper to adapt SpeakerPresetManager for FastAPI endpoints"""
    
    def __init__(self, preset_manager: SpeakerPresetManager):
        self.preset_manager = preset_manager
    
    async def add_speaker(
        self,
        speaker_name: str,
        audio_files: List[bytes],
        filenames: List[str],
        apply_enhancement: bool = False,
        apply_super_resolution: bool = False,
    ) -> Dict[str, str]:
        """Add a new speaker with audio files and optional ClearVoice processing."""
        try:
            # Check if speaker already exists - run in thread pool
            loop = asyncio.get_event_loop()
            clearvoice_requested = apply_enhancement or apply_super_resolution

            if clearvoice_requested and ClearVoice is None:
                return {
                    "status": "error",
                    "message": "ClearVoice package is required for enhancement or super-resolution. Install the `clearvoice` package to enable these options."
                }

            existing_presets = await loop.run_in_executor(executor, self.preset_manager.list_presets)
            
            if speaker_name in existing_presets:
                preset_info = existing_presets[speaker_name]
                if not _speaker_preview_exists(speaker_name):
                    audio_path = preset_info.get("audio_path")
                    if audio_path and os.path.exists(audio_path):
                        await _create_speaker_preview_mp3(audio_path, speaker_name)
                preview_available = _speaker_preview_exists(speaker_name)
                return {
                    "status": "success", 
                    "message": f"Speaker '{speaker_name}' already exists",
                    "info": "already_exists",
                    "audio_count": 1,  # SpeakerPresetManager uses single audio file
                    "description": preset_info.get("description", ""),
                    "created_at": preset_info.get("created_at", 0),
                    "preview_url": _speaker_preview_url(speaker_name) if preview_available else None,
                }
            
            # Save the first audio file (SpeakerPresetManager expects single file)
            if not audio_files:
                return {"status": "error", "message": "No audio files provided"}
            
            # Create temporary file for the first audio
            audio_data = audio_files[0]
            filename = filenames[0] if filenames else "audio.wav"
            
            # Save to temporary location
            temp_dir = Path("speaker_presets") / "temp"
            # Create directory in thread pool to avoid blocking
            await loop.run_in_executor(executor, lambda: temp_dir.mkdir(parents=True, exist_ok=True))
            
            temp_path = temp_dir / f"{speaker_name}_{filename}"
            await async_write_file(str(temp_path), audio_data)
            
            processed_paths: Set[str] = set()
            processed_paths.add(str(temp_path))
            final_audio_path = str(temp_path)

            try:
                # Cut audio to 10 seconds if it exceeds the limit
                cut_temp_path = await async_cut_audio_to_duration(str(temp_path), max_duration=10.0)
                processed_paths.add(cut_temp_path)
                final_audio_path = cut_temp_path
                
                if clearvoice_requested:
                    try:
                        final_audio_path, clearvoice_paths, _ = await apply_clearvoice_processing(
                            final_audio_path,
                            apply_enhancement,
                            apply_super_resolution,
                        )
                        processed_paths.update(clearvoice_paths)
                    except Exception as cv_error:
                        return {"status": "error", "message": f"ClearVoice processing failed: {str(cv_error)}"}
                
                processed_paths.add(final_audio_path)

                description_parts = [
                    f"Added via API with {len(audio_files)} audio files (auto-cut to 10s)"
                ]
                if clearvoice_requested:
                    cv_features = []
                    if apply_enhancement:
                        cv_features.append("MossFormer2_SE_48K enhancement")
                    if apply_super_resolution:
                        cv_features.append("MossFormer2_SR_48K super-resolution")
                    description_parts.append("ClearVoice: " + " + ".join(cv_features))
                description = " | ".join(description_parts)
                
                # Use SpeakerPresetManager to add the speaker - run in thread pool to avoid blocking
                # This operation processes audio through TTS pipeline and can take several seconds
                success = await loop.run_in_executor(
                    executor,
                    self.preset_manager.add_speaker_preset,
                    speaker_name,
                    final_audio_path,
                    description
                )
                
                if success:
                    response: Dict[str, Any] = {
                        "status": "success", 
                        "message": f"Speaker '{speaker_name}' added successfully",
                        "info": "newly_added",
                        "audio_count": len(audio_files)
                    }
                    if clearvoice_requested:
                        response["clearvoice"] = {
                            "enhancement": apply_enhancement,
                            "super_resolution": apply_super_resolution
                        }
                    preview_result = await _create_speaker_preview_mp3(final_audio_path, speaker_name)
                    if preview_result:
                        response["preview_url"] = _speaker_preview_url(speaker_name)
                    return response
                else:
                    return {"status": "error", "message": f"Failed to add speaker '{speaker_name}'"}
            
            finally:
                # Clean up temporary files asynchronously
                try:
                    for cleanup_path in processed_paths:
                        await async_remove_file(cleanup_path)
                except:
                    pass
            
        except Exception as e:
            return {"status": "error", "message": f"Failed to add speaker: {str(e)}"}
    
    async def delete_speaker(self, speaker_name: str) -> Dict[str, str]:
        """Delete a speaker"""
        try:
            # Run deletion in thread pool to avoid blocking
            loop = asyncio.get_event_loop()
            success = await loop.run_in_executor(executor, self.preset_manager.delete_preset, speaker_name)
            
            if success:
                await _remove_speaker_preview(speaker_name)
                return {
                    "status": "success",
                    "message": f"Speaker '{speaker_name}' deleted successfully"
                }
            else:
                return {"status": "error", "message": f"Speaker '{speaker_name}' not found"}
            
        except Exception as e:
            return {"status": "error", "message": f"Failed to delete speaker: {str(e)}"}
    
    async def list_speakers(self) -> Dict[str, Any]:
        """List all speakers with metadata"""
        try:
            # Run the synchronous operation in thread pool to avoid blocking
            loop = asyncio.get_event_loop()
            presets = await loop.run_in_executor(executor, self.preset_manager.list_presets)
            
            speaker_info = {}
            for speaker_name, preset_data in presets.items():
                # Calculate cache file size in thread pool to avoid blocking
                cache_file = preset_data.get('cache_file', '')
                total_size = 0
                if cache_file:
                    def get_file_size(filepath):
                        if os.path.exists(filepath):
                            return os.path.getsize(filepath)
                        return 0
                    total_size = await loop.run_in_executor(executor, get_file_size, cache_file)
                
                preview_available = _speaker_preview_exists(speaker_name)
                preview_url = _speaker_preview_url(speaker_name) if preview_available else None

                speaker_info[speaker_name] = {
                    "audio_count": 1,  # SpeakerPresetManager uses single audio file
                    "audio_files": [os.path.basename(preset_data.get('audio_path', ''))],
                    "total_size_mb": total_size / (1024 * 1024),
                    "description": preset_data.get('description', ''),
                    "created_at": preset_data.get('created_at', 0),
                    "last_used": preset_data.get('last_used', 0),
                    "preview_available": preview_available,
                    "preview_url": preview_url,
                }
            
            return {
                "status": "success",
                "speakers": speaker_info,
                "total_speakers": len(speaker_info)
            }
            
        except Exception as e:
            return {"status": "error", "message": f"Failed to list speakers: {str(e)}"}
    
    async def get_speaker_audio_paths(self, speaker_name: str) -> Optional[List[str]]:
        """Get audio paths for a specific speaker"""
        try:
            # Run in thread pool to avoid blocking
            loop = asyncio.get_event_loop()
            presets = await loop.run_in_executor(executor, self.preset_manager.list_presets)
            
            if speaker_name in presets:
                audio_path = presets[speaker_name].get('audio_path', '')
                if audio_path:
                    # Check file existence in thread pool
                    exists = await loop.run_in_executor(executor, os.path.exists, audio_path)
                    if exists:
                        return [audio_path]
            return None
        except Exception as e:
            print(f"Error getting speaker audio paths: {e}")
            return None
    
    def speaker_exists(self, speaker_name: str) -> bool:
        """Check if a speaker exists - simple check, no async needed"""
        try:
            presets = self.preset_manager.list_presets()
            return speaker_name in presets
        except Exception as e:
            print(f"Error checking speaker existence: {e}")
            return False

# Global speaker API wrapper (will be initialized after TTS)
speaker_api = None

# API Models
class TranslateRequest(BaseModel):
    audio: Optional[str] = Field(default=None, description="Base64-encoded audio or download URL.")
    dest_language: str = Field(..., description="Target language for translation, e.g., 'English'.")
    audio_mime_type: Optional[str] = Field(default=None, description="MIME type of the audio, e.g., 'audio/wav'.")
    prompt: Optional[str] = Field(default=None, description="Optional custom prompt for Gemini.")
    custom_backing_audio: Optional[str] = Field(
        default=None,
        description="Optional base64 or URL reference for a custom backing track to mix instead of the extracted instrumental.",
    )
    custom_backing_audio_mime_type: Optional[str] = Field(
        default=None,
        description="MIME type for the custom backing track (e.g., 'audio/mp3').",
    )
    response_format: Optional[Literal["mp3", "wav", "flac", "aac", "opus", "ogg", "webm"]] = Field(
        default=None, description="Desired audio format for the translated output."
    )
    bitrate: Optional[str] = Field(
        default=None,
        description="Optional bitrate (e.g., '128k') when using lossy codecs such as MP3.",
    )
    enhance_voice: Optional[bool] = Field(
        default=False,
        description="Apply ClearVoice MossFormer2_SE_48K enhancement before translation.",
    )
    super_resolution_voice: Optional[bool] = Field(
        default=False,
        description="Apply ClearVoice MossFormer2_SR_48K super-resolution before translation.",
    )
    merge_backing_track: Optional[bool] = Field(
        default=False,
        description="When enabled, mix the regenerated speech back onto an instrumental backing track extracted during ClearVoice enhancement.",
    )
    segments_json: Optional[str] = Field(
        default=None,
        description="Optional JSON array of pre-generated Gemini-like segments to skip inference.",
    )
    min_speech_ms: Optional[int] = Field(
        default=None,
        description="Override the minimum speech segment duration (ms) when merging short segments.",
    )
    max_merge_ms: Optional[int] = Field(
        default=None,
        description="Override the maximum silence gap (ms) allowed when merging neighboring segments; use 0 to skip merging.",
    )
    gemini_model: Optional[str] = Field(
        default=None,
        description="Override the Gemini model used for transcription/translation.",
    )
    gemini_api_key: Optional[str] = Field(
        default=None,
        description="Provide a Gemini API key for this request if environment key is not set.",
    )
    ignore_non_speech: Optional[bool] = Field(
        default=False,
        description="When true, ask Gemini to ignore non-speech vocalizations and background voices.",
    )
    preserve_silence_audio: Optional[bool] = Field(
        default=False,
        description="When true, reuse the original audio for any segments labeled as silence.",
    )
    generated_volume_percent: Optional[float] = Field(
        default=None,
        description="Adjust regenerated speech loudness before merging (percentage, default 100%).",
    )
    backing_volume_percent: Optional[float] = Field(
        default=None,
        description="Adjust backing track loudness when merging (percentage, default 100%).",
    )
    reuse_session_id: Optional[str] = Field(
        default=None,
        description="Reuse a previous translate session (e.g., from chunk splitting) instead of uploading audio again.",
    )


class SpeakerOverrideInput(BaseModel):
    preset_name: Optional[str] = Field(
        default=None,
        description="Speaker preset to use for the detected speaker label; leave empty to clone the original voice.",
    )
    use_emotion_prompt: Optional[bool] = Field(
        default=False,
        description="When True, feed the original segment audio as an emotion/style prompt while using the preset.",
    )
    emotion_weight: Optional[float] = Field(
        default=DEFAULT_EMOTION_WEIGHT,
        description="Emotion control weight (0.0 - 1.0) when using the original emotion prompt.",
    )
    volume_percent: Optional[float] = Field(
        default=None,
        ge=MIN_GENERATED_VOLUME_PERCENT,
        le=MAX_GENERATED_VOLUME_PERCENT,
        description="Override regenerated speech loudness for this speaker (percentage).",
    )


class TranslateSegmentInput(BaseModel):
    index: int
    type: Literal["speech", "silence"] = "speech"
    start_ms: int
    end_ms: int
    translated_text: Optional[str] = ""
    source_text: Optional[str] = ""
    generate: Optional[bool] = True
    speaker: Optional[str] = Field(default=None, description="Detected speaker label")
    volume_percent: Optional[float] = Field(
        default=None,
        ge=MIN_GENERATED_VOLUME_PERCENT,
        le=MAX_GENERATED_VOLUME_PERCENT,
        description="Override regenerated speech loudness for this segment (percentage).",
    )
    emotion_weight: Optional[float] = Field(
        default=None,
        ge=0.0,
        le=1.0,
        description="Override emotion prompt weight for this segment (0.0-1.0).",
    )


class SegmentPreviewRequest(BaseModel):
    session_id: str = Field(..., description="Active translate session identifier.")
    segment: TranslateSegmentInput = Field(..., description="Segment payload to preview.")
    generated_volume_percent: Optional[float] = Field(
        default=None,
        ge=MIN_GENERATED_VOLUME_PERCENT,
        le=MAX_GENERATED_VOLUME_PERCENT,
        description="Override the global regenerated volume percent for this preview.",
    )
    backing_volume_percent: Optional[float] = Field(
        default=None,
        ge=MIN_GENERATED_VOLUME_PERCENT,
        le=MAX_GENERATED_VOLUME_PERCENT,
        description="Override backing track volume percent for this preview.",
    )
    speaker_overrides: Optional[Dict[str, SpeakerOverrideInput]] = Field(
        default=None,
        description="Optional speaker overrides to apply only for this preview request.",
    )


class TranslateGenerateRequest(BaseModel):
    session_id: str = Field(..., description="Session identifier returned from /api/translate_segments.")
    segments: List[TranslateSegmentInput] = Field(..., description="Segments to render, including edits and selection.")
    response_format: Optional[Literal["mp3", "wav", "flac", "aac", "opus", "ogg", "webm"]] = Field(
        default=None, description="Desired audio format for output. Defaults to the original request value."
    )
    bitrate: Optional[str] = Field(default=None, description="Optional bitrate for lossy codecs.")
    merge_backing_track: Optional[bool] = Field(
        default=None,
        description="Override whether to mix generated speech with the stored backing track (requires ClearVoice enhancement).",
    )
    generated_volume_percent: Optional[float] = Field(
        default=None,
        description="Override regenerated speech loudness before merging (percentage, default 100%).",
    )
    backing_volume_percent: Optional[float] = Field(
        default=None,
        description="Override backing-track loudness before merging (percentage, default 100%).",
    )
    speaker_overrides: Optional[Dict[str, SpeakerOverrideInput]] = Field(
        default=None,
        description="Optional mapping from detected speaker ids (speaker1, speaker2, …) to preset overrides.",
    )


class MergeChunksRequest(BaseModel):
    chunk_session_ids: Optional[List[str]] = Field(
        default=None,
        description="Specific chunk session IDs to merge, ordered as provided.",
    )
    chunk_batch_id: Optional[str] = Field(
        default=None,
        description="Chunk batch identifier returned from /api/translate_split_audio.",
    )
    response_format: Optional[Literal["mp3", "wav", "flac", "aac", "opus", "ogg", "webm"]] = Field(
        default=None,
        description="Desired format for the merged output (defaults to MP3).",
    )
    bitrate: Optional[str] = Field(
        default=None,
        description="Optional bitrate (e.g., '128k') for lossy codecs.",
    )
    merge_backing_track: Optional[bool] = Field(
        default=None,
        description="Whether to mix the concatenated chunk vocals with their stored backing audio.",
    )


class ChunkBatchGenerateRequest(BaseModel):
    chunk_session_ids: List[str] = Field(
        ...,
        min_items=1,
        description="List of chunk session IDs to generate in parallel.",
    )
    dest_language: Optional[str] = Field(
        default=None,
        description="Override destination language; defaults to the stored chunk language.",
    )
    response_format: Optional[Literal["mp3", "wav", "flac", "aac", "opus", "ogg", "webm"]] = Field(
        default=None,
        description="Desired audio format for each generated chunk.",
    )
    bitrate: Optional[str] = Field(
        default=None,
        description="Optional bitrate (e.g., '128k') when using lossy codecs such as MP3.",
    )
    gemini_model: Optional[str] = Field(
        default=None,
        description="Override the Gemini model used for chunk transcription/translation.",
    )
    gemini_api_key: Optional[str] = Field(
        default=None,
        description="Provide a Gemini API key for this batch if environment defaults should be bypassed.",
    )
    merge_backing_track: Optional[bool] = Field(
        default=None,
        description="When true, attempt to mix regenerated speech with the stored backing track if available.",
    )
    ignore_non_speech: Optional[bool] = Field(
        default=None,
        description="When true, ask Gemini to ignore non-speech vocalizations.",
    )
    preserve_silence_audio: Optional[bool] = Field(
        default=None,
        description="When true, reuse the original audio for silence segments.",
    )
    generated_volume_percent: Optional[float] = Field(
        default=None,
        ge=MIN_GENERATED_VOLUME_PERCENT,
        le=MAX_GENERATED_VOLUME_PERCENT,
        description="Override regenerated speech loudness before merging (percentage, default 100%).",
    )
    backing_volume_percent: Optional[float] = Field(
        default=None,
        ge=MIN_GENERATED_VOLUME_PERCENT,
        le=MAX_GENERATED_VOLUME_PERCENT,
        description="Override backing-track loudness when merging (percentage, default 100%).",
    )


class CloneRequest(BaseModel):
    text: str = Field(..., description="The text to generate audio for.")
    reference_audio: Optional[str] = Field(default=None, description="Reference audio URL or base64")
    reference_text: Optional[str] = Field(default=None, description="Optional transcript")
    pitch: Optional[Literal["very_low", "low", "moderate", "high", "very_high"]] = Field(default=None)
    speed: Optional[Literal["very_low", "low", "moderate", "high", "very_high"]] = Field(default=None)
    temperature: float = Field(default=0.9)
    top_k: int = Field(default=50)
    top_p: float = Field(default=0.95)
    repetition_penalty: float = Field(default=1.0)
    max_tokens: int = Field(default=4096)
    length_threshold: int = Field(default=50)
    window_size: int = Field(default=50)
    stream: bool = Field(default=False)
    response_format: Literal["mp3", "opus", "aac", "flac", "wav", "pcm"] = Field(default="mp3")
    emotion_text: Optional[str] = Field(default="", description="Emotion description text for emotion control")
    emotion_weight: float = Field(default=0.6, description="Emotion control weight (0.0 to 1.0)")
    speech_length: int = Field(default=0, description="Target audio duration in milliseconds. If 0, uses default duration calculation.")
    diffusion_steps: int = Field(default=10, description="Number of diffusion steps for mel-spectrogram generation (1-50). Higher values improve quality but increase latency.")
    max_text_tokens_per_sentence: int = Field(default=120, ge=80, le=200, description="Maximum tokens per sentence for text splitting (80-200). Higher values = longer sentences but may impact quality.")

    @validator("response_format", pre=True, always=True)
    def _force_mp3(cls, value: Optional[str]) -> str:
        return "mp3"

class SpeakRequest(BaseModel):
    text: str = Field(..., description="The text to generate audio for.")
    name: Optional[str] = Field(default=None, description="The name of the voice character")
    pitch: Optional[Literal["very_low", "low", "moderate", "high", "very_high"]] = Field(default=None)
    speed: Optional[Literal["very_low", "low", "moderate", "high", "very_high"]] = Field(default=None)
    temperature: float = Field(default=0.9)
    top_k: int = Field(default=50)
    top_p: float = Field(default=0.95)
    repetition_penalty: float = Field(default=1.0)
    max_tokens: int = Field(default=4096)
    length_threshold: int = Field(default=50)
    window_size: int = Field(default=50)
    stream: bool = Field(default=False)
    response_format: Literal["mp3", "opus", "aac", "flac", "wav", "pcm"] = Field(default="mp3")
    emotion_text: Optional[str] = Field(default="", description="Emotion description text for emotion control")
    emotion_weight: float = Field(default=0.6, description="Emotion control weight (0.0 to 1.0)")
    speech_length: int = Field(default=0, description="Target audio duration in milliseconds. If 0, uses default duration calculation.")
    diffusion_steps: int = Field(default=10, description="Number of diffusion steps for mel-spectrogram generation (1-50). Higher values improve quality but increase latency.")
    max_text_tokens_per_sentence: int = Field(default=120, ge=80, le=200, description="Maximum tokens per sentence for text splitting (80-200). Higher values = longer sentences but may impact quality.")

    @validator("response_format", pre=True, always=True)
    def _force_mp3(cls, value: Optional[str]) -> str:
        return "mp3"

async def warmup_model():
    """Run warmup inferences to fully preload the model"""
    try:
        print("🔥 Running model warmup (2 inferences for full load)...")
        tts = tts_manager.get_tts()
        
        # First warmup inference
        warmup_audio_1 = os.path.join(current_dir, "examples", "voice_01.wav")
        warmup_text_1 = "你好！欢迎使用IndexTTS中文语音合成系统。这是一个功能强大的AI语音生成工具，能够准确处理中文语音合成任务。床前明月光，疑是地上霜。举头望明月，低头思故乡。这首《静夜思》是李白的名作，表达了诗人对故乡的深深思念之情。系统支持多种语音风格，让您的文本转换为自然流畅的语音。今天是2025年1月11日，时间是下午3点30分。这款产品的价格是12,999元，性价比很高。我的电话号码是138-8888-8888，欢迎联系。我正在使用IndexTTS和vLLM技术进行AI语音合成。This system supports both Chinese and English perfectly. 这个系统的RTF约为0.1，比原版快3倍！GPU memory utilization设置为85%。"
        
        # Check if first warmup audio exists
        if not os.path.exists(warmup_audio_1):
            print(f"⚠️ Warmup audio file not found: {warmup_audio_1}")
            return
        
        # Create temporary output file for first warmup
        with tempfile.NamedTemporaryFile(suffix=".wav", delete=False) as tmp_file:
            warmup_output_1 = tmp_file.name
        
        try:
            # Run first warmup inference
            print("🔥 Warmup 1/2: Modern text with voice_01.wav...")
            await tts.infer(
                spk_audio_prompt=warmup_audio_1,
                text=warmup_text_1,
                output_path=warmup_output_1,
                emo_audio_prompt=None,
                emo_alpha=0.6,
                emo_vector=None,
                use_emo_text=True,
                emo_text="兴奋",
                use_random=False,
                interval_silence=200,
                verbose=False,
                max_text_tokens_per_sentence=120,
                speaker_preset=None,
                speech_length=0,
                diffusion_steps=10
            )
            print("✅ Warmup 1/2 completed!")
        finally:
            # Clean up first temporary warmup file
            if os.path.exists(warmup_output_1):
                os.remove(warmup_output_1)
        
        # Second warmup inference
        warmup_audio_2 = os.path.join(current_dir, "examples", "voice_02.wav")
        warmup_text_2 = "人工智能是百年来最宏大的科技建设项目。它究竟是什么样子的？美国经济已经一分为二。一边是热火朝天的 AI 经济，另一边则是萎靡不振的消费经济。你可以在经济统计数据中看到这一点。上个季度，人工智能领域的支出增长超过了消费者支出的增长。如果没有 AI，美国的经济增长将会微不足道。你可以在股市中看到这一点。在过去两年里，股市增长的约 60% 来自与 AI 相关的公司，如微软、英伟达和 Meta。如果没有 AI 热潮，股市的回报率将惨不忍睹。"
        
        # Check if second warmup audio exists
        if not os.path.exists(warmup_audio_2):
            print(f"⚠️ Warmup audio file not found: {warmup_audio_2}")
            print("✅ Model warmup completed with 1/2 inferences")
            return
        
        # Create temporary output file for second warmup
        with tempfile.NamedTemporaryFile(suffix=".wav", delete=False) as tmp_file:
            warmup_output_2 = tmp_file.name
        
        try:
            # Run second warmup inference
            print("🔥 Warmup 2/2: Ancient poetry with voice_02.wav...")
            await tts.infer(
                spk_audio_prompt=warmup_audio_2,
                text=warmup_text_2,
                output_path=warmup_output_2,
                emo_audio_prompt=None,
                emo_alpha=0.6,
                emo_vector=None,
                use_emo_text=True,
                emo_text="无聊",
                use_random=False,
                interval_silence=200,
                verbose=False,
                max_text_tokens_per_sentence=120,
                speaker_preset=None,
                speech_length=0,
                diffusion_steps=10
            )
            print("✅ Warmup 2/2 completed!")
        finally:
            # Clean up second temporary warmup file
            if os.path.exists(warmup_output_2):
                os.remove(warmup_output_2)
        
        print("✅ Model warmup fully completed (2/2 inferences)!")
                
    except Exception as e:
        print(f"⚠️ Warmup failed (non-critical): {e}")
        traceback.print_exc()

# FastAPI lifespan
@asynccontextmanager
async def lifespan(app: FastAPI):
    """Lifespan event handler for startup and shutdown"""
    # Startup
    print("🚀 Starting IndexTTS vLLM v2 FastAPI WebUI...")
    await tts_manager.initialize()
    
    # Run warmup inference
    await warmup_model()
    
    yield
    # Shutdown (if needed)
    print("🔄 Shutting down IndexTTS vLLM v2...")
    # Shutdown the thread executor
    executor.shutdown(wait=True)

# Create FastAPI app
app = FastAPI(
    title="IndexTTS vLLM v2 FastAPI WebUI",
    description="Ultra-fast TTS with vLLM backend, speaker presets, and advanced translate/edit mode with Gemini integration",
    lifespan=lifespan
)

# Web Interface
@app.get("/", response_class=HTMLResponse)
async def home():
    return """
    <!DOCTYPE html>
    <html lang="en">
    <head>
        <meta charset="UTF-8">
        <meta name="viewport" content="width=device-width, initial-scale=1.0">
        <title>🚀 IndexTTS vLLM v2 - FastAPI WebUI</title>
        <style>
            * { box-sizing: border-box; margin: 0; padding: 0; }
            body {
                font-family: -apple-system, BlinkMacSystemFont, 'Segoe UI', Roboto, sans-serif;
                background: linear-gradient(135deg, #667eea 0%, #764ba2 100%);
                min-height: 100vh;
                padding: 20px;
            }
            .container {
                max-width: 1200px;
                margin: 0 auto;
                background: white;
                border-radius: 20px;
                box-shadow: 0 20px 40px rgba(0,0,0,0.1);
                overflow: hidden;
            }
            .header {
                background: linear-gradient(135deg, #667eea 0%, #764ba2 100%);
                color: white;
                padding: 40px;
                text-align: center;
            }
            .header h1 { font-size: 3em; margin-bottom: 10px; }
            .subtitle { font-size: 1.3em; opacity: 0.9; margin-bottom: 15px; }
            .performance-badge {
                background: rgba(255,255,255,0.2);
                padding: 10px 20px;
                border-radius: 25px;
                font-size: 0.95em;
                display: inline-block;
                margin: 5px;
            }
            .content { padding: 40px; }
            .tabs {
                display: flex;
                border-bottom: 2px solid #f0f0f0;
                margin-bottom: 30px;
            }
            .tab {
                padding: 15px 25px;
                cursor: pointer;
                border-bottom: 3px solid transparent;
                transition: all 0.3s;
            }
            .tab.active {
                border-bottom-color: #667eea;
                color: #667eea;
                font-weight: 600;
            }
            .tab-content { display: none; }
            .tab-content.active { display: block; }
            .form-section {
                background: #fff;
                padding: 30px;
                border-radius: 15px;
                border: 2px solid #f0f0f0;
                margin-bottom: 25px;
            }
            .form-group { margin-bottom: 25px; }
            label {
                display: block;
                margin-bottom: 8px;
                font-weight: 600;
                color: #333;
            }
            textarea, input[type="file"], input[type="text"], select {
                width: 100%;
                padding: 15px;
                border: 2px solid #e1e5e9;
                border-radius: 10px;
                font-size: 16px;
                transition: border-color 0.3s;
            }
            textarea:focus, input:focus, select:focus {
                outline: none;
                border-color: #667eea;
            }
            textarea { resize: vertical; min-height: 120px; }
            .btn {
                background: linear-gradient(135deg, #667eea 0%, #764ba2 100%);
                color: white;
                border: none;
                padding: 15px 30px;
                font-size: 16px;
                border-radius: 10px;
                cursor: pointer;
                transition: transform 0.2s;
                margin: 5px;
            }
            .btn:hover { transform: translateY(-2px); }
            .btn:disabled {
                opacity: 0.6;
                cursor: not-allowed;
                transform: none;
            }
            .btn-danger {
                background: linear-gradient(135deg, #e74c3c 0%, #c0392b 100%);
            }
            .status {
                margin-top: 20px;
                padding: 15px;
                border-radius: 10px;
                display: none;
            }
            .status.success {
                background: #d4edda;
                border: 1px solid #c3e6cb;
                color: #155724;
            }
            .status.error {
                background: #f8d7da;
                border: 1px solid #f5c6cb;
                color: #721c24;
            }
            .segment-panel {
                margin-top: 25px;
                border: 2px dashed #d7dcff;
                padding: 20px;
                border-radius: 15px;
                background: #f7f8ff;
            }
            .segment-controls {
                display: flex;
                flex-wrap: wrap;
                gap: 12px;
                align-items: center;
                justify-content: space-between;
                margin-bottom: 15px;
            }
            .segment-list {
                display: flex;
                flex-direction: column;
                gap: 16px;
                max-height: 520px;
                overflow-y: auto;
                padding-right: 8px;
            }
            .segment-card {
                border-radius: 12px;
                border: 1px solid #dce1fa;
                padding: 16px;
                background: white;
                box-shadow: 0 4px 16px rgba(102,126,234,0.08);
            }
            .segment-card.speech { border-left: 4px solid #667eea; }
            .segment-card.silence { border-left: 4px solid #9aa0b6; }
            .segment-header {
                display: flex;
                align-items: center;
                justify-content: space-between;
                gap: 12px;
            }
            .segment-meta {
                font-size: 0.9em;
                color: #666;
            }
            .segment-body {
                margin-top: 12px;
                display: grid;
                gap: 14px;
            }
            .segment-body textarea {
                min-height: 80px;
                font-size: 0.95em;
            }
            .segment-timing {
                display: grid;
                grid-template-columns: repeat(auto-fit, minmax(140px, 1fr));
                gap: 12px;
                align-items: end;
            }
            .segment-timing label {
                font-weight: 500;
                color: #444;
            }
            .segment-timing input {
                width: 100%;
            }
            .segment-duration-label {
                font-size: 0.85em;
                color: #888;
            }
            .segment-checkbox {
                display: flex;
                align-items: center;
                gap: 8px;
                font-weight: 600;
                color: #333;
            }
            .segment-audio {
                width: 100%;
                margin-top: 8px;
            }
            .segment-empty {
                padding: 20px;
                text-align: center;
                background: rgba(102, 126, 234, 0.08);
                border-radius: 12px;
                color: #445;
                font-weight: 500;
            }
            .speaker-list {
                background: #f8f9fa;
                padding: 20px;
                border-radius: 10px;
                margin-top: 20px;
            }
            .speaker-item {
                background: white;
                padding: 15px;
                border-radius: 8px;
                margin-bottom: 10px;
                border-left: 4px solid #667eea;
                display: flex;
                justify-content: space-between;
                align-items: center;
            }
            .speaker-info h4 { margin: 0; color: #333; }
            .speaker-info small { color: #666; }
            .speaker-preview {
                margin-top: 12px;
            }
            .speaker-preview label {
                font-weight: 600;
                color: #444;
                display: block;
                margin-bottom: 4px;
            }
            .speaker-preview audio {
                width: 220px;
                max-width: 100%;
                outline: none;
                border-radius: 6px;
                background: #f3f4ff;
                padding: 4px;
            }
            .speaker-assignment-panel {
                border: 1px solid #dce1fa;
                border-radius: 12px;
                padding: 16px;
                margin-bottom: 16px;
                background: #f9f9ff;
            }
            .speaker-assignment-panel h4 {
                margin: 0 0 12px 0;
                color: #333;
            }
            .speaker-assignment-item {
                display: flex;
                flex-direction: column;
                gap: 8px;
                padding: 12px;
                border-radius: 10px;
                border: 1px solid #e3e6fb;
                background: white;
                margin-bottom: 10px;
            }
            .speaker-assignment-header {
                display: flex;
                justify-content: space-between;
                align-items: center;
                gap: 12px;
            }
            .speaker-assignment-controls {
                display: flex;
                flex-wrap: wrap;
                gap: 12px;
                align-items: center;
            }
            .speaker-emo-toggle {
                display: flex;
                align-items: center;
                gap: 6px;
                font-size: 0.9em;
                color: #555;
            }
            .speaker-emo-settings {
                display: flex;
                flex-wrap: wrap;
                gap: 12px;
                align-items: center;
                margin-top: 6px;
            }
            .speaker-emo-weight {
                display: flex;
                flex-direction: column;
                gap: 4px;
                font-size: 0.85em;
                color: #555;
            }
            .speaker-emo-weight input {
                width: 110px;
            }
            .speaker-assignment-preview {
                display: flex;
                flex-direction: column;
                gap: 6px;
                margin-top: 4px;
            }
            .speaker-assignment-preview small {
                color: #777;
            }
            .speaker-assignment-preview audio {
                width: 240px;
                max-width: 100%;
                outline: none;
                border-radius: 6px;
                background: #f3f4ff;
                padding: 4px;
            }
            .segment-speaker-pill {
                display: inline-flex;
                align-items: center;
                background: #eef0ff;
                color: #4b50c1;
                border-radius: 999px;
                padding: 2px 10px;
                font-size: 0.8em;
                font-weight: 600;
            }
            .loading {
                display: inline-block;
                width: 20px;
                height: 20px;
                border: 3px solid #f3f3f3;
                border-top: 3px solid #667eea;
                border-radius: 50%;
                animation: spin 1s linear infinite;
                margin-right: 10px;
            }
            @keyframes spin {
                0% { transform: rotate(0deg); }
                100% { transform: rotate(360deg); }
            }
        </style>
    </head>
    <body>
        <div class="container">
            <div class="header">
                <h1>🚀 IndexTTS vLLM v2</h1>
                <p class="subtitle">Ultra-Fast TTS with vLLM Backend / 超快速中英文语音合成</p>
                <div>
                    <span class="performance-badge">⚡ vLLM v2 Backend</span>
                    <span class="performance-badge">🇨🇳 Chinese Support</span>
                    <span class="performance-badge">🎭 Speaker Presets</span>
                    <span class="performance-badge">🎵 MP3 Output</span>
                    <span class="performance-badge">🔌 API Integration</span>
                    <span class="performance-badge">😊 Emotion Text Control</span>
                    <span class="performance-badge">🌊 Streaming Mode</span>
                    <span class="performance-badge">🌐 Translate/Edit Mode</span>
                    <span class="performance-badge">✂️ Segment Editing</span>
                </div>
            </div>
            <div class="content">
                <div class="tabs">
                    <div class="tab active" onclick="switchTab('synthesis')">🎵 Speech Synthesis</div>
                    <div class="tab" onclick="switchTab('translate')">🌐 Speech Translate/Edit</div>
                    <div class="tab" onclick="switchTab('speakers')">🎭 Speaker Management</div>
                    <div class="tab" onclick="switchTab('api')">📚 API Documentation</div>
                </div>

                <!-- Speech Synthesis Tab -->
                <div id="synthesis" class="tab-content active">
                    <div class="form-section">
                        <h3>🎵 Generate Speech</h3>
                        
                        <!-- Chinese Demo Section -->
                        <div style="background: linear-gradient(135deg, #ff9a9e 0%, #fecfef 100%); padding: 20px; border-radius: 15px; margin-bottom: 20px;">
                            <h4 style="color: #333; margin-bottom: 15px;">🇨🇳 中文语音合成演示</h4>
                            <div style="display: grid; grid-template-columns: 1fr 1fr; gap: 15px;">
                                <button class="btn" onclick="setChineseDemo('现代文本')" style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%);">
                                    现代文本演示
                                </button>
                                <button class="btn" onclick="setChineseDemo('古诗词')" style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%);">
                                    古诗词演示
                                </button>
                                <button class="btn" onclick="setChineseDemo('数字日期')" style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%);">
                                    数字日期处理
                                </button>
                                <button class="btn" onclick="setChineseDemo('中英混合')" style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%);">
                                    中英混合文本
                                </button>
                                <button class="btn" onclick="setEmotionDemo('开心')" style="background: linear-gradient(135deg, #ff9a9e 0%, #fecfef 100%);">
                                    😊 开心情感
                                </button>
                                <button class="btn" onclick="setEmotionDemo('悲伤')" style="background: linear-gradient(135deg, #a8edea 0%, #fed6e3 100%);">
                                    😢 悲伤情感
                                </button>
                                <button class="btn" onclick="setEmotionDemo('愤怒')" style="background: linear-gradient(135deg, #ff6b6b 0%, #ffa500 100%);">
                                    😠 愤怒情感
                                </button>
                                <button class="btn" onclick="setEmotionDemo('平静')" style="background: linear-gradient(135deg, #74b9ff 0%, #0984e3 100%);">
                                    😌 平静情感
                                </button>
                            </div>
                            <p style="margin-top: 10px; font-size: 0.9em; color: #666;">
                                ✨ IndexTTS内置强大的中文文本规范化，支持数字转换、标点处理、拼音声调等
                            </p>
                        </div>
                        
                        <form id="ttsForm" enctype="multipart/form-data">
                            <div class="form-group">
                                <label for="text">Text to Synthesize / 输入要合成的文本:</label>
                                <textarea id="text" name="text" placeholder="Enter the text you want to convert to speech...&#10;输入您想要转换为语音的文本...&#10;&#10;中文示例：&#10;你好世界！今天是2025年1月11日，天气很好。&#10;这个AI语音合成系统支持中英混合文本。" required></textarea>
                            </div>
                            
                            <div class="form-group">
                                <label for="voice_files">Upload Voice Files (Optional):</label>
                                <input type="file" id="voice_files" name="voice_files" accept=".wav,.mp3,.m4a,.flac" multiple>
                            </div>
                            
                            <div class="form-group">
                                <label for="speaker">Use Speaker Preset:</label>
                                <select id="speaker" name="speaker">
                                    <option value="">Select a speaker...</option>
                                </select>
                            </div>
                            
                            <div class="form-group">
                                <label style="display: flex; align-items: center; cursor: pointer;">
                                    <input type="checkbox" id="streamingMode" name="streamingMode" style="width: auto; margin-right: 10px;">
                                    <span>⚡ Enable Streaming Mode (Play audio as it's generated)</span>
                                </label>
                                <small style="color: #666; margin-top: 5px; display: block;">
                                    Streaming mode starts playback immediately when the first chunk is ready
                                </small>
                            </div>
                            
                            <div class="form-group" id="streamingSettings" style="display: none; background: #f8f9fa; padding: 15px; border-radius: 10px; margin-top: 10px;">
                                <label for="firstChunkSize">⚡ First Chunk Size: <span id="firstChunkSizeValue">40</span> tokens</label>
                                <input type="range" id="firstChunkSize" name="firstChunkSize" 
                                       min="20" max="80" step="10" value="40"
                                       style="width: 100%; margin: 10px 0;"
                                       oninput="document.getElementById('firstChunkSizeValue').textContent = this.value">
                                <div style="display: flex; justify-content: space-between; font-size: 0.85em; color: #666;">
                                    <span>⚡ Faster (20)</span>
                                    <span>Balanced (40)</span>
                                    <span>Quality (80)</span>
                                </div>
                                <small style="color: #666; margin-top: 10px; display: block;">
                                    💡 Smaller = faster first response but more chunks. Recommended: 30-50 tokens.
                                </small>
                            </div>
                            
                            <!-- Emotion Control Section -->
                            <div style="background: linear-gradient(135deg, #ffd89b 0%, #19547b 100%); padding: 20px; border-radius: 15px; margin: 20px 0;">
                                <h4 style="color: white; margin-bottom: 15px;">😊 Emotion Text Control / 情感文本控制</h4>
                                <div class="form-group">
                                    <label for="emotionText" style="color: white;">Emotion Description / 情感描述:</label>
                                    <input type="text" id="emotionText" name="emotionText" 
                                           placeholder="e.g., happy and excited, sad and melancholic, angry and frustrated... 例如：开心兴奋，悲伤忧郁，愤怒沮丧..." 
                                           style="margin-bottom: 15px;">
                                </div>
                                <div class="form-group">
                                    <label for="emotionWeight" style="color: white;">Emotion Strength / 情感强度: <span id="emotionWeightValue">0.6</span></label>
                                    <input type="range" id="emotionWeight" name="emotionWeight" 
                                           min="0.0" max="1.0" step="0.1" value="0.6"
                                           style="width: 100%; margin-bottom: 10px;"
                                           oninput="document.getElementById('emotionWeightValue').textContent = this.value">
                                </div>
                                <p style="color: #fff; font-size: 0.9em; margin: 0;">
                                    💡 输入情感描述文本可以让AI更精准地控制语音的情感表达。留空则使用默认情感。
                                </p>
                            </div>
                            
                            <!-- Duration Control Section -->
                            <div style="background: linear-gradient(135deg, #36d1dc 0%, #5b86e5 100%); padding: 20px; border-radius: 15px; margin: 20px 0;">
                                <h4 style="color: white; margin-bottom: 15px;">⏱️ Duration Control / 时长控制</h4>
                                <div class="form-group">
                                    <label for="speechLength" style="color: white;">Target Duration / 目标时长 (milliseconds):</label>
                                    <input type="number" id="speechLength" name="speechLength" 
                                           value="0" min="0" max="6000000" step="100"
                                           placeholder="0 = auto duration"
                                           style="margin-bottom: 15px;">
                                    <button type="button" class="btn" onclick="estimateDuration()" style="background: rgba(255,255,255,0.3); margin-top: 5px;">
                                        📊 Estimate Duration from Text
                                    </button>
                                </div>
                                <div id="durationEstimate" style="color: white; font-weight: bold; margin-top: 10px; padding: 10px; background: rgba(255,255,255,0.2); border-radius: 8px; display: none;"></div>
                                <p style="color: #fff; font-size: 0.9em; margin: 10px 0 0 0;">
                                    💡 设置为 0 表示自动时长。指定毫秒数可用于视频配音/时间控制。Set to 0 for auto duration. Specify milliseconds for video dubbing/timing control.
                                </p>
                            </div>
                            
                            <!-- Diffusion Steps Control Section -->
                            <div style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%); padding: 20px; border-radius: 15px; margin: 20px 0;">
                                <h4 style="color: white; margin-bottom: 15px;">🎨 Quality Control / 质量控制</h4>
                                <div class="form-group">
                                    <label for="diffusionSteps" style="color: white;">Diffusion Steps / 扩散步数: <span id="diffusionStepsValue">10</span></label>
                                    <input type="range" id="diffusionSteps" name="diffusionSteps" 
                                           min="1" max="50" step="1" value="10"
                                           style="width: 100%; margin-bottom: 10px;"
                                           oninput="document.getElementById('diffusionStepsValue').textContent = this.value">
                                </div>
                                <p style="color: #fff; font-size: 0.9em; margin: 0;">
                                    💡 更高的步数可以提高音质但会增加延迟。建议值: 快速=5, 默认=10, 高质量=20-30。Higher steps improve quality but increase latency. Recommended: Fast=5, Default=10, High-quality=20-30.
                                </p>
                            </div>
                            
                            <!-- Text Tokens Per Sentence Control Section -->
                            <div style="background: linear-gradient(135deg, #f093fb 0%, #f5576c 100%); padding: 20px; border-radius: 15px; margin: 20px 0;">
                                <h4 style="color: white; margin-bottom: 15px;">✂️ Text Splitting / 文本分句</h4>
                                <div class="form-group">
                                    <label for="maxTextTokens" style="color: white;">Max Tokens Per Sentence / 每句最大Token数: <span id="maxTextTokensValue">120</span></label>
                                    <input type="range" id="maxTextTokens" name="maxTextTokens" 
                                           min="80" max="200" step="10" value="120"
                                           style="width: 100%; margin-bottom: 10px;"
                                           oninput="document.getElementById('maxTextTokensValue').textContent = this.value">
                                </div>
                                <div style="display: flex; justify-content: space-between; font-size: 0.85em; color: #fff;">
                                    <span>Short (80)</span>
                                    <span>Balanced (120)</span>
                                    <span>Long (200)</span>
                                </div>
                                <p style="color: #fff; font-size: 0.9em; margin: 10px 0 0 0;">
                                    💡 控制每个句子的最大长度。较短=更多句子但处理更快，较长=更少句子但减少断句。Controls max sentence length. Shorter = more sentences but faster processing, Longer = fewer sentences but fewer breaks.
                                </p>
                            </div>
                            
                            <button type="submit" class="btn" id="generateBtn">
                                🎵 Generate Speech
                            </button>
                            <button type="button" class="btn btn-danger" onclick="clearOutputs()">
                                🗑️ Clear All Outputs
                            </button>
                        </form>
                        
                        <div id="status" class="status"></div>
                        <div id="audioResult"></div>
                    </div>
                </div>

                <!-- Speech Translation Tab -->
                <div id="translate" class="tab-content">
                    <div class="form-section">
                        <h3>🌐 Speech Translate/Edit</h3>
                        <p style="color: #666; margin-bottom: 20px;">
                            Upload source speech audio, pick a destination language, and optionally enter advanced mode to audition Gemini segments, tweak timings/text, and regenerate only the pieces you need.
                        </p>
                        <form id="translateForm" enctype="multipart/form-data">
                            <div class="form-group">
                                <label for="translateAudioFile">Source Audio:</label>
                                <input type="file" id="translateAudioFile" name="audio_file" accept=".wav,.mp3,.m4a,.flac,.aac,.ogg,.opus" required>
                                <small style="color: #666; display: block; margin-top: 6px;">
                                    Supported formats: WAV, MP3, M4A, FLAC, AAC, OGG, OPUS. Audio is processed locally then sent to Gemini for transcription.
                                </small>
                            </div>
                            <div class="form-group" id="translateClearVoiceBlock">
                                <label>ClearVoice Separation & Chunking:</label>
                                <div style="display: flex; gap: 16px; flex-wrap: wrap;">
                                    <label style="display: flex; align-items: center; gap: 8px;">
                                        <input type="checkbox" id="translateEnhancement">
                                        <span>Enhance with MossFormer2_SE_48K</span>
                                    </label>
                                    <label style="display: flex; align-items: center; gap: 8px;">
                                        <input type="checkbox" id="translateSuperResolution">
                                        <span>Super Resolution with MossFormer2_SR_48K</span>
                                    </label>
                                    <label style="display: flex; align-items: center; gap: 8px;">
                                        <input type="checkbox" id="translateMergeBack" disabled>
                                        <span>Mix translated speech back into instrumental (requires enhancement)</span>
                                    </label>
                                </div>
                                <small style="color: #666; margin-top: 5px; display: block;">
                                    ClearVoice runs locally before contacting Gemini. Enable it for cleaner vocals, optional super-resolution, and backing-track extraction.
                                </small>
                                <div style="margin-top: 12px; padding: 12px; border-radius: 12px; background: rgba(102,126,234,0.08);">
                                    <label style="display: flex; align-items: center; gap: 10px; font-weight: 500;">
                                        <input type="checkbox" id="translateEnableChunkSplit">
                                        <span>Split long audio into 5–10 minute chunks before Gemini (requires ClearVoice enhancement)</span>
                                    </label>
                                    <div id="translateChunkSettings" style="display: none; margin-top: 10px;">
                                        <div style="display: flex; gap: 12px; flex-wrap: wrap;">
                                            <div style="flex: 1 1 180px;">
                                                <label for="translateChunkMinMinutes" style="font-weight: 500;">Minimum chunk length (minutes):</label>
                                                <input type="number" id="translateChunkMinMinutes" value="5" min="1" max="45" step="1">
                                            </div>
                                            <div style="flex: 1 1 180px;">
                                                <label for="translateChunkMaxMinutes" style="font-weight: 500;">Maximum chunk length (minutes):</label>
                                                <input type="number" id="translateChunkMaxMinutes" value="10" min="1" max="45" step="1">
                                            </div>
                                        </div>
                                        <div style="margin-top: 12px; display: flex; gap: 12px; flex-wrap: wrap; align-items: center;">
                                            <button type="button" class="btn btn-secondary" id="translateSplitAudioBtn">✂️ Split Audio Now</button>
                                            <small style="color: #666;">
                                                We detect long silences on the enhanced vocal track so each chunk can be processed (and mixed back) independently, then concatenated later.
                                            </small>
                                        </div>
                                    </div>
                                    <div id="translateChunkSelection" style="display: none; margin-top: 12px; padding: 10px; border-radius: 10px; border: 1px dashed #7f85f5; background: rgba(102,126,234,0.08);">
                                        <div style="display: flex; justify-content: space-between; align-items: center; gap: 12px;">
                                            <span id="translateChunkSelectionText" style="font-weight: 500;"></span>
                                            <button type="button" class="btn btn-secondary" id="translateClearChunkBtn" style="background: transparent; color: #6370ff; border-color: #6370ff;">Clear Selection</button>
                                        </div>
                                    </div>
                                    <div id="translateChunkResults" style="display: none; margin-top: 12px;">
                                        <div id="translateChunkSummary" style="font-weight: 500; color: #0a7c4a; margin-bottom: 10px;"></div>
                                        <div id="translateChunkList" style="display: flex; flex-direction: column; gap: 12px;"></div>
                                    </div>
                                    <div id="translateChunkBatchControls" style="display: none; margin-top: 12px; gap: 12px; flex-wrap: wrap; align-items: center;">
                                        <label style="display: flex; align-items: center; gap: 8px; font-size: 0.95em; margin: 0;">
                                            <input type="checkbox" id="translateChunkSelectPending">
                                            <span>Select all pending chunks</span>
                                        </label>
                                        <button type="button" class="btn btn-secondary" id="translateGenerateChunksBtn" style="display: none;">⚡ Generate Selected Chunks</button>
                                    </div>
                                    <div id="translateChunkBatchStatus" class="status"></div>
                                    <div style="margin-top: 12px;">
                                        <button type="button" class="btn btn-secondary" id="translateMergeChunksBtn" style="display: none;">🔗 Merge All Chunks</button>
                                    </div>
                                </div>
                            </div>
                            <div class="form-group">
                                <label for="translateDestLanguage">Destination Language:</label>
                                <select id="translateDestLanguage" name="dest_language" required>
                                    <option value="">Select a language...</option>
                                    <option value="English">English</option>
                                    <option value="Chinese">Chinese</option>
                                </select>
                            </div>
                            <div class="form-group">
                                <label for="translateGeminiModel">Gemini Model:</label>
                                <select id="translateGeminiModel" name="gemini_model">
                                    <option value="gemini-2.5-pro" selected>Gemini 2.5 Pro (highest accuracy)</option>
                                    <option value="gemini-flash-latest">Gemini Flash Latest (fast)</option>
                                </select>
                                <small style="color: #666; display: block; margin-top: 6px;">
                                    Choose the Gemini model used for transcription/translation. Flash is faster; Pro is more accurate.
                                </small>
                            </div>
                            <div class="form-group">
                                <label for="translateGeminiApiKey">Gemini API Key (optional):</label>
                                <input type="password" id="translateGeminiApiKey" name="gemini_api_key" placeholder="Use this key instead of the system default..." autocomplete="off">
                                <small style="color: #666; display: block; margin-top: 6px;">
                                    Provide a key if the server environment does not have one configured or you need to override it for this request.
                                </small>
                            </div>
                            <div class="form-group">
                                <label for="translateOutputFormat">Output Format:</label>
                                <select id="translateOutputFormat" name="response_format" disabled>
                                    <option value="mp3" selected>MP3 (optimized for storage & transfer)</option>
                                </select>
                                <small style="color:#666;display:block;margin-top:6px;">All outputs are delivered as MP3 to keep files lightweight.</small>
                            </div>
                            <div class="form-group">
                                <label>Segment Merge Settings (Optional):</label>
                                <div style="display: flex; gap: 16px; flex-wrap: wrap;">
                                    <div style="flex: 1 1 220px;">
                                        <label for="translateMinSpeech" style="font-weight: 500;">Minimum speech duration (ms):</label>
                                        <input type="number" id="translateMinSpeech" min="500" step="100" placeholder="Default 3000">
                                    </div>
                                    <div style="flex: 1 1 220px;">
                                        <label for="translateMaxMerge" style="font-weight: 500;">Max merge silence gap (ms):</label>
                                        <input type="number" id="translateMaxMerge" min="0" step="50" placeholder="Default 0 (0 disables)">
                                    </div>
                                </div>
                                <small style="color: #666; margin-top: 5px; display: block;">
                                    These values control Gemini segment stitching. Lower min duration keeps shorter phrases; higher max merge gap allows merging across longer silences, and setting the max gap to 0 skips automatic merging entirely.
                                </small>
                            </div>
                            <div class="form-group">
                                <label for="translateVolumePercent">Generated Speech Volume (%)</label>
                                <input type="number" id="translateVolumePercent" min="10" max="300" step="5" value="100" placeholder="Default 100%">
                                <small style="color: #666; margin-top: 5px; display: block;">
                                    Adjust the loudness of regenerated speech before mixing with backing or preserved segments. 100% keeps original volume; try 80%–150% for fine control.
                                </small>
                            </div>
                            <div class="form-group">
                                <label for="translateBackingVolumePercent">Backing Track Volume (%)</label>
                                <input type="number" id="translateBackingVolumePercent" min="10" max="300" step="5" value="100" placeholder="Default 100%">
                                <small style="color: #666; margin-top: 5px; display: block;">
                                    Controls the loudness of the instrumental backing when mix-back is enabled. Lower values keep vocals more forward.
                                </small>
                            </div>
                            <div class="form-group">
                                <label for="translateCustomBackingFile">Custom Backing Track (optional)</label>
                                <div style="display: flex; gap: 12px; flex-wrap: wrap; align-items: center;">
                                    <input type="file" id="translateCustomBackingFile" name="custom_backing_audio_file" accept=".wav,.mp3,.m4a,.flac,.aac,.ogg,.opus" style="flex: 1 1 auto;">
                                    <button type="button" class="btn btn-secondary" id="translateCustomBackingClear" style="flex: 0 0 auto;">Clear</button>
                                </div>
                                <small id="translateCustomBackingSummary" style="color: #666; margin-top: 5px; display: block;">
                                    No custom backing selected. Upload audio here to override the extracted instrumental when mix-back is enabled.
                                </small>
                            </div>
                            <div class="form-group">
                                <label style="display: flex; align-items: center; gap: 10px;">
                                    <input type="checkbox" id="translateIgnoreNonSpeech">
                                    <span>Ask Gemini to ignore non-speech (laughs, shouts, crowd noise)</span>
                                </label>
                                <small style="color: #666; margin-top: 6px; display: block;">
                                    When enabled, Gemini only transcribes spoken dialogue and skips non-speech vocalizations.
                                </small>
                            </div>
                            <div class="form-group">
                                <label style="display: flex; align-items: center; gap: 10px;">
                                    <input type="checkbox" id="translatePreserveSilence">
                                    <span>Preserve original audio for segments treated as silence</span>
                                </label>
                                <small style="color: #666; margin-top: 6px; display: block;">
                                    Keeps the source vocal audio for silent segments (helpful for laughs or crowd reactions).
                                </small>
                            </div>
                            <div class="form-group">
                                <label style="display: flex; align-items: center; gap: 10px; margin-bottom: 8px;">
                                    <input type="checkbox" id="translateManualSegmentsToggle">
                                    <span>Provide manual Gemini segments JSON (skip Gemini inference)</span>
                                </label>
                                <div id="translateManualSegmentsPanel" style="display: none;">
                                    <textarea id="translateManualSegments" rows="6" placeholder='Paste the raw JSON array returned from Gemini (or another AI). Each entry should include "start", "end", "source_text", and "translated_text".'></textarea>
                                    <small style="color: #666; display: block; margin-top: 6px;">
                                        Use the prompt templates below with any LLM to generate the JSON response, then paste it here to bypass the Gemini API step.
                                    </small>
                                </div>
                            </div>
                            <div id="translateSeparationPreview" style="display: none; margin-bottom: 16px;"></div>
                            <div class="form-group" id="translatePromptTemplates" style="display: none; background: rgba(102,126,234,0.08); padding: 16px; border-radius: 12px;">
                                <label>Gemini Prompt Templates</label>
                                <div style="display: flex; flex-wrap: wrap; gap: 16px;">
                                    <div style="flex: 1 1 250px;">
                                        <label style="font-weight: 500;">Translation mode prompt:</label>
                                        <textarea id="translatePromptTranslation" readonly style="min-height: 140px;"></textarea>
                                    </div>
                                    <div style="flex: 1 1 250px;">
                                        <label style="font-weight: 500;">Transcription-only prompt:</label>
                                        <textarea id="translatePromptTranscription" readonly style="min-height: 140px;"></textarea>
                                    </div>
                                </div>
                                <small style="color: #666; display: block; margin-top: 6px;">
                                    Copy these prompts when generating manual segments with your preferred AI model. Replace <code>{'{dest_language}'}</code> as needed.
                                </small>
                            </div>
                            <div class="form-group" style="margin-top: 20px;">
                                <label style="display: flex; align-items: center; gap: 10px;">
                                    <input type="checkbox" id="translateAdvancedMode">
                                    <span>Enable advanced translate/edit workflow</span>
                                </label>
                                <small style="color: #666; margin-top: 6px; display: block;">
                                    When enabled we will analyze segments first so you can listen, edit, and choose which parts to regenerate before final synthesis.
                                </small>
                            </div>
                            <div id="translateAdvancedSettings" style="display: none; background: rgba(102,126,234,0.08); padding: 16px; border-radius: 12px; margin-bottom: 20px;">
                                <div class="form-group" style="margin-bottom: 16px;">
                                    <label style="display: flex; align-items: center; gap: 10px; margin-bottom: 6px;">
                                        <input type="checkbox" id="translateDebugTranslate" checked>
                                        <span>Ask Gemini to translate while transcribing</span>
                                    </label>
                                    <small style="color: #666; display: block;">
                                        Uncheck to only transcribe with timestamps; you can enter translation text manually per segment.
                                    </small>
                                </div>
                                <div class="form-group" style="margin-bottom: 0;">
                                    <label for="translateCustomPrompt">Custom Gemini Prompt (optional):</label>
                                    <textarea id="translateCustomPrompt" rows="3" placeholder="Override the default Gemini prompt for segment analysis..."></textarea>
                                    <small style="color: #666; margin-top: 6px; display: block;">
                                        Leave blank to use the optimized defaults for translate/transcribe modes.
                                    </small>
                                </div>
                            </div>
                            <button type="submit" class="btn" id="translateBtn">🌐 Translate Speech</button>
                        </form>
                        <div id="translateStatus" class="status"></div>
                        <div id="translateAdvancedPanel" class="segment-panel" style="display: none;">
                            <div id="translateSpeakerAssignments" class="speaker-assignment-panel" style="display: none;"></div>
                            <div class="segment-controls">
                                <label class="segment-checkbox">
                                    <input type="checkbox" id="translateSegmentsSelectAll" checked>
                                    <span>Select all segments for generation</span>
                                </label>
                                <div style="display: flex; gap: 10px; flex-wrap: wrap;">
                                    <button type="button" class="btn" id="translateGenerateBtn">🎧 Generate Selected Segments</button>
                                </div>
                            </div>
                            <div id="translateSegmentsStatus" class="status"></div>
                            <div id="translateSegmentsList" class="segment-list"></div>
                        </div>
                        <div id="translateResult"></div>
                    </div>
                </div>

                <!-- Speaker Management Tab -->
                <div id="speakers" class="tab-content">
                    <div class="form-section">
                        <h3>➕ Add New Speaker</h3>
                        <form id="addSpeakerForm" enctype="multipart/form-data">
                            <div class="form-group">
                                <label for="speakerName">Speaker Name:</label>
                                <input type="text" id="speakerName" name="speakerName" placeholder="Enter speaker name..." required>
                            </div>
                            
                            <div class="form-group">
                                <label for="speakerAudioFiles">Audio Files:</label>
                                <input type="file" id="speakerAudioFiles" name="speakerAudioFiles" accept=".wav,.mp3,.m4a,.flac" multiple required>
                                <small style="color: #666; margin-top: 5px; display: block;">
                                    Upload multiple audio files for better voice quality<br>
                                    ✂️ Audio will be smartly cut at silence intervals (3-15s) for optimal performance
                                </small>
                            </div>
                            
                            <div class="form-group">
                                <label>Pure Voice Extraction (ClearVoice, optional):</label>
                                <div style="display: flex; gap: 16px; flex-wrap: wrap;">
                                    <label style="display: flex; align-items: center; gap: 8px;">
                                        <input type="checkbox" id="applyEnhancement">
                                        <span>Enhance with MossFormer2_SE_48K</span>
                                    </label>
                                    <label style="display: flex; align-items: center; gap: 8px;">
                                        <input type="checkbox" id="applySuperResolution">
                                        <span>Super Resolution with MossFormer2_SR_48K</span>
                                    </label>
                                </div>
                                <small style="color: #666; margin-top: 5px; display: block;">
                                    Enable ClearVoice MossFormer2 models to clean and upscale the reference audio. When both are selected, enhancement runs before super-resolution.
                                </small>
                            </div>
                            
                            <button type="submit" class="btn">➕ Add Speaker</button>
                        </form>
                        
                        <div id="speakerStatus" class="status"></div>
                    </div>

                    <div class="form-section">
                        <h3>🎭 Manage Speakers</h3>
                        <button class="btn" onclick="loadSpeakerList()">🔄 Refresh Speaker List</button>
                        <div id="speakerList" class="speaker-list"></div>
                    </div>
                </div>

                <!-- API Documentation Tab -->
                <div id="api" class="tab-content">
                    <div class="form-section">
                        <h3>📚 API Endpoints</h3>
                        
                        <h4 style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%); color: white; padding: 10px; border-radius: 8px;">🔷 API Endpoints (Recommended for External Use)</h4>
                        
                        <h5>🔍 Server Information</h5>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>GET /server_info</strong> - Get server information, model details, and available speakers
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Returns: Server version, model name, speaker list, capabilities</li>
                                </ul>
                            </li>
                        </ul>
                        
                        <h5>👥 Speaker Management</h5>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>GET /audio_roles</strong> - List all available speaker presets
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Returns: <code>{"success": true, "roles": ["speaker1", "speaker2", ...]}</code></li>
                                </ul>
                            </li>
                            <li><strong>POST /add_speaker</strong> - Register a new speaker with reference audio
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Form data: <code>name</code> (string), <code>audio_file</code> (file upload)</li>
                                    <li>Optional form data: <code>enhance_voice</code> (bool), <code>super_resolution_voice</code> (bool) — toggles ClearVoice MossFormer2_SE_48K and MossFormer2_SR_48K (both default to <code>false</code>); <code>merge_backing_track</code> (bool) mixes regenerated speech onto the extracted instrumental (requires enhancement); <code>min_speech_ms</code>/<code>max_merge_ms</code> override the segment-merging heuristics (set <code>max_merge_ms</code> to 0 to skip merging entirely); <code>segments_json</code> lets you supply Gemini-style JSON to skip inference.</li>
                                    <li>Audio will be automatically trimmed to 3-15 seconds at silence points; when both toggles are enabled, enhancement runs before super-resolution</li>
                                </ul>
                            </li>
                            <li><strong>POST /delete_speaker</strong> - Remove an existing speaker preset
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Form data: <code>name</code> (string)</li>
                                </ul>
                            </li>
                        </ul>

                        <h5>🌐 Speech Translation</h5>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>POST /api/translate_audio</strong> - Translate speech audio and regenerate voice in the target language while preserving timing.
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Multipart form fields: <code>audio_file</code> (file), <code>dest_language</code> (string); audio outputs are always MP3. Optional fields: <code>prompt</code> (custom Gemini instructions), <code>enhance_voice</code> (bool), <code>super_resolution_voice</code> (bool) to run ClearVoice preprocessing, <code>merge_backing_track</code> (bool) to blend the result with the extracted instrumental backing, <code>custom_backing_audio_file</code> (file) to override the instrumental even without enhancement, plus <code>min_speech_ms</code>/<code>max_merge_ms</code> to override segment-merging heuristics (set <code>max_merge_ms</code> to 0 to keep Gemini's original segmentation) and <code>segments_json</code> to supply pre-generated Gemini-like segments.</li>
                                    <li>JSON alternative: <code>{"audio": "&lt;base64&gt;", "dest_language": "English", "audio_mime_type": "audio/wav", "custom_backing_audio": "&lt;base64 or url&gt;", "custom_backing_audio_mime_type": "audio/mp3", "response_format": "mp3", "enhance_voice": true, "super_resolution_voice": false, "merge_backing_track": true, "segments_json": "[...]", "min_speech_ms": 3000, "max_merge_ms": 0}</code> (response_format is always mp3).</li>
                                    <li>Response: Audio stream. Inspect headers like <code>X-Translation-Model</code> and <code>X-Translation-Segments</code> for run metadata.</li>
                                </ul>
                            </li>
                        </ul>
                        
                        <h5>🎙️ Speech Generation - Non-Streaming (Standard Mode)</h5>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>POST /speak</strong> - Generate speech using a registered speaker preset
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Required: <code>text</code> (string), <code>name</code> (speaker name)</li>
                                    <li>Optional: <code>response_format</code> (always MP3 for compatibility)</li>
                                    <li>Optional: <code>emotion_text</code> (emotion description), <code>emotion_weight</code> (0.0-1.0)</li>
                                    <li>Optional: <code>diffusion_steps</code> (int, default: 10)</li>
                                    <li>Optional: <code>max_text_tokens_per_sentence</code> (int, 80-200, default: 120) - Controls text splitting</li>
                                    <li>Returns: Audio file in specified format</li>
                                </ul>
                            </li>
                            <li><strong>POST /clone_voice</strong> - Clone voice using uploaded reference audio (zero-shot)
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Required: <code>text</code> (string), <code>reference_audio_file</code> (file upload)</li>
                                    <li>Optional: Same as /speak (response_format, emotion_text, emotion_weight, diffusion_steps, max_text_tokens_per_sentence)</li>
                                    <li>Returns: Audio file cloned from reference voice</li>
                                </ul>
                            </li>
                        </ul>
                        
                        <h5>⚡ Speech Generation - Streaming (Low Latency Mode)</h5>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>POST /speak_stream</strong> - Generate speech with streaming chunks
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Same parameters as <code>/speak</code></li>
                                    <li>Streams audio chunks as they're generated</li>
                                    <li>Response format: <code>CHUNK:{idx}:{size}:{status}\n{audio_bytes}</code></li>
                                    <li>Status: CONTINUE (more chunks coming) or LAST (final chunk)</li>
                                </ul>
                            </li>
                            <li><strong>POST /clone_voice_stream</strong> - Clone voice with streaming
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Same parameters as <code>/clone_voice</code></li>
                                    <li>Same streaming format as /speak_stream</li>
                                </ul>
                            </li>
                        </ul>
                        
                        <hr style="margin: 20px 0; border: none; border-top: 2px solid #f0f0f0;">
                        
                        <h4 style="background: linear-gradient(135deg, #ff6b6b 0%, #ee5a6f 100%); color: white; padding: 10px; border-radius: 8px;">🔧 Utility API (WebUI Internal)</h4>
                        
                        <h5>🛠️ Helper Endpoints</h5>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>POST /api/estimate_duration</strong> - Estimate speech duration from text
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>JSON body: <code>{"text": "...", "language": "auto"}</code></li>
                                    <li>Returns: Estimated duration in seconds and milliseconds</li>
                                </ul>
                            </li>
                            <li><strong>POST /api/clear_outputs</strong> - Clear all generated output files
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>No parameters required</li>
                                    <li>Returns: Number of files deleted and disk space freed</li>
                                </ul>
                            </li>
                        </ul>
                        
                        <hr style="margin: 20px 0; border: none; border-top: 2px solid #f0f0f0;">
                        
                        <h4>🆕 Emotion Text Control Feature</h4>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>emotion_text</strong> (optional): Natural language emotion description
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Examples: "happy and excited", "sad and melancholic", "calm and peaceful", "angry and frustrated"</li>
                                </ul>
                            </li>
                            <li><strong>emotion_weight</strong> (optional): Control emotion intensity (0.0 = no emotion, 1.0 = maximum)
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Default: 0.6 (moderate intensity)</li>
                                    <li>Recommended range: 0.3-0.9</li>
                                </ul>
                            </li>
                            <li><strong>Example usage:</strong>
                                <pre style="background: #f5f5f5; padding: 10px; border-radius: 5px; margin-top: 10px; overflow-x: auto;"><code>{
  "text": "Hello, how are you today?",
  "name": "speaker1",
  "emotion_text": "cheerful and friendly",
  "emotion_weight": 0.7,
  "response_format": "mp3"
}</code></pre>
                            </li>
                        </ul>
                        
                        <hr style="margin: 20px 0; border: none; border-top: 2px solid #f0f0f0;">
                        
                        <h4>✂️ Text Splitting Control</h4>
                        <ul style="margin-left: 20px; line-height: 1.6;">
                            <li><strong>max_text_tokens_per_sentence</strong> (optional): Maximum tokens per sentence for text splitting (80-200)
                                <ul style="margin-left: 20px; margin-top: 5px; color: #666;">
                                    <li>Default: 120 tokens</li>
                                    <li>Range: 80-200 tokens</li>
                                    <li>Lower values (80-100): More sentences, faster processing, may sound choppy</li>
                                    <li>Balanced (110-130): Good balance of quality and processing speed</li>
                                    <li>Higher values (140-200): Fewer sentences, slower processing, may impact quality for very long sentences</li>
                                </ul>
                            </li>
                            <li><strong>Example usage:</strong>
                                <pre style="background: #f5f5f5; padding: 10px; border-radius: 5px; margin-top: 10px; overflow-x: auto;"><code>{
  "text": "This is a long text that will be split into manageable chunks for processing.",
  "name": "speaker1",
  "max_text_tokens_per_sentence": 120,
  "response_format": "mp3"
}</code></pre>
                            </li>
                        </ul>
                        
                        <hr style="margin: 20px 0; border: none; border-top: 2px solid #f0f0f0;">
                        
                        <h4>📊 Complete Endpoint Summary</h4>
                        <table style="width: 100%; border-collapse: collapse; margin-top: 15px;">
                            <thead>
                                <tr style="background: #f5f5f5;">
                                    <th style="padding: 10px; text-align: left; border: 1px solid #ddd;">Method</th>
                                    <th style="padding: 10px; text-align: left; border: 1px solid #ddd;">Endpoint</th>
                                    <th style="padding: 10px; text-align: left; border: 1px solid #ddd;">Purpose</th>
                                </tr>
                            </thead>
                            <tbody>
                                <tr>
                                    <td style="padding: 8px; border: 1px solid #ddd;">GET</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;">This web interface</td>
                                </tr>
                                <tr>
                                    <td style="padding: 8px; border: 1px solid #ddd;">GET</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/server_info</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;">Server & model information</td>
                                </tr>
                                <tr>
                                    <td style="padding: 8px; border: 1px solid #ddd;">GET</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/audio_roles</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;">List speakers</td>
                                </tr>
                                <tr>
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/add_speaker</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;">Add speaker preset</td>
                                </tr>
                                <tr>
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/delete_speaker</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;">Remove speaker preset</td>
                                </tr>
                                <tr style="background: #f9f9ff;">
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/speak</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><strong>Generate speech (standard)</strong></td>
                                </tr>
                                <tr style="background: #f9f9ff;">
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/clone_voice</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><strong>Clone voice (standard)</strong></td>
                                </tr>
                                <tr style="background: #fff9f0;">
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/speak_stream</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><strong>⚡ Generate speech (streaming)</strong></td>
                                </tr>
                                <tr style="background: #fff9f0;">
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/clone_voice_stream</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><strong>⚡ Clone voice (streaming)</strong></td>
                                </tr>
                                <tr style="background: #fff0f0;">
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/api/estimate_duration</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;">Estimate speech length</td>
                                </tr>
                                <tr style="background: #fff0f0;">
                                    <td style="padding: 8px; border: 1px solid #ddd;">POST</td>
                                    <td style="padding: 8px; border: 1px solid #ddd;"><code>/api/clear_outputs</code></td>
                                    <td style="padding: 8px; border: 1px solid #ddd;">Clean output files</td>
                                </tr>
                            </tbody>
                        </table>
                    </div>
                </div>
            </div>
        </div>

        <script>
            function switchTab(tabName) {
                // Hide all tab contents
                document.querySelectorAll('.tab-content').forEach(content => {
                    content.classList.remove('active');
                });
                
                // Remove active class from all tabs
                document.querySelectorAll('.tab').forEach(tab => {
                    tab.classList.remove('active');
                });
                
                // Show selected tab content
                document.getElementById(tabName).classList.add('active');
                
                // Add active class to clicked tab
                event.target.classList.add('active');
                
                // Load speakers if switching to speakers tab
                if (tabName === 'speakers') {
                    loadSpeakerList();
                }
            }

            function setChineseDemo(type) {
                const textArea = document.getElementById('text');
                const demos = {
                    '现代文本': '你好！欢迎使用IndexTTS中文语音合成系统。这是一个功能强大的AI语音生成工具，能够准确处理中文语音合成任务。系统支持多种语音风格，让您的文本转换为自然流畅的语音。',
                    '古诗词': '床前明月光，疑是地上霜。举头望明月，低头思故乡。这首《静夜思》是李白的名作，表达了诗人对故乡的深深思念之情。',
                    '数字日期': '今天是2025年1月11日，时间是下午3点30分。这款产品的价格是12,999元，性价比很高。我的电话号码是138-8888-8888，欢迎联系。',
                    '中英混合': '我正在使用IndexTTS和vLLM技术进行AI语音合成。This system supports both Chinese and English perfectly. 这个系统的RTF约为0.1，比原版快3倍！GPU memory utilization设置为85%。'
                };
                
                textArea.value = demos[type];
                textArea.focus();
                
                // Show a brief tooltip
                showStatus(`已设置${type}演示文本`, 'success');
                setTimeout(() => hideStatus(), 2000);
            }

            function setEmotionDemo(emotionType) {
                const textArea = document.getElementById('text');
                const emotionText = document.getElementById('emotionText');
                const emotionWeight = document.getElementById('emotionWeight');
                
                const emotionDemos = {
                    '开心': {
                        text: '今天真是太开心了！我收到了好消息，心情特别愉快。阳光明媚，鸟儿在歌唱，一切都是那么美好！',
                        emotion: 'happy and joyful',
                        weight: 0.8
                    },
                    '悲伤': {
                        text: '雨滴轻敲着窗台，就像我内心的忧伤。离别的时刻总是让人难过，回忆如潮水般涌来。',
                        emotion: 'sad and melancholic',
                        weight: 0.7
                    },
                    '愤怒': {
                        text: '这实在太过分了！我再也无法忍受这种不公正的待遇。愤怒在我心中燃烧，必须要说出来！',
                        emotion: 'angry and frustrated',
                        weight: 0.6
                    },
                    '平静': {
                        text: '静坐在湖边，微风轻拂过脸颊。内心如湖水般平静，思绪缓缓流淌，享受这宁静的时光。',
                        emotion: 'calm and peaceful',
                        weight: 0.3
                    }
                };
                
                const demo = emotionDemos[emotionType];
                if (demo) {
                    textArea.value = demo.text;
                    emotionText.value = demo.emotion;
                    emotionWeight.value = demo.weight;
                    document.getElementById('emotionWeightValue').textContent = demo.weight;
                    textArea.focus();
                    
                    // Show a brief tooltip
                    showStatus(`已设置${emotionType}情感演示 (${demo.emotion})`, 'success');
                    setTimeout(() => hideStatus(), 3000);
                }
            }

            function showStatus(message, type, elementId = 'status') {
                const status = document.getElementById(elementId);
                status.textContent = message;
                status.className = `status ${type}`;
                status.style.display = 'block';
            }

            function hideStatus(elementId = 'status') {
                document.getElementById(elementId).style.display = 'none';
            }

            async function loadSpeakers() {
                try {
                    const response = await fetch('/audio_roles');
                    const data = await response.json();
                    const select = document.getElementById('speaker');
                    
                    // Clear existing options except first
                    select.innerHTML = '<option value="">Select a speaker...</option>';
                    
                    if (data.success) {
                        const speakerMeta = data.speakers || {};
                        speakerPresetMeta = speakerMeta;
                        const roles = data.roles && data.roles.length ? data.roles : Object.keys(speakerMeta || {});
                        availableSpeakerPresets = roles || [];
                        (roles || []).forEach(speaker => {
                            const option = document.createElement('option');
                            option.value = speaker;
                            option.textContent = speaker;
                            select.appendChild(option);
                        });
                        renderSpeakerAssignments();
                    }
                } catch (error) {
                    console.error('Failed to load speakers:', error);
                }
            }

            async function loadSpeakerList() {
                try {
                    const response = await fetch('/audio_roles');
                    const data = await response.json();
                    const listDiv = document.getElementById('speakerList');
                    
                    if (data.success) {
                        const speakerMeta = data.speakers || {};
                        const speakers = data.roles && data.roles.length ? data.roles : Object.keys(speakerMeta);
                        
                        if (!speakers.length) {
                            listDiv.innerHTML = '<p>No speakers found.</p>';
                            return;
                        }
                        
                        let html = `<h4>📊 ${speakers.length} Speakers Available</h4>`;
                        
                        for (const name of speakers) {
                            const info = speakerMeta[name] || {};
                            const description = info.description && info.description.trim() !== '' ? info.description : 'Speaker preset';
                            const previewUrl = info.preview_url;
                            const previewSection = previewUrl
                                ? `<audio controls preload="none" src="${previewUrl}"></audio>`
                                : `<small style="color: #888;">No preview available</small>`;
                            const safeName = JSON.stringify(name);
                            
                            html += `
                                <div class="speaker-item">
                                    <div class="speaker-info">
                                        <h4>🎭 ${name}</h4>
                                        <small>${description}</small>
                                        <div class="speaker-preview">
                                            <label>Preview</label>
                                            ${previewSection}
                                        </div>
                                    </div>
                                    <button class="btn btn-danger" onclick='deleteSpeaker(${safeName})'>🗑️ Delete</button>
                                </div>
                            `;
                        }
                        
                        listDiv.innerHTML = html;
                    } else {
                        listDiv.innerHTML = '<p>No speakers found.</p>';
                    }
                } catch (error) {
                    console.error('Failed to load speaker list:', error);
                    document.getElementById('speakerList').innerHTML = '<p>Error loading speakers.</p>';
                }
            }

            async function deleteSpeaker(speakerName) {
                if (!confirm(`Are you sure you want to delete speaker "${speakerName}"?`)) {
                    return;
                }
                
                try {
                    const formData = new FormData();
                    formData.append('name', speakerName);
                    
                    const response = await fetch('/delete_speaker', {
                        method: 'POST',
                        body: formData
                    });
                    
                    const result = await response.json();
                    showStatus(result.success ? 'Speaker deleted successfully' : result.error, result.success ? 'success' : 'error', 'speakerStatus');
                    
                    if (result.success) {
                        loadSpeakerList();
                        loadSpeakers(); // Refresh dropdown
                    }
                } catch (error) {
                    showStatus(`Error deleting speaker: ${error.message}`, 'error', 'speakerStatus');
                }
            }

            async function estimateDuration() {
                const text = document.getElementById('text').value;
                if (!text.trim()) {
                    showStatus('Please enter text first', 'error');
                    return;
                }
                
                try {
                    showStatus('Estimating duration...', 'success');
                    
                    const response = await fetch('/api/estimate_duration', {
                        method: 'POST',
                        headers: {'Content-Type': 'application/json'},
                        body: JSON.stringify({text: text, language: 'auto'})
                    });
                    
                    const result = await response.json();
                    if (result.status === 'success') {
                        const estimateDiv = document.getElementById('durationEstimate');
                        estimateDiv.innerHTML = `📊 Estimated: <strong>${result.duration_s}s</strong> (${result.duration_ms}ms)<br>🌐 Language: ${result.detected_language} | 📝 Characters: ${result.char_count}`;
                        estimateDiv.style.display = 'block';
                        document.getElementById('speechLength').value = result.duration_ms;
                        showStatus(`Duration estimated: ${result.duration_s}s`, 'success');
                    } else {
                        showStatus(`Error: ${result.message}`, 'error');
                    }
                } catch (error) {
                    showStatus(`Error estimating duration: ${error.message}`, 'error');
                }
            }

            async function clearOutputs() {
                if (!confirm('Are you sure you want to clear all generated output files? This action cannot be undone.')) {
                    return;
                }
                
                try {
                    showStatus('Clearing outputs...', 'success');
                    
                    const response = await fetch('/api/clear_outputs', {
                        method: 'POST'
                    });
                    
                    const result = await response.json();
                    
                    if (result.status === 'success') {
                        const message = `✅ ${result.message}\n📁 Files deleted: ${result.files_deleted}\n💾 Space freed: ${result.space_freed_mb} MB`;
                        showStatus(message, 'success');
                        
                        // Clear the audio result display
                        document.getElementById('audioResult').innerHTML = '';
                    } else {
                        showStatus(`Error: ${result.message}`, 'error');
                    }
                } catch (error) {
                    showStatus(`Error clearing outputs: ${error.message}`, 'error');
                }
            }

            // Add Speaker Form
            document.getElementById('addSpeakerForm').addEventListener('submit', async function(e) {
                e.preventDefault();
                
                const speakerName = document.getElementById('speakerName').value;
                const audioFiles = document.getElementById('speakerAudioFiles').files;
                
                if (!audioFiles || audioFiles.length === 0) {
                    showStatus('Please select at least one audio file', 'error', 'speakerStatus');
                    return;
                }
                
                try {
                    showStatus('Adding speaker...', 'success', 'speakerStatus');
                    
                    const formData = new FormData();
                    formData.append('name', speakerName);
                    formData.append('audio_file', audioFiles[0]); // /add_speaker uses single file
                    formData.append('enhance_voice', document.getElementById('applyEnhancement').checked ? 'true' : 'false');
                    formData.append('super_resolution_voice', document.getElementById('applySuperResolution').checked ? 'true' : 'false');
                    
                    const response = await fetch('/add_speaker', {
                        method: 'POST',
                        body: formData
                    });
                    
                    const result = await response.json();
                    
                    if (result.success) {
                        showStatus(`Speaker "${speakerName}" added successfully!`, 'success', 'speakerStatus');
                        this.reset();
                        loadSpeakerList();
                        loadSpeakers(); // Refresh dropdown
                    } else {
                        showStatus(`Error: ${result.error}`, 'error', 'speakerStatus');
                    }
                } catch (error) {
                    showStatus(`Error adding speaker: ${error.message}`, 'error', 'speakerStatus');
                }
            });

            // TTS Form
            document.getElementById('ttsForm').addEventListener('submit', async function(e) {
                e.preventDefault();
                
                const formData = new FormData(this);
                const text = formData.get('text');
                const speaker = formData.get('speaker');
                const emotionText = document.getElementById('emotionText').value;
                const emotionWeight = parseFloat(document.getElementById('emotionWeight').value);
                const diffusionSteps = parseInt(document.getElementById('diffusionSteps').value);
                const maxTextTokens = parseInt(document.getElementById('maxTextTokens').value);
                const streamingMode = document.getElementById('streamingMode').checked;
                
                if (!text.trim()) {
                    showStatus('Please enter some text to synthesize.', 'error');
                    return;
                }
                
                try {
                    const startTime = performance.now();
                    
                    if (streamingMode) {
                        // Streaming mode
                        await handleStreamingRequest(text, speaker, emotionText, emotionWeight, diffusionSteps, maxTextTokens, formData, startTime);
                    } else {
                        // Regular mode
                        await handleRegularRequest(text, speaker, emotionText, emotionWeight, diffusionSteps, maxTextTokens, formData, startTime);
                    }
                } catch (error) {
                    showStatus(`Network error: ${error.message}`, 'error');
                }
            });

            const translateBtn = document.getElementById('translateBtn');
            const translateAdvancedToggle = document.getElementById('translateAdvancedMode');
            const translateAdvancedSettings = document.getElementById('translateAdvancedSettings');
            const translateAdvancedPanel = document.getElementById('translateAdvancedPanel');
            const translateSegmentsList = document.getElementById('translateSegmentsList');
            const translateSegmentsStatus = document.getElementById('translateSegmentsStatus');
            const translateSegmentsSelectAll = document.getElementById('translateSegmentsSelectAll');
            const translateGenerateBtn = document.getElementById('translateGenerateBtn');
            const translateDebugTranslate = document.getElementById('translateDebugTranslate');
            const translateCustomPrompt = document.getElementById('translateCustomPrompt');
            const translateGeminiModel = document.getElementById('translateGeminiModel');
            const translateGeminiApiKey = document.getElementById('translateGeminiApiKey');
            const translateDestLanguageSelect = document.getElementById('translateDestLanguage');
            const translateEnhanceEl = document.getElementById('translateEnhancement');
            const translateSuperEl = document.getElementById('translateSuperResolution');
            const translateMergeBackEl = document.getElementById('translateMergeBack');
            const translateCustomBackingInput = document.getElementById('translateCustomBackingFile');
            const translateCustomBackingClearBtn = document.getElementById('translateCustomBackingClear');
            const translateCustomBackingSummary = document.getElementById('translateCustomBackingSummary');
            const translateIgnoreNonSpeechEl = document.getElementById('translateIgnoreNonSpeech');
            const translatePreserveSilenceEl = document.getElementById('translatePreserveSilence');
            const translateSeparationPreview = document.getElementById('translateSeparationPreview');
            const translateMinSpeechInput = document.getElementById('translateMinSpeech');
            const translateMaxMergeInput = document.getElementById('translateMaxMerge');
            const translateManualSegmentsToggle = document.getElementById('translateManualSegmentsToggle');
            const translateManualSegmentsPanel = document.getElementById('translateManualSegmentsPanel');
            const translateManualSegmentsInput = document.getElementById('translateManualSegments');
            const translatePromptTranslation = document.getElementById('translatePromptTranslation');
            const translatePromptTranscription = document.getElementById('translatePromptTranscription');
            const translatePromptTemplates = document.getElementById('translatePromptTemplates');
            const DEFAULT_EMOTION_WEIGHT = 0.6;
            const DEFAULT_VOLUME_PERCENT = 100;
            const MIN_VOLUME_PERCENT = 10;
            const MAX_VOLUME_PERCENT = 300;
            const translateVolumeInput = document.getElementById('translateVolumePercent');
            const translateBackingVolumeInput = document.getElementById('translateBackingVolumePercent');
            const translateSpeakerAssignments = document.getElementById('translateSpeakerAssignments');
            const translateEnableChunkSplit = document.getElementById('translateEnableChunkSplit');
            const translateChunkSettings = document.getElementById('translateChunkSettings');
            const translateSplitAudioBtn = document.getElementById('translateSplitAudioBtn');
            const translateChunkMinInput = document.getElementById('translateChunkMinMinutes');
            const translateChunkMaxInput = document.getElementById('translateChunkMaxMinutes');
            const translateChunkResults = document.getElementById('translateChunkResults');
            const translateChunkSummary = document.getElementById('translateChunkSummary');
            const translateChunkList = document.getElementById('translateChunkList');
            const translateChunkSelectionBanner = document.getElementById('translateChunkSelection');
            const translateChunkSelectionText = document.getElementById('translateChunkSelectionText');
            const translateClearChunkBtn = document.getElementById('translateClearChunkBtn');
            const translateMergeChunksBtn = document.getElementById('translateMergeChunksBtn');
            const translateChunkBatchControls = document.getElementById('translateChunkBatchControls');
            const translateChunkSelectPending = document.getElementById('translateChunkSelectPending');
            const translateGenerateChunksBtn = document.getElementById('translateGenerateChunksBtn');
            const translateChunkBatchStatus = document.getElementById('translateChunkBatchStatus');
            const translateAudioInput = document.getElementById('translateAudioFile');
            let currentTranslateSessionId = null;
            let currentTranslateSegments = [];
            let translateSpeakerProfiles = [];
            let translateSpeakerProfileMap = {};
            let translateSpeakerOverrides = {};
            let speakerOverridesDirty = false;
            let availableSpeakerPresets = [];
            let speakerPresetMeta = {};
            let translateBackingAvailableFromSession = false;
            let promptTemplates = {
                translation: '',
                transcription: '',
                ignoreNonSpeech: '',
            };
            const NON_SPEECH_PLACEHOLDER = '{non_speech_instruction}';
            let autoManualSegmentsApplied = false;
            let translateChunkSessions = [];
            let translateChunkBatchId = null;
            let translateSelectedChunkId = null;
            let translateChunkSelections = new Set();
            let currentChunkSessionId = null;

            function updateAudioInputRequirement() {
                if (!translateAudioInput) {
                    return;
                }
                const reuseCheckbox = document.getElementById('translateReuseSeparation');
                const reuseCandidateActive =
                    reuseCheckbox && reuseCheckbox.checked && (currentChunkSessionId || currentTranslateSessionId);
                const needsFile = !currentChunkSessionId && !reuseCandidateActive;
                translateAudioInput.required = needsFile;
            }

            function resetChunkResults() {
                translateChunkSessions = [];
                translateChunkBatchId = null;
                translateSelectedChunkId = null;
                currentChunkSessionId = null;
                translateChunkSelections = new Set();
                if (translateChunkSummary) {
                    translateChunkSummary.textContent = 'Chunks will appear here after splitting.';
                }
                if (translateChunkList) {
                    translateChunkList.innerHTML = '';
                }
                if (translateChunkResults) {
                    translateChunkResults.style.display = 'none';
                }
                if (translateMergeChunksBtn) {
                    translateMergeChunksBtn.style.display = 'none';
                }
                if (translateChunkSelectPending) {
                    translateChunkSelectPending.checked = false;
                    translateChunkSelectPending.disabled = true;
                }
                hideStatus('translateChunkBatchStatus');
                updateChunkSelectionUI();
                updateChunkBatchControlsVisibility();
                updateAudioInputRequirement();
            }

            function toggleChunkControls(enabled) {
                if (translateChunkSettings) {
                    translateChunkSettings.style.display = enabled ? 'block' : 'none';
                }
                if (!enabled && translateChunkResults) {
                    translateChunkResults.style.display = 'none';
                } else if (enabled && translateChunkResults && translateChunkSessions.length) {
                    translateChunkResults.style.display = 'block';
                }
                updateChunkBatchControlsVisibility();
            }

            function renderChunkResultsFromResponse(payload) {
                if (payload && Array.isArray(payload.chunks)) {
                    translateChunkSessions = payload.chunks.slice();
                    translateChunkBatchId = payload.chunk_batch_id || translateChunkBatchId;
                }
                const validChunkIds = new Set(translateChunkSessions.map(chunk => chunk.session_id));
                translateChunkSelections = new Set(
                    Array.from(translateChunkSelections).filter(id => validChunkIds.has(id))
                );
                if (!translateChunkResults || !translateChunkSummary || !translateChunkList) {
                    return;
                }
                if (!translateChunkSessions.length) {
                    translateChunkSummary.textContent = 'Chunk split did not produce usable segments.';
                    translateChunkResults.style.display = 'none';
                    translateChunkList.innerHTML = '';
                    if (translateMergeChunksBtn) {
                        translateMergeChunksBtn.style.display = 'none';
                    }
                    updateChunkSelectionUI();
                    return;
                }
                translateChunkResults.style.display =
                    translateEnableChunkSplit && !translateEnableChunkSplit.checked ? 'none' : 'block';
                const totalLabel =
                    (payload && typeof payload.duration_label === 'string' && payload.duration_label) || '';
                const summaryParts = [`Prepared ${translateChunkSessions.length} chunk(s)`];
                if (totalLabel) {
                    summaryParts.push(`Total ${totalLabel}`);
                }
                translateChunkSummary.textContent = summaryParts.join(' • ');
                if (translateMergeChunksBtn) {
                    translateMergeChunksBtn.style.display = translateChunkSessions.length > 1 ? 'inline-flex' : 'none';
                }
                const cacheBuster = Date.now();
                translateChunkList.innerHTML = translateChunkSessions
                    .map(chunk => {
                        const isSelected = translateSelectedChunkId === chunk.session_id;
                        const isBatchSelected = translateChunkSelections.has(chunk.session_id);
                        const cardClasses = ['segment-card', 'chunk-card'];
                        if (isSelected) {
                            cardClasses.push('selected');
                        }
                        const borderStyle = isSelected ? 'border: 2px solid #6370ff; box-shadow: 0 0 0 2px rgba(99,112,255,0.2);' : '';
                        const vocalsUrl = chunk.vocals_url
                            ? `${chunk.vocals_url}?session=${chunk.session_id}&t=${cacheBuster}`
                            : '';
                        const backingUrl =
                            chunk.backing_available && chunk.backing_url
                                ? `${chunk.backing_url}?session=${chunk.session_id}&t=${cacheBuster}`
                                : '';
                        const translatedUrl = chunk.audio_url
                            ? `${chunk.audio_url}?session=${chunk.session_id}&t=${cacheBuster}`
                            : '';
                        const audioSections = [];
                        if (vocalsUrl) {
                            audioSections.push(
                                `<div style="margin-top:8px;">
                                    <div style="font-size:0.8em;font-weight:600;margin-bottom:2px;">Vocal</div>
                                    <audio controls preload="none" style="width: 100%;">
                                        <source src="${vocalsUrl}" type="audio/mpeg">
                                    </audio>
                                 </div>`
                            );
                        }
                        if (translatedUrl) {
                            audioSections.push(
                                `<div style="margin-top:8px;">
                                    <div style="font-size:0.8em;font-weight:600;margin-bottom:2px;">Translated</div>
                                    <audio controls preload="none" style="width: 100%;">
                                        <source src="${translatedUrl}" type="audio/mpeg">
                                    </audio>
                                 </div>`
                            );
                        }
                        const statusBadge = chunk.generated
                            ? '<span style="background: rgba(16, 185, 129, 0.18); color: #0a7c4a; padding: 2px 8px; border-radius: 12px; font-size: 0.8em;">Generated</span>'
                            : '<span style="background: rgba(251, 191, 36, 0.25); color: #9b6f00; padding: 2px 8px; border-radius: 12px; font-size: 0.8em;">Pending</span>';
                        return `
                            <div class="${cardClasses.join(' ')}" data-session-id="${chunk.session_id}" style="${borderStyle}">
                                <div class="segment-header" style="display:flex;justify-content:space-between;align-items:center;gap:8px;">
                                    <div style="display:flex;align-items:center;gap:8px;">
                                        <input type="checkbox" class="chunk-select-checkbox" data-session-id="${chunk.session_id}" ${isBatchSelected ? 'checked' : ''}>
                                        <span>Chunk ${chunk.chunk_index ?? ''} • ${chunk.duration_label || ''}</span>
                                    </div>
                                    ${statusBadge}
                                </div>
                                <div style="font-size: 0.85em; color: #555;">${chunk.start_label || ''} → ${chunk.end_label || ''}</div>
                                ${audioSections.join('')}
                                <button type="button" class="btn btn-secondary chunk-use-btn" data-session-id="${chunk.session_id}" style="margin-top: 10px;">
                                    Use This Chunk
                                </button>
                            </div>
                        `;
                    })
                    .join('');
                updateChunkSelectionUI();
                updateChunkBatchControlsVisibility();
            }

            function updateChunkSelectionUI() {
                if (!translateChunkSelectionBanner || !translateChunkSelectionText) {
                    return;
                }
                if (!translateSelectedChunkId) {
                    translateChunkSelectionBanner.style.display = 'none';
                    translateChunkSelectionText.textContent = '';
                    return;
                }
                const chunk = translateChunkSessions.find(entry => entry.session_id === translateSelectedChunkId);
                if (!chunk) {
                    translateChunkSelectionBanner.style.display = 'none';
                    translateChunkSelectionText.textContent = '';
                    return;
                }
                translateChunkSelectionBanner.style.display = 'block';
                translateChunkSelectionText.textContent = `Using chunk ${chunk.chunk_index ?? ''} (${chunk.start_label || '00:00'} → ${chunk.end_label || '??'})`;
            }

            function syncPendingSelectToggle() {
                if (!translateChunkSelectPending) {
                    return;
                }
                const pendingChunks = translateChunkSessions.filter(chunk => !chunk.generated);
                if (!pendingChunks.length) {
                    translateChunkSelectPending.checked = false;
                    translateChunkSelectPending.disabled = true;
                    return;
                }
                translateChunkSelectPending.disabled = false;
                const allSelected = pendingChunks.every(chunk => translateChunkSelections.has(chunk.session_id));
                translateChunkSelectPending.checked = allSelected;
            }

            function updateChunkBatchControlsVisibility() {
                if (!translateChunkBatchControls || !translateGenerateChunksBtn) {
                    return;
                }
                const shouldShow =
                    translateChunkSessions.length > 0 &&
                    translateEnableChunkSplit &&
                    translateEnableChunkSplit.checked;
                translateChunkBatchControls.style.display = shouldShow ? 'flex' : 'none';
                translateGenerateChunksBtn.style.display = shouldShow ? 'inline-flex' : 'none';
                translateGenerateChunksBtn.disabled = translateChunkSelections.size === 0;
                translateGenerateChunksBtn.textContent = translateChunkSelections.size
                    ? `⚡ Generate Selected Chunks (${translateChunkSelections.size})`
                    : '⚡ Generate Selected Chunks';
                syncPendingSelectToggle();
            }

            function applyChunkGenerationMetadata(metadata, audioUrl, options = {}) {
                if (!metadata || !metadata.chunk || !metadata.chunk.session_id) {
                    return;
                }
                const { autoSelect = true } = options;
                const chunkSessionId = metadata.chunk.session_id;
                if (autoSelect) {
                    currentChunkSessionId = chunkSessionId;
                    translateSelectedChunkId = chunkSessionId;
                }
                if (!translateChunkBatchId && metadata.chunk.batch_id) {
                    translateChunkBatchId = metadata.chunk.batch_id;
                }
                let chunkEntry = translateChunkSessions.find(entry => entry.session_id === chunkSessionId);
                if (!chunkEntry) {
                    const startMs = typeof metadata.chunk.start_ms === 'number' ? metadata.chunk.start_ms : 0;
                    const endMs = typeof metadata.chunk.end_ms === 'number' ? metadata.chunk.end_ms : startMs;
                    const durationMs = Math.max(0, endMs - startMs);
                    chunkEntry = {
                        chunk_index: metadata.chunk.chunk_index ?? metadata.chunk.index ?? translateChunkSessions.length + 1,
                        session_id: chunkSessionId,
                        reuse_session_id: chunkSessionId,
                        start_ms: startMs,
                        end_ms: endMs,
                        duration_ms: durationMs,
                        start_label: metadata.chunk.start_label || formatTimestamp(startMs),
                        end_label: metadata.chunk.end_label || formatTimestamp(endMs),
                        duration_label: metadata.chunk.duration_label || formatTimestamp(durationMs),
                        generated: false,
                        generated_at: null,
                        audio_url: metadata.chunk.audio_url || null,
                        output_format: metadata.chunk.output_format || null,
                        output_filename: metadata.chunk.output_filename || null,
                        backing_available:
                            metadata.chunk.backing_available !== undefined
                                ? Boolean(metadata.chunk.backing_available)
                                : true,
                        backing_source: metadata.chunk.backing_source || 'none',
                        vocals_url: metadata.chunk.vocals_url || `/api/translate_vocals/${chunkSessionId}`,
                        backing_url:
                            metadata.chunk.backing_available === false
                                ? null
                                : metadata.chunk.backing_url || `/api/translate_backing_track/${chunkSessionId}`,
                        batch_id: metadata.chunk.batch_id || translateChunkBatchId || null,
                    };
                    translateChunkSessions.push(chunkEntry);
                }
                chunkEntry.generated = true;
                chunkEntry.generated_at = Date.now();
                if (audioUrl) {
                    chunkEntry.audio_url = audioUrl;
                }
                if (metadata.chunk.output_format) {
                    chunkEntry.output_format = metadata.chunk.output_format;
                }
                if (metadata.chunk.output_filename) {
                    chunkEntry.output_filename = metadata.chunk.output_filename;
                }
                renderChunkResultsFromResponse();
                updateChunkSelectionUI();
                updateChunkBatchControlsVisibility();
            }

            async function handleMergeChunks() {
                if (!translateChunkSessions.length) {
                    showStatus('Split audio into chunks before merging.', 'error', 'translateStatus');
                    return;
                }
                const statusId = 'translateStatus';
                const formatSelect = document.getElementById('translateOutputFormat');
                const selectedFormat = (formatSelect && formatSelect.value ? formatSelect.value : 'mp3').toLowerCase();
                const payload = {
                    chunk_session_ids: translateChunkSessions.map(chunk => chunk.session_id),
                    chunk_batch_id: translateChunkBatchId || null,
                    response_format: selectedFormat,
                    merge_backing_track: translateMergeBackEl && translateMergeBackEl.checked ? true : false,
                };
                try {
                    showStatus('Merging chunk outputs... ⏳', 'success', statusId);
                    const response = await fetch('/api/translate_merge_chunks', {
                        method: 'POST',
                        headers: { 'Content-Type': 'application/json' },
                        body: JSON.stringify(payload),
                    });
                    const data = await response.json();
                    if (!response.ok || data.status !== 'ok') {
                        const message = data.message || `Merge failed (${response.status})`;
                        showStatus(message, 'error', statusId);
                        return;
                    }
                    renderMergedAudioResult(data, selectedFormat);
                    showStatus(data.message || 'Chunks merged successfully.', 'success', statusId);
                } catch (error) {
                    showStatus(`Merge failed: ${error.message}`, 'error', statusId);
                }
            }

            async function handleGenerateSelectedChunks() {
                const statusId = 'translateChunkBatchStatus';
                hideStatus(statusId);
                if (!translateChunkSelections.size) {
                    showStatus('Select at least one pending chunk to generate.', 'error', statusId);
                    return;
                }
                if (!translateDestLanguageSelect || !translateDestLanguageSelect.value.trim()) {
                    showStatus('Select a destination language before generating chunks.', 'error', statusId);
                    return;
                }
                const destLanguage = translateDestLanguageSelect.value.trim();
                const formatSelect = document.getElementById('translateOutputFormat');
                const selectedFormat = (formatSelect && formatSelect.value ? formatSelect.value : 'mp3').toLowerCase();
                const payload = {
                    chunk_session_ids: Array.from(translateChunkSelections),
                    dest_language: destLanguage,
                    response_format: selectedFormat,
                };
                if (translateGeminiModel && translateGeminiModel.value) {
                    payload.gemini_model = translateGeminiModel.value;
                }
                if (translateGeminiApiKey && translateGeminiApiKey.value.trim()) {
                    payload.gemini_api_key = translateGeminiApiKey.value.trim();
                }
                payload.merge_backing_track = translateMergeBackEl && translateMergeBackEl.checked ? true : false;
                payload.ignore_non_speech = translateIgnoreNonSpeechEl && translateIgnoreNonSpeechEl.checked ? true : false;
                payload.preserve_silence_audio = translatePreserveSilenceEl && translatePreserveSilenceEl.checked ? true : false;
                if (translateVolumeInput && translateVolumeInput.value) {
                    const volumeValue = parseFloat(translateVolumeInput.value);
                    if (!Number.isNaN(volumeValue)) {
                        payload.generated_volume_percent = volumeValue;
                    }
                }
                if (translateBackingVolumeInput && translateBackingVolumeInput.value) {
                    const backingValue = parseFloat(translateBackingVolumeInput.value);
                    if (!Number.isNaN(backingValue)) {
                        payload.backing_volume_percent = backingValue;
                    }
                }
                try {
                    if (translateGenerateChunksBtn) {
                        translateGenerateChunksBtn.disabled = true;
                    }
                    await streamChunkBatchGenerationRequest(payload);
                } catch (error) {
                    const message = error && error.message ? error.message : 'Chunk batch generation failed.';
                    showStatus(message, 'error', statusId);
                } finally {
                    if (translateGenerateChunksBtn) {
                        translateGenerateChunksBtn.disabled = false;
                    }
                    updateChunkBatchControlsVisibility();
                }
            }

            async function streamChunkBatchGenerationRequest(payload) {
                const statusId = 'translateChunkBatchStatus';
                showStatus('Scheduling chunk generation... ⏳', 'info', statusId);
                const response = await fetch('/api/translate_generate_chunks', {
                    method: 'POST',
                    headers: { 'Content-Type': 'application/json' },
                    body: JSON.stringify(payload),
                });

                const readError = async () => {
                    const contentType = response.headers.get('Content-Type') || '';
                    if (contentType.includes('application/json')) {
                        try {
                            const errorData = await response.json();
                            return errorData.message || errorData.error;
                        } catch (jsonError) {
                            console.warn('Failed to parse chunk batch error response:', jsonError);
                        }
                    }
                    try {
                        return await response.text();
                    } catch (textError) {
                        console.warn('Failed to read chunk batch error response:', textError);
                    }
                    return null;
                };

                if (!response.ok) {
                    const message = (await readError()) || `Chunk generation failed (${response.status})`;
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }

                if (!response.body) {
                    const message = 'Chunk generation failed: streaming not supported in this browser.';
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }

                const reader = response.body.getReader();
                const decoder = new TextDecoder();
                const newline = '\\n';
                let buffer = '';
                let completed = false;

                while (true) {
                    const { value, done } = await reader.read();
                    if (done) {
                        break;
                    }
                    buffer += decoder.decode(value, { stream: true });
                    let newlineIndex = buffer.indexOf(newline);
                    while (newlineIndex !== -1) {
                        const line = buffer.slice(0, newlineIndex).trim();
                        buffer = buffer.slice(newlineIndex + 1);
                        newlineIndex = buffer.indexOf(newline);
                        if (!line) {
                            continue;
                        }
                        let eventData;
                        try {
                            eventData = JSON.parse(line);
                        } catch (parseError) {
                            console.warn('Failed to parse chunk batch event:', parseError, line);
                            continue;
                        }
                        const eventType = eventData.event || 'status';
                        if (eventType === 'status') {
                            const message = eventData.message || 'Processing chunks...';
                            showStatus(message, 'info', statusId);
                        } else if (eventType === 'chunk_waiting') {
                            const waitSeconds = Math.ceil(eventData.delay_seconds || 0);
                            showStatus(
                                `Chunk ${eventData.chunk_index ?? ''} scheduled (starts in ~${waitSeconds}s).`,
                                'info',
                                statusId
                            );
                        } else if (eventType === 'chunk_start') {
                            showStatus(
                                `Chunk ${eventData.chunk_index ?? ''} generating...`,
                                'success',
                                statusId
                            );
                        } else if (eventType === 'chunk_complete') {
                            if (eventData.metadata) {
                                applyChunkGenerationMetadata(eventData.metadata, eventData.audio_url, { autoSelect: false });
                            }
                            if (eventData.chunk_session_id) {
                                translateChunkSelections.delete(eventData.chunk_session_id);
                            }
                            const successMessage =
                                eventData.message || `Chunk ${eventData.chunk_index ?? ''} generated successfully.`;
                            showStatus(successMessage, 'success', statusId);
                            updateChunkBatchControlsVisibility();
                        } else if (eventType === 'chunk_error') {
                            const message = eventData.message || 'Chunk generation failed.';
                            showStatus(message, 'error', statusId);
                        } else if (eventType === 'complete') {
                            completed = true;
                            const detailParts = [];
                            if (typeof eventData.completed_chunks === 'number') {
                                detailParts.push(`${eventData.completed_chunks} succeeded`);
                            }
                            if (typeof eventData.failed_chunks === 'number') {
                                detailParts.push(`${eventData.failed_chunks} failed`);
                            }
                            const summaryMessage = eventData.message || 'Chunk batch generation finished.';
                            const detailMessage = detailParts.length ? ` (${detailParts.join(', ')})` : '';
                            showStatus(`${summaryMessage}${detailMessage}`, 'success', statusId);
                        }
                    }
                }

                if (!completed) {
                    const message = 'Chunk batch generation stream ended unexpectedly.';
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }
            }

            function renderMergedAudioResult(data, format) {
                const resultDiv = document.getElementById('translateResult');
                if (!resultDiv) {
                    return;
                }
                const audioUrl = data.audio_url;
                if (!audioUrl) {
                    return;
                }
                const mediaType = getMediaTypeForFormat(format);
                const downloadName = data.file_name || `merged_chunks.${format}`;
                resultDiv.innerHTML = `
                    <h3>🔗 Merged Chunk Output</h3>
                    <audio controls preload="none" style="width: 100%; margin: 10px 0;">
                        <source src="${audioUrl}" type="${mediaType}">
                    </audio>
                    <a class="btn" href="${audioUrl}" download="${downloadName}">💾 Download Merged Audio</a>
                `;
            }

            function getMediaTypeForFormat(format) {
                switch (format) {
                    case 'mp3':
                        return 'audio/mpeg';
                    case 'wav':
                        return 'audio/wav';
                    case 'flac':
                        return 'audio/flac';
                    case 'aac':
                        return 'audio/aac';
                    case 'opus':
                        return 'audio/opus';
                    case 'ogg':
                        return 'audio/ogg';
                    case 'webm':
                        return 'audio/webm';
                    default:
                        return 'audio/mpeg';
                }
            }

            async function handleSplitAudioRequest() {
                if (!translateSplitAudioBtn) {
                    return;
                }
                const statusId = 'translateStatus';
                hideStatus(statusId);
                resetChunkResults();
                const audioInput = document.getElementById('translateAudioFile');
                if (!audioInput || !audioInput.files || !audioInput.files.length) {
                    showStatus('Select a source audio file before splitting.', 'error', statusId);
                    return;
                }
                const formData = new FormData();
                formData.append('audio_file', audioInput.files[0]);
                if (translateDestLanguageSelect && translateDestLanguageSelect.value.trim()) {
                    formData.append('dest_language', translateDestLanguageSelect.value.trim());
                }
                if (translateChunkMinInput && translateChunkMinInput.value) {
                    formData.append('chunk_min_minutes', translateChunkMinInput.value);
                }
                if (translateChunkMaxInput && translateChunkMaxInput.value) {
                    formData.append('chunk_max_minutes', translateChunkMaxInput.value);
                }
                formData.append('super_resolution_voice', translateSuperEl && translateSuperEl.checked ? 'true' : 'false');
                formData.append('enhance_voice', 'true');

                try {
                    translateSplitAudioBtn.disabled = true;
                    translateChunkSummary && (translateChunkSummary.textContent = 'Splitting audio...');
                    showStatus('Splitting audio into manageable chunks...', 'info', statusId);
                    await streamSplitAudioRequest(formData, statusId);
                } catch (error) {
                    console.error('Chunk split error:', error);
                    showStatus(`Chunk split error: ${error.message}`, 'error', statusId);
                } finally {
                    translateSplitAudioBtn.disabled = false;
                }
            }

            async function streamSplitAudioRequest(formData, statusId) {
                const response = await fetch('/api/translate_split_audio', {
                    method: 'POST',
                    body: formData,
                });

                const parseErrorPayload = async () => {
                    const contentType = response.headers.get('Content-Type') || '';
                    if (contentType.includes('application/json')) {
                        try {
                            const data = await response.json();
                            return data.message || data.error || null;
                        } catch (err) {
                            console.warn('Failed to parse split error response:', err);
                        }
                    }
                    try {
                        return await response.text();
                    } catch (err) {
                        console.warn('Failed to read split error response:', err);
                    }
                    return null;
                };

                if (!response.ok) {
                    const errorMessage =
                        (await parseErrorPayload()) || `Chunk split failed (HTTP ${response.status}).`;
                    showStatus(errorMessage, 'error', statusId);
                    throw new Error(errorMessage);
                }

                if (!response.body) {
                    const message = 'Chunk split failed: streaming not supported in this browser.';
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }

                const reader = response.body.getReader();
                const decoder = new TextDecoder();
                const newlineDelimiter = String.fromCharCode(10);
                let buffer = '';
                let splitCompleted = false;
                let lastStatusMessage = '';

                while (true) {
                    const { value, done } = await reader.read();
                    if (done) {
                        break;
                    }
                    buffer += decoder.decode(value, { stream: true });
                    let newlineIndex = buffer.indexOf(newlineDelimiter);
                    while (newlineIndex !== -1) {
                        const line = buffer.slice(0, newlineIndex).trim();
                        buffer = buffer.slice(newlineIndex + 1);
                        newlineIndex = buffer.indexOf(newlineDelimiter);
                        if (!line) {
                            continue;
                        }
                        let eventData;
                        try {
                            eventData = JSON.parse(line);
                        } catch (parseError) {
                            console.warn('Failed to parse split event:', parseError, line);
                            continue;
                        }
                        const eventType = eventData.event || 'status';
                        if (eventType === 'status') {
                            const message = eventData.message || 'Processing...';
                            lastStatusMessage = message;
                            showStatus(message, 'info', statusId);
                        } else if (eventType === 'heartbeat') {
                            const heartbeatMessage = lastStatusMessage
                                ? `Still splitting... ⏳ (Last step: ${lastStatusMessage})`
                                : 'Still splitting... ⏳';
                            showStatus(heartbeatMessage, 'info', statusId);
                        } else if (eventType === 'error') {
                            const message = eventData.message || 'Chunk split failed.';
                            showStatus(message, 'error', statusId);
                            throw new Error(message);
                        } else if (eventType === 'complete') {
                            splitCompleted = true;
                            const payload = {
                                chunks: Array.isArray(eventData.chunks) ? eventData.chunks : [],
                                chunk_batch_id: eventData.chunk_batch_id || null,
                                duration_label: eventData.duration_label,
                                duration_ms: eventData.duration_ms,
                            };
                            renderChunkResultsFromResponse(payload);
                            if (translateChunkResults && translateEnableChunkSplit && translateEnableChunkSplit.checked) {
                                translateChunkResults.style.display = 'block';
                            }
                            const successMessage =
                                eventData.message ||
                                `Prepared ${payload.chunks.length} chunk(s) for advanced processing.`;
                            showStatus(successMessage, 'success', statusId);
                        }
                    }
                }

                if (!splitCompleted) {
                    const message = 'Chunk split stream ended unexpectedly.';
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }
            }

            function applyChunkSession(chunk) {
                if (!chunk) {
                    return;
                }
                currentTranslateSessionId = chunk.session_id;
                currentChunkSessionId = chunk.session_id;
                translateSelectedChunkId = chunk.session_id;
                if (!translateChunkBatchId && chunk.batch_id) {
                    translateChunkBatchId = chunk.batch_id;
                }
                if (translateAudioInput && translateAudioInput.value) {
                    translateAudioInput.value = '';
                }
                updateAudioInputRequirement();
                translateBackingAvailableFromSession = Boolean(chunk.backing_available);
                updateCustomBackingSummary();
                syncTranslateMergeBackState();
                const metadata = {
                    session_id: chunk.session_id,
                    reuse_session_id: chunk.session_id,
                    backing_track: {
                        available: chunk.backing_available,
                        source: chunk.backing_source || 'none',
                    },
                    separation: {
                        vocals_available: true,
                        vocals_url: chunk.vocals_url,
                        backing_available: chunk.backing_available,
                        backing_url: chunk.backing_url,
                        backing_source: chunk.backing_source || 'none',
                    },
                };
                autoApplyTranslateMetadata(metadata, chunk.session_id);
                renderChunkResultsFromResponse();
                updateChunkSelectionUI();
                const reuseCheckbox = document.getElementById('translateReuseSeparation');
                if (reuseCheckbox) {
                    reuseCheckbox.checked = true;
                }
                showStatus(
                    `Chunk ${chunk.chunk_index} ready. Enable advanced mode and reuse the separation to process this portion.`,
                    'success',
                    'translateStatus'
                );
            }

            resetChunkResults();
            updateAudioInputRequirement();

            if (translateEnableChunkSplit) {
                translateEnableChunkSplit.addEventListener('change', () => {
                    const enabled = translateEnableChunkSplit.checked;
                    if (enabled && translateEnhanceEl && !translateEnhanceEl.checked) {
                        translateEnhanceEl.checked = true;
                        syncTranslateMergeBackState();
                    }
                    toggleChunkControls(enabled);
                });
                toggleChunkControls(translateEnableChunkSplit.checked);
            }

            const translateReuseCheckbox = document.getElementById('translateReuseSeparation');
            if (translateReuseCheckbox) {
                translateReuseCheckbox.addEventListener('change', () => {
                    updateAudioInputRequirement();
                });
            }

            if (translateSplitAudioBtn) {
                translateSplitAudioBtn.addEventListener('click', handleSplitAudioRequest);
            }

            if (translateChunkList) {
                translateChunkList.addEventListener('click', event => {
                    const target = event.target.closest('.chunk-use-btn');
                    if (!target) {
                        return;
                    }
                    const sessionId = target.dataset.sessionId;
                    const chunk = translateChunkSessions.find(entry => entry.session_id === sessionId);
                    if (!chunk) {
                        showStatus('Chunk metadata missing. Please split the audio again.', 'error', 'translateStatus');
                        return;
                    }
                    applyChunkSession(chunk);
                });
                translateChunkList.addEventListener('change', event => {
                    const checkbox = event.target.closest('.chunk-select-checkbox');
                    if (!checkbox) {
                        return;
                    }
                    const sessionId = checkbox.dataset.sessionId;
                    if (!sessionId) {
                        return;
                    }
                    if (checkbox.checked) {
                        translateChunkSelections.add(sessionId);
                    } else {
                        translateChunkSelections.delete(sessionId);
                    }
                    hideStatus('translateChunkBatchStatus');
                    updateChunkBatchControlsVisibility();
                });
            }

            if (translateClearChunkBtn) {
                translateClearChunkBtn.addEventListener('click', () => {
                    currentChunkSessionId = null;
                    translateSelectedChunkId = null;
                    updateChunkSelectionUI();
                    updateAudioInputRequirement();
                    showStatus('Chunk selection cleared. Upload a file or choose another chunk to continue.', 'success', 'translateStatus');
                });
            }

            if (translateChunkSelectPending) {
                translateChunkSelectPending.addEventListener('change', () => {
                    const pendingChunks = translateChunkSessions.filter(chunk => !chunk.generated);
                    if (!pendingChunks.length) {
                        translateChunkSelectPending.checked = false;
                        return;
                    }
                    if (translateChunkSelectPending.checked) {
                        pendingChunks.forEach(chunk => translateChunkSelections.add(chunk.session_id));
                    } else {
                        pendingChunks.forEach(chunk => translateChunkSelections.delete(chunk.session_id));
                    }
                    hideStatus('translateChunkBatchStatus');
                    updateChunkBatchControlsVisibility();
                });
            }

            if (translateMergeChunksBtn) {
                translateMergeChunksBtn.addEventListener('click', handleMergeChunks);
            }

            if (translateGenerateChunksBtn) {
                translateGenerateChunksBtn.addEventListener('click', handleGenerateSelectedChunks);
            }

            if (translateAudioInput) {
                translateAudioInput.addEventListener('change', () => {
                    if (translateChunkSessions.length) {
                        resetChunkResults();
                    }
                });
            }

            function formatTimestamp(ms) {
                const totalMs = Math.max(0, Math.round(ms || 0));
                const minutes = Math.floor(totalMs / 60000);
                const seconds = (totalMs % 60000) / 1000;
                const secondsStr =
                    seconds < 10
                        ? `0${seconds.toFixed(3)}`.replace(/([.][0-9]*?[1-9])0+$/,'$1').replace(/[.]0+$/,'')
                        : `${seconds.toFixed(3)}`.replace(/([.][0-9]*?[1-9])0+$/,'$1').replace(/[.]0+$/,'');
                return `${String(minutes).padStart(2, '0')}:${secondsStr}`;
            }

            function hasCustomBackingSelection() {
                if (!translateCustomBackingInput || !translateCustomBackingInput.files) {
                    return false;
                }
                return translateCustomBackingInput.files.length > 0;
            }

            function updateCustomBackingSummary() {
                if (!translateCustomBackingSummary) {
                    return;
                }
                if (hasCustomBackingSelection()) {
                    const file = translateCustomBackingInput.files[0];
                    translateCustomBackingSummary.textContent = `Selected: ${file ? file.name : ''}`;
                    translateCustomBackingSummary.style.color = '#0a7c4a';
                } else if (translateBackingAvailableFromSession) {
                    translateCustomBackingSummary.textContent = 'Using stored backing track from current session.';
                    translateCustomBackingSummary.style.color = '#0a7c4a';
                } else {
                    translateCustomBackingSummary.textContent =
                        'No custom backing selected. Upload audio here to override the extracted instrumental when mix-back is enabled.';
                    translateCustomBackingSummary.style.color = '#666';
                }
            }

            function setTranslateButtonLabel() {
                if (!translateBtn) return;
                if (translateAdvancedToggle && translateAdvancedToggle.checked) {
                    translateBtn.textContent = '🧠 Analyze Segments';
                } else {
                    translateBtn.textContent = '🌐 Translate Speech';
                }
            }

            function syncTranslateMergeBackState() {
                if (!translateMergeBackEl) {
                    return;
                }
                const enhancementEnabled = translateEnhanceEl && translateEnhanceEl.checked;
                const customSelected = hasCustomBackingSelection();
                const storedBacking = translateBackingAvailableFromSession;
                const canEnableMerge = enhancementEnabled || customSelected || storedBacking;
                translateMergeBackEl.disabled = !canEnableMerge;
                if (!canEnableMerge) {
                    translateMergeBackEl.checked = false;
                }
            }

            if (translateEnhanceEl) {
                translateEnhanceEl.addEventListener('change', syncTranslateMergeBackState);
                syncTranslateMergeBackState();
            }
            if (translateCustomBackingInput) {
                translateCustomBackingInput.addEventListener('change', () => {
                    updateCustomBackingSummary();
                    syncTranslateMergeBackState();
                });
            }
            if (translateCustomBackingClearBtn) {
                translateCustomBackingClearBtn.addEventListener('click', () => {
                    if (translateCustomBackingInput) {
                        translateCustomBackingInput.value = '';
                    }
                    updateCustomBackingSummary();
                    syncTranslateMergeBackState();
                });
            }
            updateCustomBackingSummary();
            if (translateDestLanguageSelect) {
                translateDestLanguageSelect.addEventListener('change', refreshPromptTemplates);
            }
            function syncPreserveSilenceState() {
                if (!translatePreserveSilenceEl) {
                    return;
                }
                const ignoreEnabled = translateIgnoreNonSpeechEl && translateIgnoreNonSpeechEl.checked;
                translatePreserveSilenceEl.disabled = !ignoreEnabled;
                if (!ignoreEnabled) {
                    translatePreserveSilenceEl.checked = false;
                }
            }
            if (translateIgnoreNonSpeechEl) {
                translateIgnoreNonSpeechEl.addEventListener('change', () => {
                    refreshPromptTemplates();
                    syncPreserveSilenceState();
                });
                syncPreserveSilenceState();
            } else {
                syncPreserveSilenceState();
            }

            function appendSegmentParameters(formData) {
                if (!formData) {
                    return;
                }
                if (translateMinSpeechInput) {
                    const minValue = (translateMinSpeechInput.value || '').trim();
                    if (minValue) {
                        formData.append('min_speech_ms', minValue);
                    }
                }
                if (translateMaxMergeInput) {
                    const maxValue = (translateMaxMergeInput.value || '').trim();
                    if (maxValue) {
                        formData.append('max_merge_ms', maxValue);
                    }
                }
                if (translateVolumeInput) {
                    const volumeValue = (translateVolumeInput.value || '').trim();
                    if (volumeValue) {
                        formData.append('generated_volume_percent', volumeValue);
                    }
                }
                if (translateBackingVolumeInput) {
                    const backingValue = (translateBackingVolumeInput.value || '').trim();
                    if (backingValue) {
                        formData.append('backing_volume_percent', backingValue);
                    }
                }
            }

            function appendManualSegments(formData) {
                if (
                    !formData ||
                    !translateManualSegmentsToggle ||
                    !translateManualSegmentsInput ||
                    !translateManualSegmentsToggle.checked
                ) {
                    return;
                }
                const manualText = translateManualSegmentsInput.value.trim();
                if (manualText) {
                    formData.append('segments_json', manualText);
                }
            }

            function refreshPromptTemplates() {
                const destLang = translateDestLanguageSelect ? (translateDestLanguageSelect.value || '').trim() : '';
                const replacement = destLang || '{dest_language}';
                const instructionSegment =
                    translateIgnoreNonSpeechEl &&
                    translateIgnoreNonSpeechEl.checked &&
                    typeof promptTemplates.ignoreNonSpeech === 'string' &&
                    promptTemplates.ignoreNonSpeech.trim().length > 0
                        ? `${promptTemplates.ignoreNonSpeech.trim()} `
                        : '';
                if (translatePromptTranslation) {
                    const value = promptTemplates.translation
                        ? promptTemplates.translation
                              .split('{dest_language}')
                              .join(replacement)
                              .split(NON_SPEECH_PLACEHOLDER)
                              .join(instructionSegment)
                        : '';
                    translatePromptTranslation.value = value.trim();
                }
                if (translatePromptTranscription) {
                    const value = promptTemplates.transcription
                        ? promptTemplates.transcription
                              .split(NON_SPEECH_PLACEHOLDER)
                              .join(instructionSegment)
                        : '';
                    translatePromptTranscription.value = value.trim();
                }
            }
            let updateManualSegmentsVisibility = () => {};
            if (translateManualSegmentsToggle && translateManualSegmentsPanel) {
                updateManualSegmentsVisibility = () => {
                    const enabled = translateManualSegmentsToggle.checked;
                    translateManualSegmentsPanel.style.display = enabled ? 'block' : 'none';
                    if (translatePromptTemplates) {
                        translatePromptTemplates.style.display = enabled ? 'block' : 'none';
                    }
                };
                translateManualSegmentsToggle.addEventListener('change', updateManualSegmentsVisibility);
                updateManualSegmentsVisibility();
            }

            async function loadPromptTemplates() {
                if (!translatePromptTranslation && !translatePromptTranscription) {
                    return;
                }
                try {
                    const response = await fetch('/api/prompt_templates');
                    if (!response.ok) {
                        return;
                    }
                    const data = await response.json();
                    if (typeof data.translation === 'string') {
                        promptTemplates.translation = data.translation;
                    }
                    if (typeof data.transcription === 'string') {
                        promptTemplates.transcription = data.transcription;
                    }
                    if (typeof data.ignore_non_speech_instruction === 'string') {
                        promptTemplates.ignoreNonSpeech = data.ignore_non_speech_instruction;
                    }
                    refreshPromptTemplates();
                } catch (error) {
                    console.warn('Failed to load prompt templates', error);
                }
            }

            loadPromptTemplates();

            function resetAdvancedPanel(clearSession = true) {
                if (clearSession) {
                    currentTranslateSessionId = null;
                }
                currentTranslateSegments = [];
                translateSpeakerProfiles = [];
                translateSpeakerProfileMap = {};
                translateSpeakerOverrides = {};
                speakerOverridesDirty = false;
                if (translateAdvancedPanel) {
                    translateAdvancedPanel.style.display = 'none';
                }
                if (translateSegmentsList) {
                    translateSegmentsList.innerHTML = '';
                }
                if (translateSpeakerAssignments) {
                    translateSpeakerAssignments.style.display = 'none';
                    translateSpeakerAssignments.innerHTML = '';
                }
                if (translateSeparationPreview) {
                    translateSeparationPreview.style.display = 'none';
                    translateSeparationPreview.innerHTML = '';
                }
                if (translateSegmentsStatus) {
                    hideStatus('translateSegmentsStatus');
                }
                if (translateSegmentsSelectAll) {
                    translateSegmentsSelectAll.checked = true;
                }
                translateBackingAvailableFromSession = false;
                updateCustomBackingSummary();
                syncTranslateMergeBackState();
            }

            function updateTranslateSegmentsSummary() {
                if (!translateSegmentsStatus) {
                    return;
                }
                if (!translateSegmentsList) {
                    hideStatus('translateSegmentsStatus');
                    return;
                }
                const speechCards = translateSegmentsList.querySelectorAll('.segment-card.speech');
                if (!speechCards.length) {
                    hideStatus('translateSegmentsStatus');
                    return;
                }
                let selected = 0;
                speechCards.forEach(card => {
                    const checkbox = card.querySelector('input.segment-generate');
                    if (checkbox && checkbox.checked) {
                        selected += 1;
                    }
                });
                const preserved = speechCards.length - selected;
                showStatus(
                    `Selected ${selected}/${speechCards.length} speech segments • Preserving ${preserved}`,
                    'success',
                    'translateSegmentsStatus'
                );
                if (translateSegmentsSelectAll) {
                    translateSegmentsSelectAll.checked = selected === speechCards.length;
                }
            }

            function renderTranslateSegments(segments = []) {
                if (!translateSegmentsList) {
                    return;
                }
                translateSegmentsList.innerHTML = '';
                const hasSpeech = segments.some(seg => seg.type === 'speech');
                if (!segments.length) {
                    translateSegmentsList.innerHTML = '<div class="segment-empty">No segments returned from Gemini.</div>';
                    updateTranslateSegmentsSummary();
                    return;
                }
                if (translateSegmentsSelectAll) {
                    const allSelected = segments.filter(seg => seg.type === 'speech').every(seg => seg.generate !== false);
                    translateSegmentsSelectAll.checked = allSelected;
                }
                segments.forEach(segment => {
                    const startMsVal = Number.isFinite(segment.start_ms) ? segment.start_ms : 0;
                    const endMsVal = Number.isFinite(segment.end_ms) ? segment.end_ms : startMsVal;
                    const durationVal = Number.isFinite(segment.duration_ms)
                        ? segment.duration_ms
                        : Math.max(0, endMsVal - startMsVal);
                    const card = document.createElement('div');
                    card.className = `segment-card ${segment.type}`;
                    card.dataset.index = segment.index;
                    card.dataset.type = segment.type;
                    if (segment.speaker) {
                        card.dataset.speaker = segment.speaker;
                    }

                    const header = document.createElement('div');
                    header.className = 'segment-header';

                    const title = document.createElement('div');
                    title.innerHTML = `<strong>#${segment.index}</strong> ${segment.type === 'speech' ? 'Speech Segment' : 'Silence Segment'}`;
                    header.appendChild(title);
                    if (segment.speaker) {
                        const speakerInfo = translateSpeakerProfileMap[segment.speaker] || {};
                        const speakerLabel = speakerInfo.label || segment.speaker;
                        const speakerPill = document.createElement('span');
                        speakerPill.className = 'segment-speaker-pill';
                        speakerPill.textContent = speakerLabel;
                        header.appendChild(speakerPill);
                    }

                    if (segment.type === 'speech') {
                        const checkboxLabel = document.createElement('label');
                        checkboxLabel.className = 'segment-checkbox';
                        const checkbox = document.createElement('input');
                        checkbox.type = 'checkbox';
                        checkbox.className = 'segment-generate';
                        checkbox.checked = segment.generate !== false;
                        checkbox.addEventListener('change', updateTranslateSegmentsSummary);
                        checkboxLabel.appendChild(checkbox);
                        const span = document.createElement('span');
                        span.textContent = 'Generate';
                        checkboxLabel.appendChild(span);
                        header.appendChild(checkboxLabel);
                    } else {
                        const meta = document.createElement('span');
                        meta.className = 'segment-meta';
                        meta.textContent = 'Preserved silence';
                        header.appendChild(meta);
                    }

                    card.appendChild(header);

                    const metaInfo = document.createElement('div');
                    metaInfo.className = 'segment-meta';
                    metaInfo.textContent = `${segment.start || formatTimestamp(startMsVal)} → ${segment.end || formatTimestamp(endMsVal)} (${durationVal} ms)`;
                    card.appendChild(metaInfo);

                    const body = document.createElement('div');
                    body.className = 'segment-body';

                    const timing = document.createElement('div');
                    timing.className = 'segment-timing';
                    timing.innerHTML = `
                        <label>Start (ms)
                            <input type="number" class="segment-start" value="${startMsVal}" min="0">
                        </label>
                        <label>End (ms)
                            <input type="number" class="segment-end" value="${endMsVal}" min="0">
                        </label>
                        <div class="segment-duration-label">Duration: <span class="segment-duration">${durationVal}</span> ms</div>
                    `;
                    body.appendChild(timing);

                    const startInput = timing.querySelector('.segment-start');
                    const endInput = timing.querySelector('.segment-end');
                    const durationLabel = timing.querySelector('.segment-duration');
                    const updateDuration = () => {
                        const startVal = parseInt(startInput.value || '0', 10);
                        const endVal = parseInt(endInput.value || '0', 10);
                        const diff = Math.max(0, endVal - startVal);
                        durationLabel.textContent = diff;
                    };
                    startInput.addEventListener('input', updateDuration);
                    endInput.addEventListener('input', updateDuration);

                    if (segment.type === 'speech') {
                        const sourceGroup = document.createElement('div');
                        sourceGroup.innerHTML = `
                            <label>Source Text</label>
                            <textarea class="segment-source">${segment.source_text || ''}</textarea>
                        `;
                        body.appendChild(sourceGroup);

                        const translationGroup = document.createElement('div');
                        translationGroup.innerHTML = `
                            <label>Translation Text</label>
                            <textarea class="segment-translation">${segment.translated_text || ''}</textarea>
                        `;
                        body.appendChild(translationGroup);

                        if (segment.audio_preview) {
                            const audioWrapper = document.createElement('div');
                            audioWrapper.className = 'segment-audio-original';
                            audioWrapper.innerHTML = '<label>Original audio preview</label>';
                            const audioEl = document.createElement('audio');
                            audioEl.className = 'segment-audio';
                            audioEl.controls = true;
                            audioEl.src = segment.audio_preview;
                            audioWrapper.appendChild(audioEl);
                            body.appendChild(audioWrapper);
                        }

                        const overridesWrapper = document.createElement('div');
                        overridesWrapper.className = 'segment-override-grid';
                        overridesWrapper.style.display = 'flex';
                        overridesWrapper.style.flexWrap = 'wrap';
                        overridesWrapper.style.gap = '12px';
                        overridesWrapper.style.marginTop = '10px';
                        const volumeValue =
                            typeof segment.volume_percent === 'number' ? segment.volume_percent : '';
                        const emotionValue =
                            typeof segment.emotion_weight === 'number' ? segment.emotion_weight : '';
                        overridesWrapper.innerHTML = `
                            <div class="segment-override-item">
                                <label>Segment Volume (%)</label>
                                <input type="number" class="segment-volume" min="${MIN_VOLUME_PERCENT}" max="${MAX_VOLUME_PERCENT}" step="5" value="${volumeValue}">
                                <small>Leave blank to inherit speaker/global.</small>
                            </div>
                            <div class="segment-override-item">
                                <label>Emotion Weight (0-1)</label>
                                <input type="number" class="segment-emotion" min="0" max="1" step="0.05" value="${emotionValue}">
                                <small>Overrides speaker emotion intensity.</small>
                            </div>
                        `;
                        body.appendChild(overridesWrapper);

                        const previewControls = document.createElement('div');
                        previewControls.className = 'segment-preview-controls';
                        previewControls.style.marginTop = '12px';
                        previewControls.innerHTML = `
                            <button type="button" class="btn segment-preview-btn">⚡ Preview Segment</button>
                            <small class="segment-preview-status"></small>
                            <audio class="segment-preview-audio" controls preload="none" style="width: 100%; display: none; margin-top: 8px;"></audio>
                        `;
                        body.appendChild(previewControls);
                        const previewButton = previewControls.querySelector('.segment-preview-btn');
                        previewButton.addEventListener('click', () => handleSegmentPreview(card, previewButton));
                    }

                    card.appendChild(body);
                    translateSegmentsList.appendChild(card);
                });
                if (!hasSpeech) {
                    translateSegmentsList.insertAdjacentHTML('beforeend', '<div class="segment-empty">No speech segments detected.</div>');
                }
                updateTranslateSegmentsSummary();
            }

            function readSegmentCardValues(card, options = {}) {
                const { forceGenerate = false } = options;
                if (!card) {
                    throw new Error('Segment card not found.');
                }
                const index = parseInt(card.dataset.index, 10);
                if (Number.isNaN(index)) {
                    throw new Error('Segment metadata missing index.');
                }
                const type = card.dataset.type || 'speech';
                const startInput = card.querySelector('.segment-start');
                const endInput = card.querySelector('.segment-end');
                const startMs = parseInt(startInput ? startInput.value : '0', 10);
                const endMs = parseInt(endInput ? endInput.value : '0', 10);
                if (Number.isNaN(startMs) || Number.isNaN(endMs)) {
                    throw new Error(`Segment #${index}: invalid timing.`);
                }
                if (endMs <= startMs) {
                    throw new Error(`Segment #${index}: end time must be greater than start time.`);
                }
                const durationMs = endMs - startMs;
                const payload = {
                    index,
                    type,
                    start_ms: startMs,
                    end_ms: endMs,
                    duration_ms: durationMs,
                    start: formatTimestamp(startMs),
                    end: formatTimestamp(endMs),
                    source_text: '',
                    translated_text: '',
                    generate: false,
                    keep_original: true,
                    speaker: card.dataset.speaker || null,
                };
                if (type === 'speech') {
                    const checkbox = card.querySelector('input.segment-generate');
                    const shouldGenerate = forceGenerate ? true : checkbox ? checkbox.checked : true;
                    payload.generate = shouldGenerate;
                    payload.keep_original = !shouldGenerate;
                    const sourceInput = card.querySelector('.segment-source');
                    payload.source_text = sourceInput ? sourceInput.value : '';
                    const translationInput = card.querySelector('.segment-translation');
                    payload.translated_text = translationInput ? translationInput.value : '';
                    const volumeInput = card.querySelector('.segment-volume');
                    if (volumeInput) {
                        const rawVolume = (volumeInput.value || '').trim();
                        if (rawVolume) {
                            const parsedVolume = parseFloat(rawVolume);
                            if (Number.isNaN(parsedVolume)) {
                                throw new Error(`Segment #${index}: invalid volume override.`);
                            }
                            payload.volume_percent = parsedVolume;
                        }
                    }
                    const emotionInput = card.querySelector('.segment-emotion');
                    if (emotionInput) {
                        const rawEmotion = (emotionInput.value || '').trim();
                        if (rawEmotion) {
                            const parsedEmotion = parseFloat(rawEmotion);
                            if (Number.isNaN(parsedEmotion)) {
                                throw new Error(`Segment #${index}: invalid emotion weight.`);
                            }
                            payload.emotion_weight = parsedEmotion;
                        }
                    }
                } else {
                    payload.generate = false;
                    payload.keep_original = true;
                }
                return payload;
            }

            async function handleSegmentPreview(card, triggerButton) {
                if (!currentTranslateSessionId) {
                    showStatus('Analyze audio first to enable previews.', 'error', 'translateSegmentsStatus');
                    return;
                }
                if (!card) {
                    return;
                }
                const statusEl = card.querySelector('.segment-preview-status');
                const audioEl = card.querySelector('.segment-preview-audio');
                try {
                    const segmentPayload = readSegmentCardValues(card, { forceGenerate: true });
                    if (segmentPayload.type !== 'speech') {
                        if (statusEl) {
                            statusEl.textContent = 'Only speech segments can be previewed.';
                            statusEl.style.color = '#d93025';
                        }
                        return;
                    }
                    const requestPayload = {
                        session_id: currentTranslateSessionId,
                        segment: segmentPayload,
                    };
                    if (translateVolumeInput && translateVolumeInput.value) {
                        const parsedVolume = parseFloat(translateVolumeInput.value);
                        if (!Number.isNaN(parsedVolume)) {
                            requestPayload.generated_volume_percent = parsedVolume;
                        }
                    }
                    if (translateBackingVolumeInput && translateBackingVolumeInput.value) {
                        const parsedBacking = parseFloat(translateBackingVolumeInput.value);
                        if (!Number.isNaN(parsedBacking)) {
                            requestPayload.backing_volume_percent = parsedBacking;
                        }
                    }
                    if (speakerOverridesDirty) {
                        requestPayload.speaker_overrides = buildSpeakerOverridesPayload();
                    }
                    if (triggerButton) {
                        triggerButton.disabled = true;
                    }
                    if (statusEl) {
                        statusEl.textContent = 'Generating preview...';
                        statusEl.style.color = '#666';
                    }
                    const response = await fetch('/api/translate_segment_preview', {
                        method: 'POST',
                        headers: { 'Content-Type': 'application/json' },
                        body: JSON.stringify(requestPayload),
                    });
                    if (!response.ok) {
                        let errorMessage = `Preview failed (${response.status})`;
                        try {
                            const errorData = await response.json();
                            if (errorData && errorData.message) {
                                errorMessage = errorData.message;
                            }
                        } catch (jsonError) {
                            console.warn('Failed to parse preview error response', jsonError);
                        }
                        if (statusEl) {
                            statusEl.textContent = errorMessage;
                            statusEl.style.color = '#d93025';
                        }
                        showStatus(errorMessage, 'error', 'translateSegmentsStatus');
                        return;
                    }
                    const data = await response.json();
                    if (!data || !data.audio_preview) {
                        const message = 'Preview failed: missing audio.';
                        if (statusEl) {
                            statusEl.textContent = message;
                            statusEl.style.color = '#d93025';
                        }
                        showStatus(message, 'error', 'translateSegmentsStatus');
                        return;
                    }
                    if (audioEl) {
                        audioEl.src = data.audio_preview;
                        audioEl.style.display = 'block';
                        audioEl.load();
                    }
                    if (statusEl) {
                        const label = data.media_type || 'audio';
                        statusEl.textContent = `Preview ready (${label})`;
                        statusEl.style.color = '#0a7c4a';
                    }
                } catch (error) {
                    const message = error && error.message ? error.message : 'Preview failed.';
                    if (statusEl) {
                        statusEl.textContent = message;
                        statusEl.style.color = '#d93025';
                    }
                    showStatus(message, 'error', 'translateSegmentsStatus');
                } finally {
                    if (triggerButton) {
                        triggerButton.disabled = false;
                    }
                }
            }

            function renderSeparationPreview(sessionId, metadata) {
                if (!translateSeparationPreview) {
                    return;
                }
                const separationMeta = metadata && metadata.separation;
                if (!separationMeta || !separationMeta.vocals_available || !separationMeta.vocals_url) {
                    translateSeparationPreview.style.display = 'none';
                    translateSeparationPreview.innerHTML = '';
                    return;
                }
                const cacheKey = Date.now();
                const vocalsUrl = `${separationMeta.vocals_url}?session=${sessionId}&t=${cacheKey}`;
                let backingMarkup = '';
                if (separationMeta.backing_available && separationMeta.backing_url) {
                    const backingUrl = `${separationMeta.backing_url}?session=${sessionId}&t=${cacheKey}`;
                    let backingLabel = '🎼 Instrumental Backing';
                    if (separationMeta.backing_source === 'custom') {
                        backingLabel += ' (Custom)';
                    } else if (separationMeta.backing_source === 'reuse') {
                        backingLabel += ' (Reused)';
                    } else if (separationMeta.backing_source === 'extracted') {
                        backingLabel += ' (ClearVoice)';
                    }
                    backingMarkup = `
                        <div style="margin-top: 12px;">
                            <div class="segment-header" style="margin-bottom:4px;">${backingLabel}</div>
                            <audio controls style="width: 100%;">
                                <source src="${backingUrl}" type="audio/mpeg">
                            </audio>
                        </div>
                    `;
                }
                translateSeparationPreview.innerHTML = `
                    <div class="segment-card">
                        <div class="segment-header">🎙️ Separated Vocals</div>
                        <audio controls style="width: 100%; margin-top: 6px;">
                            <source src="${vocalsUrl}" type="audio/mpeg">
                        </audio>
                        ${backingMarkup}
                        <label class="segment-checkbox" style="margin-top: 14px;">
                            <input type="checkbox" id="translateReuseSeparation" checked>
                            <span>Reuse this separation for future analyses</span>
                        </label>
                        <small style="display: block; color: #666; margin-top: 4px;">
                            Uncheck to re-run separation on the original upload.
                        </small>
                    </div>
                `;
                translateSeparationPreview.style.display = 'block';
            }

            function setSpeakerProfiles(profiles) {
                translateSpeakerProfiles = Array.isArray(profiles) ? profiles : [];
                translateSpeakerProfileMap = {};
                translateSpeakerProfiles.forEach(profile => {
                    if (profile && profile.id) {
                        translateSpeakerProfileMap[String(profile.id)] = profile;
                    }
                });
            }

            function setSpeakerOverrides(overrides) {
                translateSpeakerOverrides = {};
                if (overrides && typeof overrides === 'object') {
                    Object.entries(overrides).forEach(([key, value]) => {
                        if (!value || typeof value !== 'object') {
                            return;
                        }
                        const normalizedId = String(key || '').toLowerCase();
                        const normalizedVolume =
                            typeof value.volume_percent === 'number'
                                ? Math.min(MAX_VOLUME_PERCENT, Math.max(MIN_VOLUME_PERCENT, value.volume_percent))
                                : undefined;
                        const overrideEntry = {
                            preset_name: value.preset_name || '',
                            use_emotion_prompt: Boolean(value.use_emotion_prompt),
                            emotion_weight:
                                typeof value.emotion_weight === 'number'
                                    ? Math.min(1, Math.max(0, value.emotion_weight))
                                    : DEFAULT_EMOTION_WEIGHT,
                        };
                        if (normalizedVolume !== undefined) {
                            overrideEntry.volume_percent = normalizedVolume;
                        }
                        translateSpeakerOverrides[normalizedId] = overrideEntry;
                    });
                }
            }

            function renderSpeakerAssignments() {
                if (!translateSpeakerAssignments) {
                    return;
                }
                if (!translateSpeakerProfiles.length) {
                    translateSpeakerAssignments.style.display = 'none';
                    translateSpeakerAssignments.innerHTML = '';
                    return;
                }
                let html = '<h4>Detected Speakers</h4>';
                translateSpeakerProfiles.forEach((profile, idx) => {
                    if (!profile) {
                        return;
                    }
                    const fallbackId = profile.id ? String(profile.id) : `speaker${idx + 1}`;
                    const speakerId = fallbackId.toLowerCase();
                    const override = translateSpeakerOverrides[speakerId] || {};
                    const selectedPreset = override.preset_name || '';
                    const useEmotionPrompt = Boolean(override.use_emotion_prompt) && Boolean(selectedPreset);
                    const checkboxDisabled = !selectedPreset;
                    const weightValue =
                        typeof override.emotion_weight === 'number'
                            ? override.emotion_weight
                            : DEFAULT_EMOTION_WEIGHT;
                    const volumeValue =
                        typeof override.volume_percent === 'number'
                            ? override.volume_percent
                            : '';
                    let optionsHtml = '<option value="">Auto (clone original voice)</option>';
                    availableSpeakerPresets.forEach(name => {
                        const safeName = String(name || '');
                        const selectedAttr = safeName === selectedPreset ? 'selected' : '';
                        optionsHtml += `<option value="${safeName}" ${selectedAttr}>${safeName}</option>`;
                    });
                    const displayName = profile.label || fallbackId.toUpperCase();
                    const description = profile.description || 'No description';
                    html += `
                        <div class="speaker-assignment-item">
                            <div class="speaker-assignment-header">
                                <div>
                                    <strong>${displayName}</strong>
                                    <div style="font-size:0.85em;color:#666;">${description}</div>
                                </div>
                            </div>
                            <div class="speaker-assignment-controls">
                                <select class="speaker-override-select" data-speaker-id="${speakerId}">
                                    ${optionsHtml}
                                </select>
                                <div class="speaker-emo-settings">
                                    <label class="speaker-emo-toggle">
                                        <input type="checkbox" class="speaker-emo-checkbox" data-speaker-id="${speakerId}" ${checkboxDisabled ? 'disabled' : ''} ${useEmotionPrompt ? 'checked' : ''}>
                                        Use original emotion prompt
                                    </label>
                                    <label class="speaker-emo-weight">
                                        <span>Emotion weight</span>
                                        <input type="number" min="0" max="1" step="0.05" value="${weightValue}" class="speaker-emo-weight-input" data-speaker-id="${speakerId}" ${useEmotionPrompt ? '' : 'disabled'}>
                                    </label>
                                </div>
                                <div class="speaker-volume-settings">
                                    <label class="speaker-volume-label">
                                        <span>Volume (%)</span>
                                        <input type="number" class="speaker-volume-input" data-speaker-id="${speakerId}" min="${MIN_VOLUME_PERCENT}" max="${MAX_VOLUME_PERCENT}" step="5" value="${volumeValue}">
                                    </label>
                                    <small>Leave blank to use global setting.</small>
                                </div>
                            </div>
                            <div class="speaker-assignment-preview" data-speaker-id="${speakerId}">
                                <small class="speaker-preview-message"></small>
                                <audio controls preload="none" class="speaker-preview-audio" style="display:none"></audio>
                            </div>
                        </div>
                    `;
                });
                translateSpeakerAssignments.innerHTML = html;
                translateSpeakerAssignments.style.display = 'block';
                translateSpeakerAssignments.querySelectorAll('.speaker-override-select').forEach(select => {
                    select.addEventListener('change', onSpeakerPresetChange);
                });
                translateSpeakerAssignments.querySelectorAll('.speaker-emo-checkbox').forEach(checkbox => {
                    checkbox.addEventListener('change', onSpeakerEmotionToggle);
                });
                translateSpeakerAssignments.querySelectorAll('.speaker-emo-weight-input').forEach(input => {
                    input.addEventListener('input', onSpeakerEmotionWeightChange);
                    input.addEventListener('change', onSpeakerEmotionWeightChange);
                });
                translateSpeakerAssignments.querySelectorAll('.speaker-volume-input').forEach(input => {
                    input.addEventListener('input', onSpeakerVolumeChange);
                    input.addEventListener('change', onSpeakerVolumeChange);
                });
                translateSpeakerProfiles.forEach((profile, idx) => {
                    const fallbackId = profile.id ? String(profile.id) : `speaker${idx + 1}`;
                    const speakerId = fallbackId.toLowerCase();
                    updateSpeakerPreviewForId(speakerId);
                    updateSpeakerEmotionWeightInput(speakerId);
                    updateSpeakerVolumeInput(speakerId);
                });
            }

            function onSpeakerPresetChange(event) {
                const select = event.target;
                const speakerId = select.dataset.speakerId;
                if (!speakerId) {
                    return;
                }
                const newPreset = select.value;
                const existing = translateSpeakerOverrides[speakerId] || {};
                if (!newPreset) {
                    if (typeof existing.volume_percent === 'number') {
                        translateSpeakerOverrides[speakerId] = {
                            preset_name: '',
                            use_emotion_prompt: false,
                            emotion_weight: DEFAULT_EMOTION_WEIGHT,
                            volume_percent: existing.volume_percent,
                        };
                    } else {
                        delete translateSpeakerOverrides[speakerId];
                    }
                } else {
                    const nextOverride = {
                        preset_name: newPreset,
                        use_emotion_prompt: Boolean(existing.use_emotion_prompt),
                        emotion_weight:
                            typeof existing.emotion_weight === 'number'
                                ? existing.emotion_weight
                                : DEFAULT_EMOTION_WEIGHT,
                    };
                    if (typeof existing.volume_percent === 'number') {
                        nextOverride.volume_percent = existing.volume_percent;
                    }
                    translateSpeakerOverrides[speakerId] = nextOverride;
                }
                cleanupSpeakerOverrideIfEmpty(speakerId);
                const emoToggle = translateSpeakerAssignments.querySelector(`.speaker-emo-checkbox[data-speaker-id="${speakerId}"]`);
                if (emoToggle) {
                    if (newPreset) {
                        emoToggle.disabled = false;
                        emoToggle.checked = Boolean(translateSpeakerOverrides[speakerId]?.use_emotion_prompt);
                    } else {
                        emoToggle.disabled = true;
                        emoToggle.checked = false;
                    }
                }
                speakerOverridesDirty = true;
                updateSpeakerPreviewForId(speakerId);
                updateSpeakerEmotionWeightInput(speakerId);
                updateSpeakerVolumeInput(speakerId);
            }

            function onSpeakerEmotionToggle(event) {
                const checkbox = event.target;
                const speakerId = checkbox.dataset.speakerId;
                if (!speakerId) {
                    return;
                }
                const override = translateSpeakerOverrides[speakerId];
                if (!override) {
                    checkbox.checked = false;
                    return;
                }
                override.use_emotion_prompt = checkbox.checked;
                speakerOverridesDirty = true;
                updateSpeakerEmotionWeightInput(speakerId);
            }

            function buildSpeakerOverridesPayload() {
                const payload = {};
                Object.entries(translateSpeakerOverrides).forEach(([speakerId, config]) => {
                    if (!config) {
                        return;
                    }
                    const hasPreset = Boolean(config.preset_name);
                    const hasVolume = typeof config.volume_percent === 'number' && !Number.isNaN(config.volume_percent);
                    if (!hasPreset && !hasVolume) {
                        return;
                    }
                    const entry = {};
                    if (hasPreset) {
                        entry.preset_name = config.preset_name;
                        entry.use_emotion_prompt = Boolean(config.use_emotion_prompt);
                        entry.emotion_weight =
                            typeof config.emotion_weight === 'number'
                                ? Math.min(1, Math.max(0, config.emotion_weight))
                                : DEFAULT_EMOTION_WEIGHT;
                    }
                    if (hasVolume) {
                        entry.volume_percent = Math.min(
                            MAX_VOLUME_PERCENT,
                            Math.max(MIN_VOLUME_PERCENT, config.volume_percent)
                        );
                    }
                    payload[speakerId] = entry;
                });
                return payload;
            }

            function getPresetPreviewUrl(presetName) {
                if (!presetName) {
                    return null;
                }
                const meta = speakerPresetMeta[presetName];
                if (meta && meta.preview_url) {
                    return meta.preview_url;
                }
                return null;
            }

            function updateSpeakerPreviewForId(speakerId) {
                if (!translateSpeakerAssignments) {
                    return;
                }
                const select = translateSpeakerAssignments.querySelector(`.speaker-override-select[data-speaker-id="${speakerId}"]`);
                const previewContainer = translateSpeakerAssignments.querySelector(`.speaker-assignment-preview[data-speaker-id="${speakerId}"]`);
                if (!select || !previewContainer) {
                    return;
                }
                const messageEl = previewContainer.querySelector('.speaker-preview-message');
                const audioEl = previewContainer.querySelector('.speaker-preview-audio');
                const override = translateSpeakerOverrides[speakerId];
                const presetName = override && override.preset_name ? override.preset_name : '';
                const previewUrl = getPresetPreviewUrl(presetName);

                if (presetName && previewUrl) {
                    const cacheBustedUrl = `${previewUrl}?t=${Date.now()}`;
                    audioEl.src = cacheBustedUrl;
                    audioEl.style.display = 'block';
                    if (messageEl) {
                        messageEl.textContent = `Preview: ${presetName}`;
                    }
                } else {
                    audioEl.removeAttribute('src');
                    audioEl.style.display = 'none';
                    if (messageEl) {
                        if (!presetName) {
                            messageEl.textContent = 'Select a preset to preview.';
                        } else {
                            messageEl.textContent = 'No preview available for this preset.';
                        }
                    }
                }
            }

            function updateSpeakerEmotionWeightInput(speakerId) {
                if (!translateSpeakerAssignments) {
                    return;
                }
                const weightInput = translateSpeakerAssignments.querySelector(`.speaker-emo-weight-input[data-speaker-id="${speakerId}"]`);
                if (!weightInput) {
                    return;
                }
                const override = translateSpeakerOverrides[speakerId];
                const weightValue =
                    typeof override?.emotion_weight === 'number'
                        ? Math.min(1, Math.max(0, override.emotion_weight))
                        : DEFAULT_EMOTION_WEIGHT;
                weightInput.value = weightValue;
                const canUseEmotion = Boolean(override && override.preset_name && override.use_emotion_prompt);
                weightInput.disabled = !canUseEmotion;
            }

            function updateSpeakerVolumeInput(speakerId) {
                if (!translateSpeakerAssignments) {
                    return;
                }
                const volumeInput = translateSpeakerAssignments.querySelector(`.speaker-volume-input[data-speaker-id="${speakerId}"]`);
                if (!volumeInput) {
                    return;
                }
                const override = translateSpeakerOverrides[speakerId];
                if (override && typeof override.volume_percent === 'number') {
                    volumeInput.value = override.volume_percent;
                } else {
                    volumeInput.value = '';
                }
            }

            function onSpeakerEmotionWeightChange(event) {
                const input = event.target;
                const speakerId = input.dataset.speakerId;
                if (!speakerId) {
                    return;
                }
                if (!translateSpeakerOverrides[speakerId]) {
                    translateSpeakerOverrides[speakerId] = {
                        preset_name: '',
                        use_emotion_prompt: false,
                        emotion_weight: DEFAULT_EMOTION_WEIGHT,
                    };
                }
                const value = parseFloat(input.value);
                const normalized = Number.isFinite(value) ? Math.min(1, Math.max(0, value)) : DEFAULT_EMOTION_WEIGHT;
                translateSpeakerOverrides[speakerId].emotion_weight = normalized;
                speakerOverridesDirty = true;
                input.value = normalized;
            }

            function cleanupSpeakerOverrideIfEmpty(speakerId) {
                const override = translateSpeakerOverrides[speakerId];
                if (!override) {
                    return;
                }
                const hasPreset = Boolean(override.preset_name);
                const hasVolume = typeof override.volume_percent === 'number' && !Number.isNaN(override.volume_percent);
                if (!hasPreset && !hasVolume) {
                    delete translateSpeakerOverrides[speakerId];
                }
            }

            function onSpeakerVolumeChange(event) {
                const input = event.target;
                const speakerId = input.dataset.speakerId;
                if (!speakerId) {
                    return;
                }
                const rawValue = (input.value || '').trim();
                if (!rawValue) {
                    if (translateSpeakerOverrides[speakerId]) {
                        delete translateSpeakerOverrides[speakerId].volume_percent;
                        cleanupSpeakerOverrideIfEmpty(speakerId);
                    }
                    speakerOverridesDirty = true;
                    return;
                }
                const parsed = parseFloat(rawValue);
                if (Number.isNaN(parsed)) {
                    return;
                }
                const normalized = Math.min(MAX_VOLUME_PERCENT, Math.max(MIN_VOLUME_PERCENT, parsed));
                if (!translateSpeakerOverrides[speakerId]) {
                    translateSpeakerOverrides[speakerId] = {
                        preset_name: '',
                        use_emotion_prompt: false,
                        emotion_weight: DEFAULT_EMOTION_WEIGHT,
                    };
                }
                translateSpeakerOverrides[speakerId].volume_percent = normalized;
                speakerOverridesDirty = true;
                input.value = normalized;
            }

            function autoApplyTranslateMetadata(metadata, sessionIdOverride = null) {
                if (!metadata || typeof metadata !== 'object') {
                    return;
                }
                const backingMeta = metadata.backing_track || {};
                if (typeof backingMeta.available === 'boolean') {
                    translateBackingAvailableFromSession = Boolean(backingMeta.available);
                    updateCustomBackingSummary();
                    syncTranslateMergeBackState();
                }
                if (
                    translateVolumeInput &&
                    typeof metadata.generated_volume_percent === 'number'
                ) {
                    translateVolumeInput.value = metadata.generated_volume_percent;
                }
                if (translateBackingVolumeInput) {
                    let backingValue = null;
                    if (typeof metadata.backing_volume_percent === 'number') {
                        backingValue = metadata.backing_volume_percent;
                    } else if (
                        metadata.backing_track &&
                        typeof metadata.backing_track.volume_percent === 'number'
                    ) {
                        backingValue = metadata.backing_track.volume_percent;
                    }
                    if (backingValue !== null) {
                        translateBackingVolumeInput.value = backingValue;
                    }
                }
                if (translateManualSegmentsToggle && translateManualSegmentsInput) {
                    let manualText = '';
                    if (typeof metadata.gemini_raw_text === 'string' && metadata.gemini_raw_text.trim()) {
                        manualText = metadata.gemini_raw_text.trim();
                    } else if (Array.isArray(metadata.gemini_raw_segments)) {
                        manualText = JSON.stringify(metadata.gemini_raw_segments, null, 2);
                    }
                    if (manualText) {
                        translateManualSegmentsToggle.checked = true;
                        if (typeof updateManualSegmentsVisibility === 'function') {
                            updateManualSegmentsVisibility();
                        }
                        translateManualSegmentsInput.value = manualText;
                    }
                }
                const derivedSessionId =
                    sessionIdOverride ||
                    metadata.session_id ||
                    metadata.reuse_session_id ||
                    (metadata.separation && metadata.separation.session_id);
                if (derivedSessionId) {
                    currentTranslateSessionId = derivedSessionId;
                }
                renderSeparationPreview(currentTranslateSessionId, metadata);
                if (Array.isArray(metadata.speaker_profiles)) {
                    setSpeakerProfiles(metadata.speaker_profiles);
                }
                if (metadata.speaker_overrides !== undefined) {
                    if (metadata.speaker_overrides && typeof metadata.speaker_overrides === 'object') {
                        setSpeakerOverrides(metadata.speaker_overrides);
                    } else {
                        setSpeakerOverrides({});
                    }
                    speakerOverridesDirty = false;
                }
                if (metadata.chunk && metadata.chunk.session_id) {
                    currentChunkSessionId = metadata.chunk.session_id;
                    translateSelectedChunkId = metadata.chunk.session_id;
                }
                renderSpeakerAssignments();
                updateChunkSelectionUI();
            }

            function syncSegmentRulesFromMetadata(rules) {
                if (!rules) {
                    return;
                }
                if (translateMinSpeechInput) {
                    if (rules.min_speech_ms !== undefined && rules.min_speech_ms !== null) {
                        translateMinSpeechInput.value = rules.min_speech_ms;
                    } else {
                        translateMinSpeechInput.value = '';
                    }
                }
                if (translateMaxMergeInput) {
                    if (rules.max_merge_ms !== undefined && rules.max_merge_ms !== null) {
                        translateMaxMergeInput.value = rules.max_merge_ms;
                    } else {
                        translateMaxMergeInput.value = '';
                    }
                }
            }

            if (translateAdvancedToggle) {
                translateAdvancedToggle.addEventListener('change', () => {
                    if (translateAdvancedSettings) {
                        translateAdvancedSettings.style.display = translateAdvancedToggle.checked ? 'block' : 'none';
                    }
                    if (!translateAdvancedToggle.checked) {
                        resetAdvancedPanel();
                    }
                    setTranslateButtonLabel();
                });
                setTranslateButtonLabel();
            }

            if (translateSegmentsSelectAll && translateSegmentsList) {
                translateSegmentsSelectAll.addEventListener('change', () => {
                    const speechCheckboxes = translateSegmentsList.querySelectorAll('.segment-card.speech input.segment-generate');
                    speechCheckboxes.forEach(cb => {
                        cb.checked = translateSegmentsSelectAll.checked;
                    });
                    updateTranslateSegmentsSummary();
                });
            } else {
                setTranslateButtonLabel();
            }

            const translateForm = document.getElementById('translateForm');
            if (translateForm) {
                translateForm.addEventListener('submit', async function(e) {
                    e.preventDefault();

                    const statusId = 'translateStatus';
                    const resultDiv = document.getElementById('translateResult');
                    const audioInput = document.getElementById('translateAudioFile');
                    const destInput = document.getElementById('translateDestLanguage');
                    const formatSelect = document.getElementById('translateOutputFormat');

                    hideStatus(statusId);
                    hideStatus('translateSegmentsStatus');
                    resultDiv.innerHTML = '';

                    const destLanguage = destInput.value.trim();
                    if (!destLanguage) {
                        showStatus('Please select a destination language.', 'error', statusId);
                        return;
                    }

                    const hasChunkSelection = Boolean(currentChunkSessionId);
                    const selectedFormat = (formatSelect.value || 'mp3').toLowerCase();

                    const advancedEnabled = translateAdvancedToggle && translateAdvancedToggle.checked;
                    const reuseSeparationCheckbox = document.getElementById('translateReuseSeparation');
                    const reuseCandidateSessionId = currentChunkSessionId || currentTranslateSessionId;
                    if (
                        advancedEnabled &&
                        reuseSeparationCheckbox &&
                        reuseSeparationCheckbox.checked &&
                        !reuseCandidateSessionId
                    ) {
                        showStatus('Analyze audio once before reusing separated tracks.', 'error', statusId);
                        return;
                    }
                    const reuseSeparationEnabled = Boolean(
                        advancedEnabled &&
                        reuseSeparationCheckbox &&
                        reuseSeparationCheckbox.checked &&
                        reuseCandidateSessionId
                    );

                    if (
                        (!audioInput.files || audioInput.files.length === 0) &&
                        !reuseSeparationEnabled &&
                        !hasChunkSelection
                    ) {
                        showStatus('Please select a source audio file.', 'error', statusId);
                        return;
                    }

                    if (advancedEnabled) {
                        resetAdvancedPanel(false);
                        const formData = new FormData();
                        if (reuseSeparationEnabled) {
                            formData.append('reuse_session_id', reuseCandidateSessionId);
                        } else if (audioInput.files && audioInput.files[0]) {
                            formData.append('audio_file', audioInput.files[0]);
                        } else if (hasChunkSelection) {
                            formData.append('reuse_session_id', currentChunkSessionId);
                        }
                        if (translateCustomBackingInput && translateCustomBackingInput.files.length > 0) {
                            formData.append('custom_backing_audio_file', translateCustomBackingInput.files[0]);
                        }
                        formData.append('dest_language', destLanguage);
                        formData.append('response_format', selectedFormat);
                        formData.append('enhance_voice', translateEnhanceEl && translateEnhanceEl.checked ? 'true' : 'false');
                        formData.append('super_resolution_voice', translateSuperEl && translateSuperEl.checked ? 'true' : 'false');
                        formData.append('merge_backing_track', translateMergeBackEl && translateMergeBackEl.checked ? 'true' : 'false');
                        formData.append('ignore_non_speech', translateIgnoreNonSpeechEl && translateIgnoreNonSpeechEl.checked ? 'true' : 'false');
                        formData.append('preserve_silence_audio', translatePreserveSilenceEl && translatePreserveSilenceEl.checked ? 'true' : 'false');
                        if (translateGeminiModel && translateGeminiModel.value) {
                            formData.append('gemini_model', translateGeminiModel.value);
                        }
                        if (translateGeminiApiKey && translateGeminiApiKey.value.trim()) {
                            formData.append('gemini_api_key', translateGeminiApiKey.value.trim());
                        }
                        if (translateDebugTranslate) {
                            formData.append('translate_text', translateDebugTranslate.checked ? 'true' : 'false');
                        }
                        const customPromptValue = translateCustomPrompt ? translateCustomPrompt.value.trim() : '';
                        if (customPromptValue) {
                            formData.append('prompt', customPromptValue);
                        }
                        appendSegmentParameters(formData);
                        appendManualSegments(formData);

                        try {
                            if (translateBtn) {
                                translateBtn.disabled = true;
                            }
                            const translateEnabledNow = translateDebugTranslate ? translateDebugTranslate.checked : true;
                            await streamTranslateSegmentsRequest(formData, {
                                statusId,
                                translateEnabledNow,
                            });
                        } catch (error) {
                            console.error('Segment preparation error:', error);
                            const message = error && error.message ? error.message : 'Segment preparation error.';
                            showStatus(message, 'error', statusId);
                        } finally {
                            if (translateBtn) {
                                translateBtn.disabled = false;
                            }
                        }
                        return;
                    } else {
                        resetAdvancedPanel();
                    }

                    const formData = new FormData();
                    if (hasChunkSelection) {
                        formData.append('reuse_session_id', currentChunkSessionId);
                    } else {
                        formData.append('audio_file', audioInput.files[0]);
                    }
                    if (translateCustomBackingInput && translateCustomBackingInput.files.length > 0) {
                        formData.append('custom_backing_audio_file', translateCustomBackingInput.files[0]);
                    }
                    formData.append('dest_language', destLanguage);
                    formData.append('response_format', selectedFormat);
                    formData.append('enhance_voice', translateEnhanceEl && translateEnhanceEl.checked ? 'true' : 'false');
                    formData.append('super_resolution_voice', translateSuperEl && translateSuperEl.checked ? 'true' : 'false');
                    formData.append('merge_backing_track', translateMergeBackEl && translateMergeBackEl.checked ? 'true' : 'false');
                    formData.append('ignore_non_speech', translateIgnoreNonSpeechEl && translateIgnoreNonSpeechEl.checked ? 'true' : 'false');
                    formData.append('preserve_silence_audio', translatePreserveSilenceEl && translatePreserveSilenceEl.checked ? 'true' : 'false');
                    if (translateGeminiModel && translateGeminiModel.value) {
                        formData.append('gemini_model', translateGeminiModel.value);
                    }
                    if (translateGeminiApiKey && translateGeminiApiKey.value.trim()) {
                        formData.append('gemini_api_key', translateGeminiApiKey.value.trim());
                    }
                    appendSegmentParameters(formData);
                    appendManualSegments(formData);

                    try {
                        if (translateBtn) {
                            translateBtn.disabled = true;
                        }
                        await streamDirectTranslate(formData, selectedFormat, statusId, resultDiv);
                    } catch (error) {
                        console.error('Translation error:', error);
                        showStatus(`Translation error: ${error.message}`, 'error', statusId);
                    } finally {
                        if (translateBtn) {
                            translateBtn.disabled = false;
                        }
                    }
                });
            }

            if (translateGenerateBtn) {
                translateGenerateBtn.addEventListener('click', async () => {
                    const statusId = 'translateStatus';
                    const resultDiv = document.getElementById('translateResult');
                    hideStatus('translateSegmentsStatus');

                    if (!currentTranslateSessionId) {
                        showStatus('Analyze audio first to load segments.', 'error', 'translateSegmentsStatus');
                        return;
                    }
                    if (!translateSegmentsList) {
                        showStatus('Segment list unavailable.', 'error', 'translateSegmentsStatus');
                        return;
                    }
                    const segmentCards = translateSegmentsList.querySelectorAll('.segment-card');
                    if (!segmentCards.length) {
                        showStatus('No segments to generate.', 'error', 'translateSegmentsStatus');
                        return;
                    }

                    const segmentsPayload = [];
                    let hasError = false;

                    segmentCards.forEach(card => {
                        if (hasError) {
                            return;
                        }
                        try {
                            const segmentData = readSegmentCardValues(card);
                            segmentsPayload.push(segmentData);
                        } catch (segmentError) {
                            const message =
                                segmentError && segmentError.message
                                    ? segmentError.message
                                    : 'Segment validation failed.';
                            showStatus(message, 'error', 'translateSegmentsStatus');
                            hasError = true;
                        }
                    });

                    if (hasError || !segmentsPayload.length) {
                        return;
                    }

                    const formatSelect = document.getElementById('translateOutputFormat');
                    const selectedFormat = (formatSelect && formatSelect.value ? formatSelect.value : 'mp3').toLowerCase();

                    const payload = {
                        session_id: currentTranslateSessionId,
                        segments: segmentsPayload,
                        response_format: selectedFormat,
                        merge_backing_track: translateMergeBackEl && translateMergeBackEl.checked ? true : false,
                    };
                    if (translateVolumeInput && translateVolumeInput.value) {
                        const volumeValue = parseFloat(translateVolumeInput.value);
                        if (!Number.isNaN(volumeValue)) {
                            payload.generated_volume_percent = volumeValue;
                        }
                    }
                    if (translateBackingVolumeInput && translateBackingVolumeInput.value) {
                        const backingValue = parseFloat(translateBackingVolumeInput.value);
                        if (!Number.isNaN(backingValue)) {
                            payload.backing_volume_percent = backingValue;
                        }
                    }
                    if (speakerOverridesDirty) {
                        payload.speaker_overrides = buildSpeakerOverridesPayload();
                    }

                    try {
                        translateGenerateBtn.disabled = true;
                        await streamTranslateGenerateSegmentsRequest(payload, {
                            statusId,
                            segmentsStatusId: 'translateSegmentsStatus',
                            resultDiv,
                            selectedFormat,
                            segmentsPayload,
                        });
                    } catch (error) {
                        console.error('Segment generation error:', error);
                        const message = error && error.message ? error.message : 'Segment generation error.';
                        showStatus(message, 'error', 'translateSegmentsStatus');
                        showStatus(message, 'error', statusId);
                    } finally {
                        translateGenerateBtn.disabled = false;
                    }
                });
            }

            async function streamDirectTranslate(formData, selectedFormat, statusId, resultDiv) {
                showStatus('Translating speech... this may take a moment ⏳', 'success', statusId);

                const response = await fetch('/api/translate_audio', {
                    method: 'POST',
                    body: formData
                });

                if (!response.ok) {
                    let errorMessage = `Translation failed (${response.status})`;
                    const contentType = response.headers.get('Content-Type') || '';
                    if (contentType.includes('application/json')) {
                        try {
                            const errorData = await response.json();
                            errorMessage = errorData.message || errorData.error || errorMessage;
                        } catch (jsonError) {
                            console.warn('Failed to parse error response:', jsonError);
                        }
                    } else {
                        try {
                            errorMessage = await response.text();
                        } catch (textError) {
                            console.warn('Failed to read error response:', textError);
                        }
                    }
                    showStatus(errorMessage, 'error', statusId);
                    return;
                }

                if (!response.body) {
                    showStatus('Streaming is not supported in this browser.', 'error', statusId);
                    return;
                }

                const reader = response.body.getReader();
                const decoder = new TextDecoder();
                const newlineDelimiter = String.fromCharCode(10);
                let buffer = '';
                let translationCompleted = false;
                let lastStatusMessage = '';

                while (true) {
                    const { value, done } = await reader.read();
                    if (done) {
                        break;
                    }
                    buffer += decoder.decode(value, { stream: true });

                    let newlineIndex = buffer.indexOf(newlineDelimiter);
                    while (newlineIndex !== -1) {
                        const line = buffer.slice(0, newlineIndex).trim();
                        buffer = buffer.slice(newlineIndex + 1);
                        newlineIndex = buffer.indexOf(newlineDelimiter);

                        if (!line) {
                            continue;
                        }

                        let eventData;
                        try {
                            eventData = JSON.parse(line);
                        } catch (parseError) {
                            console.warn('Failed to parse translate event:', parseError, line);
                            continue;
                        }

                        const eventType = eventData.event || 'status';
                        if (eventType === 'status') {
                            const message = eventData.message || 'Processing...';
                            lastStatusMessage = message;
                            showStatus(message, 'success', statusId);
                        } else if (eventType === 'heartbeat') {
                            const heartbeatMessage = lastStatusMessage
                                ? `Still processing... ⏳ (Last step: ${lastStatusMessage})`
                                : 'Still processing... ⏳';
                            showStatus(heartbeatMessage, 'success', statusId);
                        } else if (eventType === 'error') {
                            const message = eventData.message || 'Translation failed.';
                            showStatus(message, 'error', statusId);
                            return;
                        } else if (eventType === 'complete') {
                            translationCompleted = true;
                            const audioUrl = eventData.audio_url;
                            if (!audioUrl) {
                                showStatus('Translation succeeded but audio URL is missing.', 'error', statusId);
                                return;
                            }
                            const downloadName = eventData.file_name || `translated_speech.${selectedFormat}`;
                            resultDiv.innerHTML = `
                                <audio controls src="${audioUrl}" style="width: 100%; margin-top: 20px;"></audio>
                                <div style="margin-top: 12px;">
                                    <a href="${audioUrl}" download="${downloadName}" class="btn">💾 Download</a>
                                </div>
                            `;

                            let statusMessage = '✅ Translation complete!';
                            const metadata = eventData.metadata || {};
                            if (typeof metadata.segment_count === 'number') {
                                statusMessage += ` (${metadata.segment_count} segments)`;
                            }
                            if (metadata.gemini_model) {
                                statusMessage += ` • Gemini model: ${metadata.gemini_model}`;
                            }
                            showStatus(statusMessage, 'success', statusId);
                            applyChunkGenerationMetadata(metadata, audioUrl);
                            autoApplyTranslateMetadata(metadata, metadata.session_id || null);
                        }
                    }
                }

                if (!translationCompleted) {
                    showStatus('Translation stream ended unexpectedly.', 'error', statusId);
                }
            }

            async function streamTranslateSegmentsRequest(formData, { statusId, translateEnabledNow }) {
                showStatus('Analyzing audio and preparing editable segments... ⏳', 'success', statusId);
                const response = await fetch('/api/translate_segments', {
                    method: 'POST',
                    body: formData,
                });

                const errorFromResponse = async () => {
                    const contentType = response.headers.get('Content-Type') || '';
                    if (contentType.includes('application/json')) {
                        try {
                            const errorData = await response.json();
                            return errorData.message || errorData.error;
                        } catch (jsonError) {
                            console.warn('Failed to parse error response:', jsonError);
                        }
                    }
                    try {
                        return await response.text();
                    } catch (textError) {
                        console.warn('Failed to read error response:', textError);
                    }
                    return null;
                };

                if (!response.ok) {
                    const message = (await errorFromResponse()) || `Segment preparation failed (${response.status})`;
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }

                if (!response.body) {
                    const message = 'Segment preparation failed: streaming not supported in this browser.';
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }

                const reader = response.body.getReader();
                const decoder = new TextDecoder();
                const newline = '\\n';
                let buffer = '';
                let lastStatusMessage = '';
                let completed = false;

                const applyCompletion = data => {
                    if (!data || !data.session_id) {
                        const message = 'Segment preparation failed: missing session data.';
                        showStatus(message, 'error', statusId);
                        throw new Error(message);
                    }

                    currentTranslateSessionId = data.session_id;

                    if (data.metadata && data.metadata.gemini_model && translateGeminiModel) {
                        translateGeminiModel.value = data.metadata.gemini_model;
                    }
                    if (translateIgnoreNonSpeechEl && data.metadata && typeof data.metadata.ignore_non_speech === 'boolean') {
                        translateIgnoreNonSpeechEl.checked = !!data.metadata.ignore_non_speech;
                        refreshPromptTemplates();
                        syncPreserveSilenceState();
                    }
                    if (translatePreserveSilenceEl && data.metadata && typeof data.metadata.preserve_silence_audio === 'boolean') {
                        translatePreserveSilenceEl.checked = !!data.metadata.preserve_silence_audio;
                        syncPreserveSilenceState();
                    }

                    const metadata = data.metadata || {};
                    autoApplyTranslateMetadata(metadata, data.session_id);
                    if (metadata.segment_rules) {
                        syncSegmentRulesFromMetadata(metadata.segment_rules);
                    }

                    currentTranslateSegments = Array.isArray(data.segments)
                        ? data.segments.map(seg => ({
                              ...seg,
                              generate: translateEnabledNow ? seg.generate !== false : false,
                          }))
                        : [];
                    renderTranslateSegments(currentTranslateSegments);
                    if (translateAdvancedPanel) {
                        translateAdvancedPanel.style.display = 'block';
                    }

                    const speechCount =
                        (metadata && metadata.speech_segment_count) ||
                        currentTranslateSegments.filter(seg => seg.type === 'speech').length;
                    const totalCount = currentTranslateSegments.length;
                    let statusMessage = `✅ Segments ready: ${totalCount}`;
                    if (typeof speechCount === 'number') {
                        statusMessage += ` total • ${speechCount} speech`;
                    }
                    showStatus(`${statusMessage}. Review below and choose segments to regenerate.`, 'success', statusId);
                    if (!currentTranslateSegments.length) {
                        showStatus('No segments detected. Try adjusting the audio or prompt.', 'error', 'translateSegmentsStatus');
                    }

                    completed = true;
                };

                while (true) {
                    const { value, done } = await reader.read();
                    if (done) {
                        break;
                    }
                    buffer += decoder.decode(value, { stream: true });

                    let newlineIndex = buffer.indexOf(newline);
                    while (newlineIndex !== -1) {
                        const line = buffer.slice(0, newlineIndex).trim();
                        buffer = buffer.slice(newlineIndex + 1);
                        newlineIndex = buffer.indexOf(newline);

                        if (!line) {
                            continue;
                        }

                        let eventData;
                        try {
                            eventData = JSON.parse(line);
                        } catch (parseError) {
                            console.warn('Failed to parse segment stream event:', parseError, line);
                            continue;
                        }

                        const eventType = eventData.event || 'status';
                        if (eventType === 'status') {
                            lastStatusMessage = eventData.message || 'Processing...';
                            showStatus(lastStatusMessage, 'success', statusId);
                        } else if (eventType === 'heartbeat') {
                            const heartbeatMessage = lastStatusMessage
                                ? `Still processing... ⏳ (Last step: ${lastStatusMessage})`
                                : 'Still processing... ⏳';
                            showStatus(heartbeatMessage, 'success', statusId);
                        } else if (eventType === 'error') {
                            const message = eventData.message || 'Failed to prepare segments.';
                            showStatus(message, 'error', statusId);
                            throw new Error(message);
                        } else if (eventType === 'complete') {
                            applyCompletion(eventData);
                        }
                    }
                }

                if (!completed) {
                    const message = 'Segment preparation stream ended unexpectedly.';
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }
            }

            async function streamTranslateGenerateSegmentsRequest(requestPayload, options) {
                const {
                    statusId,
                    segmentsStatusId = 'translateSegmentsStatus',
                    resultDiv,
                    selectedFormat,
                    segmentsPayload,
                } = options;

                showStatus('Generating selected segments... 🎧', 'success', statusId);
                const response = await fetch('/api/translate_generate_segments', {
                    method: 'POST',
                    headers: { 'Content-Type': 'application/json' },
                    body: JSON.stringify(requestPayload),
                });

                const readError = async () => {
                    const contentType = response.headers.get('Content-Type') || '';
                    if (contentType.includes('application/json')) {
                        try {
                            const errorData = await response.json();
                            return errorData.message || errorData.error;
                        } catch (jsonError) {
                            console.warn('Failed to parse error response:', jsonError);
                        }
                    }
                    try {
                        return await response.text();
                    } catch (textError) {
                        console.warn('Failed to read error response:', textError);
                    }
                    return null;
                };

                if (!response.ok) {
                    const message = (await readError()) || `Generation failed (${response.status})`;
                    showStatus(message, 'error', segmentsStatusId);
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }

                if (!response.body) {
                    const message = 'Segment generation failed: streaming not supported in this browser.';
                    showStatus(message, 'error', segmentsStatusId);
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }

                const reader = response.body.getReader();
                const decoder = new TextDecoder();
                const newline = '\\n';
                let buffer = '';
                let lastStatusMessage = '';
                let completed = false;

                const finalizeGeneration = data => {
                    const audioUrl = data && data.audio_url;
                    if (!audioUrl) {
                        const message = 'Segment generation succeeded but audio URL is missing.';
                        showStatus(message, 'error', segmentsStatusId);
                        showStatus(message, 'error', statusId);
                        throw new Error(message);
                    }

                    const downloadName = data.file_name || `translated_speech.${selectedFormat}`;
                    if (resultDiv) {
                        resultDiv.innerHTML = `
                            <audio controls src="${audioUrl}" style="width: 100%; margin-top: 20px;"></audio>
                            <div style="margin-top: 12px;">
                                <a href="${audioUrl}" download="${downloadName}" class="btn">💾 Download</a>
                            </div>
                        `;
                    }

                    const metadata = data.metadata || {};
                    let statusMessage = '✅ Advanced translation complete!';
                    if (typeof metadata.segment_count === 'number') {
                        statusMessage += ` (${metadata.segment_count} segments)`;
                    }
                    if (typeof metadata.selected_generated_count === 'number' && typeof metadata.selected_preserved_count === 'number') {
                        const detailMessage = `Generated ${metadata.selected_generated_count}, preserved ${metadata.selected_preserved_count}`;
                        showStatus(detailMessage, 'success', segmentsStatusId);
                        statusMessage += ` • Generated ${metadata.selected_generated_count}, preserved ${metadata.selected_preserved_count}`;
                    }
                    showStatus(statusMessage, 'success', statusId);
                    applyChunkGenerationMetadata(metadata, audioUrl);

                    const segmentMap = new Map(segmentsPayload.map(seg => [seg.index, seg]));
                    currentTranslateSegments = currentTranslateSegments.map(seg => {
                        const updated = segmentMap.get(seg.index);
                        if (!updated) {
                            return seg;
                        }
                        const duration = Math.max(0, updated.end_ms - updated.start_ms);
                        return {
                            ...seg,
                            start_ms: updated.start_ms,
                            end_ms: updated.end_ms,
                            duration_ms: duration,
                            start: formatTimestamp(updated.start_ms),
                            end: formatTimestamp(updated.end_ms),
                            source_text: updated.source_text || '',
                            translated_text: updated.translated_text || '',
                            generate: updated.generate,
                            volume_percent:
                                Object.prototype.hasOwnProperty.call(updated, 'volume_percent')
                                    ? updated.volume_percent
                                    : seg.volume_percent,
                            emotion_weight:
                                Object.prototype.hasOwnProperty.call(updated, 'emotion_weight')
                                    ? updated.emotion_weight
                                    : seg.emotion_weight,
                        };
                    });
                    renderTranslateSegments(currentTranslateSegments);

                    completed = true;
                };

                while (true) {
                    const { value, done } = await reader.read();
                    if (done) {
                        break;
                    }
                    buffer += decoder.decode(value, { stream: true });

                    let newlineIndex = buffer.indexOf(newline);
                    while (newlineIndex !== -1) {
                        const line = buffer.slice(0, newlineIndex).trim();
                        buffer = buffer.slice(newlineIndex + 1);
                        newlineIndex = buffer.indexOf(newline);

                        if (!line) {
                            continue;
                        }

                        let eventData;
                        try {
                            eventData = JSON.parse(line);
                        } catch (parseError) {
                            console.warn('Failed to parse generate event:', parseError, line);
                            continue;
                        }

                        const eventType = eventData.event || 'status';
                        if (eventType === 'status') {
                            lastStatusMessage = eventData.message || 'Processing...';
                            showStatus(lastStatusMessage, 'success', statusId);
                        } else if (eventType === 'heartbeat') {
                            const heartbeatMessage = lastStatusMessage
                                ? `Still processing... ⏳ (Last step: ${lastStatusMessage})`
                                : 'Still processing... ⏳';
                            showStatus(heartbeatMessage, 'success', statusId);
                        } else if (eventType === 'error') {
                            const message = eventData.message || 'Generation failed.';
                            showStatus(message, 'error', segmentsStatusId);
                            showStatus(message, 'error', statusId);
                            throw new Error(message);
                        } else if (eventType === 'complete') {
                            finalizeGeneration(eventData);
                        }
                    }
                }

                if (!completed) {
                    const message = 'Segment generation stream ended unexpectedly.';
                    showStatus(message, 'error', segmentsStatusId);
                    showStatus(message, 'error', statusId);
                    throw new Error(message);
                }
            }

            async function handleRegularRequest(text, speaker, emotionText, emotionWeight, diffusionSteps, maxTextTokens, formData, startTime) {
                    let response;
                    const voiceFiles = document.getElementById('voice_files').files;
                    
                    if (speaker) {
                        // Use /speak endpoint with speaker preset
                        const requestData = {
                            text: text, 
                            name: speaker,  // API uses 'name' not 'speaker'
                            emotion_text: emotionText || "",
                            emotion_weight: emotionWeight,
                            speech_length: parseInt(document.getElementById('speechLength').value) || 0,
                            diffusion_steps: diffusionSteps,
                            max_text_tokens_per_sentence: maxTextTokens,
                            response_format: "mp3"
                        };
                        
                        response = await fetch('/speak', {
                            method: 'POST',
                            headers: {'Content-Type': 'application/json'},
                            body: JSON.stringify(requestData)
                        });
                    } else if (voiceFiles && voiceFiles.length > 0) {
                        // Use /clone_voice endpoint with uploaded voice file
                        const cloneFormData = new FormData();
                        cloneFormData.append('text', text);
                        cloneFormData.append('reference_audio_file', voiceFiles[0]);
                        cloneFormData.append('emotion_text', emotionText || "");
                        cloneFormData.append('emotion_weight', emotionWeight.toString());
                        cloneFormData.append('speech_length', (parseInt(document.getElementById('speechLength').value) || 0).toString());
                        cloneFormData.append('diffusion_steps', diffusionSteps.toString());
                        cloneFormData.append('max_text_tokens_per_sentence', maxTextTokens.toString());
                        cloneFormData.append('response_format', 'mp3');
                        
                        response = await fetch('/clone_voice', {
                            method: 'POST',
                            body: cloneFormData
                        });
                    } else {
                        showStatus('Please select a speaker preset or upload a voice file', 'error');
                        return;
                    }
                    
                    if (response.ok) {
                        const endTime = performance.now();
                        const duration = ((endTime - startTime) / 1000).toFixed(2);
                        
                        const blob = await response.blob();
                        const audioUrl = URL.createObjectURL(blob);
                        
                        document.getElementById('audioResult').innerHTML = `
                            <h3>🎵 Generated Speech (${duration}s)</h3>
                        <audio controls autoplay preload="none" style="width: 100%; margin: 10px 0;">
                                <source src="${audioUrl}" type="audio/mpeg">
                            </audio>
                            <br>
                            <a href="${audioUrl}" download="speech.mp3" class="btn">💾 Download</a>
                        `;
                        // Show enhanced status message with emotion info
                        let statusMessage = `Speech generated in ${duration}s! 🚀`;
                        if (emotionText && emotionText.trim()) {
                            statusMessage += ` 😊 Emotion: "${emotionText}" (${emotionWeight})`;
                        }
                        showStatus(statusMessage, 'success');
                    } else {
                        const error = await response.text();
                        showStatus(`Error: ${error}`, 'error');
                    }
            }

            async function handleStreamingRequest(text, speaker, emotionText, emotionWeight, diffusionSteps, maxTextTokens, formData, startTime) {
                showStatus('⚡ Streaming: Waiting for first chunk...', 'success');
                
                // Get first chunk size setting
                const firstChunkSize = parseInt(document.getElementById('firstChunkSize').value) || 40;
                
                let endpoint, requestOptions;
                
                const voiceFiles = document.getElementById('voice_files').files;
                
                if (speaker) {
                    // Use /speak_stream endpoint with speaker preset
                    endpoint = '/speak_stream';
                    requestOptions = {
                        method: 'POST',
                        headers: {'Content-Type': 'application/json'},
                        body: JSON.stringify({
                            text: text,
                            name: speaker,  // API uses 'name' not 'speaker'
                            emotion_text: emotionText || "",
                            emotion_weight: emotionWeight,
                            speech_length: parseInt(document.getElementById('speechLength').value) || 0,
                            diffusion_steps: diffusionSteps,
                            max_text_tokens_per_sentence: maxTextTokens,
                            response_format: "mp3"
                        })
                    };
                } else if (voiceFiles && voiceFiles.length > 0) {
                    // Use /clone_voice_stream endpoint with uploaded voice file
                    endpoint = '/clone_voice_stream';
                    const cloneFormData = new FormData();
                    cloneFormData.append('text', text);
                    cloneFormData.append('reference_audio_file', voiceFiles[0]);
                    cloneFormData.append('emotion_text', emotionText || "");
                    cloneFormData.append('emotion_weight', emotionWeight.toString());
                    cloneFormData.append('speech_length', (parseInt(document.getElementById('speechLength').value) || 0).toString());
                    cloneFormData.append('diffusion_steps', diffusionSteps.toString());
                    cloneFormData.append('max_text_tokens_per_sentence', maxTextTokens.toString());
                    cloneFormData.append('response_format', 'mp3');
                    requestOptions = {
                        method: 'POST',
                        body: cloneFormData
                    };
                } else {
                    showStatus('Please select a speaker preset or upload a voice file for streaming', 'error');
                    return;
                }
                
                const response = await fetch(endpoint, requestOptions);
                
                if (!response.ok) {
                    const error = await response.text();
                    showStatus(`Error: ${error}`, 'error');
                    return;
                }
                
                const reader = response.body.getReader();
                const audioChunks = [];
                let buffer = new Uint8Array();
                let chunkCount = 0;
                let firstChunkTime = null;
                let audioContext = null;
                let audioSource = null;
                let nextStartTime = 0;
                
                // Create audio context for streaming playback
                audioContext = new (window.AudioContext || window.webkitAudioContext)();
                
                try {
                    while (true) {
                        const {done, value} = await reader.read();
                        
                        if (done) {
                            break;
                        }
                        
                        // Append new data to buffer
                        const newBuffer = new Uint8Array(buffer.length + value.length);
                        newBuffer.set(buffer);
                        newBuffer.set(value, buffer.length);
                        buffer = newBuffer;
                        
                        // Try to parse chunks from buffer
                        while (true) {
                            // Look for header: CHUNK:idx:size:status\\n
                            // Find newline character (10 = '\\n' in ASCII)
                            let headerEnd = -1;
                            for (let i = 0; i < buffer.length; i++) {
                                if (buffer[i] === 10) {
                                    headerEnd = i;
                                    break;
                                }
                            }
                            
                            if (headerEnd === -1) break;
                            
                            const headerText = new TextDecoder().decode(buffer.slice(0, headerEnd));
                            
                            if (headerText.startsWith('ERROR:')) {
                                showStatus(`Streaming error: ${headerText.substring(6)}`, 'error');
                                return;
                            }
                            
                            if (!headerText.startsWith('CHUNK:')) break;
                            
                            const parts = headerText.split(':');
                            if (parts.length !== 4) break;
                            
                            const chunkIdx = parseInt(parts[1]);
                            const chunkSize = parseInt(parts[2]);
                            const isLast = parts[3] === 'LAST';
                            
                            // Check if we have the complete chunk
                            const chunkStart = headerEnd + 1;
                            const chunkEnd = chunkStart + chunkSize;
                            
                            if (buffer.length < chunkEnd) break;
                            
                            // Extract chunk data
                            const chunkData = buffer.slice(chunkStart, chunkEnd);
                            buffer = buffer.slice(chunkEnd);
                            
                            chunkCount++;
                            
                        if (firstChunkTime === null) {
                            firstChunkTime = performance.now();
                            const ttfb = ((firstChunkTime - startTime) / 1000).toFixed(2);
                            
                            // Show first chunk performance prominently
                            const firstChunkSize = document.getElementById('firstChunkSize').value;
                            showStatus(`⚡ First chunk ready in ${ttfb}s! (${firstChunkSize} tokens) Playing now...`, 'success');
                            
                            // Show real-time performance indicator
                            document.getElementById('audioResult').innerHTML = `
                                <div style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%); padding: 20px; border-radius: 15px; color: white; margin: 10px 0;">
                                    <h3 style="margin: 0; display: flex; align-items: center; gap: 10px;">
                                        <span class="loading"></span>
                                        Streaming in progress...
                                    </h3>
                                    <div style="margin-top: 15px; background: rgba(255,255,255,0.2); padding: 15px; border-radius: 10px;">
                                        <div style="font-size: 1.2em; margin-bottom: 5px;">
                                            ⚡ First Chunk Generated
                                        </div>
                                        <div style="font-size: 2em; font-weight: bold;">
                                            ${ttfb}s
                                        </div>
                                        <div style="font-size: 0.9em; opacity: 0.9; margin-top: 5px;">
                                            🎵 Audio playing • Receiving chunk ${chunkCount}/${chunkCount}...
                                        </div>
                                    </div>
                                </div>
                            `;
                        } else {
                            // Update chunk counter during streaming
                            const currentDisplay = document.getElementById('audioResult').innerHTML;
                            if (currentDisplay.includes('Streaming in progress')) {
                                const ttfb = ((firstChunkTime - startTime) / 1000).toFixed(2);
                                document.getElementById('audioResult').innerHTML = `
                                    <div style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%); padding: 20px; border-radius: 15px; color: white; margin: 10px 0;">
                                        <h3 style="margin: 0; display: flex; align-items: center; gap: 10px;">
                                            <span class="loading"></span>
                                            Streaming in progress...
                                        </h3>
                                        <div style="margin-top: 15px; background: rgba(255,255,255,0.2); padding: 15px; border-radius: 10px;">
                                            <div style="font-size: 1.2em; margin-bottom: 5px;">
                                                ⚡ First Chunk Generated
                                            </div>
                                            <div style="font-size: 2em; font-weight: bold;">
                                                ${ttfb}s
                                            </div>
                                            <div style="font-size: 0.9em; opacity: 0.9; margin-top: 5px;">
                                                🎵 Audio playing • Received ${chunkCount} chunks...
                                            </div>
                                        </div>
                                    </div>
                                `;
                            }
                        }
                            
                            // Decode and play audio chunk
                            try {
                                const audioBlob = new Blob([chunkData], {type: 'audio/mpeg'});
                                const arrayBuffer = await audioBlob.arrayBuffer();
                                const audioBuffer = await audioContext.decodeAudioData(arrayBuffer);
                                
                                // Schedule playback
                                const source = audioContext.createBufferSource();
                                source.buffer = audioBuffer;
                                source.connect(audioContext.destination);
                                
                                const currentTime = audioContext.currentTime;
                                if (nextStartTime < currentTime) {
                                    nextStartTime = currentTime;
                                }
                                
                                source.start(nextStartTime);
                                nextStartTime += audioBuffer.duration;
                                
                                // Store for later download
                                audioChunks.push(chunkData);
                                
                                showStatus(`⚡ Streaming: Playing chunk ${chunkIdx + 1}...`, 'success');
                            } catch (decodeError) {
                                console.error('Error decoding audio chunk:', decodeError);
                                showStatus(`⚠️ Error decoding chunk ${chunkIdx}: ${decodeError.message}`, 'error');
                            }
                            
                        if (isLast) {
                            const endTime = performance.now();
                            const duration = ((endTime - startTime) / 1000).toFixed(2);
                            const firstChunkDuration = ((firstChunkTime - startTime) / 1000).toFixed(2);
                            
                            // Combine all chunks for download
                            const combinedBlob = new Blob(audioChunks, {type: 'audio/mpeg'});
                            const audioUrl = URL.createObjectURL(combinedBlob);
                            
                            // Calculate performance metrics
                            const totalGenTime = duration;
                            const firstChunkPercent = ((firstChunkDuration / totalGenTime) * 100).toFixed(0);
                            
                            document.getElementById('audioResult').innerHTML = `
                                <h3>🎵 Streamed Speech (${chunkCount} chunks)</h3>
                                <audio controls src="${audioUrl}" style="width: 100%; margin: 10px 0;"></audio>
                                <br>
                                <div style="background: #f8f9fa; padding: 15px; border-radius: 10px; margin: 10px 0;">
                                    <h4 style="margin-top: 0;">⚡ Performance Metrics</h4>
                                    <div style="display: grid; grid-template-columns: 1fr 1fr; gap: 10px; margin-bottom: 10px;">
                                        <div style="background: white; padding: 10px; border-radius: 5px; border-left: 4px solid #667eea;">
                                            <strong style="color: #667eea;">⏱️ First Chunk:</strong><br>
                                            <span style="font-size: 1.5em; font-weight: bold;">${firstChunkDuration}s</span>
                                        </div>
                                        <div style="background: white; padding: 10px; border-radius: 5px; border-left: 4px solid #764ba2;">
                                            <strong style="color: #764ba2;">🕐 Total Time:</strong><br>
                                            <span style="font-size: 1.5em; font-weight: bold;">${totalGenTime}s</span>
                                        </div>
                                    </div>
                                    <div style="background: white; padding: 10px; border-radius: 5px;">
                                        <strong>📊 First Chunk Speed:</strong> ${firstChunkPercent}% of total time<br>
                                        <div style="background: #e1e5e9; height: 10px; border-radius: 5px; margin-top: 5px; overflow: hidden;">
                                            <div style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%); height: 100%; width: ${firstChunkPercent}%;"></div>
                                        </div>
                                    </div>
                                </div>
                                <a href="${audioUrl}" download="speech.mp3" class="btn">💾 Download</a>
                            `;
                            
                            let statusMessage = `✅ Streaming complete! First chunk: ${firstChunkDuration}s, Total: ${totalGenTime}s (${chunkCount} chunks)`;
                            if (emotionText && emotionText.trim()) {
                                statusMessage += ` 😊 Emotion: "${emotionText}" (${emotionWeight})`;
                            }
                            showStatus(statusMessage, 'success');
                            return;
                        }
                        }
                    }
                } catch (streamError) {
                    console.error('Streaming error:', streamError);
                    showStatus(`Network error: ${streamError.message}`, 'error');
                }
            }

            // Toggle streaming settings visibility
            document.getElementById('streamingMode').addEventListener('change', function() {
                const streamingSettings = document.getElementById('streamingSettings');
                if (this.checked) {
                    streamingSettings.style.display = 'block';
                } else {
                    streamingSettings.style.display = 'none';
                }
            });

            // Load speakers on page load
            document.addEventListener('DOMContentLoaded', function() {
                loadSpeakers();
            });
        </script>
    </body>
    </html>
    """

# Health check endpoint
# Health check removed - use /server_info endpoint instead

# Utility endpoints
@app.post("/api/estimate_duration")
async def api_estimate_duration(request: Request):
    """API: Estimate speech duration from text"""
    try:
        data = await request.json()
        text = data.get("text", "")
        language = data.get("language", "auto")
        
        if not text or not text.strip():
            return JSONResponse(content={
                "status": "error",
                "message": "No text provided"
            })
        
        duration_ms = estimate_speech_duration(text, language)
        duration_s = duration_ms / 1000.0
        
        # Detect language for display
        chinese_chars = sum(1 for c in text if '\u4e00' <= c <= '\u9fff')
        detected_lang = "Chinese" if chinese_chars / max(len(text), 1) > 0.3 else "English"
        
        return JSONResponse(content={
            "status": "success",
            "duration_ms": duration_ms,
            "duration_s": round(duration_s, 1),
            "detected_language": detected_lang,
            "char_count": len(text)
        })
        
    except Exception as e:
        print(f"❌ Error estimating duration: {e}")
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": str(e)}
        )

@app.post("/api/clear_outputs")
async def api_clear_outputs():
    """API: Clear all generated output files"""
    try:
        outputs_dir = "outputs"
        
        if not os.path.exists(outputs_dir):
            return {
                "status": "success",
                "message": "Outputs directory does not exist",
                "files_deleted": 0,
                "space_freed_mb": 0
            }
        
        # Count files and size before deletion
        files_deleted = 0
        total_size = 0
        
        # Remove all files in outputs directory and subdirectories
        # Run file deletion in thread pool to avoid blocking
        loop = asyncio.get_event_loop()
        
        def delete_files_sync():
            deleted = 0
            size = 0
            for root, dirs, files in os.walk(outputs_dir):
                for file in files:
                    file_path = os.path.join(root, file)
                    try:
                        file_size = os.path.getsize(file_path)
                        os.remove(file_path)
                        deleted += 1
                        size += file_size
                        print(f"🗑️ Deleted: {file_path}")
                    except Exception as e:
                        print(f"⚠️ Failed to delete {file_path}: {e}")
            return deleted, size
        
        files_deleted, total_size = await loop.run_in_executor(executor, delete_files_sync)
        
        space_freed_mb = total_size / (1024 * 1024)
        
        return {
            "status": "success",
            "message": f"Successfully cleared outputs directory",
            "files_deleted": files_deleted,
            "space_freed_mb": round(space_freed_mb, 2)
        }
        
    except Exception as e:
        print(f"❌ Error clearing outputs: {e}")
        traceback.print_exc()
        return {
            "status": "error",
            "message": f"Failed to clear outputs: {str(e)}"
        }


@app.get("/api/prompt_templates")
async def api_prompt_templates():
    """Return the default Gemini prompt templates so users can run them elsewhere."""
    return {
        "translation": TRANSLATION_PROMPT_TEMPLATE,
        "transcription": TRANSCRIPTION_PROMPT_TEMPLATE,
        "ignore_non_speech_instruction": IGNORE_NON_SPEECH_PROMPT_SUFFIX,
    }


@app.post("/api/translate_split_audio")
async def api_translate_split_audio(
    request: Request,
    dest_language: Optional[str] = Form(None),
    audio: Optional[str] = Form(None),
    audio_mime_type: Optional[str] = Form(None),
    chunk_min_minutes: Optional[float] = Form(None),
    chunk_max_minutes: Optional[float] = Form(None),
    min_silence_ms: Optional[int] = Form(None),
    silence_threshold_db: Optional[float] = Form(None),
    super_resolution_voice: Optional[bool] = Form(False),
    audio_file: Optional[UploadFile] = File(None),
):
    """API: Split long audio into ClearVoice-enhanced chunks for reuse."""
    if ClearVoice is None:
        return JSONResponse(
            status_code=400,
            content={
                "status": "error",
                "message": "ClearVoice package is required for audio chunking. Install the `clearvoice` package to enable this feature.",
            },
        )

    try:
        payload: Optional[Dict[str, Any]] = None
        content_type = request.headers.get("content-type", "")
        if (
            audio_file is None
            and (audio is None or not audio.strip())
            and "application/json" in content_type.lower()
        ):
            try:
                payload = await request.json()
            except Exception as exc:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": f"Invalid JSON payload: {str(exc)}"},
                )

        if payload is not None:
            dest_language = payload.get("dest_language", dest_language)
            audio = payload.get("audio", audio)
            audio_mime_type = payload.get("audio_mime_type", audio_mime_type)
            chunk_min_minutes = payload.get("chunk_min_minutes", chunk_min_minutes)
            chunk_max_minutes = payload.get("chunk_max_minutes", chunk_max_minutes)
            min_silence_ms = payload.get("min_silence_ms", min_silence_ms)
            silence_threshold_db = payload.get("silence_threshold_db", silence_threshold_db)
            super_resolution_voice = payload.get("super_resolution_voice", super_resolution_voice)

        audio_reference_value = (audio or "").strip()
        if audio_file is None and not audio_reference_value:
            return JSONResponse(
                status_code=400,
                content={
                    "status": "error",
                    "message": "Source audio is required for chunk splitting.",
                },
            )

        dest_language_value = (dest_language or "").strip() or "unspecified"
        apply_super_resolution = _coerce_to_bool(super_resolution_voice)
        min_minutes = _coerce_positive_float(
            chunk_min_minutes,
            CHUNK_SPLIT_DEFAULT_MIN_MINUTES,
            min_value=CHUNK_SPLIT_MIN_MINUTES,
            max_value=CHUNK_SPLIT_MAX_MINUTES,
        )
        max_minutes = _coerce_positive_float(
            chunk_max_minutes,
            CHUNK_SPLIT_DEFAULT_MAX_MINUTES,
            min_value=min_minutes,
            max_value=CHUNK_SPLIT_MAX_MINUTES,
        )
        if max_minutes < min_minutes:
            max_minutes = min_minutes
        min_chunk_ms = int(min_minutes * 60_000)
        max_chunk_ms = int(max_minutes * 60_000)
        min_chunk_ms = max(60_000, min_chunk_ms)
        max_chunk_ms = max(min_chunk_ms, max_chunk_ms)

        min_silence_ms_value = _coerce_positive_int(
            min_silence_ms,
            CHUNK_SPLIT_MIN_SILENCE_MS,
            min_value=500,
            max_value=120_000,
        )
        silence_threshold_value = _coerce_float_range(
            silence_threshold_db,
            CHUNK_SPLIT_SILENCE_THRESHOLD_DB,
            min_value=-80.0,
            max_value=-10.0,
        )

        preloaded_audio_bytes: Optional[bytes] = None
        uploaded_filename: Optional[str] = None
        audio_mime_type_value = audio_mime_type
        audio_file_for_pipeline = audio_file

        if audio_file is not None:
            try:
                audio_io = await load_audio_bytes_from_request(audio_file, None)
            except HTTPException as exc:
                return JSONResponse(
                    status_code=exc.status_code,
                    content={"status": "error", "message": exc.detail},
                )
            preloaded_audio_bytes = audio_io.read()
            if not preloaded_audio_bytes:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": "Uploaded audio file is empty."},
                )
            uploaded_filename = audio_file.filename
            audio_mime_type_value = audio_file.content_type or audio_mime_type_value
            audio_file_for_pipeline = None

        split_request_summary = {
            "dest_language": dest_language_value,
            "chunk_min_minutes": min_minutes,
            "chunk_max_minutes": max_minutes,
            "min_silence_ms": min_silence_ms_value,
            "silence_threshold_db": silence_threshold_value,
            "super_resolution": apply_super_resolution,
        }

        async def split_stream():
            queue: asyncio.Queue[Optional[Dict[str, Any]]] = asyncio.Queue()

            async def emit(event_type: str, **payload: Any) -> None:
                event = {
                    "event": event_type,
                    "timestamp": time.time(),
                    **payload,
                }
                await queue.put(event)

            async def emit_status(**payload: Any) -> None:
                await emit("status", **payload)

            async def heartbeat_task():
                try:
                    while True:
                        await asyncio.sleep(10)
                        await emit_status(stage="heartbeat", message="Still splitting audio...")
                except asyncio.CancelledError:
                    pass

            async def run_pipeline():
                heartbeat = asyncio.create_task(heartbeat_task())
                try:
                    await emit_status(stage="start", message="Split request accepted.", summary=split_request_summary)

                    (
                        processed_audio,
                        input_mime_type_value,
                        _processed_bytes,
                        _gemini_mime_type,
                        backing_track_audio,
                        _merge_flag,
                        backing_track_source,
                    ) = await _prepare_audio_assets(
                        reuse_source_session=None,
                        audio_file=audio_file_for_pipeline,
                        audio_reference=audio_reference_value if audio_reference_value else None,
                        preloaded_audio_bytes=preloaded_audio_bytes,
                        source_audio_filename=uploaded_filename,
                        audio_mime_type_value=audio_mime_type_value,
                        apply_enhancement=True,
                        apply_super_resolution=apply_super_resolution,
                        requested_merge_backing=False,
                        emit_status=emit_status,
                    )

                    await emit_status(stage="chunking", message="Analyzing silence to plan chunk ranges...")
                    chunk_ranges, silence_stats = _plan_chunk_ranges(
                        processed_audio,
                        min_chunk_ms=min_chunk_ms,
                        max_chunk_ms=max_chunk_ms,
                        min_silence_ms=min_silence_ms_value,
                        silence_threshold_db=silence_threshold_value,
                    )

                    if not chunk_ranges:
                        chunk_ranges = [
                            {
                                "start_ms": 0,
                                "end_ms": len(processed_audio),
                                "cut_reason": "full_audio",
                                "silence_midpoint_ms": None,
                            }
                        ]

                    chunk_entries: List[Dict[str, Any]] = []
                    total_duration_ms = len(processed_audio)
                    gemini_model_name = _get_gemini_model_name()
                    chunk_batch_id = uuid.uuid4().hex
                    _persist_chunk_batch_media(chunk_batch_id, processed_audio, "vocals_full")
                    if backing_track_audio is not None:
                        _persist_chunk_batch_media(chunk_batch_id, backing_track_audio, "backing_full")

                    await emit_status(
                        stage="chunking",
                        message=f"Creating up to {len(chunk_ranges)} chunk session(s)...",
                    )
                    created_chunks = 0

                    for chunk_idx, entry in enumerate(chunk_ranges, start=1):
                        start_ms = entry["start_ms"]
                        end_ms = entry["end_ms"]
                        duration_ms = max(0, end_ms - start_ms)
                        if duration_ms < CHUNK_SPLIT_MIN_CHUNK_MS:
                            continue
                        chunk_audio = processed_audio[start_ms:end_ms]

                        chunk_session = await _create_translate_session(
                            chunk_audio,
                            dest_language_value,
                            prompt="",
                            translate_enabled=True,
                            response_format=TRANSLATE_DEFAULT_OUTPUT_FORMAT,
                            bitrate=TRANSLATE_DEFAULT_BITRATE,
                            input_mime_type=input_mime_type_value,
                            clearvoice_settings={"enhancement": True, "super_resolution": apply_super_resolution},
                            base_segments=[],
                            gemini_chunks=[],
                            gemini_model=gemini_model_name,
                            gemini_api_key=None,
                            backing_track_audio=None,
                            backing_track_source="none",
                            merge_with_backing=False,
                            ignore_non_speech=False,
                            preserve_silence_audio=False,
                            generated_volume_percent=DEFAULT_GENERATED_VOLUME_PERCENT,
                            backing_volume_percent=DEFAULT_GENERATED_VOLUME_PERCENT,
                            chunk_parent_id=chunk_batch_id,
                            chunk_index=chunk_idx,
                            chunk_start_ms=start_ms,
                            chunk_end_ms=end_ms,
                            chunk_cut_reason=entry.get("cut_reason"),
                            chunk_silence_midpoint_ms=entry.get("silence_midpoint_ms"),
                            persist_media=True,
                        )

                        chunk_entry = _serialize_chunk_session(chunk_session)
                        chunk_entries.append(chunk_entry)
                        created_chunks += 1
                        await emit_status(
                            stage="chunking",
                            message=f"Chunk {created_chunks} created (target {len(chunk_ranges)}).",
                        )

                    if not chunk_entries and total_duration_ms >= CHUNK_SPLIT_MIN_CHUNK_MS:
                        await emit_status(stage="chunking", message="Fallback: keeping full audio as single chunk.")
                        fallback_session = await _create_translate_session(
                            processed_audio,
                            dest_language_value,
                            prompt="",
                            translate_enabled=True,
                            response_format=TRANSLATE_DEFAULT_OUTPUT_FORMAT,
                            bitrate=TRANSLATE_DEFAULT_BITRATE,
                            input_mime_type=input_mime_type_value,
                            clearvoice_settings={"enhancement": True, "super_resolution": apply_super_resolution},
                            base_segments=[],
                            gemini_chunks=[],
                            gemini_model=gemini_model_name,
                            gemini_api_key=None,
                            backing_track_audio=None,
                            backing_track_source="none",
                            merge_with_backing=False,
                            ignore_non_speech=False,
                            preserve_silence_audio=False,
                            generated_volume_percent=DEFAULT_GENERATED_VOLUME_PERCENT,
                            backing_volume_percent=DEFAULT_GENERATED_VOLUME_PERCENT,
                            chunk_parent_id=chunk_batch_id,
                            chunk_index=1,
                            chunk_start_ms=0,
                            chunk_end_ms=total_duration_ms,
                            chunk_cut_reason="full_audio",
                            persist_media=True,
                        )
                        chunk_entries.append(_serialize_chunk_session(fallback_session))

                    if not chunk_entries:
                        raise TranslateWorkflowHttpError(
                            400,
                            {
                                "status": "error",
                                "message": "Unable to derive valid chunks from the provided audio.",
                            },
                        )

                    response_payload = {
                        "status": "ok",
                        "message": f"Prepared {len(chunk_entries)} chunk(s) for advanced processing.",
                        "chunk_count": len(chunk_entries),
                        "duration_ms": total_duration_ms,
                        "duration_label": _format_ms_to_timestamp(total_duration_ms),
                        "chunks": chunk_entries,
                        "chunk_batch_id": chunk_batch_id,
                        "strategy": {
                            "min_chunk_ms": min_chunk_ms,
                            "max_chunk_ms": max_chunk_ms,
                            "min_minutes": min_minutes,
                            "max_minutes": max_minutes,
                            "min_silence_ms": min_silence_ms_value,
                            "silence_threshold_db": silence_threshold_value,
                            "silence_count": silence_stats.get("silence_count", 0),
                        },
                        "clearvoice": {
                            "enhancement": True,
                            "super_resolution": apply_super_resolution,
                            "backing_available": backing_track_audio is not None,
                            "backing_source": backing_track_source,
                        },
                        "session_ttl_seconds": ADVANCED_TRANSLATE_SESSION_TTL_SECONDS,
                    }

                    await emit("complete", **response_payload)

                except TranslateWorkflowHttpError as http_error:
                    await emit(
                        "error",
                        status_code=http_error.status_code,
                        message=http_error.content.get("message") or "Chunk splitting failed.",
                        details=http_error.content,
                    )
                except Exception as exc:
                    traceback.print_exc()
                    await emit(
                        "error",
                        status_code=500,
                        message=f"Failed to split audio: {str(exc)}",
                    )
                finally:
                    heartbeat.cancel()
                    try:
                        await heartbeat
                    except asyncio.CancelledError:
                        pass
                    await queue.put(None)

            asyncio.create_task(run_pipeline())
            while True:
                event = await queue.get()
                if event is None:
                    break
                yield (json.dumps(event, ensure_ascii=False) + "\n").encode("utf-8")

        return StreamingResponse(split_stream(), media_type="application/json")

    except TranslateWorkflowHttpError as http_error:
        return JSONResponse(status_code=http_error.status_code, content=http_error.content)
    except Exception as exc:
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to split audio: {str(exc)}"},
        )


@app.post("/api/translate_merge_chunks")
async def api_translate_merge_chunks(payload: MergeChunksRequest):
    """API: Merge multiple chunk sessions back into a single audio file."""
    try:
        session_ids: List[str] = [
            sid for sid in (payload.chunk_session_ids or []) if isinstance(sid, str) and sid.strip()
        ]
        chunk_batch_id = (payload.chunk_batch_id or "").strip()

        sessions: List[TranslateSessionData] = []
        if session_ids:
            for sid in session_ids:
                session = await _get_translate_session(sid)
                if session is None:
                    return JSONResponse(
                        status_code=404,
                        content={"status": "error", "message": f"Chunk session '{sid}' not found or expired."},
                    )
                if session.chunk_parent_id is None:
                    return JSONResponse(
                        status_code=400,
                        content={"status": "error", "message": f"Session '{sid}' is not a chunk session."},
                    )
                sessions.append(session)
        elif chunk_batch_id:
            sessions = await _list_chunk_sessions(chunk_batch_id)
            if not sessions:
                return JSONResponse(
                    status_code=404,
                    content={"status": "error", "message": "No chunk sessions found for this batch."},
                )
            sessions.sort(key=lambda s: (s.chunk_index or 0, s.chunk_start_ms or 0))
        else:
            return JSONResponse(
                status_code=400,
                content={
                    "status": "error",
                    "message": "Provide chunk_session_ids (ordered list) or chunk_batch_id to merge.",
                },
            )

        merge_backing_request = _coerce_to_bool(payload.merge_backing_track)
        merged_audio: Optional[AudioSegment] = None
        chunk_results: List[Dict[str, Any]] = []
        for session in sessions:
            segment_audio = _load_chunk_audio_for_merge(session)
            if segment_audio is None:
                return JSONResponse(
                    status_code=500,
                    content={
                        "status": "error",
                        "message": f"Chunk session '{session.session_id}' has no audio available.",
                    },
                )
            chunk_results.append(
                {
                    "session_id": session.session_id,
                    "chunk_index": session.chunk_index,
                    "generated": bool(session.chunk_generated),
                    "duration_ms": len(segment_audio),
                    "source": "generated" if session.chunk_generated else "original",
                    "audio_url": _chunk_output_url(session) if session.chunk_generated else None,
                }
            )
            merged_audio = segment_audio if merged_audio is None else merged_audio + segment_audio

        if merged_audio is None:
            return JSONResponse(
                status_code=400,
                content={"status": "error", "message": "No audio chunks were provided to merge."},
            )

        response_format_value = TRANSLATE_DEFAULT_OUTPUT_FORMAT
        bitrate_value = payload.bitrate or TRANSLATE_DEFAULT_BITRATE
        final_audio = merged_audio
        if merge_backing_request:
            batch_id = chunk_batch_id or (sessions[0].chunk_parent_id if sessions else None)
            if batch_id:
                backing_path = _chunk_batch_media_path(batch_id, "backing_full")
                if os.path.exists(backing_path):
                    backing_ext = os.path.splitext(backing_path)[1].lstrip(".") or None
                    full_backing_audio = AudioSegment.from_file(backing_path, format=backing_ext)
                    backing_len = len(full_backing_audio)
                    vocal_len = len(merged_audio)
                    if backing_len >= vocal_len:
                        final_audio = full_backing_audio.overlay(merged_audio)
                    else:
                        print(
                            f"⚠️ Backing track ({backing_len} ms) shorter than merged vocals ({vocal_len} ms); using vocal timeline as base."
                        )
                        final_audio = merged_audio.overlay(full_backing_audio)
                else:
                    print(f"⚠️ Full backing track not found at {backing_path}; exporting vocals only.")
        merged_bytes = await _export_audio_segment_bytes(
            final_audio,
            fmt=response_format_value,
            bitrate=bitrate_value if response_format_value in {"mp3", "ogg", "opus", "aac", "webm"} else None,
        )

        output_filename = f"translate_merge_{uuid.uuid4().hex}.{response_format_value}"
        output_path = os.path.join(TRANSLATE_OUTPUT_DIR, output_filename)
        with open(output_path, "wb") as outfile:
            outfile.write(merged_bytes)

        audio_url = f"/api/translate_outputs/{output_filename}"

        return JSONResponse(
            status_code=200,
            content={
                "status": "ok",
                "message": f"Merged {len(chunk_results)} chunk(s).",
                "audio_url": audio_url,
                "file_name": output_filename,
                "response_format": response_format_value,
                "chunk_results": chunk_results,
                "chunk_batch_id": chunk_batch_id or sessions[0].chunk_parent_id,
            },
        )
    except Exception as exc:
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to merge chunks: {str(exc)}"},
        )


@app.post("/api/translate_generate_chunks")
async def api_translate_generate_chunks(payload: ChunkBatchGenerateRequest):
    """API: Generate translated audio for multiple chunk sessions in parallel."""
    try:
        session_ids = [sid.strip() for sid in payload.chunk_session_ids if isinstance(sid, str) and sid.strip()]
        if not session_ids:
            return JSONResponse(
                status_code=400,
                content={"status": "error", "message": "Select at least one chunk session to generate."},
            )

        sessions: List[TranslateSessionData] = []
        for sid in session_ids:
            session = await _get_translate_session(sid)
            if session is None:
                return JSONResponse(
                    status_code=404,
                    content={"status": "error", "message": f"Chunk session '{sid}' not found or expired."},
                )
            if session.chunk_parent_id is None:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": f"Session '{sid}' is not a chunk session."},
                )
            sessions.append(session)

        config_template = sessions[0]
        dest_language_value = (payload.dest_language or config_template.dest_language or "").strip()
        if not dest_language_value:
            return JSONResponse(
                status_code=400,
                content={"status": "error", "message": "Destination language (dest_language) is required."},
            )

        response_format_value = (payload.response_format or config_template.response_format or TRANSLATE_DEFAULT_OUTPUT_FORMAT).lower()
        bitrate_value = payload.bitrate or config_template.bitrate or TRANSLATE_DEFAULT_BITRATE
        gemini_model_value = _normalize_gemini_model_name(payload.gemini_model or config_template.gemini_model)
        gemini_api_key_value = (payload.gemini_api_key or config_template.gemini_api_key or "").strip()
        ignore_non_speech_flag = _coerce_to_bool(
            payload.ignore_non_speech if payload.ignore_non_speech is not None else config_template.ignore_non_speech
        )
        preserve_silence_flag = _coerce_to_bool(
            payload.preserve_silence_audio
            if payload.preserve_silence_audio is not None
            else config_template.preserve_silence_audio
        )
        generated_volume_percent_value = _coerce_volume_percent(
            payload.generated_volume_percent,
            config_template.generated_volume_percent,
        )
        backing_volume_percent_value = _coerce_volume_percent(
            payload.backing_volume_percent,
            config_template.backing_volume_percent,
        )
        merge_backing_requested = _coerce_to_bool(
            payload.merge_backing_track
            if payload.merge_backing_track is not None
            else config_template.merge_with_backing
        )

        summary_payload = {
            "chunks": len(sessions),
            "dest_language": dest_language_value,
            "response_format": response_format_value,
            "bitrate": bitrate_value,
            "gemini_model": gemini_model_value,
            "merge_backing": merge_backing_requested,
        }

        async def chunk_generate_stream():
            queue: asyncio.Queue[Optional[Dict[str, Any]]] = asyncio.Queue()

            async def emit(event_type: str, **payload_data: Any) -> None:
                event = {
                    "event": event_type,
                    "timestamp": time.time(),
                    **payload_data,
                }
                await queue.put(event)

            async def run_batch():
                await emit(
                    "status",
                    stage="start",
                    message=f"Queued {len(sessions)} chunk(s) for generation.",
                    summary=summary_payload,
                )

                success_count = 0
                failure_count = 0
                counter_lock = asyncio.Lock()

                async def handle_chunk(session: TranslateSessionData, order_index: int):
                    nonlocal success_count, failure_count
                    delay_seconds = order_index * CHUNK_BATCH_GENERATE_DELAY_SECONDS
                    if delay_seconds > 0:
                        await emit(
                            "chunk_waiting",
                            chunk_session_id=session.session_id,
                            chunk_index=session.chunk_index,
                            delay_seconds=delay_seconds,
                        )
                        await asyncio.sleep(delay_seconds)

                    await emit(
                        "chunk_start",
                        chunk_session_id=session.session_id,
                        chunk_index=session.chunk_index,
                    )

                    try:
                        audio_url, file_name, metadata = await _generate_chunk_audio_from_session(
                            session,
                            dest_language=dest_language_value,
                            response_format=response_format_value,
                            bitrate=bitrate_value,
                            gemini_model=gemini_model_value,
                            gemini_api_key=gemini_api_key_value,
                            ignore_non_speech=ignore_non_speech_flag,
                            preserve_silence_audio=preserve_silence_flag,
                            generated_volume_percent=generated_volume_percent_value,
                            backing_volume_percent=backing_volume_percent_value,
                            merge_backing_track=merge_backing_requested,
                        )
                        async with counter_lock:
                            success_count += 1
                        await emit(
                            "chunk_complete",
                            chunk_session_id=session.session_id,
                            chunk_index=session.chunk_index,
                            audio_url=audio_url,
                            file_name=file_name,
                            metadata=metadata,
                        )
                    except TranslateWorkflowHttpError as http_error:
                        async with counter_lock:
                            failure_count += 1
                        await emit(
                            "chunk_error",
                            chunk_session_id=session.session_id,
                            chunk_index=session.chunk_index,
                            status_code=http_error.status_code,
                            message=http_error.content.get("message") or "Chunk generation failed.",
                            details=http_error.content,
                        )
                    except Exception as exc:
                        async with counter_lock:
                            failure_count += 1
                        traceback.print_exc()
                        await emit(
                            "chunk_error",
                            chunk_session_id=session.session_id,
                            chunk_index=session.chunk_index,
                            status_code=500,
                            message=f"Chunk generation failed: {str(exc)}",
                        )

                tasks = [
                    asyncio.create_task(handle_chunk(session, idx))
                    for idx, session in enumerate(sessions)
                ]
                await asyncio.gather(*tasks, return_exceptions=True)

                await emit(
                    "complete",
                    message="Chunk batch generation finished.",
                    total_chunks=len(sessions),
                    completed_chunks=success_count,
                    failed_chunks=failure_count,
                )
                await queue.put(None)

            asyncio.create_task(run_batch())

            while True:
                event = await queue.get()
                if event is None:
                    break
                yield (json.dumps(event, ensure_ascii=False) + "\n").encode("utf-8")

        return StreamingResponse(chunk_generate_stream(), media_type="application/json")
    except TranslateWorkflowHttpError as http_error:
        return JSONResponse(status_code=http_error.status_code, content=http_error.content)
    except Exception as exc:
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to generate chunk audios: {str(exc)}"},
        )


@app.post("/api/translate_segments")
async def api_translate_segments(
    request: Request,
    dest_language: Optional[str] = Form(None),
    response_format: Optional[str] = Form(None),
    bitrate: Optional[str] = Form(None),
    audio: Optional[str] = Form(None),
    audio_mime_type: Optional[str] = Form(None),
    custom_backing_audio: Optional[str] = Form(None),
    custom_backing_audio_mime_type: Optional[str] = Form(None),
    prompt: Optional[str] = Form(None),
    translate_text: Optional[bool] = Form(True),
    gemini_model: Optional[str] = Form(None),
    gemini_api_key: Optional[str] = Form(None),
    enhance_voice: Optional[bool] = Form(False),
    super_resolution_voice: Optional[bool] = Form(False),
    merge_backing_track: Optional[bool] = Form(False),
    min_speech_ms: Optional[int] = Form(None),
    max_merge_ms: Optional[int] = Form(None),
    segments_json: Optional[str] = Form(None),
    ignore_non_speech: Optional[bool] = Form(False),
    preserve_silence_audio: Optional[bool] = Form(False),
    generated_volume_percent: Optional[float] = Form(None),
    backing_volume_percent: Optional[float] = Form(None),
    reuse_session_id: Optional[str] = Form(None),
    audio_file: Optional[UploadFile] = File(None),
    custom_backing_audio_file: Optional[UploadFile] = File(None),
):
    """API: Prepare translation segments for advanced translate/edit workflow."""
    reuse_session_id_value: Optional[str] = reuse_session_id
    try:
        payload: Optional[Dict[str, Any]] = None
        dest_language_value = dest_language
        response_format_value = response_format
        bitrate_value = bitrate
        audio_reference = audio
        audio_mime_type_value = audio_mime_type
        custom_backing_audio_value = custom_backing_audio
        custom_backing_audio_mime_type_value = custom_backing_audio_mime_type
        prompt_override = prompt
        translate_flag_value = translate_text
        gemini_model_value = gemini_model
        gemini_api_key_value = gemini_api_key
        enhance_voice_value = enhance_voice
        super_resolution_voice_value = super_resolution_voice
        merge_backing_track_value = merge_backing_track
        min_speech_duration_value = min_speech_ms
        max_merge_interval_value = max_merge_ms
        segments_override_value = segments_json
        ignore_non_speech_value = ignore_non_speech
        preserve_silence_audio_value = preserve_silence_audio
        generated_volume_percent_value = generated_volume_percent
        backing_volume_percent_value = backing_volume_percent

        content_type = request.headers.get("content-type", "")
        if (
            dest_language is None
            and not audio_reference
            and audio_file is None
            and "application/json" in content_type.lower()
        ):
            try:
                payload = await request.json()
            except Exception as exc:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": f"Invalid JSON payload: {str(exc)}"},
                )

        if payload is not None:
            dest_language_value = payload.get("dest_language", dest_language_value)
            response_format_value = payload.get("response_format", response_format_value)
            bitrate_value = payload.get("bitrate", bitrate_value)
            audio_reference = payload.get("audio", audio_reference)
            audio_mime_type_value = payload.get("audio_mime_type", audio_mime_type_value)
            custom_backing_audio_value = payload.get("custom_backing_audio", custom_backing_audio_value)
            custom_backing_audio_mime_type_value = payload.get(
                "custom_backing_audio_mime_type",
                custom_backing_audio_mime_type_value,
            )
            prompt_override = payload.get("prompt", prompt_override)
            translate_flag_value = payload.get("translate", translate_flag_value)
            gemini_model_value = payload.get("gemini_model", gemini_model_value)
            gemini_api_key_value = payload.get("gemini_api_key", gemini_api_key_value)
            enhance_voice_value = payload.get("enhance_voice", enhance_voice_value)
            super_resolution_voice_value = payload.get("super_resolution_voice", super_resolution_voice_value)
            merge_backing_track_value = payload.get("merge_backing_track", merge_backing_track_value)
            min_speech_duration_value = payload.get("min_speech_ms", min_speech_duration_value)
            max_merge_interval_value = payload.get("max_merge_ms", max_merge_interval_value)
            segments_override_value = payload.get("segments_json", segments_override_value)
            ignore_non_speech_value = payload.get("ignore_non_speech", ignore_non_speech_value)
            preserve_silence_audio_value = payload.get("preserve_silence_audio", preserve_silence_audio_value)
            generated_volume_percent_value = payload.get(
                "generated_volume_percent",
                generated_volume_percent_value,
            )
            backing_volume_percent_value = payload.get(
                "backing_volume_percent",
                backing_volume_percent_value,
            )
            reuse_session_id_value = payload.get("reuse_session_id", reuse_session_id_value)

        dest_language_value = (dest_language_value or "").strip()
        if not dest_language_value:
            return JSONResponse(
                status_code=400,
                content={"status": "error", "message": "Destination language (dest_language) is required."},
            )

        response_format_value = TRANSLATE_DEFAULT_OUTPUT_FORMAT
        bitrate_value = bitrate_value or TRANSLATE_DEFAULT_BITRATE
        translate_enabled = _coerce_to_bool(translate_flag_value if translate_flag_value is not None else True)
        ignore_non_speech_flag = _coerce_to_bool(ignore_non_speech_value)
        preserve_silence_audio_flag = _coerce_to_bool(preserve_silence_audio_value)
        apply_enhancement = _coerce_to_bool(enhance_voice_value)
        apply_super_resolution = _coerce_to_bool(super_resolution_voice_value)
        custom_backing_present = bool(custom_backing_audio_file) or bool((custom_backing_audio_value or "").strip())
        merge_backing_requested_raw = _coerce_to_bool(merge_backing_track_value)
        min_speech_duration = _coerce_positive_int(
            min_speech_duration_value,
            MIN_SPEECH_DURATION_MS,
            min_value=500,
        )
        max_merge_interval = _coerce_positive_int(
            max_merge_interval_value,
            MAX_MERGE_INTERVAL_MS,
            min_value=0,
        )
        generated_volume_percent_value = _coerce_volume_percent(
            generated_volume_percent_value,
            DEFAULT_GENERATED_VOLUME_PERCENT,
        )
        backing_volume_percent_value = _coerce_volume_percent(
            backing_volume_percent_value,
            DEFAULT_GENERATED_VOLUME_PERCENT,
        )
        reuse_source_session: Optional[TranslateSessionData] = None
        reuse_session_id_value = (reuse_session_id_value or "").strip()
        if reuse_session_id_value:
            reuse_source_session = await _get_translate_session(reuse_session_id_value)
            if reuse_source_session is None:
                return JSONResponse(
                    status_code=404,
                    content={
                        "status": "error",
                        "message": "Reuse session not found or expired. Please re-upload the audio.",
                    },
                )
        reuse_backing_available = bool(reuse_source_session and _session_has_backing_audio(reuse_source_session))
        requested_merge_backing = _coerce_merge_backing_flag(
            merge_backing_requested_raw,
            apply_enhancement,
            custom_backing_present or reuse_backing_available,
        )
        if reuse_source_session is not None and reuse_source_session.chunk_parent_id:
            requested_merge_backing = False
        resolved_gemini_model = _normalize_gemini_model_name(gemini_model_value)
        gemini_api_key_value = (gemini_api_key_value or "").strip()

        request_summary = {
            "dest_language": dest_language_value,
            "response_format": response_format_value,
            "bitrate": bitrate_value,
            "enhancement": apply_enhancement,
            "super_resolution": apply_super_resolution,
            "merge_backing": requested_merge_backing,
            "custom_backing": custom_backing_present,
            "reuse_backing": reuse_backing_available,
            "ignore_non_speech": ignore_non_speech_flag,
            "preserve_silence_audio": preserve_silence_audio_flag,
            "generated_volume_percent": generated_volume_percent_value,
            "backing_volume_percent": backing_volume_percent_value,
            "translate_enabled": translate_enabled,
        }
        reuse_session_for_segments = reuse_source_session
        print(
            "[translate_segments] dest=%s reuse_session=%s chunk_index=%s upload=%s format=%s backing=%s merge_backing=%s"
            % (
                dest_language_value,
                bool(reuse_session_for_segments),
                getattr(reuse_session_for_segments, "chunk_index", None),
                bool(audio_file and not reuse_session_for_segments),
                response_format_value,
                custom_backing_present
                or bool(reuse_session_for_segments and _session_has_backing_audio(reuse_session_for_segments)),
                requested_merge_backing,
            )
        )

        async def translate_stream():
            queue: asyncio.Queue[Optional[Dict[str, Any]]] = asyncio.Queue()

            async def emit(event_type: str, **payload: Any) -> None:
                event = {
                    "event": event_type,
                    "timestamp": time.time(),
                    **payload,
                }
                await queue.put(event)

            async def emit_status(**payload: Any) -> None:
                await emit("status", **payload)

            async def heartbeat_task():
                try:
                    while True:
                        await asyncio.sleep(10)
                        await emit_status(message="Still preparing translation segments...", stage="heartbeat")
                except asyncio.CancelledError:
                    pass

            async def run_pipeline():
                heartbeat = asyncio.create_task(heartbeat_task())
                try:
                    await emit_status(stage="start", message="Segment request accepted.", summary=request_summary)
                    print(
                        "[translate_segments] pipeline start reuse_session=%s chunk_id=%s"
                        % (
                            reuse_session_for_segments.session_id if reuse_session_for_segments else None,
                            getattr(reuse_session_for_segments, "chunk_index", None),
                        )
                    )

                    (
                        original_audio,
                        input_mime_type_value,
                        processed_audio_bytes,
                        gemini_mime_type,
                        backing_track_audio,
                        merge_with_backing,
                        backing_track_source,
                    ) = await _prepare_audio_assets(
                        reuse_source_session=reuse_session_for_segments,
                        audio_file=audio_file,
                        audio_reference=audio_reference,
                        audio_mime_type_value=audio_mime_type_value,
                        apply_enhancement=apply_enhancement,
                        apply_super_resolution=apply_super_resolution,
                        requested_merge_backing=requested_merge_backing,
                        custom_backing_audio_file=custom_backing_audio_file,
                        custom_backing_audio_reference=custom_backing_audio_value,
                        custom_backing_mime_type_value=custom_backing_audio_mime_type_value,
                        emit_status=emit_status,
                    )

                    final_prompt = _resolve_final_prompt(
                        prompt_override,
                        dest_language_value,
                        translate_enabled,
                        ignore_non_speech_flag,
                    )

                    segment_result = await _build_translation_segments(
                        original_audio=original_audio,
                        processed_audio_bytes=processed_audio_bytes,
                        gemini_mime_type=gemini_mime_type,
                        dest_language=dest_language_value,
                        final_prompt=final_prompt,
                        translate_enabled=translate_enabled,
                        response_format_value=response_format_value,
                        bitrate_value=bitrate_value,
                        input_mime_type=input_mime_type_value,
                        apply_enhancement=apply_enhancement,
                        apply_super_resolution=apply_super_resolution,
                        ignore_non_speech_flag=ignore_non_speech_flag,
                        preserve_silence_audio_flag=preserve_silence_audio_flag,
                        generated_volume_percent_value=generated_volume_percent_value,
                        backing_volume_percent_value=backing_volume_percent_value,
                        backing_track_audio=backing_track_audio,
                        backing_track_source=backing_track_source,
                        merge_with_backing=merge_with_backing,
                        segments_override_value=segments_override_value,
                        min_speech_duration=min_speech_duration,
                        max_merge_interval=max_merge_interval,
                        resolved_gemini_model=resolved_gemini_model,
                        gemini_api_key_value=gemini_api_key_value or None,
                        emit_status=emit_status,
                        source_chunk_session=reuse_session_for_segments,
                    )

                    metadata = segment_result.metadata
                    if segment_result.gemini_raw_text is not None:
                        metadata["gemini_raw_text"] = segment_result.gemini_raw_text
                    if reuse_session_for_segments is not None:
                        metadata["reuse_source_session_id"] = reuse_session_id_value

                    await emit(
                        "complete",
                        message="Segments ready.",
                        session_id=segment_result.session.session_id,
                        segments=segment_result.ui_segments,
                        metadata=metadata,
                        gemini_raw_segments=segment_result.gemini_chunks,
                        separation=metadata.get("separation"),
                    )
                    print(
                        "[translate_segments] complete session_id=%s chunk_id=%s segments=%s"
                        % (
                            segment_result.session.session_id,
                            getattr(reuse_session_for_segments, "chunk_index", None),
                            len(segment_result.ui_segments),
                        )
                    )

                except TranslateWorkflowHttpError as http_error:
                    await emit(
                        "error",
                        status_code=http_error.status_code,
                        message=http_error.content.get("message") or "Translation failed.",
                        details=http_error.content,
                    )
                except Exception as exc:
                    traceback.print_exc()
                    await emit(
                        "error",
                        status_code=500,
                        message=f"Translation failed: {str(exc)}",
                    )
                finally:
                    heartbeat.cancel()
                    try:
                        await heartbeat
                    except asyncio.CancelledError:
                        pass
                    await queue.put(None)
            asyncio.create_task(run_pipeline())
            while True:
                item = await queue.get()
                if item is None:
                    break
                yield (json.dumps(item, ensure_ascii=False) + "\n").encode("utf-8")

        return StreamingResponse(translate_stream(), media_type="application/json")
    except RuntimeError as runtime_error:
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": str(runtime_error)},
        )
    except Exception as exc:
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to prepare translation segments: {str(exc)}"},
        )


@app.post("/api/translate_generate_segments")
async def api_translate_generate_segments(payload: TranslateGenerateRequest):
    """API: Generate translated audio from edited segments."""
    try:
        session = await _get_translate_session(payload.session_id)
        if session is None:
            return JSONResponse(
                status_code=404,
                content={"status": "error", "message": "Translate session not found or expired."},
            )

        merge_preference = session.merge_with_backing
        if payload.merge_backing_track is not None:
            merge_preference = _coerce_to_bool(payload.merge_backing_track)
            session.merge_with_backing = merge_preference
        merge_with_backing = merge_preference and _session_has_backing_audio(session)
        if merge_preference and not _session_has_backing_audio(session):
            print("⚠️ Merge-back preference is enabled but no backing track is stored for this session.")

        response_format_value = TRANSLATE_DEFAULT_OUTPUT_FORMAT

        bitrate_value = payload.bitrate or session.bitrate or TRANSLATE_DEFAULT_BITRATE
        max_duration = _session_audio_duration_ms(session)
        base_segment_map = {seg.get("index"): seg for seg in session.base_segments}

        volume_percent = session.generated_volume_percent or DEFAULT_GENERATED_VOLUME_PERCENT
        backing_volume_percent = session.backing_volume_percent or DEFAULT_GENERATED_VOLUME_PERCENT
        if payload.generated_volume_percent is not None:
            volume_percent = _coerce_volume_percent(
                payload.generated_volume_percent,
                volume_percent,
            )
        session.generated_volume_percent = volume_percent
        if payload.backing_volume_percent is not None:
            backing_volume_percent = _coerce_volume_percent(
                payload.backing_volume_percent,
                backing_volume_percent,
            )
            session.backing_volume_percent = backing_volume_percent

        chunk_source_session: Optional[TranslateSessionData] = None
        if session.chunk_source_session_id:
            chunk_source_session = await _get_translate_session(session.chunk_source_session_id)

        async def generate_stream():
            queue: asyncio.Queue[Optional[Dict[str, Any]]] = asyncio.Queue()

            async def emit(event_type: str, **payload: Any) -> None:
                event = {
                    "event": event_type,
                    "timestamp": time.time(),
                    **payload,
                }
                await queue.put(event)

            async def emit_status(**payload: Any) -> None:
                await emit("status", **payload)

            async def heartbeat_task():
                try:
                    while True:
                        await asyncio.sleep(10)
                        await emit_status(stage="heartbeat", message="Still synthesizing segments...", session_id=session.session_id)
                except asyncio.CancelledError:
                    pass

            chunk_session_for_generation = chunk_source_session

            async def run_pipeline():
                heartbeat = asyncio.create_task(heartbeat_task())
                try:
                    await emit_status(stage="start", message="Segment synthesis request accepted.", session_id=session.session_id)

                    final_segments: List[Dict[str, Any]] = []
                    sanitized_segments: List[Dict[str, Any]] = []

                    if payload.speaker_overrides is not None:
                        raw_override_input = {
                            key: value.dict(exclude_none=True)
                            for key, value in payload.speaker_overrides.items()
                        }
                        normalized_overrides = _normalize_speaker_overrides(
                            raw_override_input,
                            session.speaker_profiles,
                        )
                        session.speaker_overrides = normalized_overrides
                        await _update_translate_session_speaker_overrides(
                            session.session_id,
                            normalized_overrides,
                        )

                    for seg_input in payload.segments:
                        start_ms = max(0, int(seg_input.start_ms))
                        end_ms = max(0, int(seg_input.end_ms))
                        if end_ms > max_duration:
                            end_ms = max_duration
                        if end_ms <= start_ms:
                            raise TranslateWorkflowHttpError(
                                400,
                                {
                                    "status": "error",
                                    "message": f"Segment index {seg_input.index} has invalid timing (end <= start).",
                                },
                            )
                        duration_ms = end_ms - start_ms
                        start_label = _format_ms_to_timestamp(start_ms)
                        end_label = _format_ms_to_timestamp(end_ms)
                        translated_text = (seg_input.translated_text or "").strip()
                        source_text = (seg_input.source_text or "").strip()

                        is_speech = seg_input.type == "speech"
                        generate_flag = bool(seg_input.generate) if is_speech else False
                        keep_original = not generate_flag if is_speech else True

                        segment_payload: Dict[str, Any] = {
                            "index": seg_input.index,
                            "type": seg_input.type,
                            "start_ms": start_ms,
                            "end_ms": end_ms,
                            "duration_ms": duration_ms,
                            "start": start_label,
                            "end": end_label,
                            "source_text": source_text,
                            "translated_text": translated_text,
                            "generate": generate_flag if is_speech else False,
                            "keep_original": keep_original,
                        }
                        if is_speech and seg_input.volume_percent is not None:
                            segment_payload["volume_percent"] = _coerce_volume_percent(
                                seg_input.volume_percent,
                                DEFAULT_GENERATED_VOLUME_PERCENT,
                            )
                        if is_speech and seg_input.emotion_weight is not None:
                            segment_payload["emotion_weight"] = _coerce_emotion_weight(
                                seg_input.emotion_weight,
                                DEFAULT_EMOTION_WEIGHT,
                            )

                        base_info = base_segment_map.get(seg_input.index)
                        speaker_label = None
                        if base_info and base_info.get("speaker"):
                            speaker_label = base_info["speaker"]
                        elif seg_input.speaker:
                            speaker_label = seg_input.speaker
                        if speaker_label:
                            segment_payload["speaker"] = speaker_label
                        if base_info and base_info.get("text_keys"):
                            segment_payload["text_keys"] = base_info["text_keys"]

                        final_segments.append(segment_payload)

                        sanitized_segment: Dict[str, Any] = {
                            "index": seg_input.index,
                            "type": seg_input.type,
                            "start_ms": start_ms,
                            "end_ms": end_ms,
                            "duration_ms": duration_ms,
                            "start": start_label,
                            "end": end_label,
                            "source_text": source_text,
                            "translated_text": translated_text,
                        }
                        if is_speech and "volume_percent" in segment_payload:
                            sanitized_segment["volume_percent"] = segment_payload["volume_percent"]
                        if is_speech and "emotion_weight" in segment_payload:
                            sanitized_segment["emotion_weight"] = segment_payload["emotion_weight"]
                        if base_info and base_info.get("text_keys"):
                            sanitized_segment["text_keys"] = base_info["text_keys"]
                        if speaker_label:
                            sanitized_segment["speaker"] = speaker_label
                        sanitized_segments.append(sanitized_segment)

                    final_segments.sort(key=lambda seg: (int(seg.get("start_ms", 0)), int(seg.get("index", 0))))
                    sanitized_segments.sort(key=lambda seg: (int(seg.get("start_ms", 0)), int(seg.get("index", 0))))

                    await emit_status(
                        stage="synthesis",
                        message=f"Synthesizing translated speech ({len(final_segments)} selected segments)...",
                        session_id=session.session_id,
                    )

                    audio_payload, media_type, metadata = await _synthesize_translated_audio(
                        _get_session_original_audio(session),
                        final_segments,
                        session.dest_language,
                        response_format=response_format_value,
                        bitrate=bitrate_value,
                        input_mime_type=session.input_mime_type,
                        clearvoice_settings=session.clearvoice_settings,
                        backing_track_audio=_get_session_backing_audio(session),
                        backing_track_source=session.backing_track_source,
                        merge_with_backing=merge_with_backing,
                        preserve_silence_audio=session.preserve_silence_audio,
                        generated_volume_percent=volume_percent,
                        speaker_overrides=session.speaker_overrides,
                        backing_volume_percent=backing_volume_percent,
                    )

                    backing_meta = metadata.setdefault("backing_track", {})
                    backing_meta["requested"] = session.merge_with_backing
                    backing_meta["volume_percent"] = backing_volume_percent
                    backing_meta.setdefault("source", session.backing_track_source or "none")
                    metadata["ignore_non_speech"] = session.ignore_non_speech
                    metadata["preserve_silence_audio"] = session.preserve_silence_audio
                    metadata["speaker_overrides"] = copy.deepcopy(session.speaker_overrides)
                    metadata["backing_volume_percent"] = backing_volume_percent
                    if session.gemini_raw_text is not None:
                        metadata["gemini_raw_text"] = session.gemini_raw_text
                    generated_count = sum(
                        1 for seg in final_segments if seg.get("type") == "speech" and not seg.get("keep_original", False)
                    )
                    preserved_count = sum(
                        1 for seg in final_segments if seg.get("type") == "speech" and seg.get("keep_original", False)
                    )

                    metadata["selected_generated_count"] = generated_count
                    metadata["selected_preserved_count"] = preserved_count
                    metadata["session_id"] = session.session_id
                    metadata["gemini_model"] = session.gemini_model or _get_gemini_model_name()

                    await _update_translate_session_segments(session.session_id, sanitized_segments)
                    await _update_translate_session_metadata(
                        session.session_id,
                        response_format=response_format_value,
                        bitrate=bitrate_value,
                        gemini_model=session.gemini_model,
                        generated_volume_percent=volume_percent,
                        backing_volume_percent=backing_volume_percent,
                    )

                    headers = {
                        "Content-Disposition": f"attachment; filename=translated_speech.{response_format_value}",
                        "X-Translation-Model": session.gemini_model or _get_gemini_model_name(),
                        "X-Translation-Segments": str(len(final_segments)),
                        "X-Translation-Generated": str(generated_count),
                        "X-Translation-Preserved": str(preserved_count),
                        "X-Translation-Input-Mime": session.input_mime_type or "",
                        "X-Translate-Session": session.session_id,
                        "X-Translation-Volume-Percent": f"{volume_percent:.2f}",
                    }
                    clearvoice_settings = session.clearvoice_settings or {}
                    if clearvoice_settings:
                        headers["X-Translation-ClearVoice"] = (
                            f"enhancement={str(clearvoice_settings.get('enhancement', False)).lower()};"
                            f"super_resolution={str(clearvoice_settings.get('super_resolution', False)).lower()}"
                        )
                    headers["X-Translation-Backing"] = (
                        f"available={str(_session_has_backing_audio(session)).lower()};merged={str(merge_with_backing).lower()}"
                    )

                    output_filename = f"translate_{uuid.uuid4().hex}.{response_format_value}"
                    output_path = os.path.join(TRANSLATE_OUTPUT_DIR, output_filename)
                    with open(output_path, "wb") as outfile:
                        outfile.write(audio_payload)
                    audio_url = f"/api/translate_outputs/{output_filename}"

                    if chunk_session_for_generation and chunk_session_for_generation.chunk_parent_id:
                        _mark_chunk_generated(
                            chunk_session_for_generation,
                            output_path,
                            output_filename,
                            response_format_value,
                        )
                        chunk_meta = metadata.get("chunk") or {}
                        chunk_meta.update(
                            {
                                "session_id": chunk_session_for_generation.session_id,
                                "chunk_index": chunk_session_for_generation.chunk_index,
                                "start_ms": chunk_session_for_generation.chunk_start_ms,
                                "end_ms": chunk_session_for_generation.chunk_end_ms,
                                "start_label": _format_ms_to_timestamp(chunk_session_for_generation.chunk_start_ms or 0),
                                "end_label": _format_ms_to_timestamp(chunk_session_for_generation.chunk_end_ms or 0),
                                "duration_label": _format_ms_to_timestamp(
                                    max(
                                        0,
                                        (chunk_session_for_generation.chunk_end_ms or 0)
                                        - (chunk_session_for_generation.chunk_start_ms or 0),
                                    )
                                ),
                                "batch_id": chunk_session_for_generation.chunk_parent_id,
                                "cut_reason": chunk_session_for_generation.chunk_cut_reason,
                                "silence_midpoint_ms": chunk_session_for_generation.chunk_silence_midpoint_ms,
                                "backing_available": bool(chunk_session_for_generation.backing_track_audio),
                                "backing_source": chunk_session_for_generation.backing_track_source or "none",
                                "vocals_url": f"/api/translate_vocals/{chunk_session_for_generation.session_id}",
                                "backing_url": (
                                    f"/api/translate_backing_track/{chunk_session_for_generation.session_id}"
                                    if chunk_session_for_generation.backing_track_audio is not None
                                    else None
                                ),
                                "audio_url": audio_url,
                                "output_format": response_format_value,
                                "output_filename": output_filename,
                            }
                        )
                        metadata["chunk"] = chunk_meta

                    await emit(
                        "complete",
                        message="Segment synthesis complete.",
                        audio_url=audio_url,
                        media_type=media_type,
                        headers=headers,
                        metadata=metadata,
                        file_name=output_filename,
                    )

                except TranslateWorkflowHttpError as http_error:
                    await emit(
                        "error",
                        status_code=http_error.status_code,
                        message=http_error.content.get("message") or "Failed to synthesize translation.",
                        details=http_error.content,
                    )
                except Exception as exc:
                    traceback.print_exc()
                    await emit(
                        "error",
                        status_code=500,
                        message=f"Failed to synthesize translation: {str(exc)}",
                    )
                finally:
                    heartbeat.cancel()
                    try:
                        await heartbeat
                    except asyncio.CancelledError:
                        pass
                    await queue.put(None)

            asyncio.create_task(run_pipeline())

            while True:
                item = await queue.get()
                if item is None:
                    break
                yield (json.dumps(item, ensure_ascii=False) + "\n").encode("utf-8")

        return StreamingResponse(generate_stream(), media_type="application/json")
    except RuntimeError as runtime_error:
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": str(runtime_error)},
        )
    except Exception as exc:
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to synthesize translation: {str(exc)}"},
        )


@app.post("/api/translate_segment_preview")
async def api_translate_segment_preview(payload: SegmentPreviewRequest):
    """API: Generate a quick inline preview for a single translated segment."""
    try:
        session = await _get_translate_session(payload.session_id)
        if session is None:
            return JSONResponse(
                status_code=404,
                content={"status": "error", "message": "Translate session not found or expired."},
            )

        seg_input = payload.segment
        if seg_input.type != "speech":
            return JSONResponse(
                status_code=400,
                content={"status": "error", "message": "Only speech segments can be previewed."},
            )

        max_duration = _session_audio_duration_ms(session)
        start_ms = max(0, int(seg_input.start_ms))
        end_ms = max(0, int(seg_input.end_ms))
        if end_ms > max_duration:
            end_ms = max_duration
        if end_ms <= start_ms:
            raise TranslateWorkflowHttpError(
                400,
                {
                    "status": "error",
                    "message": f"Segment index {seg_input.index} has invalid timing (end <= start).",
                },
            )
        duration_ms = end_ms - start_ms
        start_label = _format_ms_to_timestamp(start_ms)
        end_label = _format_ms_to_timestamp(end_ms)
        translated_text = (seg_input.translated_text or "").strip()
        source_text = (seg_input.source_text or "").strip()

        segment_payload: Dict[str, Any] = {
            "index": seg_input.index,
            "type": "speech",
            "start_ms": start_ms,
            "end_ms": end_ms,
            "duration_ms": duration_ms,
            "start": start_label,
            "end": end_label,
            "source_text": source_text,
            "translated_text": translated_text,
            "generate": True,
            "keep_original": False,
        }
        if seg_input.volume_percent is not None:
            segment_payload["volume_percent"] = _coerce_volume_percent(
                seg_input.volume_percent,
                DEFAULT_GENERATED_VOLUME_PERCENT,
            )
        if seg_input.emotion_weight is not None:
            segment_payload["emotion_weight"] = _coerce_emotion_weight(
                seg_input.emotion_weight,
                DEFAULT_EMOTION_WEIGHT,
            )

        base_segment_map = {seg.get("index"): seg for seg in session.base_segments}
        base_info = base_segment_map.get(seg_input.index)
        speaker_label = None
        if base_info and base_info.get("speaker"):
            speaker_label = base_info["speaker"]
        elif seg_input.speaker:
            speaker_label = seg_input.speaker
        if speaker_label:
            segment_payload["speaker"] = speaker_label
        if base_info and base_info.get("text_keys"):
            segment_payload["text_keys"] = base_info["text_keys"]

        override_payload: Dict[str, Dict[str, Any]] = session.speaker_overrides or {}
        if payload.speaker_overrides is not None:
            raw_override_input = {
                key: value.dict(exclude_none=True)
                for key, value in payload.speaker_overrides.items()
            }
            override_payload = _normalize_speaker_overrides(
                raw_override_input,
                session.speaker_profiles,
            )

        volume_percent = session.generated_volume_percent or DEFAULT_GENERATED_VOLUME_PERCENT
        if payload.generated_volume_percent is not None:
            volume_percent = _coerce_volume_percent(payload.generated_volume_percent, volume_percent)
        backing_volume = session.backing_volume_percent or DEFAULT_GENERATED_VOLUME_PERCENT
        if payload.backing_volume_percent is not None:
            backing_volume = _coerce_volume_percent(payload.backing_volume_percent, backing_volume)

        audio_bytes, media_type, metadata = await _synthesize_translated_audio(
            _get_session_original_audio(session),
            [segment_payload],
            session.dest_language,
            response_format=session.response_format or TRANSLATE_DEFAULT_OUTPUT_FORMAT,
            bitrate=session.bitrate or TRANSLATE_DEFAULT_BITRATE,
            input_mime_type=session.input_mime_type,
            clearvoice_settings=session.clearvoice_settings,
            backing_track_audio=None,
            merge_with_backing=False,
            preserve_silence_audio=session.preserve_silence_audio,
            generated_volume_percent=volume_percent,
            speaker_overrides=override_payload,
            backing_volume_percent=backing_volume,
            pad_to_original=False,
        )

        metadata["preview"] = True
        metadata["preview_segment_index"] = seg_input.index

        audio_data_uri = f"data:{media_type};base64,{base64.b64encode(audio_bytes).decode('ascii')}"
        return JSONResponse(
            status_code=200,
            content={
                "status": "success",
                "segment_index": seg_input.index,
                "audio_preview": audio_data_uri,
                "media_type": media_type,
                "metadata": metadata,
            },
        )
    except TranslateWorkflowHttpError as http_error:
        return JSONResponse(status_code=http_error.status_code, content=http_error.content)
    except Exception as exc:
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to preview segment: {str(exc)}"},
        )


@app.get("/api/translate_backing_track/{session_id}")
async def api_translate_backing_track(session_id: str):
    """API: Stream the stored instrumental backing track for an advanced translate session."""
    session = await _get_translate_session(session_id)
    if session is None:
        return JSONResponse(
            status_code=404,
            content={"status": "error", "message": "Translate session not found or expired."},
        )
    backing_audio = _get_session_backing_audio(session)
    if backing_audio is None:
        return JSONResponse(
            status_code=404,
            content={"status": "error", "message": "No backing track is available for this session."},
        )

    try:
        buffer = BytesIO()
        backing_audio.export(buffer, format="mp3", bitrate="128k")
        audio_bytes = buffer.getvalue()
    except Exception as exc:
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to export backing track: {str(exc)}"},
        )

    headers = {
        "Content-Disposition": f'inline; filename="translate_backing_{session_id}.mp3"',
        "Cache-Control": "no-store, no-cache",
    }
    return Response(content=audio_bytes, media_type="audio/mpeg", headers=headers)


@app.get("/api/translate_vocals/{session_id}")
async def api_translate_vocals(session_id: str):
    """API: Stream the separated vocal track for an advanced translate session."""
    session = await _get_translate_session(session_id)
    if session is None:
        return JSONResponse(
            status_code=404,
            content={"status": "error", "message": "Translate session not found or expired."},
        )
    try:
        original_audio = _get_session_original_audio(session)
    except RuntimeError:
        return JSONResponse(
            status_code=404,
            content={"status": "error", "message": "No separated vocals are available for this session."},
        )

    try:
        buffer = BytesIO()
        original_audio.export(buffer, format="mp3", bitrate="128k")
        audio_bytes = buffer.getvalue()
    except Exception as exc:
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Failed to export vocals: {str(exc)}"},
        )

    headers = {
        "Content-Disposition": f'inline; filename="translate_vocals_{session_id}.mp3"',
        "Cache-Control": "no-store, no-cache",
    }
    return Response(content=audio_bytes, media_type="audio/mpeg", headers=headers)


@app.get("/api/translate_outputs/{filename}")
async def api_translate_outputs(filename: str):
    """Serve generated translate audio files by filename."""
    safe_name = os.path.basename(filename)
    if not safe_name or safe_name != filename:
        return JSONResponse(
            status_code=400,
            content={"status": "error", "message": "Invalid filename."},
        )

    file_path = os.path.join(TRANSLATE_OUTPUT_DIR, safe_name)
    if not os.path.exists(file_path):
        return JSONResponse(
            status_code=404,
            content={"status": "error", "message": "Requested audio not found."},
        )

    media_type = _guess_media_type_from_extension(safe_name)
    return FileResponse(
        file_path,
        media_type=media_type,
        filename=safe_name,
        headers={"Cache-Control": "no-store"},
    )


@app.post("/api/translate_audio")
async def api_translate_audio(
    request: Request,
    dest_language: Optional[str] = Form(None),
    response_format: Optional[str] = Form(None),
    bitrate: Optional[str] = Form(None),
    audio: Optional[str] = Form(None),
    audio_mime_type: Optional[str] = Form(None),
    custom_backing_audio: Optional[str] = Form(None),
    custom_backing_audio_mime_type: Optional[str] = Form(None),
    prompt: Optional[str] = Form(None),
    gemini_model: Optional[str] = Form(None),
    gemini_api_key: Optional[str] = Form(None),
    enhance_voice: Optional[bool] = Form(False),
    super_resolution_voice: Optional[bool] = Form(False),
    merge_backing_track: Optional[bool] = Form(False),
    min_speech_ms: Optional[int] = Form(None),
    max_merge_ms: Optional[int] = Form(None),
    segments_json: Optional[str] = Form(None),
    ignore_non_speech: Optional[bool] = Form(False),
    preserve_silence_audio: Optional[bool] = Form(False),
    generated_volume_percent: Optional[float] = Form(None),
    backing_volume_percent: Optional[float] = Form(None),
    reuse_session_id: Optional[str] = Form(None),
    audio_file: Optional[UploadFile] = File(None),
    custom_backing_audio_file: Optional[UploadFile] = File(None),
):
    """API: Translate speech audio to a target language and return synthesized audio."""
    reuse_session_id_value: Optional[str] = reuse_session_id
    try:
        payload: Optional[Dict[str, Any]] = None
        dest_language_value = dest_language
        audio_reference = audio
        audio_mime_type_value = audio_mime_type
        custom_backing_audio_value = custom_backing_audio
        custom_backing_audio_mime_type_value = custom_backing_audio_mime_type
        prompt_override = prompt
        response_format_value = response_format
        bitrate_value = bitrate
        gemini_model_value = gemini_model
        gemini_api_key_value = gemini_api_key
        enhance_voice_value = enhance_voice
        super_resolution_voice_value = super_resolution_voice
        merge_backing_track_value = merge_backing_track
        min_speech_duration_value = min_speech_ms
        max_merge_interval_value = max_merge_ms
        segments_override_value = segments_json
        ignore_non_speech_value = ignore_non_speech
        preserve_silence_audio_value = preserve_silence_audio
        generated_volume_percent_value = generated_volume_percent
        backing_volume_percent_value = backing_volume_percent

        content_type = request.headers.get("content-type", "")
        if (
            dest_language is None
            and not audio_reference
            and audio_file is None
            and "application/json" in content_type.lower()
        ):
            try:
                payload = await request.json()
            except Exception as exc:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": f"Invalid JSON payload: {str(exc)}"},
                )

        if payload is not None:
            try:
                translate_req = TranslateRequest(**payload)
            except Exception as exc:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": f"Invalid translate request: {str(exc)}"},
                )
            dest_language_value = translate_req.dest_language
            audio_reference = translate_req.audio or audio_reference
            audio_mime_type_value = translate_req.audio_mime_type or audio_mime_type_value
            custom_backing_audio_value = translate_req.custom_backing_audio or custom_backing_audio_value
            custom_backing_audio_mime_type_value = (
                translate_req.custom_backing_audio_mime_type or custom_backing_audio_mime_type_value
            )
            prompt_override = translate_req.prompt or prompt_override
            response_format_value = translate_req.response_format or response_format_value
            bitrate_value = translate_req.bitrate or bitrate_value
            gemini_model_value = translate_req.gemini_model or gemini_model_value
            gemini_api_key_value = translate_req.gemini_api_key or gemini_api_key_value
            enhance_voice_value = translate_req.enhance_voice if translate_req.enhance_voice is not None else enhance_voice_value
            super_resolution_voice_value = (
                translate_req.super_resolution_voice if translate_req.super_resolution_voice is not None else super_resolution_voice_value
            )
            merge_backing_track_value = (
                translate_req.merge_backing_track if translate_req.merge_backing_track is not None else merge_backing_track_value
            )
            min_speech_duration_value = (
                translate_req.min_speech_ms if translate_req.min_speech_ms is not None else min_speech_duration_value
            )
            max_merge_interval_value = (
                translate_req.max_merge_ms if translate_req.max_merge_ms is not None else max_merge_interval_value
            )
            segments_override_value = (
                translate_req.segments_json if translate_req.segments_json is not None else segments_override_value
            )
            ignore_non_speech_value = (
                translate_req.ignore_non_speech if translate_req.ignore_non_speech is not None else ignore_non_speech_value
            )
            preserve_silence_audio_value = (
                translate_req.preserve_silence_audio
                if translate_req.preserve_silence_audio is not None
                else preserve_silence_audio_value
            )
            generated_volume_percent_value = (
                translate_req.generated_volume_percent
                if translate_req.generated_volume_percent is not None
                else generated_volume_percent_value
            )
            backing_volume_percent_value = (
                translate_req.backing_volume_percent
                if translate_req.backing_volume_percent is not None
                else backing_volume_percent_value
            )
            reuse_session_id_value = translate_req.reuse_session_id or reuse_session_id_value

        reuse_source_session: Optional[TranslateSessionData] = None
        reuse_session_id_value = (reuse_session_id_value or "").strip()
        if reuse_session_id_value:
            reuse_source_session = await _get_translate_session(reuse_session_id_value)
            if reuse_source_session is None:
                return JSONResponse(
                    status_code=404,
                    content={
                        "status": "error",
                        "message": "Reuse session not found or expired. Please re-upload the audio.",
                    },
                )

        dest_language_value = (dest_language_value or "").strip()
        if not dest_language_value:
            return JSONResponse(
                status_code=400,
                content={"status": "error", "message": "Destination language (dest_language) is required."},
            )

        response_format_value = TRANSLATE_DEFAULT_OUTPUT_FORMAT
        bitrate_value = bitrate_value or TRANSLATE_DEFAULT_BITRATE
        ignore_non_speech_flag = _coerce_to_bool(ignore_non_speech_value)
        preserve_silence_audio_flag = _coerce_to_bool(preserve_silence_audio_value)
        apply_enhancement = _coerce_to_bool(enhance_voice_value)
        apply_super_resolution = _coerce_to_bool(super_resolution_voice_value)
        custom_backing_present = bool(custom_backing_audio_file) or bool((custom_backing_audio_value or "").strip())
        merge_backing_requested_raw = _coerce_to_bool(merge_backing_track_value)
        reuse_backing_available = bool(reuse_source_session and _session_has_backing_audio(reuse_source_session))
        requested_merge_backing = _coerce_merge_backing_flag(
            merge_backing_requested_raw,
            apply_enhancement,
            custom_backing_present or reuse_backing_available,
        )
        if reuse_source_session is not None and reuse_source_session.chunk_parent_id:
            requested_merge_backing = False
        min_speech_duration = _coerce_positive_int(
            min_speech_duration_value,
            MIN_SPEECH_DURATION_MS,
            min_value=500,
        )
        max_merge_interval = _coerce_positive_int(
            max_merge_interval_value,
            MAX_MERGE_INTERVAL_MS,
            min_value=0,
        )
        generated_volume_percent_value = _coerce_volume_percent(
            generated_volume_percent_value,
            DEFAULT_GENERATED_VOLUME_PERCENT,
        )
        backing_volume_percent_value = _coerce_volume_percent(
            backing_volume_percent_value,
            DEFAULT_GENERATED_VOLUME_PERCENT,
        )
        resolved_gemini_model = _normalize_gemini_model_name(gemini_model_value)
        gemini_api_key_value = (gemini_api_key_value or "").strip()


        audio_bytes: Optional[bytes] = None
        if reuse_source_session is None:
            audio_io = await load_audio_bytes_from_request(audio_file, audio_reference)
            if audio_io is None:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": "No audio provided for translation."},
                )

            audio_bytes = audio_io.read()
            if not audio_bytes:
                return JSONResponse(
                    status_code=400,
                    content={"status": "error", "message": "Provided audio data is empty."},
                )

        input_mime_type = audio_mime_type_value or (audio_file.content_type if audio_file else None) or "audio/wav"

        request_summary = {
            "dest_language": dest_language_value,
            "response_format": response_format_value,
            "bitrate": bitrate_value,
            "enhancement": apply_enhancement,
            "super_resolution": apply_super_resolution,
            "merge_backing": requested_merge_backing,
            "custom_backing": custom_backing_present,
            "ignore_non_speech": ignore_non_speech_flag,
            "preserve_silence_audio": preserve_silence_audio_flag,
            "generated_volume_percent": generated_volume_percent_value,
            "backing_volume_percent": backing_volume_percent_value,
            "reuse_session": bool(reuse_source_session),
        }
        reuse_session_for_translate = reuse_source_session
        print(
            "[translate_audio] dest=%s reuse_session=%s chunk_index=%s upload=%s format=%s backing=%s merge_backing=%s"
            % (
                dest_language_value,
                bool(reuse_session_for_translate),
                getattr(reuse_session_for_translate, "chunk_index", None),
                bool(audio_file and not reuse_session_for_translate),
                response_format_value,
                custom_backing_present
                or bool(reuse_session_for_translate and _session_has_backing_audio(reuse_session_for_translate)),
                requested_merge_backing,
            )
        )

        async def translate_stream():
            queue: asyncio.Queue[Optional[Dict[str, Any]]] = asyncio.Queue()

            async def emit(event_type: str, **payload: Any) -> None:
                event = {
                    "event": event_type,
                    "timestamp": time.time(),
                    **payload,
                }
                await queue.put(event)

            async def emit_status(**payload: Any) -> None:
                await emit("status", **payload)

            async def heartbeat_task():
                try:
                    while True:
                        await asyncio.sleep(10)
                        await emit_status(stage="heartbeat", message="Still processing translation...")
                except asyncio.CancelledError:
                    pass

            async def run_pipeline():
                heartbeat = asyncio.create_task(heartbeat_task())
                try:
                    await emit_status(stage="start", message="Translate request accepted.", summary=request_summary)
                    print(
                        "[translate_audio] pipeline start reuse_session=%s chunk_id=%s"
                        % (
                            reuse_session_for_translate.session_id if reuse_session_for_translate else None,
                            getattr(reuse_session_for_translate, "chunk_index", None),
                        )
                    )

                    session: Optional[TranslateSessionData] = None
                    (
                        original_audio,
                        input_mime_type_resolved,
                        processed_audio_bytes,
                        gemini_mime_type,
                        backing_track_audio,
                        merge_with_backing,
                        backing_track_source,
                    ) = await _prepare_audio_assets(
                        reuse_source_session=reuse_session_for_translate,
                        audio_file=None if reuse_session_for_translate else audio_file,
                        audio_reference=None if reuse_session_for_translate else audio_reference,
                        preloaded_audio_bytes=audio_bytes,
                        audio_mime_type_value=input_mime_type,
                        apply_enhancement=apply_enhancement,
                        apply_super_resolution=apply_super_resolution,
                        requested_merge_backing=requested_merge_backing,
                        custom_backing_audio_file=custom_backing_audio_file,
                        custom_backing_audio_reference=custom_backing_audio_value,
                        custom_backing_mime_type_value=custom_backing_audio_mime_type_value,
                        emit_status=emit_status,
                    )
                    input_mime_type_local = input_mime_type_resolved or input_mime_type

                    final_prompt = _resolve_final_prompt(
                        prompt_override,
                        dest_language_value,
                        True,
                        ignore_non_speech_flag,
                    )

                    segment_result = await _build_translation_segments(
                        original_audio=original_audio,
                        processed_audio_bytes=processed_audio_bytes,
                        gemini_mime_type=gemini_mime_type,
                        dest_language=dest_language_value,
                        final_prompt=final_prompt,
                        translate_enabled=True,
                        response_format_value=response_format_value,
                        bitrate_value=bitrate_value,
                        input_mime_type=input_mime_type_local,
                        apply_enhancement=apply_enhancement,
                        apply_super_resolution=apply_super_resolution,
                        ignore_non_speech_flag=ignore_non_speech_flag,
                        preserve_silence_audio_flag=preserve_silence_audio_flag,
                        generated_volume_percent_value=generated_volume_percent_value,
                        backing_volume_percent_value=backing_volume_percent_value,
                        backing_track_audio=backing_track_audio,
                        backing_track_source=backing_track_source,
                        merge_with_backing=merge_with_backing,
                        segments_override_value=segments_override_value,
                        min_speech_duration=min_speech_duration,
                        max_merge_interval=max_merge_interval,
                        resolved_gemini_model=resolved_gemini_model,
                        gemini_api_key_value=gemini_api_key_value or None,
                        emit_status=emit_status,
                        source_chunk_session=reuse_session_for_translate,
                    )
                    session = segment_result.session
                    segments = segment_result.segments

                    await emit_status(
                        stage="synthesis",
                        message=f"Synthesizing translated speech ({len(segments)} total segments)...",
                    )

                    audio_payload, media_type, synthesis_metadata = await _synthesize_translated_audio(
                        original_audio,
                        segments,
                        dest_language_value,
                        response_format=response_format_value,
                        bitrate=bitrate_value,
                        input_mime_type=input_mime_type_local,
                        clearvoice_settings={
                            "enhancement": apply_enhancement,
                            "super_resolution": apply_super_resolution,
                        },
                        backing_track_audio=backing_track_audio,
                        backing_track_source=backing_track_source,
                        merge_with_backing=merge_with_backing,
                        preserve_silence_audio=preserve_silence_audio_flag,
                        generated_volume_percent=generated_volume_percent_value,
                        backing_volume_percent=backing_volume_percent_value,
                    )

                    metadata = dict(segment_result.metadata)
                    metadata.update(synthesis_metadata or {})
                    metadata["ignore_non_speech"] = ignore_non_speech_flag
                    metadata["preserve_silence_audio"] = preserve_silence_audio_flag
                    metadata["generated_volume_percent"] = generated_volume_percent_value
                    metadata["backing_volume_percent"] = backing_volume_percent_value
                    metadata["gemini_raw_segments"] = segment_result.gemini_chunks
                    if segment_result.gemini_raw_text is not None:
                        metadata["gemini_raw_text"] = segment_result.gemini_raw_text
                    if session is not None:
                        metadata["speaker_overrides"] = copy.deepcopy(session.speaker_overrides)
                    else:
                        metadata["speaker_overrides"] = {}
                    backing_meta = metadata.setdefault("backing_track", {})
                    backing_meta["requested"] = requested_merge_backing
                    backing_meta["available"] = backing_track_audio is not None
                    backing_meta["merged"] = merge_with_backing
                    backing_meta["volume_percent"] = backing_volume_percent_value
                    backing_meta.setdefault("source", backing_track_source or ("custom" if custom_backing_present else "extracted" if apply_enhancement else "none"))
                    metadata["segment_rules"] = {
                        "min_speech_ms": min_speech_duration,
                        "max_merge_ms": max_merge_interval,
                    }
                    metadata["gemini_model"] = resolved_gemini_model
                    if session is not None:
                        metadata["session_id"] = session.session_id
                        metadata["reuse_session_id"] = session.session_id
                        metadata["separation"] = {
                            "vocals_available": True,
                            "vocals_url": f"/api/translate_vocals/{session.session_id}",
                            "backing_available": backing_track_audio is not None,
                            "backing_url": f"/api/translate_backing_track/{session.session_id}" if backing_track_audio is not None else None,
                            "session_id": session.session_id,
                        }

                    headers = {
                        "X-Translation-Model": resolved_gemini_model,
                        "X-Translation-Segments": str(metadata.get("segment_count", len(segments))),
                        "X-Translation-Speech-Segments": str(metadata.get("speech_segment_count", 0)),
                        "X-Translation-Silence-Segments": str(metadata.get("silence_segment_count", 0)),
                        "X-Translation-Input-Mime": input_mime_type_local or "",
                        "X-Translation-ClearVoice": (
                            f"enhancement={str(apply_enhancement).lower()};super_resolution={str(apply_super_resolution).lower()}"
                        ),
                        "X-Translation-Backing": (
                            f"available={str(bool(backing_track_audio)).lower()};merged={str(merge_with_backing).lower()};"
                            f"volume_percent={backing_volume_percent_value:.2f}"
                        ),
                    }

                    output_filename = f"translate_{uuid.uuid4().hex}.{response_format_value}"
                    output_path = os.path.join(TRANSLATE_OUTPUT_DIR, output_filename)
                    with open(output_path, "wb") as outfile:
                        outfile.write(audio_payload)
                    audio_url = f"/api/translate_outputs/{output_filename}"

                    if reuse_session_for_translate and reuse_session_for_translate.chunk_parent_id:
                        _mark_chunk_generated(
                            reuse_session_for_translate,
                            output_path,
                            output_filename,
                            response_format_value,
                        )
                        chunk_meta = metadata.get("chunk") or {}
                        chunk_meta.update(
                            {
                                "session_id": reuse_session_for_translate.session_id,
                                "chunk_index": reuse_session_for_translate.chunk_index,
                                "start_ms": reuse_session_for_translate.chunk_start_ms,
                                "end_ms": reuse_session_for_translate.chunk_end_ms,
                                "start_label": _format_ms_to_timestamp(reuse_session_for_translate.chunk_start_ms or 0),
                                "end_label": _format_ms_to_timestamp(reuse_session_for_translate.chunk_end_ms or 0),
                                "duration_label": _format_ms_to_timestamp(
                                    max(
                                        0,
                                        (reuse_session_for_translate.chunk_end_ms or 0)
                                        - (reuse_session_for_translate.chunk_start_ms or 0),
                                    )
                                ),
                                "batch_id": reuse_session_for_translate.chunk_parent_id,
                                "cut_reason": reuse_session_for_translate.chunk_cut_reason,
                                "silence_midpoint_ms": reuse_session_for_translate.chunk_silence_midpoint_ms,
                                "backing_available": _session_has_backing_audio(reuse_session_for_translate),
                                "backing_source": reuse_session_for_translate.backing_track_source or "none",
                                "vocals_url": f"/api/translate_vocals/{reuse_session_for_translate.session_id}",
                                "backing_url": (
                                    f"/api/translate_backing_track/{reuse_session_for_translate.session_id}"
                                    if _session_has_backing_audio(reuse_session_for_translate)
                                    else None
                                ),
                                "audio_url": audio_url,
                                "output_format": response_format_value,
                                "output_filename": output_filename,
                            }
                        )
                        metadata["chunk"] = chunk_meta

                    await emit(
                        "complete",
                        message="Translation complete.",
                        audio_url=audio_url,
                        media_type=media_type,
                        headers=headers,
                        metadata=metadata,
                        file_name=output_filename,
                    )
                    print(
                        "[translate_audio] complete audio_url=%s chunk_id=%s generated=%s"
                        % (
                            audio_url,
                            getattr(reuse_session_for_translate, "session_id", None)
                            if reuse_session_for_translate
                            else (session.session_id if session else None),
                            bool(reuse_session_for_translate and reuse_session_for_translate.chunk_parent_id),
                        )
                    )

                except TranslateWorkflowHttpError as http_error:
                    await emit(
                        "error",
                        status_code=http_error.status_code,
                        message=http_error.content.get("message") or "Translation failed.",
                        details=http_error.content,
                    )
                except Exception as exc:
                    traceback.print_exc()
                    await emit(
                        "error",
                        status_code=500,
                        message=f"Translation failed: {str(exc)}",
                    )
                finally:
                    heartbeat.cancel()
                    try:
                        await heartbeat
                    except asyncio.CancelledError:
                        pass
                    await queue.put(None)
            asyncio.create_task(run_pipeline())

            while True:
                item = await queue.get()
                if item is None:
                    break
                yield (json.dumps(item, ensure_ascii=False) + "\n").encode("utf-8")

        return StreamingResponse(translate_stream(), media_type="application/json")

    except RuntimeError as runtime_error:
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": str(runtime_error)},
        )
    except Exception as exc:
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"status": "error", "message": f"Translation failed: {str(exc)}"},
        )


# API Helper Functions (matching deploy_vllm_indextts.py exactly)
async def get_audio_bytes_from_url(url: str) -> bytes:
    """Download audio from URL"""
    try:
        import httpx
        async with httpx.AsyncClient() as client:
            response = await client.get(url)
            if response.status_code != 200:
                raise HTTPException(status_code=400, detail="Cannot download audio from URL")
            return response.content
    except ImportError:
        # Fallback if httpx is not available - run in thread pool to avoid blocking
        loop = asyncio.get_event_loop()
        
        def download_sync():
            try:
                with urllib.request.urlopen(url) as response:
                    if response.status != 200:
                        raise Exception("Cannot download audio from URL")
                    return response.read()
            except Exception as e:
                raise Exception(f"Failed to download audio: {str(e)}")
        
        try:
            return await loop.run_in_executor(executor, download_sync)
        except Exception as e:
            raise HTTPException(status_code=400, detail=str(e))

async def load_base64_or_url(audio: str) -> BytesIO:
    """Load audio from base64 or URL"""
    if audio.startswith("http://") or audio.startswith("https://"):
        audio_bytes = await get_audio_bytes_from_url(audio)
    else:
        payload = audio.strip()
        if payload.startswith("data:"):
            try:
                _, payload = payload.split(",", 1)
            except ValueError as e:
                raise HTTPException(status_code=400, detail=f"Invalid data URI audio: {str(e)}") from e
        try:
            audio_bytes = base64.b64decode(payload)
        except Exception as e:
            raise HTTPException(status_code=400, detail=f"Invalid base64 audio data: {str(e)}")
    
    return BytesIO(audio_bytes)

async def load_audio_bytes_from_request(audio_file, audio):
    """Load audio bytes from file or reference audio string"""
    if audio_file is None:
        if audio is None:
            return None
        return await load_base64_or_url(audio)
    else:
        content = await audio_file.read()
        if not content:
            raise HTTPException(status_code=400, detail="Reference audio file is empty")
        return BytesIO(content)

# API Compatibility Endpoints
@app.post("/add_speaker")
async def add_speaker(
    background_tasks: BackgroundTasks,
    name: str = Form(..., description="The name of the speaker"),
    audio: Optional[str] = Form(None, description="Reference audio URL or base64"),
    reference_text: Optional[str] = Form(None, description="Optional transcript"),
    audio_file: Optional[UploadFile] = File(None, description="Upload reference audio file"),
    enhance_voice: bool = Form(False, description="Apply ClearVoice MossFormer2_SE_48K enhancement"),
    super_resolution_voice: bool = Form(False, description="Apply ClearVoice MossFormer2_SR_48K super-resolution"),
):
    """API: Add a new speaker"""
    try:
        print(f"🎭 API: Adding speaker '{name}'")
        print(f"🔍 Debug: audio_file={audio_file}, audio={audio is not None}, reference_text={reference_text}")
        
        if not speaker_api:
            return JSONResponse(
                status_code=500,
                content={"success": False, "error": "Speaker manager not initialized"}
            )
        
        # Load audio from file or reference string (matching deploy_vllm_indextts.py)
        try:
            audio_io = await load_audio_bytes_from_request(audio_file, audio)
            if audio_io is None:
                print(f"❌ API: No audio provided for speaker '{name}'")
                return JSONResponse(
                    status_code=400,
                    content={"success": False, "error": "No audio provided"}
                )
        except Exception as audio_error:
            print(f"❌ API: Audio loading failed for speaker '{name}': {audio_error}")
            return JSONResponse(
                status_code=400,
                content={"success": False, "error": f"Audio loading failed: {str(audio_error)}"}
            )
        
        # Get audio data and filename
        audio_data = audio_io.read()
        filename = audio_file.filename if audio_file else f"{name}_reference.wav"
        
        apply_enhancement = bool(enhance_voice)
        apply_super_resolution_flag = bool(super_resolution_voice)
        print(f"🎚️ API: ClearVoice options -> enhancement={apply_enhancement}, super_resolution={apply_super_resolution_flag}")
        
        if (apply_enhancement or apply_super_resolution_flag) and ClearVoice is None:
            error_msg = "ClearVoice is required for enhancement or super-resolution. Install the `clearvoice` package to enable these options."
            print(f"❌ API: {error_msg}")
            return JSONResponse(
                status_code=500,
                content={"success": False, "error": error_msg}
            )
        
        # Add speaker using SpeakerPresetManager (handles ClearVoice processing internally)
        result = await speaker_api.add_speaker(
            name,
            [audio_data],
            [filename],
            apply_enhancement=apply_enhancement,
            apply_super_resolution=apply_super_resolution_flag,
        )
        
        if result["status"] == "success":
            payload = {"success": True, "role": name}
            if result.get("clearvoice"):
                payload["clearvoice"] = result["clearvoice"]
            return JSONResponse(content=payload)
        else:
            return JSONResponse(
                status_code=500,
                content={"success": False, "error": result["message"]}
            )
            
    except Exception as e:
        error_msg = f"Failed to add speaker '{name}': {str(e)}"
        print(f"❌ API: {error_msg}")
        return JSONResponse(
            status_code=500,
            content={"success": False, "error": error_msg}
        )

@app.post("/delete_speaker")
async def delete_speaker(
    background_tasks: BackgroundTasks,
    name: str = Form(..., description="The name of the speaker")
):
    """API: Delete a speaker"""
    try:
        print(f"🗑️ API: Deleting speaker '{name}'")
        
        if not speaker_api:
            return JSONResponse(
                status_code=500,
                content={"success": False, "error": "Speaker manager not initialized"}
            )
        
        result = await speaker_api.delete_speaker(name)
        
        if result["status"] == "success":
            return JSONResponse(content={"success": True, "role": name})
        else:
            return JSONResponse(
                status_code=500,
                content={"success": False, "error": result["message"]}
            )
            
    except Exception as e:
        error_msg = f"Failed to delete speaker '{name}': {str(e)}"
        print(f"❌ API: {error_msg}")
        return JSONResponse(
            status_code=500,
            content={"success": False, "error": error_msg}
        )

@app.get("/audio_roles")
async def audio_roles():
    """API: List available speakers"""
    try:
        print("📋 API: Listing audio roles")
        
        if not speaker_api:
            return JSONResponse(content={"success": False, "roles": [], "speakers": {}})
        
        speakers_data = await speaker_api.list_speakers()
        
        if speakers_data["status"] == "success":
            speakers = speakers_data.get("speakers", {})
            roles = list(speakers.keys())
            return JSONResponse(
                content={
                    "success": True,
                    "roles": roles,
                    "speakers": speakers,
                    "total_speakers": speakers_data.get("total_speakers", len(roles)),
                }
            )
        else:
            return JSONResponse(content={"success": False, "roles": [], "speakers": {}})
            
    except Exception as e:
        error_msg = f"Failed to list audio roles: {str(e)}"
        print(f"❌ API: {error_msg}")
        return JSONResponse(
            status_code=500,
            content={"success": False, "error": error_msg}
        )


@app.get("/api/speaker_preview/{speaker_name}")
async def api_speaker_preview(speaker_name: str):
    """API: Return stored MP3 preview for a speaker."""
    preview_path = _get_speaker_preview_path(speaker_name)
    if not preview_path.exists():
        raise HTTPException(status_code=404, detail="Speaker preview not found")
    return FileResponse(
        preview_path,
        media_type="audio/mpeg",
        filename=f"{speaker_name}_preview.mp3",
        headers={"Cache-Control": "public, max-age=86400"},
    )


@app.post("/speak")
async def speak(req: SpeakRequest):
    """API: Generate speech using registered speaker"""
    try:
        print(f"🎭 API: Speaking with '{req.name}' - '{req.text[:50]}...'")
        
        if not req.name:
            return JSONResponse(
                status_code=400,
                content={"success": False, "error": "Speaker name is required"}
            )
        
        # Simple speaker validation to prevent failures
        if speaker_api and not speaker_api.speaker_exists(req.name):
            speakers_data = await speaker_api.list_speakers()
            available_roles = list(speakers_data.get("speakers", {}).keys())
            error_msg = f"'{req.name}' is not in the list of existing roles: {', '.join(available_roles)}"
            return JSONResponse(
                status_code=500,
                content={"success": False, "error": error_msg}
            )
        
        tts = tts_manager.get_tts()
        
        # Generate speech
        output_path = os.path.join("outputs", f"speak_{uuid.uuid4().hex}.wav")
        
        # Check if emotion text is provided and not empty
        use_emotion_text = req.emotion_text and req.emotion_text.strip() != ""
        
        result = await tts.infer(
            spk_audio_prompt="",
            text=req.text,
            output_path=output_path,
            speaker_preset=req.name,
            use_emo_text=use_emotion_text,
            emo_text=req.emotion_text if use_emotion_text else None,
            emo_alpha=req.emotion_weight,
            speech_length=req.speech_length,
            diffusion_steps=req.diffusion_steps,
            max_text_tokens_per_sentence=req.max_text_tokens_per_sentence,
            verbose=cmd_args.verbose
        )
        
        # Convert to requested format and return as bytes (matching deploy_vllm_indextts.py)
        if req.response_format != "wav":
            # Read audio data once
            audio_data, sample_rate = await async_audio_read(result)
            # Convert to requested format and get bytes
            audio_bytes, media_type, _ = await convert_audio_to_format(
                audio_data, sample_rate, req.response_format, "128k"
            )
        else:
            # Read WAV file as bytes
            audio_bytes = await async_read_file(result)
            media_type = "audio/wav"
        
        # Set content type (matching deploy_vllm_indextts.py)
        content_type_map = {
            "mp3": "audio/mpeg",
            "opus": "audio/opus", 
            "aac": "audio/aac",
            "flac": "audio/flac",
            "wav": "audio/wav",
            "pcm": "audio/pcm",
        }
        content_type = content_type_map.get(req.response_format, f"audio/{req.response_format}")
        
        print(f"✅ API: Generated {len(audio_bytes)} bytes of {req.response_format.upper()} audio")
        
        # Cleanup temporary file
        await async_remove_file(result)
        
        # Return Response with bytes (matching deploy_vllm_indextts.py format exactly)
        return Response(
            content=audio_bytes,
            media_type=content_type,
            headers={
                "Content-Disposition": f"attachment; filename=speech.{req.response_format}",
                "Cache-Control": "no-cache",
            }
        )
        
    except Exception as e:
        import traceback
        error_msg = f"Voice synthesis failed: {str(e)}"
        print(f"❌ API: {error_msg}")
        print(f"🔍 Full traceback:")
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"success": False, "error": error_msg}
        )

def parse_clone_form(
    text: str = Form(...),
    reference_audio: Optional[str] = Form(None),
    reference_text: Optional[str] = Form(None),
    pitch: Optional[Literal["very_low", "low", "moderate", "high", "very_high"]] = Form(None),
    speed: Optional[Literal["very_low", "low", "moderate", "high", "very_high"]] = Form(None),
    temperature: float = Form(0.9),
    top_k: int = Form(50),
    top_p: float = Form(0.95),
    repetition_penalty: float = Form(1.0),
    max_tokens: int = Form(4096),
    length_threshold: int = Form(50),
    window_size: int = Form(50),
    stream: bool = Form(False),
    response_format: Literal["mp3", "opus", "aac", "flac", "wav", "pcm"] = Form("mp3"),
    emotion_text: Optional[str] = Form(""),
    emotion_weight: float = Form(0.6),
    diffusion_steps: int = Form(10),
    max_text_tokens_per_sentence: int = Form(120),
):
    return CloneRequest(
        text=text, reference_audio=reference_audio, reference_text=reference_text,
        pitch=pitch, speed=speed, temperature=temperature, top_k=top_k, top_p=top_p,
        repetition_penalty=repetition_penalty, max_tokens=max_tokens,
        length_threshold=length_threshold, window_size=window_size,
        stream=stream, response_format=response_format,
        emotion_text=emotion_text, emotion_weight=emotion_weight,
        diffusion_steps=diffusion_steps, max_text_tokens_per_sentence=max_text_tokens_per_sentence
    )

@app.post("/clone_voice")
async def clone_voice(
    req: CloneRequest = Depends(parse_clone_form),
    reference_audio_file: Optional[UploadFile] = File(None),
):
    """API: Clone voice using reference audio"""
    try:
        print(f"🎵 API: Cloning voice - '{req.text[:50]}...'")
        
        # Load reference audio (matching deploy_vllm_indextts.py)
        audio_io = await load_audio_bytes_from_request(reference_audio_file, req.reference_audio)
        if audio_io is None:
            return JSONResponse(
                status_code=400,
                content={"success": False, "error": "No reference audio provided"}
            )
        
        # Save reference audio to temporary file
        audio_data = audio_io.read()
        with tempfile.NamedTemporaryFile(suffix=".wav", delete=False) as tmp_file:
            tmp_path = tmp_file.name
        await async_write_file(tmp_path, audio_data)
        
        try:
            tts = tts_manager.get_tts()
            
            # Generate speech using reference audio
            output_path = os.path.join("outputs", f"clone_{uuid.uuid4().hex}.wav")
            
            # Check if emotion text is provided and not empty
            use_emotion_text = req.emotion_text and req.emotion_text.strip() != ""
            
            result = await tts.infer(
                spk_audio_prompt=tmp_path,
                text=req.text,
                output_path=output_path,
                use_emo_text=use_emotion_text,
                emo_text=req.emotion_text if use_emotion_text else None,
                emo_alpha=req.emotion_weight,
                speech_length=req.speech_length,
                diffusion_steps=req.diffusion_steps,
                max_text_tokens_per_sentence=req.max_text_tokens_per_sentence,
                verbose=cmd_args.verbose
            )
            
            # Convert to requested format and return as bytes (matching deploy_vllm_indextts.py)
            if req.response_format != "wav":
                # Read audio data once
                audio_data, sample_rate = await async_audio_read(result)
                # Convert to requested format and get bytes
                audio_bytes, media_type, _ = await convert_audio_to_format(
                    audio_data, sample_rate, req.response_format, "128k"
                )
            else:
                # Read WAV file as bytes
                audio_bytes = await async_read_file(result)
                media_type = "audio/wav"
            
            # Set content type (matching deploy_vllm_indextts.py)
            content_type_map = {
                "mp3": "audio/mpeg",
                "opus": "audio/opus",
                "aac": "audio/aac", 
                "flac": "audio/flac",
                "wav": "audio/wav",
                "pcm": "audio/pcm",
            }
            content_type = content_type_map.get(req.response_format, f"audio/{req.response_format}")
            
            print(f"✅ API: Cloned voice - {len(audio_bytes)} bytes of {req.response_format.upper()}")
            
            # Cleanup temporary file
            await async_remove_file(result)
            
            return Response(
                content=audio_bytes,
                media_type=content_type,
                headers={
                    "Content-Disposition": f"attachment; filename=speech.{req.response_format}",
                    "Cache-Control": "no-cache",
                }
            )
            
        finally:
            # Cleanup
            await async_remove_file(tmp_path)
                
    except Exception as e:
        error_msg = f"Failed to clone voice: {str(e)}"
        print(f"❌ API: {error_msg}")
        return JSONResponse(
            status_code=500,
            content={"success": False, "error": error_msg}
        )

@app.get("/server_info")
async def server_info():
    """API: Get server information"""
    try:
        if not speaker_api:
            roles = []
        else:
            speakers_data = await speaker_api.list_speakers()
            roles = list(speakers_data["speakers"].keys()) if speakers_data["status"] == "success" else []
        
        return JSONResponse(content={
            "success": True,
            "info": {
                "model": "IndexTTS-vLLM-v2",
                "roles": roles,
                "sample_rate": 22050,
                "engine": "vLLM v2",
                "chinese_support": True,
                "speaker_presets": True,
                "speaker_manager": "SpeakerPresetManager"
            }
        })
        
    except Exception as e:
        return JSONResponse(
            status_code=500,
            content={
                "success": False,
                "error": f"Failed to get server info: {str(e)}"
            }
        )

@app.post("/speak_stream")
async def speak_stream(req: SpeakRequest):
    """API: Generate speech using registered speaker with streaming"""
    from fastapi.responses import StreamingResponse
    
    try:
        print(f"🎭 API Streaming: Speaking with '{req.name}' - '{req.text[:50]}...'")
        
        if not req.name:
            return JSONResponse(
                status_code=400,
                content={"success": False, "error": "Speaker name is required"}
            )
        
        # Simple speaker validation to prevent failures
        if speaker_api and not speaker_api.speaker_exists(req.name):
            speakers_data = await speaker_api.list_speakers()
            available_roles = list(speakers_data.get("speakers", {}).keys())
            error_msg = f"'{req.name}' is not in the list of existing roles: {', '.join(available_roles)}"
            return JSONResponse(
                status_code=500,
                content={"success": False, "error": error_msg}
            )
        
        tts = tts_manager.get_tts()
        
        # Check if emotion text is provided and not empty
        use_emotion_text = req.emotion_text and req.emotion_text.strip() != ""
        
        async def audio_stream_generator():
            """Generator that yields audio chunks as they are produced"""
            try:
                chunk_count = 0
                async for chunk_idx, wav_cpu, is_last in tts.infer_stream(
                    spk_audio_prompt="",
                    text=req.text,
                    speaker_preset=req.name,
                    use_emo_text=use_emotion_text,
                    emo_text=req.emotion_text if use_emotion_text else None,
                    emo_alpha=req.emotion_weight,
                    speech_length=req.speech_length,
                    diffusion_steps=req.diffusion_steps,
                    max_text_tokens_per_sentence=req.max_text_tokens_per_sentence,
                    first_chunk_max_tokens=40,  # Default first chunk size
                    verbose=cmd_args.verbose
                ):
                    chunk_count += 1
                    print(f"🎵 Streaming chunk {chunk_idx} (is_last={is_last})")
                    
                    # Convert tensor to WAV bytes
                    wav_data = wav_cpu.numpy().astype(np.int16)
                    
                    # Create WAV file in memory
                    with BytesIO() as wav_buffer:
                        sf.write(wav_buffer, wav_data.T, 22050, format='WAV')
                        wav_bytes = wav_buffer.getvalue()
                    
                    # Convert to requested format
                    if req.response_format == "wav":
                        audio_bytes = wav_bytes
                    else:
                        audio_segment = AudioSegment.from_wav(BytesIO(wav_bytes))
                        with BytesIO() as audio_buffer:
                            audio_segment.export(audio_buffer, format=req.response_format, bitrate="128k" if req.response_format == "mp3" else None)
                            audio_bytes = audio_buffer.getvalue()
                    
                    # Yield chunk with metadata header
                    header = f"CHUNK:{chunk_idx}:{len(audio_bytes)}:{'LAST' if is_last else 'MORE'}\n".encode('utf-8')
                    yield header + audio_bytes
                
                print(f"✅ Streaming complete: {chunk_count} chunks sent")
                
            except Exception as e:
                error_msg = f"ERROR:{str(e)}\n".encode('utf-8')
                print(f"❌ Streaming error: {e}")
                traceback.print_exc()
                yield error_msg
        
        return StreamingResponse(
            audio_stream_generator(),
            media_type="application/octet-stream",
            headers={
                "Cache-Control": "no-cache",
                "X-Accel-Buffering": "no",  # Disable proxy buffering
            }
        )
        
    except Exception as e:
        import traceback
        error_msg = f"Voice synthesis streaming failed: {str(e)}"
        print(f"❌ API Streaming: {error_msg}")
        print(f"🔍 Full traceback:")
        traceback.print_exc()
        return JSONResponse(
            status_code=500,
            content={"success": False, "error": error_msg}
        )

@app.post("/clone_voice_stream")
async def clone_voice_stream(
    req: CloneRequest = Depends(parse_clone_form),
    reference_audio_file: Optional[UploadFile] = File(None),
):
    """API: Clone voice using reference audio with streaming"""
    from fastapi.responses import StreamingResponse
    
    try:
        print(f"🎵 API Streaming: Cloning voice - '{req.text[:50]}...'")
        
        # Load reference audio (matching deploy_vllm_indextts.py)
        audio_io = await load_audio_bytes_from_request(reference_audio_file, req.reference_audio)
        if audio_io is None:
            return JSONResponse(
                status_code=400,
                content={"success": False, "error": "No reference audio provided"}
            )
        
        # Save reference audio to temporary file
        audio_data = audio_io.read()
        with tempfile.NamedTemporaryFile(suffix=".wav", delete=False) as tmp_file:
            tmp_path = tmp_file.name
        await async_write_file(tmp_path, audio_data)
        
        tts = tts_manager.get_tts()
        
        # Check if emotion text is provided and not empty
        use_emotion_text = req.emotion_text and req.emotion_text.strip() != ""
        
        async def audio_stream_generator():
            """Generator that yields audio chunks as they are produced"""
            try:
                chunk_count = 0
                async for chunk_idx, wav_cpu, is_last in tts.infer_stream(
                    spk_audio_prompt=tmp_path,
                    text=req.text,
                    use_emo_text=use_emotion_text,
                    emo_text=req.emotion_text if use_emotion_text else None,
                    emo_alpha=req.emotion_weight,
                    speech_length=req.speech_length,
                    diffusion_steps=req.diffusion_steps,
                    max_text_tokens_per_sentence=req.max_text_tokens_per_sentence,
                    first_chunk_max_tokens=40,  # Default first chunk size
                    verbose=cmd_args.verbose
                ):
                    chunk_count += 1
                    print(f"🎵 Streaming chunk {chunk_idx} (is_last={is_last})")
                    
                    # Convert tensor to WAV bytes
                    wav_data = wav_cpu.numpy().astype(np.int16)
                    
                    # Create WAV file in memory
                    with BytesIO() as wav_buffer:
                        sf.write(wav_buffer, wav_data.T, 22050, format='WAV')
                        wav_bytes = wav_buffer.getvalue()
                    
                    # Convert to requested format
                    if req.response_format == "wav":
                        audio_bytes = wav_bytes
                    else:
                        audio_segment = AudioSegment.from_wav(BytesIO(wav_bytes))
                        with BytesIO() as audio_buffer:
                            audio_segment.export(audio_buffer, format=req.response_format, bitrate="128k" if req.response_format == "mp3" else None)
                            audio_bytes = audio_buffer.getvalue()
                    
                    # Yield chunk with metadata header
                    header = f"CHUNK:{chunk_idx}:{len(audio_bytes)}:{'LAST' if is_last else 'MORE'}\n".encode('utf-8')
                    yield header + audio_bytes
                
                print(f"✅ Streaming complete: {chunk_count} chunks sent")
                
            except Exception as e:
                error_msg = f"ERROR:{str(e)}\n".encode('utf-8')
                print(f"❌ Streaming error: {e}")
                traceback.print_exc()
                yield error_msg
            finally:
                # Cleanup temporary file after streaming is complete
                await async_remove_file(tmp_path)
        
        return StreamingResponse(
            audio_stream_generator(),
            media_type="application/octet-stream",
            headers={
                "Cache-Control": "no-cache",
                "X-Accel-Buffering": "no",  # Disable proxy buffering
            }
        )
                
    except Exception as e:
        error_msg = f"Failed to clone voice with streaming: {str(e)}"
        print(f"❌ API Streaming: {error_msg}")
        return JSONResponse(
            status_code=500,
            content={"success": False, "error": error_msg}
        )

if __name__ == "__main__":
    import uvicorn
    print("🚀 Starting IndexTTS vLLM v2 FastAPI WebUI...")
    print(f"📁 Model directory: {cmd_args.model_dir}")
    print(f"🔧 GPU memory utilization: {cmd_args.gpu_memory_utilization}")
    print(f"🎯 FP16 mode: {cmd_args.is_fp16}")
    print(f"🌐 Server will start on {cmd_args.host}:{cmd_args.port}")
    print(f"🎯 Concurrent capacity: 100 requests (matching Modal deployment)")
    print(f"⚡ Single worker process for optimal GPU utilization")
    print(f"💡 Features:")
    print(f"   - IndexTTS vLLM v2 backend for ultra-fast inference")
    print(f"   - Speaker preset management with persistent storage")
    print(f"   - API compatibility for external integrations")
    print(f"   - Modern web interface with Chinese support")
    print(f"   - MP3 output for smaller file sizes")
    print(f"   - High concurrency support (100 concurrent connections)")
    print(f"   - Advanced translate/edit mode with segment editing")
    print(f"   - Gemini model selection (Flash vs Pro) with API key override")
    print(f"   - Per-segment generation control for efficient processing")
    
    uvicorn.run(
        app,
        host=cmd_args.host,
        port=cmd_args.port,
        log_level="info",
        workers=1,  # Single worker to match Modal's single container
        limit_concurrency=100,  # Match Modal's max_inputs=100
        limit_max_requests=None,  # No limit on total requests
        backlog=2048,  # Handle request queue efficiently
        timeout_keep_alive=300,  # Set timeout to 300 seconds
        h11_max_incomplete_event_size=16777216,  # 16MB for large audio uploads
        access_log=True  # Enable access logging for debugging
    )
