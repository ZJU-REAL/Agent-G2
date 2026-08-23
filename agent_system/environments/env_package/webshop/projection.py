# Copyright 2025 Nanyang Technological University (NTU), Singapore
# and the verl-agent (GiGPO) team.
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

from typing import List
import re

INVALID_WEBSHOP_ACTION = "__invalid__"
INTERNAL_SEARCH_PREFIXES = {"<a>", "<c>", "<q>", "<r>"}


def _is_valid_webshop_action(action: str) -> bool:
    if action.startswith("click[") and action.endswith("]"):
        return action[6:-1].strip() != ""

    if action.startswith("search[") and action.endswith("]"):
        query = action[7:-1].strip()
        if not query:
            return False
        first_token = query.split(maxsplit=1)[0]
        return first_token not in INTERNAL_SEARCH_PREFIXES

    return False


def webshop_projection(actions: List[str]):
    """
    A function to process the actions.
    actions: the list of actions to be processed, it is a list of strings.
    Expected format:
        <think>some reasoning...</think><action>search[keywords]</action>
        <think>some reasoning...</think><action>click[value]</action>
    """

    valids = [0] * len(actions)

    for i in range(len(actions)):
        original_str = actions[i]  # keep the original string
        actions[i] = actions[i].lower()

        # Attempt to extract the substring within <action>...</action>
        start_tag = "<action>"
        end_tag = "</action>"
        start_idx = actions[i].find(start_tag)
        end_idx = actions[i].find(end_tag)
        try:
            if start_idx == -1 or end_idx == -1:
                # If we can't find a valid <action>...</action> block, mark as invalid
                actions[i] = INVALID_WEBSHOP_ACTION
                continue

            # Extract just the content between the tags
            extracted_action = actions[i][start_idx + len(start_tag):end_idx].strip().lower()
            
            actions[i] = extracted_action
            valids[i] = 1

        except:
            actions[i] = INVALID_WEBSHOP_ACTION

        if not _is_valid_webshop_action(actions[i]):
            actions[i] = INVALID_WEBSHOP_ACTION
            valids[i] = 0

        # check <think>...</think>
        think_start_idx = original_str.find("<think>")
        think_end_idx = original_str.find("</think>")
        if think_start_idx == -1 or think_end_idx == -1:
            valids[i] = 0

        # check if contains any Chinese characters
        if re.search(r'[\u4e00-\u9fff]', original_str):
            valids[i] = 0

    return actions, valids
