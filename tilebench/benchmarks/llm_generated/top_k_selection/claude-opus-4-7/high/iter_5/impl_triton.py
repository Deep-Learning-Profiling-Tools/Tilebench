import torch
import triton
import triton.language as tl

_LAST_CFG: dict = {}


@triton.jit
def _topk_stage_kernel(in_ptr, out_ptr, N_IN,
                       K: tl.constexpr, CHUNK: tl.constexpr):
    pid = tl.program_id(0)
    offs = pid * CHUNK + tl.arange(0, CHUNK)
    mask = offs < N_IN
    x = tl.load(in_ptr + offs, mask=mask, other=-float('inf'))
    sorted_x = tl.sort(x, descending=True)
    idx = tl.arange(0, CHUNK)
    store_offs = pid * K + idx
    tl.store(out_ptr + store_offs, sorted_x, mask=idx < K)


def run(input: torch.Tensor, N: int, k: int, **kwargs):
    assert input.is_cuda
    assert input.dtype == torch.float32
    output = torch.empty(k, dtype=torch.float32, device=input.device)

    # Use a larger CHUNK to reduce the number of sequential launches.
    # For N=1M k=1024: stages = 128->16->2->1 (4 launches) vs CHUNK=4096's 5 launches.
    CHUNK = 8192
    num_warps = 32
    num_stages = 2

    stages = []
    cur_size = N
    while True:
        num_blocks = (cur_size + CHUNK - 1) // CHUNK
        if num_blocks <= 1:
            stages.append((cur_size, k, 1))
            break
        next_size = num_blocks * k
        stages.append((cur_size, next_size, num_blocks))
        cur_size = next_size

    max_inter = k
    for _, out_size, num_blocks in stages:
        if num_blocks > 1:
            max_inter = max(max_inter, out_size)

    if len(stages) > 1:
        buf_a = torch.empty(max_inter, dtype=torch.float32, device=input.device)
        buf_b = torch.empty(max_inter, dtype=torch.float32, device=input.device)
    else:
        buf_a = buf_b = None

    src = input
    use_a = True
    for in_size, out_size, num_blocks in stages:
        if num_blocks == 1:
            dst = output
        else:
            dst = buf_a if use_a else buf_b
        _topk_stage_kernel[(num_blocks,)](
            src, dst, in_size,
            K=k, CHUNK=CHUNK,
            num_warps=num_warps, num_stages=num_stages,
        )
        src = dst
        use_a = not use_a

    _LAST_CFG.clear()
    _LAST_CFG.update({"CHUNK": CHUNK, "num_warps": num_warps, "num_stages": num_stages})
    return output


def get_last_config() -> dict | None:
    return dict(_LAST_CFG) if _LAST_CFG else None
