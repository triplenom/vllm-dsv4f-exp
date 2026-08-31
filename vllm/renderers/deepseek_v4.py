# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM project

from vllm.config import VllmConfig
from vllm.entrypoints.chat_utils import (
    MODALITY_PLACEHOLDERS_MAP,
    ChatCompletionMessageParam,
    ConversationMessage,
    parse_chat_messages,
    parse_chat_messages_async,
)
from vllm.tokenizers.deepseek_v4 import DeepseekV4Tokenizer
from vllm.utils.async_utils import make_async

from .base import BaseRenderer
from .inputs import DictPrompt
from .inputs.preprocess import parse_dec_only_prompt
from .params import ChatParams

# parse_chat_messages(content_format="string") inlines the framework's
# generic "<##IMAGE##>" marker at each image position; DeepSeek's official
# message encoding (encoding/encoding_dsv4.py,
# ``distribute_image_placeholder``) uses ``<｜deepseek_image｜>`` instead.
# Swap the markers before the chat template runs so the placeholder survives
# tokenization as a single special token; the mm processor later expands
# each placeholder into the full synthetic image block.
#
# NOTE: keep this constant in sync with IMAGE_PLACEHOLDER in
# vllm/models/deepseek_v4/image_processing.py (the model package pulls in
# CUDA/Triton modules, so it must not be imported from the renderer).
IMAGE_PLACEHOLDER = "<｜deepseek_image｜>"
_FRAMEWORK_IMAGE_PLACEHOLDER = MODALITY_PLACEHOLDERS_MAP["image"]


def _substitute_image_placeholders(
    conversation: list[ConversationMessage],
) -> None:
    for msg in conversation:
        content = msg.get("content")
        if isinstance(content, str) and _FRAMEWORK_IMAGE_PLACEHOLDER in content:
            msg["content"] = content.replace(
                _FRAMEWORK_IMAGE_PLACEHOLDER, IMAGE_PLACEHOLDER
            )


class DeepseekV4Renderer(BaseRenderer[DeepseekV4Tokenizer]):
    def __init__(
        self,
        config: VllmConfig,
        tokenizer: DeepseekV4Tokenizer | None,
    ) -> None:
        super().__init__(config, tokenizer)

        self._apply_chat_template_async = make_async(
            self._apply_chat_template, executor=self._executor
        )

    def _apply_chat_template(self, *args, **kwargs):
        return self.get_tokenizer().apply_chat_template(*args, **kwargs)

    def render_messages(
        self,
        messages: list[ChatCompletionMessageParam],
        params: ChatParams,
    ) -> tuple[list[ConversationMessage], DictPrompt]:
        conversation, mm_data, mm_uuids = parse_chat_messages(
            messages,
            self.model_config,
            content_format="string",
            media_io_kwargs=params.media_io_kwargs,
            mm_processor_kwargs=params.mm_processor_kwargs,
        )
        _substitute_image_placeholders(conversation)

        prompt_raw = self._apply_chat_template(
            conversation=conversation,
            messages=messages,
            **params.get_apply_chat_template_kwargs(),
        )

        prompt = parse_dec_only_prompt(prompt_raw)
        if mm_data is not None:
            prompt["multi_modal_data"] = mm_data
        if mm_uuids is not None:
            prompt["multi_modal_uuids"] = mm_uuids

        return conversation, prompt

    async def render_messages_async(
        self,
        messages: list[ChatCompletionMessageParam],
        params: ChatParams,
    ) -> tuple[list[ConversationMessage], DictPrompt]:
        conversation, mm_data, mm_uuids = await parse_chat_messages_async(
            messages,
            self.model_config,
            content_format="string",
            media_io_kwargs=params.media_io_kwargs,
            mm_processor_kwargs=params.mm_processor_kwargs,
        )
        _substitute_image_placeholders(conversation)

        prompt_raw = await self._apply_chat_template_async(
            conversation=conversation,
            messages=messages,
            **params.get_apply_chat_template_kwargs(),
        )

        prompt = parse_dec_only_prompt(prompt_raw)
        if mm_data is not None:
            prompt["multi_modal_data"] = mm_data
        if mm_uuids is not None:
            prompt["multi_modal_uuids"] = mm_uuids

        return conversation, prompt
