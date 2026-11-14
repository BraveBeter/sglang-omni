# SPDX-License-Identifier: Apache-2.0
"""Minimal TTS request, public HTTP and stage-lifecycle contracts."""

import base64
import os
from pathlib import Path
from types import SimpleNamespace
from unittest.mock import Mock, patch

import httpx
import numpy as np
import pytest
import soundfile
import torch
import torchaudio
import torchaudio.compliance.kaldi as kaldi
from fastapi.testclient import TestClient
from sglang.srt.mem_cache.allocator.token import TokenToKVPoolAllocator
from typer.testing import CliRunner

from sglang_omni.cli import app
from sglang_omni.models.moss_speech.codec import MossSpeechCodec
from sglang_omni.models.moss_speech.config import MossSpeechPipelineConfig
from sglang_omni.models.moss_speech.engine_builder import MossSpeechEngineBuilder
from sglang_omni.models.moss_speech.fsm import AUDIO_PAD, MODALITY_PAD
from sglang_omni.models.moss_speech.hf_config import (
    MAX_CONTEXT_TOKENS,
    MossSpeechConfig,
)
from sglang_omni.models.moss_speech.request_builders import (
    MossSpeechState,
    RequestValidationError,
    build_result,
    build_sglang_moss_request,
    preprocess_request,
)
from sglang_omni.models.moss_speech.stages import create_audio_vocoder_executor
from sglang_omni.proto.request import OmniRequest, StagePayload
from sglang_omni.scheduling.omni_scheduler import OmniScheduler
from sglang_omni.serve.launcher import model_capabilities_log_summary
from sglang_omni.serve.openai_api import create_app
from sglang_omni.utils.audio import load_audio
from tests.unit_test.fixtures.moss_speech import (
    SpeechClient,
    TextTokenizer,
    audio_reference,
    make_codec,
)


def test_native_prompt_preserves_user_question_and_budget() -> None:
    """Questions must reach the model without an injected repetition instruction."""
    payload = StagePayload(
        "request",
        OmniRequest(
            inputs="What is the capital of France?",
            params={"seed": 19, "max_new_tokens": 32},
            metadata={"tts_params": {"ref_audio": "reference.wav"}},
        ),
        {},
    )
    prepared = preprocess_request(payload, TextTokenizer())
    state = MossSpeechState.from_dict(prepared.data)
    assert bytes(state.text_token_ids).decode() == (
        "<|im_start|>system\nYou are a helpful voice assistant. Answer the user's questions with spoken responses.<|im_end|>\n"
        "<|im_start|>user\nWhat is the capital of France?<|im_end|>\n"
        "<|im_start|>assistant\n<|object_ref_start|>"
    )
    native = build_sglang_moss_request(prepared)
    assert state.reference_audio == "reference.wav"
    assert native.effective_seed == 19 and native.max_new_tokens == 32
    assert native.prompt_rows[:, 0].tolist() == state.text_token_ids
    assert native.prompt_rows[:, 1].tolist() == [AUDIO_PAD] * state.prompt_token_count
    assert native.req.sampling_params.max_new_tokens == 32


def test_remaining_context_and_explicit_budget_boundary() -> None:
    payload = StagePayload(
        "boundary",
        OmniRequest(
            inputs="x",
            params={},
            metadata={"tts_params": {"ref_audio": "reference.wav"}},
        ),
        {},
    )
    overhead = (
        MossSpeechState.from_dict(
            preprocess_request(payload, TextTokenizer()).data
        ).prompt_token_count
        - 1
    )
    payload.request.inputs = "x" * (MAX_CONTEXT_TOKENS - overhead - 1)
    prepared = preprocess_request(payload, TextTokenizer())
    assert build_sglang_moss_request(prepared).max_new_tokens == 1
    payload.request.params["max_new_tokens"] = 2
    with pytest.raises(RequestValidationError, match="budget"):
        preprocess_request(payload, TextTokenizer())
    payload.request.params.clear()
    payload.request.inputs += "x"
    with pytest.raises(RequestValidationError, match="budget"):
        preprocess_request(payload, TextTokenizer())


@pytest.mark.parametrize(
    "options",
    [
        {"stream": True},
        {"min_p": 0.2},
        {"stop": ["stop"]},
        {"top_k": -2},
        {"temperature": float("nan")},
        {"seed": 2**64},
        {"stage_params": {"ar_engine": {}}},
    ],
)
def test_unsupported_sampling_fails_before_generation(
    options: dict[str, object]
) -> None:
    with pytest.raises(RequestValidationError):
        preprocess_request(
            StagePayload(
                "invalid",
                OmniRequest(
                    inputs="Hello",
                    params=options,
                    metadata={"tts_params": {"ref_audio": "reference.wav"}},
                ),
                {},
            ),
            TextTokenizer(),
        )


@pytest.mark.parametrize(
    "body",
    [
        {"input": "Hello", "stream": True},
        {"input": "Hello", "voice": "other"},
        {"input": "Hello", "instructions": "whisper"},
        {"input": "Hello", "max_new_tokens": 1},
    ],
)
def test_http_rejects_unsupported_or_empty_audio_without_server_error(
    body: dict[str, object]
) -> None:
    with TestClient(
        create_app(SpeechClient(make_codec()), model_name="moss-speech")
    ) as http:
        response = http.post(
            "/v1/audio/speech", json={"ref_audio": audio_reference(), **body}
        )
        assert response.status_code == 400, response.text


@pytest.mark.parametrize(
    "reference_audio",
    [None, "", "data:audio/wav;base64,YmFk", audio_reference(sample_count=1)],
)
def test_http_rejects_missing_or_invalid_reference_audio(
    reference_audio: str | None,
) -> None:
    with TestClient(
        create_app(SpeechClient(make_codec()), model_name="moss-speech")
    ) as http:
        response = http.post(
            "/v1/audio/speech",
            json={"input": "Hello", "max_new_tokens": 3, "ref_audio": reference_audio},
        )
        assert response.status_code == 400, response.text


def test_http_reference_audio_changes_per_request_without_restarting_codec() -> None:
    codec = make_codec()
    with TestClient(create_app(SpeechClient(codec), model_name="moss-speech")) as http:
        responses = [
            http.post(
                "/v1/audio/speech",
                json={
                    "input": "Hello",
                    "ref_audio": reference,
                    "max_new_tokens": 3,
                    "seed": 7,
                },
            )
            for reference in (
                audio_reference(220),
                audio_reference(880),
                audio_reference(220),
            )
        ]
        assert all(response.status_code == 200 for response in responses)
        assert responses[0].content == responses[2].content
        assert responses[0].content != responses[1].content


def test_native_reference_descriptor_survives_result_adapter() -> None:
    reference = audio_reference()
    prepared = preprocess_request(
        StagePayload(
            "reference",
            OmniRequest(
                inputs={
                    "text": "Hello",
                    "references": [
                        {"media_type": "audio/wav", "data": reference.split(",", 1)[1]}
                    ],
                }
            ),
            {},
        ),
        TextTokenizer(),
    )
    native = build_sglang_moss_request(prepared)
    native.output_rows = [(MODALITY_PAD, 3)]
    assert (
        MossSpeechState.from_dict(build_result(native).data).reference_audio
        == reference
    )


def test_codec_preserves_usage_rng_and_releases_models() -> None:
    codec = make_codec()
    state = MossSpeechState(
        reference_audio=audio_reference(),
        audio_codes=[3, 4],
        prompt_token_count=12,
        completion_token_count=3,
        effective_seed=7,
        finish_reason="length",
    )
    payload = StagePayload("codec", OmniRequest(inputs="Hello"), state.to_dict())
    generator_state = torch.get_rng_state().clone()
    first, second = codec.decode(payload), codec.decode(payload)
    assert first.data == second.data
    assert first.data["usage"] == {
        "prompt_tokens": 12,
        "completion_tokens": 3,
        "total_tokens": 15,
    }
    assert (
        first.data["sample_rate"] == 24000 and first.data["finish_reason"] == "length"
    )
    assert torch.equal(torch.get_rng_state(), generator_state)
    codec.close()
    assert codec.decoder is None and codec.encoder is None


@pytest.mark.accelerator
@pytest.mark.parametrize("flow_dtype", [torch.float32, torch.bfloat16])
def test_real_codec_keeps_flow_precision_and_request_rng(
    flow_dtype: torch.dtype,
) -> None:
    """The default FP32 time grid must not promote the BF16 Euler state."""
    codec_path = os.environ.get("MOSS_SPEECH_CODEC_PATH")
    reference_path = os.environ.get("MOSS_SPEECH_REFERENCE_AUDIO")
    if not torch.cuda.is_available() or not codec_path or not reference_path:
        pytest.skip("Requires CUDA and local codec/reference assets")
    else:
        pass
    codec = MossSpeechCodec(codec_path, torch.device("cuda"), flow_dtype=flow_dtype)
    assert codec.decoder is not None
    waveform, sample_rate = torchaudio.load(reference_path)
    codes = codec.encode_tokens(waveform, sample_rate).cpu().tolist()
    state = MossSpeechState(
        reference_audio=reference_path,
        audio_codes=codes,
        effective_seed=42,
        output_modality="audio",
    )
    payload = StagePayload("precision", OmniRequest(inputs="Hello"), state.to_dict())
    estimator = (
        codec.decoder.flow.decoder.decoder.estimator
        if flow_dtype is torch.bfloat16
        else codec.decoder.flow.decoder.estimator
    )
    observed_dtypes: list[tuple[torch.dtype, ...]] = []

    def record_dtypes(
        module: torch.nn.Module, inputs: tuple[torch.Tensor, ...]
    ) -> None:
        observed_dtypes.append(tuple(tensor.dtype for tensor in inputs[:6]))

    hook = estimator.register_forward_pre_hook(record_dtypes)
    cpu_rng = torch.get_rng_state().clone()
    cuda_rng = torch.cuda.get_rng_state().clone()
    first, second = codec.decode(payload), codec.decode(payload)
    hook.remove()
    assert first.data == second.data
    assert torch.equal(cpu_rng, torch.get_rng_state())
    assert torch.equal(cuda_rng, torch.cuda.get_rng_state())
    assert len(observed_dtypes) == 20
    assert all(dtypes == (flow_dtype,) * 6 for dtypes in observed_dtypes)
    assert all(
        parameter.dtype is flow_dtype for parameter in codec.decoder.flow.parameters()
    )
    assert all(
        parameter.dtype is torch.float32
        for parameter in codec.decoder.hift.parameters()
    )
    assert all(
        parameter.dtype is torch.float32 for parameter in codec.encoder.parameters()
    )
    assert torch.isfinite(torch.tensor(first.data["audio_data"])).all()
    codec.close()
    assert codec.decoder is None and codec.encoder is None


@pytest.mark.parametrize("sample_rate", [16000, 24000, 44100, 48000])
@pytest.mark.parametrize("transport", ["path", "file-uri", "data-uri", "https"])
def test_conditioning_uses_independent_token_and_speaker_resampling(
    tmp_path: Path, sample_rate: int, transport: str
) -> None:
    """Token conditioning must resample the original audio directly to 16 kHz."""
    seconds = np.arange(sample_rate // 3) / sample_rate
    samples = 0.1 * np.sin(2 * np.pi * 7311 * seconds)
    path = tmp_path / "reference voice.wav"
    soundfile.write(path, samples, sample_rate, subtype="PCM_16")
    sources = {
        "path": str(path),
        "file-uri": path.as_uri(),
        "data-uri": "data:audio/wav;base64,"
        + base64.b64encode(path.read_bytes()).decode(),
        "https": "https://voice.example/reference.wav",
    }
    waveform, _ = torchaudio.load(path)
    expected_token_waveform = torchaudio.transforms.Resample(sample_rate, 16000)(
        waveform
    )
    expected_mel_waveform = torchaudio.transforms.Resample(sample_rate, 24000)(waveform)
    expected_speaker_waveform = torchaudio.transforms.Resample(24000, 16000)(
        expected_mel_waveform
    )
    codec = make_codec()
    codec.feature_extractor = Mock(wraps=codec.feature_extractor)
    codec.feature_extractor.hop_length = 160
    codec.feature_extractor.sampling_rate = 16000
    expected_mel = codec.decoder.feat_extractor(expected_mel_waveform)
    expected_speaker_mel = kaldi.fbank(
        expected_speaker_waveform,
        num_mel_bins=80,
        dither=0,
        sample_frequency=16000,
    )
    expected_speaker_mel -= expected_speaker_mel.mean(dim=0, keepdim=True)
    response = httpx.Response(
        200, content=path.read_bytes(), request=httpx.Request("GET", sources["https"])
    )
    with patch("sglang_omni.utils.audio.httpx.get", return_value=response):
        conditioning = codec.encode_reference(sources[transport])
    np.testing.assert_array_equal(
        codec.feature_extractor.call_args.args[0][0], expected_token_waveform[0].numpy()
    )
    expected_mel = expected_mel.transpose(1, 2)
    assert torch.equal(
        conditioning["prompt_feat"],
        expected_mel[:, : conditioning["prompt_feat"].shape[1]],
    )
    np.testing.assert_array_equal(
        codec.decoder.campplus_session.run.call_args.args[1]["speech"],
        expected_speaker_mel.unsqueeze(0).numpy(),
    )


def test_stereo_reference_downmix_preserves_native_sample_rate(tmp_path: Path) -> None:
    samples = np.random.default_rng(42).uniform(-0.2, 0.2, (4410, 2)).astype(np.float32)
    path = tmp_path / "stereo.wav"
    soundfile.write(path, samples, 44100, subtype="FLOAT")
    waveform, sample_rate = load_audio(str(path), preserve_sample_rate=True)
    assert sample_rate == 44100
    np.testing.assert_array_equal(waveform, torch.from_numpy(samples.T).mean(dim=0))


@pytest.mark.parametrize("sample_count", [1, 31 * 24000])
def test_reference_duration_is_validated(tmp_path: Path, sample_count: int) -> None:
    path = tmp_path / "invalid-duration.wav"
    soundfile.write(path, np.zeros(sample_count), 24000)
    with pytest.raises(RequestValidationError):
        make_codec().encode_reference(str(path))


def test_nonfinite_reference_is_rejected(tmp_path: Path) -> None:
    path = tmp_path / "nonfinite.wav"
    soundfile.write(path, np.full(24000, np.nan), 24000, subtype="FLOAT")
    with pytest.raises(RequestValidationError, match="finite"):
        make_codec().encode_reference(str(path))


def test_cli_binds_only_three_stages_and_vocoder_assets(tmp_path: Path) -> None:
    MossSpeechConfig(
        audio_vocab_size=16512, architectures=["MossSpeechForCausalLM"]
    ).to_json_file(tmp_path / "config.json")
    with patch("sglang_omni.cli.serve.launch_server") as launch:
        result = CliRunner().invoke(
            app,
            [
                "serve",
                "--model-path",
                str(tmp_path),
                "--audio_vocoder.factory.codec_path",
                "codec",
            ],
        )
        assert result.exit_code == 0, result.output + repr(result.exception)
        config = launch.call_args.args[0]
        assert isinstance(config, MossSpeechPipelineConfig)
        assert model_capabilities_log_summary(config)["reference_audio"] is True
        assert [stage.name for stage in config.stages] == [
            "preprocessing",
            "ar_engine",
            "audio_vocoder",
        ]
        assert config.stage_named("audio_vocoder").factory.codec_path == "codec"
    with pytest.raises(ValueError, match="codec_path"):
        create_audio_vocoder_executor(
            model_path="unused", codec_path=None, flow_dtype="float32", device="cpu"
        )


@pytest.mark.parametrize("prompt_tokens,budget", [(40959, 1), (39960, 1000)])
def test_full_context_survives_scheduler_admission(
    prompt_tokens: int, budget: int
) -> None:
    scheduler = object.__new__(OmniScheduler)
    scheduler.model_config = SimpleNamespace(context_len=40960)
    scheduler.max_total_num_tokens = 40962
    scheduler.model_runner = Mock()
    scheduler.kv_shard_widening = scheduler.page_size = 1
    scheduler.max_new_tokens_limit = scheduler.sliding_window_size = (
        scheduler.draft_worker
    ) = None
    scheduler.chunked_prefill_size = -1
    scheduler.token_to_kv_pool_allocator = TokenToKVPoolAllocator(
        size=40962, dtype=torch.bfloat16, device="cpu", kvcache=None, need_sort=False
    )
    MossSpeechEngineBuilder().post_scheduler_setup(scheduler, scheduler.model_runner)
    state = MossSpeechState(text_token_ids=[12] * prompt_tokens, max_new_tokens=budget)
    request = build_sglang_moss_request(
        StagePayload("window", OmniRequest(inputs="Hello"), state.to_dict())
    )
    assert scheduler.prepare_request_limits(request) is None
    assert (
        request.req.sampling_params.max_new_tokens == request.max_new_tokens == budget
    )
    assert scheduler.request_kv_capacity_error(request.req) is None


@pytest.mark.parametrize("dtype", ["bfloat16", "bf16"])
def test_engine_accepts_bf16_spellings(dtype: str) -> None:
    builder = MossSpeechEngineBuilder()
    builder.server_args_overrides = {"max_running_requests": 4}
    overrides = {"dtype": dtype}
    builder.adjust_overrides(overrides)
    assert overrides["dtype"] == "bfloat16"
    with pytest.raises(ValueError, match="rejects dtype"):
        builder.adjust_overrides({"dtype": "float16"})
