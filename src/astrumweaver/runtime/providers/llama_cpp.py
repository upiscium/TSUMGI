"""First-class llama.cpp RuntimeProvider."""

from __future__ import annotations

import asyncio
import contextlib
import json
import os
import hashlib
import stat
from collections.abc import AsyncIterator, Mapping
from dataclasses import dataclass
from enum import StrEnum
from pathlib import Path
from typing import Any, Protocol, runtime_checkable
from urllib.parse import urlsplit

import httpx

from ...execution import (
    JobEvent,
    JobEventSink,
    JobExecutionError,
    JobExecutor,
    JobRequest,
    JobResult,
    ResidencyItem,
    ResidencyReport,
)
from ...gateway.chat import (
    CHAT_JOB_SCHEMA,
    LLAMA_CPP_CHAT_ADAPTER,
    ChatGatewayError,
    validate_chat_stream_chunk,
)
from ...gateway.embedding import (
    EMBEDDING_JOB_SCHEMA,
    LLAMA_CPP_EMBEDDING_ADAPTER,
    EmbeddingGatewayError,
    validate_embedding_response,
)
from ...gateway.decision import (
    DECISION_JOB_SCHEMA,
    LLAMA_CPP_SYSTEM_ONE_ADAPTER,
    DecisionGatewayError,
    validate_decision_provider_response,
)
from ..contracts import (
    CompatibilityReason,
    GPUTopology,
    ManagedRuntime,
    ModelPreparationPolicy,
    ModelTopology,
    ResidencyPolicy,
    RuntimeCompatibility,
    RuntimeCompatibilityContext,
    RuntimeHealth,
    RuntimeHealthState,
    RuntimeProvider,
    RuntimeProviderInfo,
    RuntimeSetupIntent,
)


LLAMA_CPP_PROVIDER_ID = "llama-cpp"
# Official opt-in scope. No other Bonsai packing is qualified in this revision.
LLAMA_CPP_BONSAI_MODEL_NAME = "Ternary-Bonsai-2-27B-PQ2_0.gguf"
LLAMA_CPP_BONSAI_MODEL_SHA256 = "3907dc1658db1f78a9826bf8d5bcb8dc65db0d466388937af57f2294fae62ec1"
LLAMA_CPP_BONSAI_MODEL_SIZE_BYTES = 7206168928
LLAMA_CPP_BONSAI_RUNTIME = "/nix/var/nix/profiles/astrumweaver-runtime-bonsai/bin/llama-server"
LLAMA_CPP_BONSAI_PACKAGE = "bonsai-llama-cpp"
# Pin the opt-in Qwen3.8 executable and its install intent as one pair.
# The absolute package reference is retained for existing operator-managed
# profiles; qwen38-llama-cpp is the CLI manager's installable selector.
LLAMA_CPP_QWEN38_PROFILE = "/nix/var/nix/profiles/astrumweaver-runtime-qwen38"
LLAMA_CPP_QWEN38_RUNTIME = LLAMA_CPP_QWEN38_PROFILE + "/bin/llama-server"
LLAMA_CPP_QWEN38_PACKAGE = "qwen38-llama-cpp"
LLAMA_CPP_STANDARD_RUNTIME = "/nix/var/nix/profiles/astrumweaver-runtime-llama-cpp/bin/llama-server"
LLAMA_CPP_CAPABILITIES = frozenset({"llm.chat", "text.generate"})
LLAMA_CPP_EMBEDDING_CAPABILITIES = frozenset({"text.embed"})
LLAMA_CPP_DECISION_CAPABILITIES = frozenset({"decision.system_one"})


def _verify_bonsai_model_bytes(model_ref: str) -> None:
    """Fail closed if the loaded PQ2_0 bytes are not the reviewed artifact.

    This is checked before each owned child launch and never relies on a
    model basename alone. The surrounding LXC is an operator-trusted scope;
    this is not a TOCTOU-proof hostile same-UID filesystem guarantee.
    """
    path = Path(model_ref)
    try:
        with path.open("rb") as handle:
            model_stat = os.fstat(handle.fileno())
            if (
                not stat.S_ISREG(model_stat.st_mode)
                or model_stat.st_size != LLAMA_CPP_BONSAI_MODEL_SIZE_BYTES
            ):
                raise RuntimeError("Bonsai 2 model size/format does not match the pinned artifact")
            digest = hashlib.sha256()
            for chunk in iter(lambda: handle.read(4 * 1024 * 1024), b""):
                digest.update(chunk)
    except OSError as exc:
        raise RuntimeError("Bonsai 2 pinned model cannot be read") from exc
    if digest.hexdigest() != LLAMA_CPP_BONSAI_MODEL_SHA256:
        raise RuntimeError("Bonsai 2 model SHA-256 does not match pinned artifact")


def _nonblank(value: str, field_name: str) -> str:
    normalized = str(value).strip()
    if not normalized:
        raise ValueError(f"{field_name} must not be blank")
    return normalized


class LlamaCppSplitMode(StrEnum):
    NONE = "none"
    LAYER = "layer"
    ROW = "row"
    TENSOR = "tensor"


@dataclass(frozen=True, slots=True)
class LlamaCppProviderConfig:
    base_url: str = "http://127.0.0.1:8080"
    executable: str = "llama-server"
    package_reference: str = "llama-cpp"
    startup_timeout_seconds: float = 120.0
    request_timeout_seconds: float = 300.0
    context_size: int = 4096
    gpu_layers: int | str | None = None
    split_mode: LlamaCppSplitMode | None = None
    tensor_split: tuple[float, ...] | None = None
    main_gpu: int = 0
    fit: bool | None = None
    fit_target_mb: tuple[int, ...] | None = None
    cpu_moe: bool = False
    n_cpu_moe: int | None = None
    n_cpu_ffn: int | None = None
    offline: bool = True
    no_webui: bool = True
    jinja: bool = False
    chat_template_file: str | None = None
    embeddings: bool = False
    pooling: str | None = None
    decision: bool = False
    # upstream is unchanged; Bonsai 2 is a separate, pinned Nix binary flavor.
    runtime_flavor: str = "upstream"

    def __post_init__(self) -> None:
        base_url = _nonblank(self.base_url, "base_url").rstrip("/")
        parsed = urlsplit(base_url)
        if (
            parsed.scheme != "http"
            or parsed.hostname not in {"127.0.0.1", "localhost"}
            or parsed.port is None
        ):
            raise ValueError(
                "llama.cpp provider requires a local loopback HTTP endpoint with port"
            )
        object.__setattr__(self, "base_url", base_url)
        object.__setattr__(
            self,
            "executable",
            _nonblank(self.executable, "executable"),
        )
        object.__setattr__(
            self,
            "package_reference",
            _nonblank(self.package_reference, "package_reference"),
        )
        if self.startup_timeout_seconds <= 0:
            raise ValueError("startup_timeout_seconds must be positive")
        if self.request_timeout_seconds <= 0:
            raise ValueError("request_timeout_seconds must be positive")
        if self.context_size < 0:
            raise ValueError("context_size must not be negative")
        if self.main_gpu < 0:
            raise ValueError("main_gpu must not be negative")
        if type(self.jinja) is not bool:
            raise TypeError("jinja must be boolean")
        if type(self.embeddings) is not bool:
            raise TypeError("embeddings must be boolean")
        if type(self.decision) is not bool:
            raise TypeError("decision must be boolean")
        if self.embeddings and self.decision:
            raise ValueError(
                "llama.cpp deployment cannot mix embedding and decision modes"
            )
        if self.decision and (self.jinja or self.chat_template_file is not None):
            raise ValueError(
                "decision mode cannot enable chat templates"
            )
        if self.embeddings:
            if self.jinja or self.chat_template_file is not None:
                raise ValueError(
                    "embedding mode cannot enable chat templates"
                )
            pooling = _nonblank(self.pooling or "", "pooling")
            if pooling not in {"mean", "cls", "last"}:
                raise ValueError(
                    "embedding mode pooling must be mean, cls, or last"
                )
            object.__setattr__(self, "pooling", pooling)
        elif self.pooling is not None:
            raise ValueError("pooling requires embeddings=true")
        if self.chat_template_file is not None:
            template = _nonblank(
                self.chat_template_file,
                "chat_template_file",
            )
            if not self.jinja:
                raise ValueError(
                    "chat_template_file requires jinja=true"
                )
            object.__setattr__(self, "chat_template_file", template)

        if self.gpu_layers is not None:
            value = self.gpu_layers
            if isinstance(value, bool):
                raise TypeError("gpu_layers must be int, auto, all, or None")
            if isinstance(value, int):
                if value < 0:
                    raise ValueError("gpu_layers must not be negative")
            elif str(value) not in {"auto", "all"}:
                raise ValueError("gpu_layers must be int, auto, all, or None")

        if self.split_mode is not None:
            object.__setattr__(
                self,
                "split_mode",
                LlamaCppSplitMode(self.split_mode),
            )

        if self.tensor_split is not None:
            tensor_split = tuple(float(value) for value in self.tensor_split)
            if not tensor_split or any(value <= 0 for value in tensor_split):
                raise ValueError("tensor_split values must be positive")
            object.__setattr__(self, "tensor_split", tensor_split)

        if self.fit_target_mb is not None:
            targets = tuple(int(value) for value in self.fit_target_mb)
            if not targets or any(value < 0 for value in targets):
                raise ValueError("fit_target_mb values must be non-negative")
            object.__setattr__(self, "fit_target_mb", targets)

        for field_name in ("n_cpu_moe", "n_cpu_ffn"):
            value = getattr(self, field_name)
            if value is not None and value < 0:
                raise ValueError(f"{field_name} must not be negative")

        if self.runtime_flavor not in {"upstream", "bonsai2-pq2"}:
            raise ValueError("unsupported llama.cpp runtime_flavor")
        if self.runtime_flavor == "bonsai2-pq2":
            if self.executable not in {
                "llama-server",
                LLAMA_CPP_STANDARD_RUNTIME,
                LLAMA_CPP_BONSAI_RUNTIME,
            }:
                raise ValueError("Bonsai 2 requires the pinned Nix runtime executable")
            if self.package_reference not in {"llama-cpp", LLAMA_CPP_BONSAI_PACKAGE}:
                raise ValueError("Bonsai 2 requires the pinned Nix runtime package")
            object.__setattr__(self, "executable", LLAMA_CPP_BONSAI_RUNTIME)
            object.__setattr__(self, "package_reference", LLAMA_CPP_BONSAI_PACKAGE)
            # Real OpenCode structured tools rely on llama.cpp Jinja templates.
            object.__setattr__(self, "jinja", True)
            if self.embeddings or self.decision:
                raise ValueError("Bonsai 2 is qualified for Chat/Tool Call only")
            if self.context_size < 8192:
                object.__setattr__(self, "context_size", 8192)
        elif (
            self.executable == LLAMA_CPP_BONSAI_RUNTIME
            or self.package_reference == LLAMA_CPP_BONSAI_PACKAGE
        ):
            raise ValueError("upstream llama.cpp cannot use the pinned Bonsai runtime")

        # Keep unmodified generic upstream configurations working; only the
        # dedicated opt-in Qwen3.8 runtime is required to bind its executable
        # and package/profile provenance, including the pre-existing site
        # format that references the absolute managed Nix profile.
        qwen38_executable = self.executable == LLAMA_CPP_QWEN38_RUNTIME
        qwen38_package = self.package_reference in {
            LLAMA_CPP_QWEN38_PACKAGE, LLAMA_CPP_QWEN38_PROFILE
        }
        if qwen38_executable != qwen38_package:
            raise ValueError(
                "Qwen3.8 pinned runtime requires matching executable and package reference"
            )


@dataclass(frozen=True, slots=True)
class LlamaCppLaunchPolicy:
    gpu_layers: int | str
    split_mode: LlamaCppSplitMode
    fit: bool
    tensor_split: tuple[float, ...] | None
    fit_target_mb: tuple[int, ...] | None
    main_gpu: int
    cpu_moe: bool
    n_cpu_moe: int | None
    n_cpu_ffn: int | None


def _launch_policy(
    context: RuntimeCompatibilityContext,
    config: LlamaCppProviderConfig,
) -> LlamaCppLaunchPolicy:
    demand = context.demand
    gpu_count = context.worker.resources.gpu_count

    gpu_layers: int | str
    if config.gpu_layers is not None:
        gpu_layers = config.gpu_layers
    elif demand.residency_policy is ResidencyPolicy.VRAM_ONLY:
        gpu_layers = "all"
    else:
        gpu_layers = "auto"

    if config.split_mode is not None:
        split_mode = config.split_mode
    elif demand.gpu_topology is GPUTopology.MULTI_GPU:
        split_mode = LlamaCppSplitMode.LAYER
    else:
        split_mode = LlamaCppSplitMode.NONE

    fit = (
        config.fit
        if config.fit is not None
        else demand.residency_policy is not ResidencyPolicy.VRAM_ONLY
    )

    if gpu_count == 0:
        split_mode = LlamaCppSplitMode.NONE
        gpu_layers = 0
        fit = False

    return LlamaCppLaunchPolicy(
        gpu_layers=gpu_layers,
        split_mode=split_mode,
        fit=fit,
        tensor_split=config.tensor_split,
        fit_target_mb=config.fit_target_mb,
        main_gpu=config.main_gpu,
        cpu_moe=config.cpu_moe,
        n_cpu_moe=config.n_cpu_moe,
        n_cpu_ffn=config.n_cpu_ffn,
    )


@runtime_checkable
class LlamaCppApi(Protocol):
    async def health(self) -> bool: ...

    async def models(self) -> tuple[str, ...]: ...

    async def chat(self, payload: Mapping[str, Any]) -> Mapping[str, Any]: ...

    def chat_stream(
        self,
        payload: Mapping[str, Any],
    ) -> AsyncIterator[Mapping[str, Any]]: ...

    async def chat_input_tokens(self, payload: Mapping[str, Any]) -> int: ...

    async def completion(self, payload: Mapping[str, Any]) -> Mapping[str, Any]: ...

    async def embeddings(self, payload: Mapping[str, Any]) -> Mapping[str, Any]: ...

    async def system_one(self, payload: Mapping[str, Any]) -> Mapping[str, Any]: ...

    async def decision_capable(self, model_id: str) -> bool: ...

    async def tokenize(self, content: str) -> int: ...

    async def close(self) -> None: ...


class HttpLlamaCppApi:
    def __init__(
        self,
        base_url: str,
        *,
        timeout_seconds: float = 300.0,
        transport: httpx.AsyncBaseTransport | None = None,
        api_key: str | None = None,
        unix_socket_path: str | None = None,
    ) -> None:
        if api_key is not None and (not isinstance(api_key, str) or not api_key):
            raise ValueError("llama.cpp client API key must be nonempty")
        if unix_socket_path is not None:
            if (
                not Path(unix_socket_path).is_absolute()
                or not unix_socket_path.endswith(".sock")
                or api_key is None
                or transport is not None
            ):
                raise ValueError("private Unix socket requires absolute .sock path and an owned bearer")
            # A Worker-private UDS transport has no attacker-raceable TCP port.
            # It is protected by the owning temporary directory's mode 0700.
            transport = httpx.AsyncHTTPTransport(uds=unix_socket_path)
        self._client = httpx.AsyncClient(
            base_url=base_url.rstrip("/"),
            timeout=timeout_seconds,
            transport=transport,
            headers=(None if api_key is None else {"Authorization": "Bearer " + api_key}),
            # The composite native child uses a secret bearer. Never allow
            # inherited HTTP_PROXY/HTTPS_PROXY/ALL_PROXY to receive that secret
            # or unredacted inference traffic. Preserve unauthenticated legacy
            # clients' existing environment-proxy behavior.
            trust_env=api_key is None,
            follow_redirects=False,
        )

    async def health(self) -> bool:
        try:
            response = await self._client.get("/health")
        except httpx.HTTPError:
            return False
        return response.status_code == 200

    async def _json(
        self,
        method: str,
        path: str,
        *,
        json: Mapping[str, Any] | None = None,
    ) -> Mapping[str, Any]:
        kwargs = {} if json is None else {"json": json}
        response = await self._client.request(method, path, **kwargs)
        response.raise_for_status()
        body = response.json()
        if not isinstance(body, Mapping):
            raise RuntimeError("llama.cpp server returned a non-object response")
        return body

    async def models(self) -> tuple[str, ...]:
        body = await self._json("GET", "/v1/models")
        data = body.get("data", ())
        if not isinstance(data, list):
            raise RuntimeError("llama.cpp /v1/models returned invalid data")
        result: list[str] = []
        for item in data:
            if not isinstance(item, Mapping):
                continue
            model_id = item.get("id")
            if isinstance(model_id, str) and model_id.strip():
                result.append(model_id.strip())
        return tuple(result)

    async def chat(self, payload: Mapping[str, Any]) -> Mapping[str, Any]:
        return await self._json(
            "POST",
            "/v1/chat/completions",
            json=payload,
        )

    async def chat_stream(
        self,
        payload: Mapping[str, Any],
    ) -> AsyncIterator[Mapping[str, Any]]:
        async with self._client.stream(
            "POST",
            "/v1/chat/completions",
            json=dict(payload),
        ) as response:
            response.raise_for_status()
            async for raw_line in response.aiter_lines():
                line = raw_line.strip()
                if not line or line.startswith(":"):
                    continue
                if not line.startswith("data:"):
                    raise RuntimeError("llama.cpp stream returned invalid SSE framing")
                data = line[5:].strip()
                if data == "[DONE]":
                    return
                try:
                    value = json.loads(data)
                except json.JSONDecodeError as exc:
                    raise RuntimeError(
                        "llama.cpp stream returned invalid JSON"
                    ) from exc
                if not isinstance(value, Mapping):
                    raise RuntimeError(
                        "llama.cpp stream returned a non-object event"
                    )
                yield value

    async def chat_input_tokens(self, payload: Mapping[str, Any]) -> int:
        body = await self._json(
            "POST",
            "/v1/chat/completions/input_tokens",
            json=payload,
        )
        value = body.get("input_tokens")
        if isinstance(value, bool) or not isinstance(value, int) or value < 0:
            raise RuntimeError(
                "llama.cpp token-count endpoint returned invalid input_tokens"
            )
        return value

    async def completion(self, payload: Mapping[str, Any]) -> Mapping[str, Any]:
        return await self._json(
            "POST",
            "/v1/completions",
            json=payload,
        )

    async def embeddings(
        self,
        payload: Mapping[str, Any],
    ) -> Mapping[str, Any]:
        return await self._json(
            "POST",
            "/v1/embeddings",
            json=payload,
        )

    async def system_one(
        self,
        payload: Mapping[str, Any],
    ) -> Mapping[str, Any]:
        return await self._json(
            "POST",
            "/v1/systemone",
            json=payload,
        )

    async def decision_capable(self, model_id: str) -> bool:
        body = await self._json("GET", "/v1/models")
        data = body.get("data", ())
        if not isinstance(data, list):
            raise RuntimeError("llama.cpp /v1/models returned invalid data")
        for item in data:
            if not isinstance(item, Mapping) or item.get("id") != model_id:
                continue
            architecture = item.get("architecture")
            if not isinstance(architecture, Mapping):
                return False
            outputs = architecture.get("output_modalities")
            return (
                isinstance(outputs, list)
                and all(isinstance(value, str) for value in outputs)
                and "decisions" in outputs
            )
        return False

    async def tokenize(self, content: str) -> int:
        body = await self._json(
            "POST",
            "/tokenize",
            json={"content": content, "add_special": False},
        )
        tokens = body.get("tokens")
        if not isinstance(tokens, list) or any(
            isinstance(token, bool) or not isinstance(token, int)
            for token in tokens
        ):
            raise RuntimeError(
                "llama.cpp tokenize endpoint returned invalid tokens"
            )
        return len(tokens)

    async def close(self) -> None:
        await self._client.aclose()


@runtime_checkable
class LlamaCppProcessController(Protocol):
    @property
    def running(self) -> bool: ...

    async def start(self) -> None: ...

    async def stop(self) -> None: ...


class LlamaCppSubprocessController:
    def __init__(
        self,
        *,
        executable: str,
        base_url: str,
        model_ref: str,
        model_alias: str,
        gpu_uuids: tuple[str, ...],
        context_size: int,
        launch_policy: LlamaCppLaunchPolicy,
        offline: bool,
        no_webui: bool,
        jinja: bool = False,
        chat_template_file: str | None = None,
        embeddings: bool = False,
        pooling: str | None = None,
        api_key_file: str | None = None,
        unix_socket_path: str | None = None,
        reasoning_off: bool = False,
        flash_attn: bool = False,
    ) -> None:
        if api_key_file is not None and not Path(api_key_file).is_absolute():
            raise ValueError("llama.cpp API-key file must be absolute")
        if unix_socket_path is not None and (
            not Path(unix_socket_path).is_absolute()
            or not unix_socket_path.endswith(".sock")
            or api_key_file is None
        ):
            raise ValueError("private native Unix socket requires owned absolute path and key file")
        self.api_key_file = api_key_file
        self.unix_socket_path = unix_socket_path
        self.executable = executable
        self.base_url = base_url
        self.model_ref = model_ref
        self.model_alias = model_alias
        self.gpu_uuids = gpu_uuids
        self.context_size = context_size
        self.launch_policy = launch_policy
        self.offline = offline
        self.no_webui = no_webui
        self.jinja = jinja
        self.chat_template_file = chat_template_file
        self.embeddings = embeddings
        self.pooling = pooling
        self.reasoning_off = reasoning_off
        self.flash_attn = flash_attn
        self._process: asyncio.subprocess.Process | None = None

    @property
    def running(self) -> bool:
        return self._process is not None and self._process.returncode is None

    def command(self) -> tuple[str, ...]:
        parsed = urlsplit(self.base_url)
        assert parsed.hostname is not None
        assert parsed.port is not None

        # A composite runtime binds a random, Worker-owned Unix-domain socket
        # inside its private 0700 directory. It must NOT listen on the public
        # loopback port carried in the backwards-compatible base_url manifest.
        listen_args = (
            ["--host", self.unix_socket_path]
            if self.unix_socket_path is not None
            else ["--host", parsed.hostname, "--port", str(parsed.port)]
        )
        args: list[str] = [
            self.executable,
            *listen_args,
            "--model",
            self.model_ref,
            "--alias",
            self.model_alias,
            "--parallel",
            "1",
            "--ctx-size",
            str(self.context_size),
            "--n-gpu-layers",
            str(self.launch_policy.gpu_layers),
            "--fit",
            "on" if self.launch_policy.fit else "off",
        ]
        if self.no_webui:
            args.append("--no-webui")
        if self.offline:
            args.append("--offline")
        if self.api_key_file is not None:
            args.extend(["--api-key-file", self.api_key_file])
        if self.jinja:
            args.append("--jinja")
        if self.reasoning_off:
            args.extend(["--reasoning", "off"])
        if self.flash_attn:
            args.extend(["--flash-attn", "on"])
        if self.chat_template_file is not None:
            args.extend(
                ["--chat-template-file", self.chat_template_file]
            )
        if self.embeddings:
            args.append("--embeddings")
            if self.pooling is None:
                raise RuntimeError(
                    "embedding-mode llama.cpp process requires pooling"
                )
            args.extend(["--pooling", self.pooling])

        if self.gpu_uuids:
            visible = [f"CUDA{index}" for index in range(len(self.gpu_uuids))]
            args.extend(["--device", ",".join(visible)])
            args.extend(
                ["--split-mode", self.launch_policy.split_mode.value]
            )
            if self.launch_policy.split_mode in {
                LlamaCppSplitMode.NONE,
                LlamaCppSplitMode.ROW,
            }:
                args.extend(
                    ["--main-gpu", str(self.launch_policy.main_gpu)]
                )
            if self.launch_policy.tensor_split is not None:
                args.extend(
                    [
                        "--tensor-split",
                        ",".join(
                            str(value)
                            for value in self.launch_policy.tensor_split
                        ),
                    ]
                )
            if self.launch_policy.fit_target_mb is not None:
                args.extend(
                    [
                        "--fit-target",
                        ",".join(
                            str(value)
                            for value in self.launch_policy.fit_target_mb
                        ),
                    ]
                )

        if self.launch_policy.cpu_moe:
            args.append("--cpu-moe")
        if self.launch_policy.n_cpu_moe is not None:
            args.extend(
                ["--n-cpu-moe", str(self.launch_policy.n_cpu_moe)]
            )
        if self.launch_policy.n_cpu_ffn is not None:
            args.extend(
                ["--n-cpu-ffn", str(self.launch_policy.n_cpu_ffn)]
            )

        return tuple(args)

    async def start(self) -> None:
        if self.running:
            return
        env = dict(os.environ)
        if self.gpu_uuids:
            env["CUDA_VISIBLE_DEVICES"] = ",".join(self.gpu_uuids)
        try:
            self._process = await asyncio.create_subprocess_exec(
                *self.command(),
                env=env,
            )
        except OSError as exc:
            raise RuntimeError(
                "failed to start llama.cpp server process"
            ) from exc

    async def stop(self) -> None:
        process = self._process
        if process is None:
            return
        if process.returncode is None:
            process.terminate()
            try:
                await asyncio.wait_for(process.wait(), timeout=10.0)
            except asyncio.TimeoutError:
                process.kill()
                await process.wait()
        self._process = None


class LlamaCppExecutor(JobExecutor):
    capabilities = LLAMA_CPP_CAPABILITIES

    def __init__(
        self,
        *,
        api: LlamaCppApi,
        model_ref: str,
        model_alias: str,
        residency_metadata: Mapping[str, Any],
        tools_enabled: bool = False,
        embeddings: bool = False,
        pooling: str | None = None,
        decision: bool = False,
    ) -> None:
        self.api = api
        self.model_ref = _nonblank(model_ref, "model_ref")
        self.model_alias = _nonblank(model_alias, "model_alias")
        self.residency_metadata = dict(residency_metadata)
        if type(tools_enabled) is not bool:
            raise TypeError("tools_enabled must be boolean")
        if type(embeddings) is not bool:
            raise TypeError("embeddings must be boolean")
        if type(decision) is not bool:
            raise TypeError("decision must be boolean")
        if embeddings and decision:
            raise ValueError(
                "llama.cpp executor cannot mix embedding and decision modes"
            )
        if (embeddings or decision) and tools_enabled:
            raise ValueError(
                "llama.cpp specialized executor cannot enable chat tools"
            )
        if embeddings:
            normalized_pooling = _nonblank(pooling or "", "pooling")
            if normalized_pooling not in {"mean", "cls", "last"}:
                raise ValueError(
                    "embedding pooling must be mean, cls, or last"
                )
        else:
            if pooling is not None:
                raise ValueError("pooling requires embedding mode")
            normalized_pooling = None
        self.tools_enabled = tools_enabled
        self.embedding_mode = embeddings
        self.decision_mode = decision
        self.pooling = normalized_pooling
        self.capabilities = (
            LLAMA_CPP_EMBEDDING_CAPABILITIES
            if embeddings
            else LLAMA_CPP_DECISION_CAPABILITIES
            if decision
            else LLAMA_CPP_CAPABILITIES
        )
        self.serving_features = (
            {
                "text.embed": frozenset(
                    {
                        "float",
                        f"pooling-{normalized_pooling}",
                        "normalization-l2",
                    }
                )
            }
            if embeddings
            else {
                "decision.system_one": frozenset(
                    {
                        "native-decision-head",
                        "choice-probabilities",
                        "multi-token-choice-labels",
                        "provider-temperature-softmax",
                    }
                )
            }
            if decision
            else {
                "llm.chat": (
                    frozenset({"tools"})
                    if tools_enabled
                    else frozenset()
                )
            }
        )
        self._inflight: dict[str, asyncio.Task[Any]] = {}

    def _payload(self, job: JobRequest) -> dict[str, Any]:
        payload = dict(job.payload)
        supplied_model = payload.pop("model", None)
        if supplied_model is not None and str(supplied_model) not in {
            self.model_ref,
            self.model_alias,
        }:
            raise ValueError(
                "job model does not match the model bound to this llama.cpp runtime"
            )
        payload["model"] = self.model_alias
        payload["stream"] = False
        return payload

    def _gateway_chat_payload(
        self,
        job: JobRequest,
    ) -> tuple[dict[str, Any], dict[str, int]] | None:
        envelope = dict(job.payload)
        if envelope.get("schema_version") != CHAT_JOB_SCHEMA:
            return None
        if set(envelope) != {"schema_version", "adapter_id", "request", "limits"}:
            raise JobExecutionError(
                "invalid_chat_job",
                "chat job envelope uses unsupported fields",
                retryable=False,
            )
        if envelope.get("adapter_id") != LLAMA_CPP_CHAT_ADAPTER:
            raise JobExecutionError(
                "unsupported_chat_adapter",
                "chat job targets an unsupported provider adapter",
                retryable=False,
            )
        raw_request = envelope.get("request")
        raw_limits = envelope.get("limits")
        if not isinstance(raw_request, Mapping) or not isinstance(raw_limits, Mapping):
            raise JobExecutionError(
                "invalid_chat_job",
                "chat job request/limits must be objects",
                retryable=False,
            )
        request = dict(raw_request)
        if not isinstance(request.get("messages"), list):
            raise JobExecutionError(
                "invalid_chat_job",
                "chat job requires a messages array",
                retryable=False,
            )
        if type(request.get("stream")) is not bool:
            raise JobExecutionError(
                "invalid_chat_job",
                "chat job stream flag must be boolean",
                retryable=False,
            )
        output_tokens = request.get("max_tokens")
        if (
            isinstance(output_tokens, bool)
            or not isinstance(output_tokens, int)
            or output_tokens < 1
        ):
            raise JobExecutionError(
                "invalid_chat_job",
                "chat job max_tokens must be a positive integer",
                retryable=False,
            )
        limits: dict[str, int] = {}
        for key in ("input_tokens", "output_tokens", "total_tokens"):
            value = raw_limits.get(key)
            if isinstance(value, bool) or not isinstance(value, int) or value < 1:
                raise JobExecutionError(
                    "invalid_chat_job",
                    "chat job token limits must be positive integers",
                    retryable=False,
                )
            limits[key] = value
        if (
            limits["input_tokens"] > limits["total_tokens"]
            or limits["output_tokens"] > limits["total_tokens"]
        ):
            raise JobExecutionError(
                "invalid_chat_job",
                "chat job token limit exceeds total context",
                retryable=False,
            )
        if output_tokens > limits["output_tokens"]:
            raise JobExecutionError(
                "output_limit_exceeded",
                "chat output budget exceeds the bound serving profile",
                retryable=False,
            )
        supplied_model = request.pop("model", None)
        if supplied_model is not None:
            raise JobExecutionError(
                "invalid_chat_job",
                "gateway chat job must not supply a runtime model name",
                retryable=False,
            )
        uses_tools = bool(request.get("tools"))
        tool_choice = request.get("tool_choice")
        uses_tools = uses_tools or (
            tool_choice is not None and tool_choice != "none"
        )
        for message in request.get("messages", ()):
            if isinstance(message, Mapping) and (
                message.get("role") == "tool"
                or message.get("tool_calls") is not None
            ):
                uses_tools = True
                break
        if uses_tools and not self.tools_enabled:
            raise JobExecutionError(
                "unsupported_feature",
                "llama.cpp serving deployment does not enable structured tools",
                retryable=False,
            )

        request["model"] = self.model_alias
        return request, limits

    def _gateway_embedding_payload(
        self,
        job: JobRequest,
    ) -> tuple[dict[str, Any], dict[str, int], str]:
        envelope = dict(job.payload)
        if envelope.get("schema_version") != EMBEDDING_JOB_SCHEMA:
            raise JobExecutionError(
                "invalid_embedding_job",
                "embedding job requires the reviewed gateway envelope",
                retryable=False,
            )
        if set(envelope) != {
            "schema_version",
            "adapter_id",
            "embedding_space_id",
            "request",
            "limits",
        }:
            raise JobExecutionError(
                "invalid_embedding_job",
                "embedding job envelope uses unsupported fields",
                retryable=False,
            )
        if envelope.get("adapter_id") != LLAMA_CPP_EMBEDDING_ADAPTER:
            raise JobExecutionError(
                "unsupported_embedding_adapter",
                "embedding job targets an unsupported provider adapter",
                retryable=False,
            )
        space_id = envelope.get("embedding_space_id")
        semantic_revision = job.metadata.get("serving_semantic_revision")
        if (
            not isinstance(space_id, str)
            or semantic_revision != space_id
        ):
            raise JobExecutionError(
                "embedding_space_mismatch",
                "embedding job does not match the locally verified serving space",
                retryable=False,
            )
        raw_request = envelope.get("request")
        raw_limits = envelope.get("limits")
        if not isinstance(raw_request, Mapping) or not isinstance(raw_limits, Mapping):
            raise JobExecutionError(
                "invalid_embedding_job",
                "embedding job request/limits must be objects",
                retryable=False,
            )
        request = dict(raw_request)
        if set(request) != {"input", "encoding_format"}:
            raise JobExecutionError(
                "invalid_embedding_job",
                "embedding runtime request uses unsupported fields",
                retryable=False,
            )
        inputs = request.get("input")
        if (
            not isinstance(inputs, list)
            or not inputs
            or any(not isinstance(item, str) or not item for item in inputs)
        ):
            raise JobExecutionError(
                "invalid_embedding_job",
                "embedding runtime input must be non-empty strings",
                retryable=False,
            )
        if request.get("encoding_format") != "float":
            raise JobExecutionError(
                "unsupported_embedding_encoding",
                "embedding runtime supports only float vectors",
                retryable=False,
            )

        required_limits = (
            "item_tokens",
            "item_bytes",
            "batch_items",
            "batch_bytes",
            "aggregate_tokens",
            "dimensions",
        )
        limits: dict[str, int] = {}
        for key in required_limits:
            value = raw_limits.get(key)
            if isinstance(value, bool) or not isinstance(value, int) or value < 1:
                raise JobExecutionError(
                    "invalid_embedding_job",
                    "embedding job limits must be positive integers",
                    retryable=False,
                )
            limits[key] = value
        if set(raw_limits) != set(required_limits):
            raise JobExecutionError(
                "invalid_embedding_job",
                "embedding job limits use unsupported fields",
                retryable=False,
            )
        if len(inputs) > limits["batch_items"]:
            raise JobExecutionError(
                "embedding_batch_exceeded",
                "embedding job exceeds the bound batch-item limit",
                retryable=False,
            )
        sizes = [len(item.encode("utf-8")) for item in inputs]
        if any(size > limits["item_bytes"] for size in sizes):
            raise JobExecutionError(
                "embedding_input_exceeded",
                "embedding item exceeds the bound byte limit",
                retryable=False,
            )
        if sum(sizes) > limits["batch_bytes"]:
            raise JobExecutionError(
                "embedding_batch_exceeded",
                "embedding batch exceeds the bound byte limit",
                retryable=False,
            )
        request["model"] = self.model_alias
        return request, limits, space_id

    def _gateway_decision_payload(
        self,
        job: JobRequest,
    ) -> tuple[
        dict[str, Any],
        dict[str, int],
        str,
        tuple[str, ...],
        tuple[str, ...],
    ]:
        envelope = dict(job.payload)
        if envelope.get("schema_version") != DECISION_JOB_SCHEMA:
            raise JobExecutionError(
                "invalid_decision_job",
                "decision job requires the reviewed gateway envelope",
                retryable=False,
            )
        expected_fields = {
            "schema_version",
            "adapter_id",
            "decision_semantics_id",
            "choice_ids",
            "provider_choice_keys",
            "request",
            "limits",
        }
        if set(envelope) != expected_fields:
            raise JobExecutionError(
                "invalid_decision_job",
                "decision job envelope uses unsupported fields",
                retryable=False,
            )
        if envelope.get("adapter_id") != LLAMA_CPP_SYSTEM_ONE_ADAPTER:
            raise JobExecutionError(
                "unsupported_decision_adapter",
                "decision job targets an unsupported provider adapter",
                retryable=False,
            )
        semantics_id = envelope.get("decision_semantics_id")
        semantic_revision = job.metadata.get("serving_semantic_revision")
        if (
            not isinstance(semantics_id, str)
            or semantic_revision != semantics_id
        ):
            raise JobExecutionError(
                "decision_semantics_mismatch",
                "decision job does not match locally verified semantics",
                retryable=False,
            )
        raw_request = envelope.get("request")
        raw_limits = envelope.get("limits")
        if not isinstance(raw_request, Mapping) or not isinstance(
            raw_limits, Mapping
        ):
            raise JobExecutionError(
                "invalid_decision_job",
                "decision job request/limits must be objects",
                retryable=False,
            )
        request = dict(raw_request)
        if set(request) != {"state", "questions"}:
            raise JobExecutionError(
                "invalid_decision_job",
                "decision runtime request uses unsupported fields",
                retryable=False,
            )
        state = request.get("state")
        questions = request.get("questions")
        if not isinstance(state, str) or not state.strip():
            raise JobExecutionError(
                "invalid_decision_job",
                "decision runtime state must be non-empty text",
                retryable=False,
            )
        if not isinstance(questions, Mapping) or set(questions) != {"decision"}:
            raise JobExecutionError(
                "invalid_decision_job",
                "decision runtime requires exactly one bounded question",
                retryable=False,
            )
        question = questions.get("decision")
        if not isinstance(question, Mapping) or set(question) != {
            "type",
            "instructions",
            "criteria",
        }:
            raise JobExecutionError(
                "invalid_decision_job",
                "decision runtime question has an invalid shape",
                retryable=False,
            )
        if question.get("type") != "choice":
            raise JobExecutionError(
                "invalid_decision_job",
                "first decision adapter supports choice questions only",
                retryable=False,
            )
        instructions = question.get("instructions")
        criteria = question.get("criteria")
        if not isinstance(instructions, str) or not instructions.strip():
            raise JobExecutionError(
                "invalid_decision_job",
                "decision instructions must be non-empty text",
                retryable=False,
            )
        if not isinstance(criteria, Mapping) or len(criteria) < 2:
            raise JobExecutionError(
                "invalid_decision_job",
                "decision criteria must contain at least two choices",
                retryable=False,
            )

        choice_ids_raw = envelope.get("choice_ids")
        provider_keys_raw = envelope.get("provider_choice_keys")
        if (
            not isinstance(choice_ids_raw, list)
            or not isinstance(provider_keys_raw, list)
            or len(choice_ids_raw) != len(provider_keys_raw)
            or len(choice_ids_raw) != len(criteria)
            or len(set(choice_ids_raw)) != len(choice_ids_raw)
            or len(set(provider_keys_raw)) != len(provider_keys_raw)
            or any(
                not isinstance(value, str) or not value
                for value in choice_ids_raw
            )
            or any(
                not isinstance(value, str) or not value
                for value in provider_keys_raw
            )
        ):
            raise JobExecutionError(
                "invalid_decision_job",
                "decision choice mapping is invalid",
                retryable=False,
            )
        provider_keys = tuple(provider_keys_raw)
        if set(criteria) != set(provider_keys):
            raise JobExecutionError(
                "invalid_decision_job",
                "decision provider keys do not match criteria",
                retryable=False,
            )

        required_limits = {
            "state_bytes",
            "question_bytes",
            "choice_count",
            "choice_id_bytes",
            "choice_label_bytes",
            "state_tokens",
            "question_tokens",
            "choice_label_tokens",
            "aggregate_tokens",
        }
        if set(raw_limits) != required_limits:
            raise JobExecutionError(
                "invalid_decision_job",
                "decision job limits use unsupported fields",
                retryable=False,
            )
        limits: dict[str, int] = {}
        for key in required_limits:
            value = raw_limits.get(key)
            if isinstance(value, bool) or not isinstance(value, int) or value < 1:
                raise JobExecutionError(
                    "invalid_decision_job",
                    "decision job limits must be positive integers",
                    retryable=False,
                )
            limits[key] = value
        if len(choice_ids_raw) > limits["choice_count"]:
            raise JobExecutionError(
                "decision_input_exceeded",
                "decision job exceeds the bound choice-count limit",
                retryable=False,
            )
        if len(state.encode("utf-8")) > limits["state_bytes"]:
            raise JobExecutionError(
                "decision_input_exceeded",
                "decision state exceeds the bound byte limit",
                retryable=False,
            )
        if len(instructions.encode("utf-8")) > limits["question_bytes"]:
            raise JobExecutionError(
                "decision_input_exceeded",
                "decision question exceeds the bound byte limit",
                retryable=False,
            )
        for choice_id in choice_ids_raw:
            if len(choice_id.encode("utf-8")) > limits["choice_id_bytes"]:
                raise JobExecutionError(
                    "decision_input_exceeded",
                    "decision choice ID exceeds the bound byte limit",
                    retryable=False,
                )
        for label in criteria.values():
            if not isinstance(label, str) or not label.strip():
                raise JobExecutionError(
                    "invalid_decision_job",
                    "decision choice labels must be non-empty text",
                    retryable=False,
                )
            if len(label.encode("utf-8")) > limits["choice_label_bytes"]:
                raise JobExecutionError(
                    "decision_input_exceeded",
                    "decision choice label exceeds the bound byte limit",
                    retryable=False,
                )

        return (
            request,
            limits,
            semantics_id,
            tuple(choice_ids_raw),
            provider_keys,
        )

    async def _enforce_decision_token_limits(
        self,
        request: Mapping[str, Any],
        limits: Mapping[str, int],
    ) -> None:
        state = str(request["state"])
        question = request["questions"]["decision"]
        instructions = str(question["instructions"])
        criteria = question["criteria"]
        state_tokens = await self.api.tokenize(state)
        question_tokens = await self.api.tokenize(instructions)
        label_tokens = [
            await self.api.tokenize(str(label))
            for label in criteria.values()
        ]
        if state_tokens > limits["state_tokens"]:
            raise JobExecutionError(
                "decision_input_exceeded",
                "decision state exceeds the bound token limit",
                retryable=False,
            )
        if question_tokens > limits["question_tokens"]:
            raise JobExecutionError(
                "decision_input_exceeded",
                "decision question exceeds the bound token limit",
                retryable=False,
            )
        if any(
            count > limits["choice_label_tokens"]
            for count in label_tokens
        ):
            raise JobExecutionError(
                "decision_input_exceeded",
                "decision choice label exceeds the bound token limit",
                retryable=False,
            )
        if (
            state_tokens + question_tokens + sum(label_tokens)
            > limits["aggregate_tokens"]
        ):
            raise JobExecutionError(
                "decision_input_exceeded",
                "decision request exceeds the aggregate token limit",
                retryable=False,
            )

    async def _enforce_embedding_token_limits(
        self,
        inputs: list[str],
        limits: Mapping[str, int],
    ) -> None:
        counts = [await self.api.tokenize(item) for item in inputs]
        if any(count > limits["item_tokens"] for count in counts):
            raise JobExecutionError(
                "embedding_input_exceeded",
                "embedding item exceeds the bound token limit",
                retryable=False,
            )
        if sum(counts) > limits["aggregate_tokens"]:
            raise JobExecutionError(
                "embedding_batch_exceeded",
                "embedding batch exceeds the aggregate token limit",
                retryable=False,
            )

    async def _enforce_chat_limits(
        self,
        payload: Mapping[str, Any],
        limits: Mapping[str, int],
    ) -> None:
        input_tokens = await self.api.chat_input_tokens(payload)
        output_tokens = int(payload["max_tokens"])
        if input_tokens > limits["input_tokens"]:
            raise JobExecutionError(
                "context_length_exceeded",
                "chat input exceeds the deployed input-token limit",
                retryable=False,
            )
        if input_tokens + output_tokens > limits["total_tokens"]:
            raise JobExecutionError(
                "context_length_exceeded",
                "chat input plus output reservation exceeds deployed context",
                retryable=False,
            )

    async def execute(self, job: JobRequest) -> JobResult:
        if job.capability not in self.capabilities:
            raise ValueError(
                f"llama.cpp executor does not support capability: {job.capability}"
            )

        if job.capability == "decision.system_one":
            (
                payload,
                limits,
                semantics_id,
                _choice_ids,
                provider_keys,
            ) = self._gateway_decision_payload(job)
            await self._enforce_decision_token_limits(payload, limits)
            call = self.api.system_one(payload)
            task = asyncio.create_task(call)
            self._inflight[job.job_id] = task
            try:
                response = await task
            finally:
                self._inflight.pop(job.job_id, None)
            try:
                _scores, usage = validate_decision_provider_response(
                    response,
                    provider_choice_keys=provider_keys,
                )
            except DecisionGatewayError as exc:
                raise JobExecutionError(
                    "invalid_provider_response",
                    "llama.cpp returned an invalid decision response",
                    retryable=False,
                ) from exc
            return JobResult(
                outputs=dict(response),
                metrics=dict(usage),
                metadata={
                    "runtime_provider": LLAMA_CPP_PROVIDER_ID,
                    "model": self.model_ref,
                    "model_alias": self.model_alias,
                    "decision_semantics_id": semantics_id,
                    "score_kind": "choice_set_probability",
                    "calibration_status": "uncalibrated",
                },
            )

        if job.capability == "text.embed":
            payload, limits, space_id = self._gateway_embedding_payload(job)
            inputs = list(payload["input"])
            await self._enforce_embedding_token_limits(inputs, limits)
            call = self.api.embeddings(payload)
            task = asyncio.create_task(call)
            self._inflight[job.job_id] = task
            try:
                response = await task
            finally:
                self._inflight.pop(job.job_id, None)
            try:
                data, usage = validate_embedding_response(
                    response,
                    item_count=len(inputs),
                    dimensions=limits["dimensions"],
                )
            except EmbeddingGatewayError as exc:
                raise JobExecutionError(
                    "invalid_provider_response",
                    "llama.cpp returned invalid embedding vectors",
                    retryable=False,
                ) from exc
            metrics = {
                key: value
                for key, value in usage.items()
                if isinstance(value, int)
            }
            return JobResult(
                outputs={
                    "object": "list",
                    "data": data,
                    "model": self.model_alias,
                    "usage": usage,
                },
                metrics=metrics,
                metadata={
                    "runtime_provider": LLAMA_CPP_PROVIDER_ID,
                    "model": self.model_ref,
                    "model_alias": self.model_alias,
                    "embedding_space_id": space_id,
                    "pooling": self.pooling,
                    "normalization": "l2",
                },
            )

        gateway_chat = (
            self._gateway_chat_payload(job)
            if job.capability == "llm.chat"
            else None
        )
        if gateway_chat is None:
            payload = self._payload(job)
        else:
            payload, limits = gateway_chat

        if job.capability == "llm.chat":
            if not isinstance(payload.get("messages"), list):
                raise ValueError("llm.chat requires a messages list")
            if gateway_chat is not None:
                if payload.get("stream") is True:
                    raise JobExecutionError(
                        "streaming_requires_event_sink",
                        "streaming chat requires the fenced Job event channel",
                        retryable=False,
                    )
                await self._enforce_chat_limits(payload, limits)
            call = self.api.chat(payload)
        else:
            if not isinstance(payload.get("prompt"), str):
                raise ValueError("text.generate requires a prompt string")
            call = self.api.completion(payload)

        task = asyncio.create_task(call)
        self._inflight[job.job_id] = task
        try:
            response = await task
        finally:
            self._inflight.pop(job.job_id, None)

        text: str | None = None
        choices = response.get("choices")
        if isinstance(choices, list) and choices:
            first = choices[0]
            if isinstance(first, Mapping):
                if job.capability == "llm.chat":
                    message = first.get("message")
                    if isinstance(message, Mapping):
                        content = message.get("content")
                        if isinstance(content, str):
                            text = content
                else:
                    candidate = first.get("text")
                    if isinstance(candidate, str):
                        text = candidate

        metrics: dict[str, int | float] = {}
        usage = response.get("usage")
        if isinstance(usage, Mapping):
            for key in (
                "prompt_tokens",
                "completion_tokens",
                "total_tokens",
            ):
                value = usage.get(key)
                if isinstance(value, (int, float)) and not isinstance(value, bool):
                    metrics[key] = value

        return JobResult(
            outputs=dict(response),
            metrics=metrics,
            text=text,
            metadata={
                "runtime_provider": LLAMA_CPP_PROVIDER_ID,
                "model": self.model_ref,
                "model_alias": self.model_alias,
            },
        )

    async def execute_stream(
        self,
        job: JobRequest,
        sink: JobEventSink,
    ) -> JobResult:
        if job.capability != "llm.chat":
            return await self.execute(job)
        gateway_chat = self._gateway_chat_payload(job)
        if gateway_chat is None:
            return await self.execute(job)
        payload, limits = gateway_chat
        if payload.get("stream") is not True:
            return await self.execute(job)

        await self._enforce_chat_limits(payload, limits)
        payload["stream"] = True
        payload["stream_options"] = {"include_usage": True}

        metrics: dict[str, int | float] = {}
        text_parts: list[str] = []
        current = asyncio.current_task()
        if current is None:
            raise RuntimeError("streaming execution task is unavailable")
        self._inflight[job.job_id] = current
        try:
            async for raw_chunk in self.api.chat_stream(payload):
                try:
                    chunk = validate_chat_stream_chunk(raw_chunk)
                except ChatGatewayError as exc:
                    raise JobExecutionError(
                        "invalid_provider_response",
                        "llama.cpp returned an invalid chat stream chunk",
                        retryable=False,
                    ) from exc
                choices = chunk.get("choices")
                if isinstance(choices, list) and choices:
                    choice = choices[0]
                    if isinstance(choice, Mapping):
                        delta = choice.get("delta")
                        if isinstance(delta, Mapping):
                            content = delta.get("content")
                            if isinstance(content, str):
                                text_parts.append(content)
                usage = chunk.get("usage")
                if isinstance(usage, Mapping):
                    for key in (
                        "prompt_tokens",
                        "completion_tokens",
                        "total_tokens",
                    ):
                        value = usage.get(key)
                        if (
                            isinstance(value, (int, float))
                            and not isinstance(value, bool)
                        ):
                            metrics[key] = value
                await sink.emit(
                    JobEvent(
                        kind="chat.completion.chunk",
                        payload=chunk,
                    )
                )
        finally:
            if self._inflight.get(job.job_id) is current:
                self._inflight.pop(job.job_id, None)

        return JobResult(
            outputs={"streamed": True},
            metrics=metrics,
            text="".join(text_parts) if text_parts else None,
            metadata={
                "runtime_provider": LLAMA_CPP_PROVIDER_ID,
                "model": self.model_ref,
                "model_alias": self.model_alias,
            },
        )

    async def cancel(self, job_id: str) -> None:
        task = self._inflight.get(job_id)
        if task is None or task.done():
            return
        task.cancel()
        with contextlib.suppress(asyncio.CancelledError):
            await task

    async def residency(self) -> ResidencyReport:
        return ResidencyReport(
            items=(
                ResidencyItem(
                    name=self.model_ref,
                    kind="gguf-model",
                    metadata=dict(self.residency_metadata),
                ),
            ),
            metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
        )


class LlamaCppManagedRuntime(ManagedRuntime):
    provider_id = LLAMA_CPP_PROVIDER_ID

    def __init__(
        self,
        *,
        api: LlamaCppApi,
        process: LlamaCppProcessController,
        context: RuntimeCompatibilityContext,
        model_ref: str,
        model_alias: str,
        startup_timeout_seconds: float,
        launch_policy: LlamaCppLaunchPolicy,
        tools_enabled: bool = False,
        embeddings: bool = False,
        pooling: str | None = None,
        decision: bool = False,
        verify_bonsai_artifact: bool = False,
    ) -> None:
        self.api = api
        self.process = process
        self.verify_bonsai_artifact = verify_bonsai_artifact
        self.context = context
        self.model_ref = model_ref
        self.model_alias = model_alias
        self.startup_timeout_seconds = startup_timeout_seconds
        self.launch_policy = launch_policy
        self.decision_mode = decision
        self._closed = False
        self._executor = LlamaCppExecutor(
            api=api,
            model_ref=model_ref,
            model_alias=model_alias,
            tools_enabled=tools_enabled,
            embeddings=embeddings,
            pooling=pooling,
            decision=decision,
            residency_metadata={
                "residency_policy": context.demand.residency_policy.value,
                "gpu_topology": context.demand.gpu_topology.value,
                "gpu_count": context.worker.resources.gpu_count,
                "gpu_layers": launch_policy.gpu_layers,
                "split_mode": launch_policy.split_mode.value,
                "fit": launch_policy.fit,
                "tensor_split": (
                    list(launch_policy.tensor_split)
                    if launch_policy.tensor_split is not None
                    else None
                ),
                "cpu_moe": launch_policy.cpu_moe,
                "n_cpu_moe": launch_policy.n_cpu_moe,
                "n_cpu_ffn": launch_policy.n_cpu_ffn,
            },
        )

    async def _server_reachable(self) -> bool:
        return await self.api.health()

    async def start(self) -> None:
        if self._closed:
            raise RuntimeError("llama.cpp runtime has already been released")

        reachable = await self._server_reachable()
        if reachable and not self.process.running:
            raise RuntimeError(
                "an external llama.cpp server is already using the configured endpoint"
            )
        if self.verify_bonsai_artifact and not self.process.running:
            await asyncio.to_thread(_verify_bonsai_model_bytes, self.model_ref)

        started_here = False
        if not self.process.running:
            await self.process.start()
            started_here = True

        try:
            deadline = (
                asyncio.get_running_loop().time()
                + self.startup_timeout_seconds
            )
            while True:
                if not self.process.running:
                    raise RuntimeError(
                        "llama.cpp owned process exited before readiness; "
                        "inspect Worker service logs"
                    )
                if await self._server_reachable():
                    break
                if asyncio.get_running_loop().time() >= deadline:
                    raise RuntimeError(
                        "llama.cpp server did not become ready before timeout"
                    )
                await asyncio.sleep(0.1)

            models = await self.api.models()
            if self.model_alias not in models:
                raise RuntimeError(
                    "llama.cpp server did not expose the configured model alias"
                )
            if self.decision_mode and not await self.api.decision_capable(
                self.model_alias
            ):
                raise RuntimeError(
                    "llama.cpp model does not advertise native decision output"
                )
        except Exception:
            if started_here:
                with contextlib.suppress(Exception):
                    await self.process.stop()
            raise

    async def stop(self) -> None:
        await self.process.stop()

    async def health(self) -> RuntimeHealth:
        reachable = await self._server_reachable()
        if not reachable:
            return RuntimeHealth(
                state=(
                    RuntimeHealthState.STARTING
                    if self.process.running
                    else RuntimeHealthState.STOPPED
                ),
                ready=False,
                metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
            )
        if not self.process.running:
            return RuntimeHealth(
                state=RuntimeHealthState.FAILED,
                ready=False,
                detail="external llama.cpp process detected at managed endpoint",
                metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
            )
        try:
            models = await self.api.models()
        except Exception:
            return RuntimeHealth(
                state=RuntimeHealthState.DEGRADED,
                ready=False,
                detail="llama.cpp model inventory is unavailable",
                metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
            )
        if self.model_alias not in models:
            return RuntimeHealth(
                state=RuntimeHealthState.FAILED,
                ready=False,
                detail="configured llama.cpp model alias is unavailable",
                metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
            )
        if self.decision_mode:
            try:
                decision_capable = await self.api.decision_capable(
                    self.model_alias
                )
            except Exception:
                return RuntimeHealth(
                    state=RuntimeHealthState.DEGRADED,
                    ready=False,
                    detail="llama.cpp decision capability is unavailable",
                    metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
                )
            if not decision_capable:
                return RuntimeHealth(
                    state=RuntimeHealthState.FAILED,
                    ready=False,
                    detail="configured model is not a native decision model",
                    metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
                )
        # An owned process may exit during the awaited inventory request.
        if not self.process.running:
            return RuntimeHealth(
                state=RuntimeHealthState.STOPPED,
                ready=False,
                metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
            )
        return RuntimeHealth(
            state=RuntimeHealthState.READY,
            ready=True,
            metadata={
                "runtime_provider": LLAMA_CPP_PROVIDER_ID,
                "model": self.model_ref,
                "model_alias": self.model_alias,
            },
        )

    async def residency(self) -> ResidencyReport:
        return await self._executor.residency()

    def executor(self) -> JobExecutor:
        return self._executor

    async def release(self) -> None:
        if self._closed:
            return
        await self.api.close()
        self._closed = True


class LlamaCppProvider(RuntimeProvider):
    def __init__(
        self,
        config: LlamaCppProviderConfig | None = None,
        *,
        api_factory: Any | None = None,
        process_factory: Any | None = None,
    ) -> None:
        self.config = config or LlamaCppProviderConfig()
        self._api_factory = api_factory or (
            lambda base_url: HttpLlamaCppApi(
                base_url,
                timeout_seconds=self.config.request_timeout_seconds,
            )
        )
        self._process_factory = process_factory or (
            lambda **kwargs: LlamaCppSubprocessController(**kwargs)
        )
        self._info = RuntimeProviderInfo(
            provider_id=LLAMA_CPP_PROVIDER_ID,
            display_name="llama.cpp",
            description=(
                "GGUF runtime for GPU-resident, CPU/GPU hybrid, and "
                "heterogeneous multi-GPU inference."
            ),
        )

    @property
    def info(self) -> RuntimeProviderInfo:
        return self._info

    def compatibility(
        self,
        context: RuntimeCompatibilityContext,
    ) -> RuntimeCompatibility:
        reasons: list[CompatibilityReason] = []
        demand = context.demand
        model = demand.model
        resources = context.worker.resources
        policy = _launch_policy(context, self.config)

        if model.model_format != "gguf":
            reasons.append(
                CompatibilityReason(
                    code="model-format-unsupported",
                    message="llama.cpp provider requires model_format=gguf",
                )
            )

        if demand.residency_policy is ResidencyPolicy.VRAM_ONLY:
            if model.estimated_size_mb is None:
                reasons.append(
                    CompatibilityReason(
                        code="model-size-required-for-vram-only",
                        message=(
                            "llama.cpp vram_only planning requires an "
                            "estimated GGUF size"
                        ),
                    )
                )
            elif demand.gpu_topology is GPUTopology.SINGLE_GPU:
                if model.estimated_size_mb > resources.max_single_gpu_vram_mb:
                    reasons.append(
                        CompatibilityReason(
                            code="model-exceeds-single-gpu-vram",
                            message=(
                                "estimated GGUF size exceeds the selected "
                                "single GPU VRAM"
                            ),
                        )
                    )
            elif model.estimated_size_mb > resources.total_vram_mb:
                reasons.append(
                    CompatibilityReason(
                        code="model-exceeds-total-vram",
                        message=(
                            "estimated GGUF size exceeds Worker total VRAM"
                        ),
                    )
                )

            if policy.gpu_layers != "all" or policy.fit:
                reasons.append(
                    CompatibilityReason(
                        code="vram-only-policy-overridden",
                        message=(
                            "vram_only requires gpu_layers=all and fit=off"
                        ),
                    )
                )
            if (
                policy.cpu_moe
                or policy.n_cpu_moe not in (None, 0)
                or policy.n_cpu_ffn not in (None, 0)
            ):
                reasons.append(
                    CompatibilityReason(
                        code="cpu-offload-conflicts-with-vram-only",
                        message=(
                            "CPU FFN/MoE offload options conflict with vram_only"
                        ),
                    )
                )

        if (
            demand.gpu_topology is not GPUTopology.MULTI_GPU
            and policy.tensor_split is not None
        ):
            reasons.append(
                CompatibilityReason(
                    code="tensor-split-requires-multi-gpu",
                    message="tensor_split is only valid for multi_gpu execution",
                )
            )

        if (
            resources.gpu_count > 0
            and policy.split_mode
            in {LlamaCppSplitMode.NONE, LlamaCppSplitMode.ROW}
            and policy.main_gpu >= resources.gpu_count
        ):
            reasons.append(
                CompatibilityReason(
                    code="main-gpu-outside-visible-set",
                    message=(
                        "main_gpu must refer to a GPU inside the Worker-visible set"
                    ),
                )
            )

        if demand.gpu_topology is GPUTopology.SINGLE_GPU:
            if policy.split_mode is not LlamaCppSplitMode.NONE:
                reasons.append(
                    CompatibilityReason(
                        code="single-gpu-split-mode-invalid",
                        message="single_gpu requires split_mode=none",
                    )
                )

        if demand.gpu_topology is GPUTopology.MULTI_GPU:
            if policy.split_mode is LlamaCppSplitMode.NONE:
                reasons.append(
                    CompatibilityReason(
                        code="multi-gpu-split-mode-invalid",
                        message="multi_gpu requires a split mode other than none",
                    )
                )
            if policy.tensor_split is not None and (
                len(policy.tensor_split) != resources.gpu_count
            ):
                reasons.append(
                    CompatibilityReason(
                        code="tensor-split-length-mismatch",
                        message=(
                            "tensor_split must contain one proportion per "
                            "Worker GPU"
                        ),
                    )
                )
            if policy.fit_target_mb is not None and len(
                policy.fit_target_mb
            ) not in {1, resources.gpu_count}:
                reasons.append(
                    CompatibilityReason(
                        code="fit-target-length-mismatch",
                        message=(
                            "fit_target_mb must contain one value or one value "
                            "per Worker GPU"
                        ),
                    )
                )
            if policy.split_mode is LlamaCppSplitMode.TENSOR:
                reasons.append(
                    CompatibilityReason(
                        code="tensor-split-experimental",
                        message=(
                            "llama.cpp split_mode=tensor is upstream "
                            "experimental"
                        ),
                        blocking=False,
                    )
                )
            elif policy.tensor_split is None:
                reasons.append(
                    CompatibilityReason(
                        code="heterogeneous-auto-fit",
                        message=(
                            "llama.cpp will fit/split across visible GPUs using "
                            "its own device-memory information"
                        ),
                        blocking=False,
                    )
                )

        if demand.gpu_topology is GPUTopology.NONE:
            if self.config.tensor_split is not None:
                reasons.append(
                    CompatibilityReason(
                        code="cpu-only-tensor-split-invalid",
                        message="CPU-only execution cannot use tensor_split",
                    )
                )

        if model.topology is ModelTopology.DENSE:
            if policy.cpu_moe or policy.n_cpu_moe not in (None, 0):
                reasons.append(
                    CompatibilityReason(
                        code="moe-offload-on-dense-model",
                        message=(
                            "cpu_moe/n_cpu_moe are only valid for MoE models"
                        ),
                    )
                )
        elif model.topology is ModelTopology.MOE:
            if policy.n_cpu_ffn not in (None, 0):
                reasons.append(
                    CompatibilityReason(
                        code="dense-ffn-offload-on-moe-model",
                        message=(
                            "n_cpu_ffn is reserved for dense FFN offload; "
                            "use cpu_moe/n_cpu_moe for MoE expert weights"
                        ),
                    )
                )

        if demand.residency_policy is ResidencyPolicy.CPU_GPU_HYBRID:
            if (
                model.estimated_size_mb is not None
                and model.estimated_size_mb
                > resources.total_vram_mb + context.host.host_ram_mb
            ):
                reasons.append(
                    CompatibilityReason(
                        code="model-exceeds-combined-memory",
                        message=(
                            "estimated GGUF size exceeds combined Worker VRAM "
                            "and host RAM"
                        ),
                    )
                )
            if (
                self.config.gpu_layers is None
                and not policy.cpu_moe
                and policy.n_cpu_moe is None
                and policy.n_cpu_ffn is None
            ):
                reasons.append(
                    CompatibilityReason(
                        code="hybrid-offload-auto",
                        message=(
                            "llama.cpp will choose GPU layer placement "
                            "automatically; set provider offload options for an "
                            "explicit partition"
                        ),
                        blocking=False,
                    )
                )

        model_name = Path(model.model_ref).name
        if self.config.runtime_flavor == "bonsai2-pq2":
            if model_name != LLAMA_CPP_BONSAI_MODEL_NAME:
                reasons.append(CompatibilityReason(
                    code="bonsai-model-not-qualified",
                    message="Only the pinned Bonsai 2 27B PQ2_0 GGUF is qualified",
                ))
            if model.topology is not ModelTopology.DENSE:
                reasons.append(CompatibilityReason(
                    code="bonsai-topology-mismatch",
                    message="Bonsai 2 27B PQ2_0 is a dense model",
                ))
            if resources.gpu_count == 0:
                reasons.append(CompatibilityReason(
                    code="bonsai-gpu-required",
                    message="Bonsai 2 GPU qualification requires a selected GPU",
                ))
            if demand.gpu_topology is not GPUTopology.SINGLE_GPU or resources.gpu_count != 1:
                reasons.append(CompatibilityReason(
                    code="bonsai-single-gpu-only",
                    message="Initial Bonsai 2 PQ2_0 acceptance requires exactly one GPU",
                ))
            if demand.residency_policy is not ResidencyPolicy.VRAM_ONLY:
                reasons.append(CompatibilityReason(
                    code="bonsai-vram-only",
                    message="Initial Bonsai 2 PQ2_0 acceptance requires vram_only",
                ))
            if model.estimated_size_mb is not None and model.estimated_size_mb < 6873:
                reasons.append(CompatibilityReason(
                    code="bonsai-model-size-understated",
                    message="Bonsai PQ2_0 is at least 6873 MiB on disk",
                ))
        elif model_name == LLAMA_CPP_BONSAI_MODEL_NAME:
            reasons.append(CompatibilityReason(
                code="bonsai-specialized-runtime-required",
                message="Bonsai PQ2_0 must use the pinned Bonsai backend, not upstream llama.cpp",
            ))
        return RuntimeCompatibility(
            provider_id=LLAMA_CPP_PROVIDER_ID,
            reasons=tuple(reasons),
        )

    def setup_intent(
        self,
        context: RuntimeCompatibilityContext,
    ) -> RuntimeSetupIntent:
        report = self.compatibility(context)
        if not report.compatible:
            raise RuntimeError(
                "cannot build llama.cpp setup intent for incompatible demand"
            )
        policy = _launch_policy(context, self.config)
        return RuntimeSetupIntent(
            provider_id=LLAMA_CPP_PROVIDER_ID,
            package_references=(self.config.package_reference,),
            configuration={
                "base_url": self.config.base_url,
                "executable": self.config.executable,
                **(
                    {"runtime_flavor": "bonsai2-pq2"}
                    if self.config.runtime_flavor == "bonsai2-pq2"
                    else {}
                ),
                "model_ref": context.demand.model.model_ref,
                "model_alias": "astrumweaver",
                "context_size": self.config.context_size,
                "gpu_uuids": list(context.worker.gpu_uuids),
                "gpu_layers": policy.gpu_layers,
                "split_mode": policy.split_mode.value,
                "tensor_split": (
                    list(policy.tensor_split)
                    if policy.tensor_split is not None
                    else None
                ),
                "main_gpu": policy.main_gpu,
                "fit": policy.fit,
                "fit_target_mb": (
                    list(policy.fit_target_mb)
                    if policy.fit_target_mb is not None
                    else None
                ),
                "cpu_moe": policy.cpu_moe,
                "n_cpu_moe": policy.n_cpu_moe,
                "n_cpu_ffn": policy.n_cpu_ffn,
                "offline": self.config.offline,
                "no_webui": self.config.no_webui,
                "jinja": self.config.jinja,
                "chat_template_file": self.config.chat_template_file,
                "embeddings": self.config.embeddings,
                "pooling": self.config.pooling,
                "decision": self.config.decision,
                "capabilities": sorted(
                    LLAMA_CPP_EMBEDDING_CAPABILITIES
                    if self.config.embeddings
                    else LLAMA_CPP_DECISION_CAPABILITIES
                    if self.config.decision
                    else LLAMA_CPP_CAPABILITIES
                ),
            },
            model_preparation=ModelPreparationPolicy.REFERENCE_ONLY,
            model_ref=context.demand.model.model_ref,
            requires_privilege=True,
            metadata={"runtime_provider": LLAMA_CPP_PROVIDER_ID},
        )

    def create_runtime(
        self,
        context: RuntimeCompatibilityContext,
        setup: RuntimeSetupIntent,
    ) -> ManagedRuntime:
        if setup.provider_id != LLAMA_CPP_PROVIDER_ID:
            raise ValueError("setup intent does not belong to llama.cpp provider")
        report = self.compatibility(context)
        if not report.compatible:
            raise RuntimeError(
                "cannot create llama.cpp runtime for incompatible demand"
            )

        cfg = dict(setup.configuration)
        if cfg.get("runtime_flavor", "upstream") != self.config.runtime_flavor:
            raise ValueError("runtime flavor does not match reviewed setup")
        if self.config.executable == LLAMA_CPP_QWEN38_RUNTIME:
            if setup.package_references != (self.config.package_reference,):
                raise ValueError("Qwen3.8 setup must retain the selected Nix package reference")
            if cfg.get("executable") != LLAMA_CPP_QWEN38_RUNTIME:
                raise ValueError("Qwen3.8 setup executable differs from pinned Nix runtime")
        if self.config.runtime_flavor == "bonsai2-pq2":
            if setup.package_references != (LLAMA_CPP_BONSAI_PACKAGE,):
                raise ValueError("Bonsai setup must reference only the pinned Nix package")
            if cfg.get("executable", self.config.executable) != LLAMA_CPP_BONSAI_RUNTIME:
                raise ValueError("Bonsai executable differs from pinned Nix runtime")
            if Path(str(cfg.get("model_ref", ""))).name != LLAMA_CPP_BONSAI_MODEL_NAME:
                raise ValueError("Bonsai model differs from qualified PQ2_0 reference")
            if str(cfg.get("model_ref", "")) != context.demand.model.model_ref:
                raise ValueError("Bonsai model path differs from reviewed demand")
            if cfg.get("gpu_layers") != "all" or cfg.get("fit") is not False:
                raise ValueError("Bonsai requires full-VRAM GPU layers and fit=off")
            if str(cfg.get("split_mode")) != "none":
                raise ValueError("Bonsai requires single-GPU no-split placement")
            if cfg.get("tensor_split") is not None:
                raise ValueError("Bonsai does not support tensor-split deployment")
            if cfg.get("jinja") is not True:
                raise ValueError("Bonsai requires Jinja structured-tool support")
            if cfg.get("offline") is not True or cfg.get("no_webui") is not True:
                raise ValueError("Bonsai requires offline native runtime with no Web UI")
            if int(cfg.get("context_size", 0)) < 8192:
                raise ValueError("Bonsai Coding Leaf requires at least 8192 context tokens")
        base_url = str(cfg.get("base_url") or self.config.base_url)
        model_ref = str(
            cfg.get("model_ref") or context.demand.model.model_ref
        )
        model_alias = str(cfg.get("model_alias") or "astrumweaver")
        executable = str(cfg.get("executable") or self.config.executable)
        jinja = cfg.get("jinja", self.config.jinja)
        if type(jinja) is not bool:
            raise ValueError("llama.cpp deployment jinja must be boolean")
        raw_template = cfg.get(
            "chat_template_file",
            self.config.chat_template_file,
        )
        chat_template_file = (
            None
            if raw_template is None
            else _nonblank(str(raw_template), "chat_template_file")
        )
        if chat_template_file is not None and not jinja:
            raise ValueError(
                "llama.cpp chat_template_file requires jinja=true"
            )
        embeddings = cfg.get("embeddings", self.config.embeddings)
        if type(embeddings) is not bool:
            raise ValueError("llama.cpp deployment embeddings must be boolean")
        decision = cfg.get("decision", self.config.decision)
        if type(decision) is not bool:
            raise ValueError("llama.cpp deployment decision must be boolean")
        if embeddings and decision:
            raise ValueError(
                "llama.cpp deployment cannot mix embedding and decision modes"
            )
        raw_pooling = cfg.get("pooling", self.config.pooling)
        pooling = (
            None
            if raw_pooling is None
            else _nonblank(str(raw_pooling), "pooling")
        )
        if embeddings:
            if jinja or chat_template_file is not None:
                raise ValueError(
                    "llama.cpp embedding deployment cannot enable chat templates"
                )
            if pooling not in {"mean", "cls", "last"}:
                raise ValueError(
                    "llama.cpp embedding deployment requires supported pooling"
                )
        elif pooling is not None:
            raise ValueError(
                "llama.cpp deployment pooling requires embeddings=true"
            )
        if decision and (jinja or chat_template_file is not None):
            raise ValueError(
                "llama.cpp decision deployment cannot enable chat templates"
            )

        split_mode = LlamaCppSplitMode(
            str(cfg.get("split_mode") or _launch_policy(context, self.config).split_mode)
        )
        tensor_split_raw = cfg.get("tensor_split")
        fit_target_raw = cfg.get("fit_target_mb")
        policy = LlamaCppLaunchPolicy(
            gpu_layers=cfg.get(
                "gpu_layers",
                _launch_policy(context, self.config).gpu_layers,
            ),
            split_mode=split_mode,
            fit=bool(cfg.get("fit", _launch_policy(context, self.config).fit)),
            tensor_split=(
                tuple(float(value) for value in tensor_split_raw)
                if isinstance(tensor_split_raw, (list, tuple))
                else None
            ),
            fit_target_mb=(
                tuple(int(value) for value in fit_target_raw)
                if isinstance(fit_target_raw, (list, tuple))
                else None
            ),
            main_gpu=int(cfg.get("main_gpu", self.config.main_gpu)),
            cpu_moe=bool(cfg.get("cpu_moe", self.config.cpu_moe)),
            n_cpu_moe=(
                int(cfg["n_cpu_moe"])
                if cfg.get("n_cpu_moe") is not None
                else None
            ),
            n_cpu_ffn=(
                int(cfg["n_cpu_ffn"])
                if cfg.get("n_cpu_ffn") is not None
                else None
            ),
        )

        api = self._api_factory(base_url)
        process = self._process_factory(
            executable=executable,
            base_url=base_url,
            model_ref=model_ref,
            model_alias=model_alias,
            gpu_uuids=context.worker.gpu_uuids,
            context_size=int(
                cfg.get("context_size", self.config.context_size)
            ),
            launch_policy=policy,
            offline=bool(cfg.get("offline", self.config.offline)),
            no_webui=bool(cfg.get("no_webui", self.config.no_webui)),
            jinja=jinja,
            chat_template_file=chat_template_file,
            embeddings=embeddings,
            pooling=pooling,
            **(
                {"reasoning_off": True, "flash_attn": True}
                if self.config.runtime_flavor == "bonsai2-pq2"
                else {}
            ),
        )

        return LlamaCppManagedRuntime(
            api=api,
            process=process,
            context=context,
            model_ref=model_ref,
            model_alias=model_alias,
            startup_timeout_seconds=self.config.startup_timeout_seconds,
            launch_policy=policy,
            tools_enabled=jinja,
            embeddings=embeddings,
            pooling=pooling,
            decision=decision,
            verify_bonsai_artifact=self.config.runtime_flavor == "bonsai2-pq2",
        )