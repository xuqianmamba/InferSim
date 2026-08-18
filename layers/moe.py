from flops.flops import gemm_flops
from hardware.gpu import TFLOPS_TO_GFLOPS, gpu_map
from layers.attn import get_gemm_mfu_and_latency, get_gemm_perf
from mfu.mfu import (get_gemm_mfu, get_groupedgemm_decode_mfu,
                     get_groupedgemm_prefill_mfu)
from params.params import get_expected_active_experts, load_moe_weights_time


class MoE:
    """
    MoE/FFN layer, dense FFN is treated as a special 1-expert MoE
    """

    def __init__(self, config, use_fp8_gemm, tp_size, prefill_mfu=None):
        self.use_fp8_gemm = use_fp8_gemm
        self.config = config
        self.tp_size = tp_size
        self.prefill_mfu = prefill_mfu

    def decode_moe(
        self,
        bs,
        device_type,
        num_gpus,
        overlap_shared_expert=False,
    ):
        gpu = gpu_map[device_type]

        # TP shards intermediate_size; hidden_size is NOT sharded
        tp_intermediate_size = self.config.intermediate_size // self.tp_size
        routed_experts_gflops = gemm_flops(
            1, self.config.hidden_size, tp_intermediate_size
        )
        routed_experts_gflops *= bs * self.config.num_experts_per_tok * 3.0 / 1e9

        if self.config.is_moe:
            routed_experts_mfu = max(
                get_groupedgemm_decode_mfu(
                    self.config, bs, device_type, num_gpus, self.use_fp8_gemm, self.tp_size
                )
            )
        else:  # Dense FFN is treated as a special 1-expert MoE
            routed_experts_mfu = get_gemm_mfu(
                device_type,
                bs,
                self.config.hidden_size,
                self.config.intermediate_size * 2 // num_gpus,
            )

        routed_experts_latency = routed_experts_gflops / (
            gpu.fp16_tflops * TFLOPS_TO_GFLOPS * routed_experts_mfu
        )
        if self.use_fp8_gemm:
            routed_experts_latency = routed_experts_gflops / (
                gpu.fp8_tflops * TFLOPS_TO_GFLOPS * routed_experts_mfu
            )

        active_experts = get_expected_active_experts(
            self.config, num_gpus, self.tp_size, bs
        )
        moe_load_time = load_moe_weights_time(
            self.config,
            self.use_fp8_gemm,
            gpu,
            num_gpus,
            self.tp_size,
            num_tokens=bs,
        )
        print("{:<40} {:<10.2f}".format("Routed experts/FFN MFU:", routed_experts_mfu))
        print("{:<40} {:<10.2f}".format("Expected active experts:", active_experts))
        print(
            "{:<40} {:<10.2f}".format(
                "Routed experts/FFN latency (us):", routed_experts_latency * 1e6
            )
        )
        print(
            "{:<40} {:<10.2f}".format(
                "Experts loading latency (us):", moe_load_time * 1e6
            )
        )
        t = max(routed_experts_latency, moe_load_time)

        if self.config.num_shared_experts > 0:
            # TP shards intermediate_size; hidden_size is NOT sharded
            shared_expert_up_mfu, shared_expert_up_proj = get_gemm_perf(
                m=bs,
                k=self.config.hidden_size,
                n=tp_intermediate_size * 2 * self.config.num_shared_experts,
                device_type=device_type,
                use_fp8_gemm=self.use_fp8_gemm,
            )

            shared_expert_down_mfu, shared_expert_down_proj = get_gemm_perf(
                m=bs,
                k=tp_intermediate_size * self.config.num_shared_experts,
                n=self.config.hidden_size,
                device_type=device_type,
                use_fp8_gemm=self.use_fp8_gemm,
            )
            shared_expert_latency = shared_expert_up_proj + shared_expert_down_proj
            print(
                "{:<40} {:<10.2f}".format(
                    "Shared expert latency (us):",
                    shared_expert_latency * 1e6,
                )
            )
            print(
                "{:<40} {:<10.3f}".format(
                    "Shared expert up-proj MFU:", shared_expert_up_mfu
                )
            )
            print(
                "{:<40} {:<10.3f}".format(
                    "Shared expert down-proj MFU:", shared_expert_down_mfu
                )
            )
            if overlap_shared_expert:
                t = max(t, shared_expert_latency)
                print("{:<40} {:<10}".format("Shared expert execution:", "overlap"))
            else:
                t += shared_expert_latency
                print("{:<40} {:<10}".format("Shared expert execution:", "serial"))
        return t

    def prefill_moe(self, seq_len, device_type, num_gpus):
        gpu = gpu_map[device_type]

        # TP shards intermediate_size; hidden_size is NOT sharded
        tp_intermediate_size = self.config.intermediate_size // self.tp_size
        routed_experts_gflops = gemm_flops(
            1, self.config.hidden_size, tp_intermediate_size
        )
        routed_experts_gflops *= seq_len * self.config.num_experts_per_tok * 3.0 / 1e9

        if self.prefill_mfu is not None:
            routed_experts_mfu = self.prefill_mfu
        elif self.config.is_moe:
            routed_experts_mfu = max(
                get_groupedgemm_prefill_mfu(
                    self.config, seq_len, device_type, num_gpus, self.use_fp8_gemm, self.tp_size
                )
            )
        else:  # Dense FFN is treated as a special 1-expert MoE
            routed_experts_mfu = get_gemm_mfu(
                device_type,
                seq_len,
                self.config.hidden_size,
                self.config.intermediate_size * 2 // num_gpus,
            )

        routed_experts_latency = routed_experts_gflops / (
            gpu.fp16_tflops * TFLOPS_TO_GFLOPS * routed_experts_mfu
        )
        if self.use_fp8_gemm:
            routed_experts_latency = routed_experts_gflops / (
                gpu.fp8_tflops * TFLOPS_TO_GFLOPS * routed_experts_mfu
            )

        moe_load_time = load_moe_weights_time(
            self.config, self.use_fp8_gemm, gpu, num_gpus, self.tp_size
        )
        print("{:<40} {:<10.2f}".format("Routed experts MFU:", routed_experts_mfu))
        print(
            "{:<40} {:<10.2f}".format(
                "Routed experts latency (us):", routed_experts_latency * 1e6
            )
        )
        print(
            "{:<40} {:<10.2f}".format(
                "Experts loading latency (us):", moe_load_time * 1e6
            )
        )
        t = max(routed_experts_latency, moe_load_time)

        if self.config.num_shared_experts > 0:
            # TP shards intermediate_size; hidden_size is NOT sharded
            shared_expert_up_proj = get_gemm_mfu_and_latency(
                m=seq_len,
                k=self.config.hidden_size,
                n=tp_intermediate_size * 2 * self.config.num_shared_experts,
                device_type=device_type,
                use_fp8_gemm=self.use_fp8_gemm,
            )

            shared_expert_down_proj = get_gemm_mfu_and_latency(
                m=seq_len,
                k=tp_intermediate_size * self.config.num_shared_experts,
                n=self.config.hidden_size,
                device_type=device_type,
                use_fp8_gemm=self.use_fp8_gemm,
            )
            print(
                "{:<40} {:<10.2f}".format(
                    "Shared expert latency (us):",
                    (shared_expert_up_proj + shared_expert_down_proj) * 1e6,
                )
            )
            t += shared_expert_up_proj + shared_expert_down_proj
        return t
