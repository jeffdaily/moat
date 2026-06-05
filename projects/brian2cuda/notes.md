# brian2cuda notes

## HIP/ROCm Backend Implementation

This is a **runtime code generator** project (not Strategy A or B). The port adds HIP/ROCm support by:

1. Adding a CUDA-to-HIP compatibility header (`brianlib/cuda_to_hip.h`) that maps CUDA symbols to HIP equivalents at compile time
2. Modifying the device to detect HIP backend and generate HIP-compatible makefiles
3. Using `-fgpu-rdc` flag for relocatable device code (required for cross-TU device symbol linking)

### Build Instructions (linux-gfx90a)

```bash
# Install brian2cuda
cd projects/brian2cuda/src
pip install -e .

# Run with HIP backend (auto-detected when ROCm present and CUDA absent, or set explicitly)
export USE_HIP=1
export HIP_VISIBLE_DEVICES=0  # or 1 for second GPU

# Example test
python -c "
from brian2 import *
import brian2cuda
set_device('cuda_standalone', build_on_run=False)
G = NeuronGroup(100, 'dv/dt = -v/(10*ms) : 1', method='linear')
G.v = 'i / 100.'
run(1*ms)
device.build(directory='/tmp/brian2cuda_test', compile=True, run=True)
"
```

### Validated

- Platform: linux-gfx90a (MI250X)
- ROCm: 7.2.1
- Simple neuron group simulation matches expected values

## Review 2026-06-05

### Port Correctness

**Critical: Wave64 spin-lock deadlock hazard (spikequeue.h:25-32)**

The `CudaSpikeQueue` class uses an atomicCAS-based spin-lock pattern for semaphore acquire:

```cpp
__device__ void acquire_semaphore(volatile int *lock){
    while (atomicCAS((int *)lock, 0, 1) != 0);
}
```

This pattern DEADLOCKS on wave64 (CDNA/gfx90a). CUDA Volta+ has Independent Thread Scheduling, so a lane that wins the CAS makes forward progress even while its warp-siblings spin. CDNA has NO per-lane forward-progress guarantee within a wavefront -- the winner is stuck at SIMT reconvergence waiting on the losing lanes, which spin forever.

Per PORTING_GUIDE (line 282), the fix is to wave-serialize the lock under `USE_HIP`/`__HIP_DEVICE_COMPILE__`: elect one active lane of the wavefront at a time and let it fully acquire/run/release before the next. Example pattern from PORTING_GUIDE:

```cpp
int lane=__lane_id();
unsigned long long need=__ballot(1);
while(need){
    int L=__ffsll((long long)need)-1;
    if(lane==L){
        while(atomicCAS(m,0,1)!=0){}
        __threadfence();
        <critical section>;
        __threadfence();
        atomicExch(m,0);
    }
    need&=~(1ull<<L);
}
```

The plan.md correctly identified this risk (line 148: "atomicCAS -- atomic operations") but the port did not address it. The current spikequeue.h is unmodified from upstream.

The pattern is used in `push_synapses()` (line 326) and `push_bundles()` (line 484), both critical paths for synaptic propagation. This will hang simulations with synapses on gfx90a.

**Required action**: Implement wave-serialized locking in spikequeue.h, guarded by `#if defined(__HIP_PLATFORM_AMD__) || defined(USE_HIP)`.

### Other Findings

The rest of the port is sound:
- cuda_to_hip.h compat header correctly maps all used symbols
- Warp size is correctly queried at runtime via `props.warpSize` (objects.cu:363)
- makefile_hip template is correct with -fgpu-rdc for cross-TU device linking
- No MOAT jargon in upstream-visible text
- Commit message follows conventions (has [ROCm] prefix, mentions Claude, no noreply trailer)
- No hardcoded warp size 32 in kernel code (only runtime query)

### Recommendation

**Request Changes** -- the spin-lock deadlock is a blocking correctness bug that will hang synaptic simulations on wave64 GPUs.
