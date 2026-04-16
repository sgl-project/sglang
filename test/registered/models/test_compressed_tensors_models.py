# Model tests for compressed tensors (FP8)

import unittest
from types import SimpleNamespace

from sglang.srt.utils import is_hip, kill_process_tree
from sglang.test.ci.ci_register import register_amd_ci, register_cuda_ci
from sglang.test.few_shot_gsm8k import run_eval
from sglang.test.test_utils import (
    DEFAULT_TIMEOUT_FOR_SERVER_LAUNCH,
    DEFAULT_URL_FOR_TEST,
    CustomTestCase,
    popen_launch_server,
)

register_cuda_ci(est_time=42, suite="stage-b-test-large-1-gpu")
register_amd_ci(est_time=42, suite="stage-b-test-small-1-gpu-amd")


class TestCompressedTensorsLlama3FP8(CustomTestCase):
    @classmethod
    def setUpClass(cls):
        cls.model = "RedHatAI/Meta-Llama-3.1-8B-FP8"
        cls.base_url = DEFAULT_URL_FOR_TEST
        cls.process = popen_launch_server(
            cls.model,
            cls.base_url,
            timeout=DEFAULT_TIMEOUT_FOR_SERVER_LAUNCH,
            other_args=[],
        )

    @classmethod
    def tearDownClass(cls):
        kill_process_tree(cls.process.pid)

    def test_gsm8k(self):
        args = SimpleNamespace(
            num_shots=5,
            data_path=None,
            num_questions=200,
            max_new_tokens=512,
            parallel=128,
            host="http://127.0.0.1",
            port=int(self.base_url.split(":")[-1]),
        )
        metrics = run_eval(args)
        print(f"{metrics=}")
        if is_hip():
            # Lower threshold for AMD because FP8 dtype differs (fp8_fnuz)
            self.assertGreaterEqual(metrics["accuracy"], 0.40)
        else:
            self.assertGreaterEqual(metrics["accuracy"], 0.45)


if __name__ == "__main__":
    unittest.main()
