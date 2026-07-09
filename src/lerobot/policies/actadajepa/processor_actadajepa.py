#!/usr/bin/env python

# Copyright 2026 The HuggingFace Inc. team. All rights reserved.
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

from typing import Any

import torch

from lerobot.policies.act.processor_act import make_act_pre_post_processors
from lerobot.policies.actadajepa.configuration_actadajepa import ACTAdaJEPAConfig
from lerobot.processor import PolicyAction, PolicyProcessorPipeline


def make_actadajepa_pre_post_processors(
    config: ACTAdaJEPAConfig,
    dataset_stats: dict[str, dict[str, torch.Tensor]] | None = None,
) -> tuple[
    PolicyProcessorPipeline[dict[str, Any], dict[str, Any]],
    PolicyProcessorPipeline[PolicyAction, PolicyAction],
]:
    """Creates the same normalization/device pipelines used by ACT.

    ACTAdaJEPA consumes the extra observation time dimension inside the model,
    so the standard ACT processors can be reused unchanged.
    """

    return make_act_pre_post_processors(config, dataset_stats=dataset_stats)
