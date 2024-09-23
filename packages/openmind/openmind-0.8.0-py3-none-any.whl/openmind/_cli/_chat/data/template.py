# Copyright 2024 the LlamaFactory team.
# Copyright (c) 2024 Huawei Technologies Co., Ltd.
#
# This code is inspired by the LLaMA-Factory.
# https://github.com/hiyouga/LLaMA-Factory/blob/main/src/llamafactory/data/template.py
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.


from dataclasses import dataclass
from typing import List, Sequence, Dict, Tuple, Optional

from transformers import PreTrainedTokenizer

from .data_utils import Role, SLOTS
from ....utils import replace_invalid_characters, logging
from .formatter import Formatter, EmptyFormatter, StringFormatter, FunctionFormatter, ToolFormatter

logger = logging.get_logger()
logging.set_verbosity_info()


@dataclass
class Template:
    format_user: "Formatter"
    format_assistant: "Formatter"
    format_system: "Formatter"
    format_function: "Formatter"
    format_tools: "Formatter"
    format_separator: "Formatter"
    format_prefix: "Formatter"
    default_system: str
    stop_words: List[str]
    efficient_eos: bool
    replace_eos: bool

    def encode(
        self, tokenizer: "PreTrainedTokenizer", messages: Sequence[Dict[str, str]]
    ) -> Tuple[List[int], List[int]]:
        encoded_messages = self._encode(tokenizer, messages)

        prompt_ids = []
        for encoded_ids in encoded_messages[:-1]:
            prompt_ids += encoded_ids

        answer_ids = encoded_messages[-1]

        return prompt_ids, answer_ids

    def _encode(
        self,
        tokenizer: "PreTrainedTokenizer",
        messages: Sequence[Dict[str, str]],
    ) -> List[List[int]]:
        encoded_messages = []

        for idx, msg in enumerate(messages):
            elements = []

            if idx == 0:
                elements += self.format_prefix.apply()
                if self.default_system:
                    elements += self.format_system.apply(content=self.default_system)

            if idx > 0 and idx % 2 == 0:
                elements += self.format_separator.apply()

            if msg["role"] == Role.USER.value:
                elements += self.format_user.apply(content=msg["content"], idx=str(idx // 2))
            elif msg["role"] == Role.ASSISTANT.value:
                elements += self.format_assistant.apply(content=msg["content"])
            elif msg["role"] == Role.FUNCTION.value:
                elements += self.format_function.apply(content=msg["content"])
            else:
                err_msg = f"Unexpected role: {msg['role']}"
                raise NotImplementedError(replace_invalid_characters(err_msg))

            encoded_messages.append(convert_elements_to_ids(tokenizer, elements))

        return encoded_messages


def register_template(
    name: str,
    format_user: Optional["Formatter"] = None,
    format_assistant: Optional["Formatter"] = None,
    format_system: Optional["Formatter"] = None,
    format_function: Optional["Formatter"] = None,
    format_tools: Optional["Formatter"] = None,
    format_separator: Optional["Formatter"] = None,
    format_prefix: Optional["Formatter"] = None,
    default_system: str = "",
    stop_words: List[str] = [],
    efficient_eos: bool = False,
    replace_eos: bool = False,
) -> None:
    eos_slots = [] if efficient_eos else [{"eos_token"}]
    default_user_formatter = StringFormatter(slots=["{{content}}"])
    default_assistant_formatter = StringFormatter(slots=["{{content}}"] + eos_slots)
    default_function_formatter = FunctionFormatter(slots=eos_slots, tool_format="default")
    default_tool_formatter = ToolFormatter(tool_format="default")
    default_separator_formatter = EmptyFormatter()
    default_prefix_formatter = EmptyFormatter()
    TEMPLATES[name] = Template(
        format_user=format_user or default_user_formatter,
        format_assistant=format_assistant or default_assistant_formatter,
        format_system=format_system or default_user_formatter,
        format_function=format_function or default_function_formatter,
        format_tools=format_tools or default_tool_formatter,
        format_separator=format_separator or default_separator_formatter,
        format_prefix=format_prefix or default_prefix_formatter,
        default_system=default_system,
        stop_words=stop_words,
        efficient_eos=efficient_eos,
        replace_eos=replace_eos,
    )


TEMPLATES: Dict[str, Template] = {}


register_template(
    name="baichuan2",
    format_user=StringFormatter(slots=["<reserved_106>{{content}}<reserved_107>"]),
    efficient_eos=True,
)


def convert_elements_to_ids(tokenizer: "PreTrainedTokenizer", elements: "SLOTS") -> List[int]:
    token_ids = []

    for elem in elements:
        if isinstance(elem, str):
            if len(elem) != 0:
                token_ids += tokenizer.encode(elem, add_special_tokens=False)
        elif isinstance(elem, dict):
            token_ids += [tokenizer.convert_tokens_to_ids(elem.get("token"))]
        elif isinstance(elem, set):
            if "bos_token" in elem and tokenizer.bos_token_id is not None:
                token_ids += [tokenizer.bos_token_id]
            elif "eos_token" in elem and tokenizer.eos_token_id is not None:
                token_ids += [tokenizer.eos_token_id]
        else:
            err_msg = f"Input elements must be string, dict[str, str] or set[str], got {type(elem)}."
            raise ValueError(replace_invalid_characters(err_msg))

    return token_ids


def add_or_replace_eos_token(tokenizer: "PreTrainedTokenizer", eos_token: str) -> None:
    is_added = tokenizer.eos_token_id is None

    num_added_tokens = tokenizer.add_special_tokens({"eos_token": eos_token})

    if is_added:
        logger.info(f"Add eos token: {tokenizer.eos_token}")
    else:
        logger.info(f"Replace eos token: {tokenizer.eos_token}")

    if num_added_tokens > 0:
        logger.warning("New tokens have been added, make sure `resize_vocab` is True.")


def jinja_escape(content: str) -> str:
    return content.replace("'", r"\'")


def convert_slots_to_jinja(slots: "SLOTS", tokenizer: "PreTrainedTokenizer", placeholder: str = "content") -> str:
    slot_items = []

    for slot in slots:
        if isinstance(slot, str):
            slot_pieces = slot.split("{{content}}")
            if slot_pieces[0]:
                slot_items.append("'" + jinja_escape(slot_pieces[0]) + "'")
            if len(slot_pieces) > 1:
                slot_items.append(placeholder)
                if slot_pieces[1]:
                    slot_items.append("'" + jinja_escape(slot_pieces[1]) + "'")
        elif isinstance(slot, set):  # do not use {{ eos_token }} since it may be replaced
            if "bos_token" in slot and tokenizer.bos_token_id is not None:
                slot_items.append("'" + tokenizer.bos_token + "'")
            elif "eos_token" in slot and tokenizer.eos_token_id is not None:
                slot_items.append("'" + tokenizer.eos_token + "'")
        elif isinstance(slot, dict):
            raise ValueError("Dict is not supported.")

    return " + ".join(slot_items)


def get_jinja_template(template: "Template", tokenizer: "PreTrainedTokenizer") -> str:
    jinja_template = ""

    prefix = convert_slots_to_jinja(template.format_prefix.apply(), tokenizer)
    if prefix:
        jinja_template += "{{ " + prefix + " }}"

    if template.default_system:
        jinja_template += "{% set system_message = '" + jinja_escape(template.default_system) + "' %}"

    jinja_template += (
        "{% if messages[0]['role'] == 'system' %}{% set loop_messages = messages[1:] %}"
        "{% set system_message = messages[0]['content'] %}{% else %}{% set loop_messages = messages %}{% endif %}"
    )

    jinja_template += "{% for message in loop_messages %}"
    jinja_template += "{% set content = message['content'] %}"

    jinja_template += "{% if message['role'] == 'user' %}"
    user_message = convert_slots_to_jinja(template.format_user.apply(), tokenizer)
    jinja_template += "{{ " + user_message + " }}"

    jinja_template += "{% elif message['role'] == 'assistant' %}"
    assistant_message = convert_slots_to_jinja(
        template.format_assistant.apply() + template.format_separator.apply(), tokenizer
    )
    jinja_template += "{{ " + assistant_message + " }}"
    jinja_template += "{% endif %}"
    jinja_template += "{% endfor %}"
    return jinja_template
