# Copyright 2022-2026 Xinference Holdings Pte. Ltd
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#      http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

import asyncio
import json
import logging
import os
import time
import uuid
from typing import Any, Dict, List, Optional, Tuple, Union, cast

from ....core.replica_load import EngineLoad
from ....device_utils import is_vacc_available
from ....types import Embedding, EmbeddingData, EmbeddingUsage
from ....utils import dependency_import_guard, dependency_import_message
from ...batch import BatchMixin
from ...utils import check_dependency_available
from ..core import EmbeddingModel, EmbeddingModelFamilyV2, EmbeddingSpecV1
from ..embeddinggemma2 import MATRYOSHKA_DIMENSIONS
from ..embeddinggemma2 import MODEL_NAME as EMBEDDINGGEMMA2_MODEL_NAME
from ..embeddinggemma2 import load_prompts
from ..embeddinggemma2 import normalize_inputs as normalize_embeddinggemma2_inputs
from ..embeddinggemma2 import resolve_dtype, validate_dimensions
from ..wemm import WeMMInput, is_wemm_model, iter_wemm_media, normalize_wemm_inputs

logger = logging.getLogger(__name__)
SUPPORTED_MODELS_PREFIXES = [
    "bge",
    "gte",
    "text2vec",
    "m3e",
    "Qwen3",
    "bce",
    "WeMM",
]


class _SchedulerLoad:
    """One vLLM scheduler's latest queue count and continuous backlog duration."""

    def __init__(self):
        self.waiting = 0
        self.running = 0
        self.waiting_since = 0.0

    def record(self, scheduler_stats, iteration_stats, **kwargs):
        waiting = getattr(scheduler_stats, "num_waiting_reqs", None)
        if not isinstance(waiting, int):
            return
        self.update(
            waiting + getattr(scheduler_stats, "num_skipped_waiting_reqs", 0),
            scheduler_stats.num_running_reqs,
        )

    def update(self, waiting: int, running: int):
        if waiting and not self.waiting:
            self.waiting_since = time.monotonic()
        self.waiting = waiting
        self.running = running

    def backlog_age(self, now: float):
        return max(0.0, now - self.waiting_since) if self.waiting else 0.0

    def log(self):
        pass

    def log_engine_initialized(self):
        pass

    def record_sleep_state(self, *args, **kwargs):
        pass


class _PoolingProgress:
    """Count unfinished inputs through LLM.embed's progress callback."""

    def __init__(self, count: int):
        self.count = count
        self.n = 0
        self.load = _SchedulerLoad()

    def __call__(self, iterable=None, **kwargs):
        # Older vLLM also passes the input iterator to tqdm during submission.
        return self if iterable is None else iterable

    def update(self, count: int):
        self.n += count

    def refresh(self):
        pass

    def close(self):
        pass


class VLLMEmbeddingModel(EmbeddingModel, BatchMixin):
    replica_autoscaling = "native"

    # The backend can be either a synchronous LLM or an asynchronous engine.
    _model: Any
    _tokenizer: Any

    def __init__(self, *args, **kwargs):
        EmbeddingModel.__init__(self, *args, **kwargs)
        BatchMixin.__init__(self, self.create_embedding, **kwargs)  # type: ignore
        self._context_length = None
        self._chat_template = None
        self._native_pooling = False
        self._scheduler_load: Optional[Dict[int, _SchedulerLoad]] = None
        self._native_requests = 0
        self._sync_capacity: Optional[int] = None
        self._sync_metrics_verified = False
        self._sync_progress: Optional[_PoolingProgress] = None
        self._prompts: Dict[str, str] = {}
        self._dimensions = None

    def load(self):
        with dependency_import_guard("vllm"):
            if is_vacc_available():
                import vllm_vacc  # noqa: F401
            from packaging.version import Version
            from vllm import LLM
            from vllm import __version__ as vllm_version

        engine_version = Version(vllm_version)
        # vLLM 0.12 removed V0. VACC can provide a different engine.
        vllm_v1 = engine_version >= Version("0.12.0") and not is_vacc_available()
        if not vllm_v1 and self._scheduler_load is not None:
            raise ValueError(
                "vLLM embedding autoscaling requires vLLM V1 (vLLM >= 0.12, excluding VACC)"
            )
        self._kwargs.pop("batch_size", None)
        self._kwargs.pop("batch_interval", None)

        if self.model_family.model_name in {
            "Qwen3-Embedding-0.6B",
            "Qwen3-Embedding-4B",
            "Qwen3-Embedding-8B",
        }:
            if "hf_overrides" not in self._kwargs:
                self._kwargs["hf_overrides"] = {
                    "is_matryoshka": True,
                }
            elif isinstance(self._kwargs["hf_overrides"], dict):
                self._kwargs["hf_overrides"].update(
                    is_matryoshka=True,
                )
            elif isinstance(self._kwargs["hf_overrides"], str):
                self._kwargs["hf_overrides"] = json.loads(self._kwargs["hf_overrides"])
                self._kwargs["hf_overrides"].update(
                    is_matryoshka=True,
                )

        native = (
            vllm_v1
            and engine_version >= Version("0.19.0")
            and self.model_family.model_name != EMBEDDINGGEMMA2_MODEL_NAME
            and not is_wemm_model(self.model_family.model_name)
            and not self.model_family.model_name.startswith("Qwen3-VL-Embedding")
        )
        report_sync_load = (
            self.__dict__.get("_scheduler_load") is not None and vllm_v1 and not native
        )
        if report_sync_load:
            self._kwargs["disable_log_stats"] = False

        if self.model_family.model_name == EMBEDDINGGEMMA2_MODEL_NAME:
            supported = self._check_embeddinggemma2_support()
            if supported != True:
                raise ImportError(supported[1])
            self._dimensions = self._kwargs.pop("dimensions", None)
            validate_dimensions(self._dimensions)
            dtype = self._kwargs.pop("torch_dtype", self._kwargs.get("dtype"))
            self._kwargs["dtype"] = str(
                resolve_dtype(dtype, self._device or "cuda")
            ).split(".")[-1]
            self._kwargs.setdefault("max_model_len", self.model_family.max_tokens)
            overrides = self._kwargs.get("hf_overrides", {})
            if isinstance(overrides, str):
                overrides = json.loads(overrides)
            if not isinstance(overrides, dict):
                raise ValueError(
                    "EmbeddingGemma 2 hf_overrides must be a dict or JSON object"
                )
            self._kwargs["hf_overrides"] = {
                **overrides,
                "is_matryoshka": True,
                "matryoshka_dimensions": list(MATRYOSHKA_DIMENSIONS),
            }
            self._prompts = load_prompts(self._model_path)
            with open(
                os.path.join(self._model_path, "chat_template.jinja"), encoding="utf-8"
            ) as file:
                self._chat_template = file.read()
            self._model = LLM(model=self._model_path, runner="pooling", **self._kwargs)
        elif is_wemm_model(self.model_family.model_name):
            if engine_version < Version("0.27.0"):
                raise ValueError("WeMM-Embedding requires vLLM>=0.27.0")
            template_path = os.path.join(
                self._model_path, "embedding_chat_template.jinja"
            )
            if not os.path.isfile(template_path):
                raise FileNotFoundError(
                    f"Missing WeMM-Embedding chat template: {template_path}"
                )
            with open(template_path, encoding="utf-8") as template_file:
                self._chat_template = template_file.read()
            self._kwargs.setdefault("gpu_memory_utilization", 0.6)
            self._model = LLM(model=self._model_path, runner="pooling", **self._kwargs)
        elif self.model_family.model_name.startswith("Qwen3-VL-Embedding"):
            if engine_version < Version("0.14.0"):
                raise ValueError("Qwen3-VL embedding requires vLLM>=0.14.0")
            self._model = LLM(model=self._model_path, runner="pooling", **self._kwargs)
        elif native:
            from vllm.engine.arg_utils import AsyncEngineArgs
            from vllm.v1.engine.async_llm import AsyncLLM

            self._kwargs.setdefault("runner", "pooling")
            engine_args = AsyncEngineArgs(model=self._model_path, **self._kwargs)
            if self._scheduler_load is None:
                self._model = AsyncLLM.from_engine_args(engine_args)
            else:
                self._model = AsyncLLM.from_engine_args(
                    engine_args, stat_loggers=[self._scheduler_load_logger]
                )
            self._native_pooling = True
            # Submit requests immediately; vLLM owns the cross-request queue.
            self.create_embedding = self._async_create_embedding
        else:
            if engine_version >= Version("0.13.0"):
                self._model = LLM(
                    model=self._model_path, runner="pooling", **self._kwargs
                )
            else:
                self._model = LLM(model=self._model_path, task="embed", **self._kwargs)
        self._tokenizer = self._model.get_tokenizer()
        if report_sync_load:
            config = self._model.llm_engine.vllm_config
            self._sync_capacity = config.scheduler_config.max_num_seqs

    def enable_engine_load_reporting(self):
        self._scheduler_load = {}

    def _scheduler_load_logger(self, vllm_config, engine_index: int = 0):
        assert self._scheduler_load is not None
        load = _SchedulerLoad()
        self._scheduler_load[engine_index] = load
        return load

    def get_engine_load(self) -> Optional[EngineLoad]:
        progress = self._sync_progress
        sync_capacity = self._sync_capacity
        if sync_capacity is not None:
            if progress is None:
                if not self._sync_metrics_verified:
                    self._sync_metrics_verified = (
                        self._get_sync_scheduler_load() is not None
                    )
                return EngineLoad() if self._sync_metrics_verified else None
            metrics = self._get_sync_scheduler_load()
            if metrics is None:
                return None
            waiting, running = metrics
            if progress is not self._sync_progress:
                return EngineLoad()
            # Synchronous pooling can retain inputs outside EngineCore.
            # At most max_num_seqs of the unfinished inputs can run at once.
            waiting = max(waiting, progress.count - progress.n - sync_capacity)
            progress.load.update(waiting, running)
            return EngineLoad(
                waiting, progress.load.backlog_age(time.monotonic()), running
            )
        schedulers = self._scheduler_load
        if not schedulers:
            return None
        if not self._native_requests:
            return EngineLoad()
        now = time.monotonic()
        waiting = sum(load.waiting for load in schedulers.values())
        backlog_seconds = max(load.backlog_age(now) for load in schedulers.values())
        return EngineLoad(
            waiting, backlog_seconds, sum(load.running for load in schedulers.values())
        )

    def _get_sync_scheduler_load(self) -> Optional[Tuple[int, int]]:
        counts = {"vllm:num_requests_waiting": 0, "vllm:num_requests_running": 0}
        seen = set()
        try:
            for metric in self._model.get_metrics():
                if metric.name in counts:
                    seen.add(metric.name)
                    counts[metric.name] += int(metric.value)
        except Exception:
            logger.debug("Could not read vLLM scheduler metrics", exc_info=True)
            return None
        if seen != counts.keys():
            return None
        return counts["vllm:num_requests_waiting"], counts["vllm:num_requests_running"]

    @staticmethod
    def _get_detailed_instruct(task_description: str, query: str) -> str:
        return f"Instruct: {task_description}\nQuery:{query}"  # noqa: E231

    def _prepare_embedding(
        self,
        sentences: Union[str, Dict[str, Any], List[Union[str, Dict[str, Any]]]],
        **kwargs,
    ):
        from packaging.version import Version
        from vllm import PoolingParams
        from vllm import __version__ as vllm_version

        sentences = self._fix_langchain_openai_inputs(sentences)
        model_uid = kwargs.pop("model_uid", None)

        normalize_embedding = kwargs.get("normalize_embedding", True)
        dimensions = kwargs.get("dimensions", None)
        if self.model_family.model_name == EMBEDDINGGEMMA2_MODEL_NAME:
            normalize_embedding = kwargs.get(
                "normalize_embeddings", normalize_embedding
            )
            dimensions = kwargs.get("dimensions", self._dimensions)
            validate_dimensions(dimensions)
            if kwargs.get("return_sparse", False):
                raise ValueError("EmbeddingGemma 2 does not support sparse embeddings.")

        assert self._model is not None

        # Check and truncate sentences that exceed context_length
        if (
            self._context_length is not None
            and not is_wemm_model(self.model_family.model_name)
            and self.model_family.model_name != EMBEDDINGGEMMA2_MODEL_NAME
        ):
            truncated_sentences = []
            for sentence in sentences if isinstance(sentences, list) else [sentences]:
                # Use tokenizer to check token length
                tokens = self._tokenizer(sentence, add_special_tokens=True)
                if len(tokens.input_ids) > self._context_length:
                    # Truncate to maximum length
                    # Truncate one extra token to prevent overflow
                    truncated_tokens = tokens.input_ids[: self._context_length - 1]
                    truncated_sentence = self._tokenizer.decode(
                        truncated_tokens, skip_special_tokens=True
                    )
                    truncated_sentences.append(truncated_sentence)
                    logger.warning(
                        f"Sentence truncated from {len(tokens.input_ids)} tokens to {self._context_length} tokens"
                    )
                else:
                    truncated_sentences.append(sentence)

            # If original input is string, maintain string format
            if isinstance(sentences, str):
                sentences = truncated_sentences[0]
            else:
                sentences = truncated_sentences
        if Version(vllm_version) > Version("0.16.0"):
            pool_params = PoolingParams(
                dimensions=dimensions, use_activation=normalize_embedding
            )
        elif Version(vllm_version) > Version("0.10.1"):
            pool_params = PoolingParams(
                dimensions=dimensions, normalize=normalize_embedding
            )
        else:
            if not normalize_embedding:
                raise ValueError(
                    f"vLLM version {vllm_version} does not support "
                    f"unnormalized embeddings. "
                    f"Please upgrade to v0.10.1 or later."
                )
            pool_params = PoolingParams(dimensions=dimensions)
        return sentences, pool_params, model_uid

    def _embed_sync(self, prompts: Any, use_tqdm: bool = False, **kwargs):
        if self.__dict__.get("_sync_capacity") is None:
            return self._model.embed(prompts, use_tqdm=use_tqdm, **kwargs)
        progress = _PoolingProgress(len(prompts) if isinstance(prompts, list) else 1)
        self._sync_progress = progress
        try:
            return self._model.embed(prompts, use_tqdm=progress, **kwargs)
        finally:
            self._sync_progress = None

    def _create_embedding(self, sentences: Any, **kwargs) -> Embedding:
        sentences, pool_params, model_uid = self._prepare_embedding(sentences, **kwargs)
        if self.model_family.model_name == EMBEDDINGGEMMA2_MODEL_NAME:
            outputs = self._embed_embeddinggemma2(sentences, pool_params, **kwargs)
        elif is_wemm_model(self.model_family.model_name):
            outputs = self._embed_wemm(sentences, pool_params)
        elif self.model_family.model_name.startswith("Qwen3-VL-Embedding"):
            outputs = self._embed_vl(sentences)
        else:
            outputs = self._embed_sync(sentences, pooling_params=pool_params)
        result = self._format_embedding_outputs(outputs, model_uid)
        self._clean_cache_if_needed(result["usage"]["total_tokens"])
        return self._with_token_counts(
            result,
            [
                (
                    len(output.prompt_token_ids)
                    if hasattr(output, "prompt_token_ids")
                    else 0
                )
                for output in outputs
            ],
        )

    @staticmethod
    def _check_embeddinggemma2_support() -> Union[bool, Tuple[bool, str]]:
        try:
            from vllm import ModelRegistry
        except ImportError:
            return (
                False,
                "EmbeddingGemma 2 requires vLLM>=0.32.0 with EmbeddingGemma2Model support.",
            )
        if "EmbeddingGemma2Model" not in ModelRegistry.get_supported_archs():
            return (
                False,
                "EmbeddingGemma 2 requires vLLM>=0.32.0 with EmbeddingGemma2Model support.",
            )
        return True

    def _embed_embeddinggemma2(self, inputs: Any, pool_params: Any, **kwargs: Any):
        from vllm.multimodal.utils import fetch_audio, fetch_image, fetch_video

        messages_batch = normalize_embeddinggemma2_inputs(
            inputs, self._prompts, **kwargs
        )
        loaders = {"image": fetch_image, "video": fetch_video, "audio": fetch_audio}
        vllm_inputs = []
        for messages in messages_batch:
            prompt = self._tokenizer.apply_chat_template(
                messages,
                tokenize=False,
                add_generation_prompt=False,
                chat_template=self._chat_template,
            )
            media: Dict[str, List[Any]] = {}
            for part in messages[0]["content"]:
                modality = part["type"]
                if modality == "text":
                    continue
                value = part[modality]
                if isinstance(value, str):
                    if not value.startswith(
                        ("http://", "https://", "data:", "file://")
                    ):
                        value = f"file://{os.path.abspath(value)}"
                    value = loaders[modality](value)
                media.setdefault(modality, []).append(value)
            item: Dict[str, Any] = {"prompt": prompt}
            if media:
                item["multi_modal_data"] = media
            if kwargs.get("processing_kwargs"):
                item["mm_processor_kwargs"] = kwargs["processing_kwargs"]
            vllm_inputs.append(item)
        if not vllm_inputs:
            return []
        return self._embed_sync(vllm_inputs, pooling_params=pool_params)

    async def _async_create_embedding(self, sentences: Any, **kwargs) -> Embedding:
        from vllm.outputs import EmbeddingRequestOutput

        truncate_prompt_tokens = kwargs.pop("truncate_prompt_tokens", None)
        if truncate_prompt_tokens is not None:
            sentences = self._truncate_sentences(sentences, truncate_prompt_tokens)
        sentences, pool_params, model_uid = self._prepare_embedding(sentences, **kwargs)
        pool_params.task = "embed"
        prompts = [sentences] if isinstance(sentences, str) else sentences
        request_id = uuid.uuid4().hex

        async def encode(index: int, prompt: str):
            output = None
            async for output in self._model.encode(
                prompt, pool_params, f"{request_id}-{index}"
            ):
                pass
            if output is None:
                raise RuntimeError("vLLM returned no embedding output")
            return EmbeddingRequestOutput.from_base(output)

        schedulers = self._scheduler_load
        if schedulers is not None:
            if not self._native_requests:
                for load in schedulers.values():
                    load.waiting = load.running = 0
            self._native_requests += 1
        tasks = [asyncio.create_task(encode(i, p)) for i, p in enumerate(prompts)]
        try:
            outputs = await asyncio.gather(*tasks)
        finally:
            # Cancelling encode also aborts its request in vLLM. A failed input
            # must not leave sibling inputs running after the caller has exited.
            for task in tasks:
                if not task.done():
                    task.cancel()
            try:
                await asyncio.gather(*tasks, return_exceptions=True)
            finally:
                if schedulers is not None:
                    self._native_requests -= 1
        # vLLM owns the worker's GPU allocations. Avoid collecting the actor's
        # Python heap every few requests while native inference is in flight.
        return self._format_embedding_outputs(outputs, model_uid)

    def _format_embedding_outputs(
        self, outputs: List[Any], model_uid: Optional[str]
    ) -> Embedding:
        embedding_list = []
        all_token_nums = 0
        for index, output in enumerate(outputs):
            embedding_list.append(
                EmbeddingData(
                    index=index, object="embedding", embedding=output.outputs.embedding
                )
            )
            if hasattr(output, "prompt_token_ids"):
                all_token_nums += len(output.prompt_token_ids)
        usage = EmbeddingUsage(
            prompt_tokens=all_token_nums, total_tokens=all_token_nums
        )
        result = Embedding(
            object="list",
            model=model_uid,
            model_replica=self._model_uid,
            data=embedding_list,
            usage=usage,
        )
        return result

    def _embed_wemm(self, inputs: WeMMInput, pool_params):
        from vllm.multimodal.utils import fetch_image, fetch_video

        messages_batch = normalize_wemm_inputs(inputs)
        assert self._model is not None
        assert self._chat_template is not None

        def _media_url(value: Any, modality: str) -> Any:
            if not isinstance(value, str):
                return value
            if value.startswith(("http://", "https://", "data:", "file://")):
                return value
            path = os.path.abspath(value)
            if not os.path.exists(path):
                raise FileNotFoundError(f"WeMM-Embedding {modality} not found: {path}")
            return f"file://{path}"

        vllm_inputs: List[Dict[str, Any]] = []
        for messages in messages_batch:
            prompt = self._tokenizer.apply_chat_template(
                messages,
                tokenize=False,
                add_generation_prompt=False,
                chat_template=self._chat_template,
            )
            media: Dict[str, List[Any]] = {"image": [], "video": []}
            for modality, value in iter_wemm_media(messages):
                url_or_data = _media_url(value, modality)
                if modality == "image":
                    media[modality].append(
                        fetch_image(url_or_data)
                        if isinstance(url_or_data, str)
                        else url_or_data
                    )
                else:
                    media[modality].append(
                        fetch_video(url_or_data)
                        if isinstance(url_or_data, str)
                        else url_or_data
                    )
            multi_modal_data = {
                modality: values[0] if len(values) == 1 else values
                for modality, values in media.items()
                if values
            }
            item: Dict[str, Any] = {"prompt": prompt}
            if multi_modal_data:
                item["multi_modal_data"] = multi_modal_data
            vllm_inputs.append(item)

        return self._embed_sync(vllm_inputs, pooling_params=pool_params)

    def _embed_vl(
        self, inputs: Union[str, List[str], Dict[str, Any], List[Dict[str, Any]]]
    ):
        import base64
        import re
        from io import BytesIO

        from PIL import Image
        from vllm.multimodal.utils import fetch_image

        if isinstance(inputs, str):
            normalized: List[Dict[str, Any]] = [{"text": inputs}]
        elif isinstance(inputs, dict):
            normalized = [inputs]
        elif isinstance(inputs, list) and inputs and isinstance(inputs[0], str):
            normalized = [{"text": item} for item in inputs]
        elif isinstance(inputs, list):
            normalized = cast(List[Dict[str, Any]], inputs)
        else:
            raise ValueError("Unsupported input type for Qwen3-VL embedding.")

        vllm_inputs: List[Dict[str, Any]] = []

        def _format_input_to_conversation(
            input_dict: Dict[str, Any], instruction: str = "Represent the user's input."
        ) -> List[Dict]:
            content = []

            text = input_dict.get("text")
            image = input_dict.get("image")

            if image:
                image_content = None
                if isinstance(image, str):
                    if re.match(r"^data:image/.+;base64,", image):
                        image_content = image
                    elif image.startswith(("http", "https", "oss")):
                        image_content = image
                    else:
                        abs_image_path = os.path.abspath(image)
                        image_content = "file://" + abs_image_path
                else:
                    image_content = image

                if image_content:
                    content.append(
                        {
                            "type": "image",
                            "image": image_content,
                        }
                    )

            if text:
                content.append({"type": "text", "text": text})

            if not content:
                content.append({"type": "text", "text": ""})

            conversation = [
                {"role": "system", "content": [{"type": "text", "text": instruction}]},
                {"role": "user", "content": content},
            ]

            return conversation

        def _prepare_vllm_inputs(
            input_dict: Dict[str, Any],
            llm,
            instruction: str = "Represent the user's input.",
        ) -> Dict[str, Any]:
            image = input_dict.get("image")

            conversation = _format_input_to_conversation(input_dict, instruction)

            assert self._model is not None
            prompt_text = self._model.llm_engine.tokenizer.apply_chat_template(
                conversation, tokenize=False, add_generation_prompt=True
            )

            multi_modal_data = None
            if image:
                if isinstance(image, str):
                    if re.match(r"^data:image/.+;base64,", image):
                        base64_data = image.split(",", 1)[1]
                        data = base64.b64decode(base64_data)
                        image_obj = Image.open(BytesIO(data)).convert("RGB")
                        multi_modal_data = {"image": image_obj}
                    elif image.startswith(("http", "https", "oss")):
                        try:
                            image_obj = fetch_image(image)
                            multi_modal_data = {"image": image_obj}
                        except Exception as e:
                            print(f"Warning: Failed to fetch image {image}: {e}")
                    else:
                        abs_image_path = os.path.abspath(image)
                        if os.path.exists(abs_image_path):
                            image_obj = Image.open(abs_image_path)
                            multi_modal_data = {"image": image_obj}
                        else:
                            print(f"Warning: Image file not found: {abs_image_path}")
                else:
                    multi_modal_data = {"image": image}

            result = {"prompt": prompt_text, "multi_modal_data": multi_modal_data}
            return result

        assert self._model is not None
        vllm_inputs = [_prepare_vllm_inputs(item, self._model) for item in normalized]
        return self._embed_sync(vllm_inputs, use_tqdm=True)

    @classmethod
    def check_lib(cls) -> Union[bool, Tuple[bool, str]]:
        dep_check = check_dependency_available("vllm", "vLLM")
        if dep_check != True:
            return dep_check
        return True

    @classmethod
    def match_json(
        cls,
        model_family: EmbeddingModelFamilyV2,
        model_spec: EmbeddingSpecV1,
        quantization: str,
    ) -> Union[bool, Tuple[bool, str]]:
        if model_family.model_name == EMBEDDINGGEMMA2_MODEL_NAME:
            from ...utils import virtual_env_allows_missing_engine

            if model_spec.model_format != "pytorch":
                return False, "EmbeddingGemma 2 vLLM supports pytorch format only"
            if virtual_env_allows_missing_engine():
                return True
            return cls._check_embeddinggemma2_support()
        required_vllm_version = None
        if is_wemm_model(model_family.model_name):
            required_vllm_version = "0.27.0"
        elif model_family.model_name.startswith("Qwen3-VL-Embedding"):
            required_vllm_version = "0.14.0"
        if required_vllm_version is not None:
            # In virtualenv mode vLLM (and a compatible version) can be
            # installed on demand, so only the missing-library / old-version
            # rejection is exempt here; the format/prefix compatibility checks
            # below still apply (virtualenv cannot make an incompatible spec
            # work).
            from ...utils import virtual_env_allows_missing_engine

            allow_missing_env = virtual_env_allows_missing_engine()
            try:
                import vllm
                from packaging import version
            except ImportError as exc:
                if not allow_missing_env:
                    return False, dependency_import_message("vllm", exc)
            else:
                if not allow_missing_env and version.parse(
                    vllm.__version__
                ) < version.parse(required_vllm_version):
                    return (
                        False,
                        f"{model_family.model_name} requires "
                        f"vLLM>={required_vllm_version}, current: {vllm.__version__}",
                    )
        if model_spec.model_format not in ["pytorch"]:
            return False, "vLLM embedding engine only supports pytorch format"
        prefix = model_family.model_name.split("-", 1)[0]
        if prefix not in SUPPORTED_MODELS_PREFIXES:
            return (
                False,
                f"Model family {model_family.model_name} is not in the supported model prefix list for vLLM embeddings",
            )
        return True

    def stop(self):
        if self._native_pooling and self._model is not None:
            self._model.shutdown()

    def wait_for_load(self):
        if self._native_pooling:
            return
        # set context length after engine inited
        self._set_context_length()

    def _set_context_length(self):
        """Set context length"""
        from packaging import version
        from vllm import __version__ as vllm_version
        from vllm import envs

        # For vLLM >= 0.11.1, v1 is default; older versions rely on env var.
        if version.parse(vllm_version) > version.parse("0.11.0"):
            use_v1 = True
        else:
            use_v1 = False
            if hasattr(envs, "VLLM_USE_V1"):
                try:
                    use_v1 = envs.is_set("VLLM_USE_V1") and envs.VLLM_USE_V1
                except AttributeError:
                    use_v1 = False

        if not use_v1:
            # v0
            self._context_length = (
                self._model.llm_engine.vllm_config.model_config.max_model_len
            )
        else:
            # v1
            logger.warning("vLLM v1 is not supported, ignore context length setting")
        logger.debug("Model context length: %s", self._context_length)
