# Copyright 2026 Huawei Technologies Co., Ltd
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
# http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
# ============================================================================
"""Framework-free launchers for FP32 Muon relay and missing-gradient shards."""

from pathlib import Path

from tests.common.distributed_launcher import torchrun_case
from tests.common.mark_utils import arg_mark


_WORKER = str(Path(__file__).with_name("_test_muon_ns_precision.py"))


@arg_mark(plat_marks=["platform_ascend910b"], level_mark="level1",
          card_mark="allcards", essential_mark="essential")
def test_muon_fp32_ns_sharding() -> None:
    """Compare ten FP32 NS updates under full and hybrid eight-rank sharding."""
    torchrun_case(_WORKER, "test_muon_fp32_ns_sharding", num_proc=8)


@arg_mark(plat_marks=["platform_ascend910b"], level_mark="level1",
          card_mark="allcards", essential_mark="essential")
def test_muon_fp32_ns_missing_gradients() -> None:
    """Run real gathers and relays when one rank has no gradient or an empty shard."""
    torchrun_case(_WORKER, "test_muon_fp32_ns_missing_gradients", num_proc=2)
