<!-- Converted from snapdragon-npu-partitioner.md.pdf — 1 pages -->

## Page 1

---name: snapdragon-npu-partitioner description: Validates and configures large LLMs for Qualcomm Hexagon NPU multi-device execution. triggers: - "run model on npu" - "partition llm weights" - "configure htp execution" inputs: model_path: string context_length: integer tools_required: - terminal_exec - file_inspector ---
# Operating Instructions
1. **Inspect Model Footprint:** - Query the target model size in gigabytes. - Calculate estimated KV Cache: `(2 * layers * heads * head_dim * context_len * precision)`.
2. **Evaluate Process Domain (PD) Allocation:** - Total Memory = `Model Size + KV Cache Overhead`. - If Total Memory <= 3.2 GB: Allocate single domain (`D=HTP0`). - If 3.2 GB < Total Memory <= 6.5 GB: Allocate dual domain (`D=HTP0,HTP1`). - If Total Memory > 6.5 GB: Enforce 3-way split (`D=HTP0,HTP1,HTP2`) or offload embedding heads to CPU/GPU.
3. **Verify Runtime Environment:** - Check presence of `libQnnHtp.so` or `libggml-htp.so` in dynamic linker path. - Confirm `/dev/adsprpc-smd` (FastRPC character device) is accessible with read/write permissions.
4. **Emit Verified Run Command:** - Return the exact execution flags to the executor daemon without manual user intervention.