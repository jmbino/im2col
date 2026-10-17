# Explicit im2col convolution core

This project implements signed convolution (cross-correlation) using a square
systolic array. Before computation, the MMU materializes the full im2col matrix
in per-channel scratch SRAMs. The core then runs the array for each spatial
kernel tap and accumulates partial results in output SRAM. Each PE
has two stationary weight registers: one supplies the current tap while the
other receives the next tap from the kernel SRAM.

## Logical tensor shapes

These shapes describe convolution dimensions and coordinates independently of
how values are stored in tensor files or SRAM.

| Tensor | Logical shape | Coordinates |
|---|---|---|
| Input | `(N,C,H,W)` | `(n,c,h,w)` |
| Kernel | `(K,C,R,S)` | `(k,c,r,s)` |
| Output | `(N,K,P,Q)` | `(n,k,p,q)` |

The core processes `N` images per start, all using the same kernel. Images
are interleaved within each tap. Logical channel counts satisfy
`1 <= C,K <= ARRAY_SIZE`; `N` is positive and limited by SRAM capacity.

## Runtime configuration

| Setting | Interface |
|---|---|
| Runtime dimensions | `cfg_N`, `cfg_C`, `cfg_K`, `cfg_H`, `cfg_W`, `cfg_R`, `cfg_S`, `cfg_P`, `cfg_Q` |
| Runtime padding | `cfg_pad_i`, `cfg_pad_j` |
| Runtime stride | `cfg_stride_i`, `cfg_stride_j` |
| Runtime dilation | `cfg_dilation_i`, `cfg_dilation_j` |
| Fixed hardware parameters | `ARRAY_SIZE`, `BIT_WIDTH`, `ACC_WIDTH`, `ADDR_WIDTH`, `KERNEL_ADDR_WIDTH`, `CFG_WIDTH` |

Configuration ports are unsigned `CFG_WIDTH`-bit values, defaulting to 32 bits.
The core captures all configuration into registers on the rising edge that
accepts `start` while idle. Changing the ports during a run does not affect
that run. They are direct RTL ports; the design has no register-bus interface.

`i` is the height axis; `j` is the width axis. Padding is symmetric within each
axis. Software supplies `P,Q` consistent with the geometry:

```text
extent_i = dilation_i*(R-1) + 1
extent_j = dilation_j*(S-1) + 1
P = floor((H + 2*pad_i - extent_i) / stride_i) + 1
Q = floor((W + 2*pad_j - extent_j) / stride_j) + 1
```

Dimensions, stride, and dilation are positive; padding is nonnegative. The
dilated kernel fits within the padded input. Configuration and tensor contents
must fit the fixed memory capacities. Kernel coordinates use `CFG_WIDTH` bits.

## Tensor-file and SRAM storage layouts

| Tensor | Tensor-file order | SRAM array | Within-array order | SRAM address |
|---|---|---|---|---|
| Input | NCHW | Input array `c` | HWN | `(h*W+w)*N+n` |
| Kernel | KCRS | Kernel array `k` | CRS | `(c*R+r)*S+s` |
| Output | NKPQ | Output array `k` | PQN | `(p*Q+q)*N+n` |

In each storage order, the rightmost coordinate varies fastest. Tensor files
contain hexadecimal values in the logical dimension order. The testbench
rearranges inputs into the per-channel SRAM layout and exports outputs in
NKPQ order.
Kernel-file values map to kernel array `k`, with `(c,r,s)` varying within
that array.

Within each input or output SRAM array, images are interleaved with `n`
varying fastest.
For `N=2`, input SRAM array `c` starts with logical `(n,c,h,w)` coordinates
`(0,c,0,0)`, `(1,c,0,0)`, `(0,c,0,1)`, `(1,c,0,1)`, and so on.
Inputs and outputs occupy separate SRAM arrays, each starting at address zero.
Outputs use the same image-minor ordering. Each SRAM word contains one value.

The physical storage has fixed array counts and depths. The logical tensor
shapes are runtime values; they determine which SRAM arrays and addresses
are used.

## Modules

| Module | Responsibility |
|---|---|
| `im2col_addr_gen` | Source address and padding validity while building the explicit matrix. |
| `MAC` | Registered signed multiply-accumulate with two stationary weight registers. |
| `MMU` | Explicit matrix build sequencing, matrix read addresses, and PE wiring. |
| `channel_bank` | Owns input, im2col scratch, and output SRAMs. |
| `activation_feeder` | Row skew, synchronous scratch-read alignment, and activation gating. |
| `output_accumulator` | Owns the writeback counter, addresses, and accumulation across taps. |
| `systolic_array` | PE grid, weight forwarding, and registered column outputs. |
| `kernel_bank` | One output channel’s kernel SRAM and synchronous read interface. |
| `weight_loader` | Kernel read addresses and initial/background weight shifting. |
| `row_sram` | Parameterized SRAM model with one write port and one synchronous read port. |
| `conv_core` | Runtime configuration registers and module wiring. |
| `conv_controller` | Matrix-build startup, tap sequencing, pass timing, and active weight-buffer selection. |

The hardware hierarchy is:

```text
conv_core                       Configuration capture and module wiring
├── conv_controller             Tap sequencing and run control
├── weight_loader               Initial and background weight loading
├── kernel_bank × ARRAY_SIZE    Kernel storage
└── MMU                         Address generation and stream position
    ├── im2col_addr_gen
    ├── channel_bank × ARRAY_SIZE
    │   ├── activation_feeder
    │   ├── output_accumulator
    │   ├── row_sram             Input storage, BIT_WIDTH bits
    │   └── row_sram             Output/partial sums, ACC_WIDTH bits
    └── systolic_array
        └── MAC × ARRAY_SIZE²
```

Each `channel_bank` instance owns three independent SRAM arrays. External writes
preload its input SRAM. During the build phase, the MMU reads those raw inputs
and writes the channel's patch rows into the im2col scratch SRAM. During compute,
the activation feeder reads the materialized matrix. The output accumulator
reads and writes the output SRAM. Input and output channels at a physical lane
are enabled independently by `C` and `K`.
The MMU's `u_im2col_sram` is separate from the raw input SRAM, so building the
expanded matrix never overwrites the preloaded input tensor.
The weight loader owns the descending row counter and prefetch/shift phases.
The convolution controller owns tap coordinates, run timing, and active
weight-buffer selection. Each activation feeder adds one stage to the shared
row-skew chain (row zero has no delay), then aligns validity with its SRAM read.
Each output accumulator owns its writeback counter and output pointer.

## Explicit im2col construction and array operation

### Matrix construction

After `start`, the controller holds the array idle while the MMU visits flattened
reduction rows `d` and output positions `m`. The logical matrix has shape
`(C*R*S, N*P*Q)`. Rows are stored in `C` scratch banks; each channel bank keeps
its `R*S` rows contiguously:

```text
n = m % N
pix = m / N
p = pix / Q
q = pix % Q
c = d / (R*S)
r = (d / S) % R
s = d % S
h = p*stride_i + r*dilation_i - pad_i
w = q*stride_j + s*dilation_j - pad_j
input_addr = (h*W+w)*N+n
im2col_addr = (r*S+s)*(N*P*Q)+m  // in scratch bank c
```

`im2col_addr_gen` converts `(m,r,s)` to the raw input address. The synchronous
input read and scratch write are pipelined; invalid `(h,w)` coordinates are
written as zero. The builder writes every matrix element before kernel loading
and compute begin. The scratch address width is `ADDR_WIDTH+KERNEL_ADDR_WIDTH`,
which covers the largest legal product of output positions and kernel area.

### Matrix reads and array operation

For tap `(r,s)`, the stream reads row `c*R*S+r*S+s` from each active channel
bank and visits all output positions in image-minor order. The MMU presents the
next scratch address one cycle ahead of activation feeding for synchronous SRAM
reads. The existing `C`-row systolic schedule is preserved, but compute now
reads the fully materialized matrix instead of calculating input addresses in
every tap pass.

### Kernel addresses and weight loading

`weight_loader` generates the shared kernel SRAM read address:

```text
kernel_raddr = (c_read*R + kernel_r)*S + kernel_s
```

Every `kernel_bank` instance receives the same address. Instance `k` supplies
weight `(k,c_read,kernel_r,kernel_s)` from its independent SRAM array; `k` is
selected by the instance, not encoded in the address. Initial loading uses the
current tap `(r,s)`. Background loading during RUN uses `(next_r,next_s)` and
writes the inactive PE weight registers while the current tap computes.

Weights enter the top PE row and shift downward. The loader supplies channel
coordinates in descending physical-row order, from `ARRAY_SIZE-1` to zero,
so each weight reaches its corresponding row. Kernel reads are synchronous:
one PRIME or PREFETCH cycle fetches the first row before shifting begins.
During each shift, `c_load` identifies the row being loaded, while the SRAM
read requests the following row:

```text
c_read = (load_weights && c_load != 0) ? c_load-1 : c_load
```

The returned data is available for the next clock's weight shift. Reads for
`c_read >= C` or kernel instances `k >= K` return zero. The loader performs
`ARRAY_SIZE` shifts even when fewer input channels are active. There is no
background preload after the final tap.

### Array operation and writeback

PE row `c` consumes input channel `c`; PE column `k` produces output channel
`k`. Activations move right and partial sums move down. The MMU
prefetches for the one-cycle SRAM read latency. Activation feeders form a shared
chain that delays the feed bundle by `c` cycles for row `c`. The bottom physical
row supplies registered column results. Rows `c >= C` receive zero activations and weights; columns
`k >= K` receive zero weights and have writeback disabled. The physical array
is `ARRAY_SIZE` by `ARRAY_SIZE`. Internal activation, weight, and partial-sum
connections are unpacked arrays of separate word-sized PE nets. Each column
has a registered output from the bottom physical row.

A direct MMU caller pulses `build_start`, holds `build_active` high until
`build_done`, then keeps its configuration, `(r,s)`, and `accumulate` stable throughout each pass,
loads weights across all physical rows in descending row order, and runs each
pass for `N*P*Q+2*ARRAY_SIZE` cycles. The first tap overwrites
outputs; later taps use `accumulate=1`. Writeback writes exactly `N*P*Q` words
per active column. Feed enables stop after the configured output positions,
while the physical pipeline drains. The caller controls pass duration and
asserts `clear_pass` between passes to clear counters and partial sums.
`load_weights` shifts weights into the register selected by `weight_write_buffer`;
`weight_read_buffer` selects the register used for multiplication. Loading and
computation are independent. A manual caller can hold both buffer selectors at
zero and assert `clear_pass` during loading. `conv_core` handles these steps internally.

## Memory layout and precision

There are `ARRAY_SIZE` input SRAM arrays, `ARRAY_SIZE` im2col scratch SRAMs,
`ARRAY_SIZE` output SRAM arrays, and `ARRAY_SIZE` kernel SRAM arrays:
`4*ARRAY_SIZE` modeled memories in total.
Runtime `C,K` select active channels; they do not change the physical array count.
Each PE also has two `BIT_WIDTH` stationary weight registers, totaling
`2*ARRAY_SIZE*ARRAY_SIZE` weight words, separate from kernel SRAM and the
registered weight-forwarding chain. Memories are RTL arrays without instantiated
physical SRAM macros. Each input/output/scratch SRAM has one write port and one
synchronous read port.

| Memory | Word width | Depth per array | Required words per active array |
|---|---|---|---|
| Input SRAM | `BIT_WIDTH` | `2**ADDR_WIDTH` | `N*H*W` |
| Im2col scratch SRAM | `BIT_WIDTH` | `2**(ADDR_WIDTH+KERNEL_ADDR_WIDTH)` | `R*S*N*P*Q` per channel |
| Output/partial-sum SRAM | `ACC_WIDTH` | `2**ADDR_WIDTH` | `N*P*Q` |
| Kernel SRAM | `BIT_WIDTH` | `2**KERNEL_ADDR_WIDTH` | `C*R*S` |

Inputs and outputs each start at address zero in their own memories. The input
and output capacities apply independently. Addresses and tensor-file orders are listed in
[Tensor-file and SRAM storage layouts](#tensor-file-and-sram-storage-layouts).
Every job uses the kernels preloaded for its configured shape.

Activations and weights are signed `BIT_WIDTH` values. Input SRAM stores the
operand-width bits directly. Products, partial sums, output writes, and
cross-tap accumulation use `ACC_WIDTH` bits and wrap at that width.
Use `ACC_WIDTH >= BIT_WIDTH`. The output SRAM read port prefetches the previous
output value one cycle ahead of read-modify-write accumulation across taps.

## Running the core

1. Assert `nrst=0` across a rising clock edge, then release reset.
2. While `busy=0`, preload inputs using `sram_we_ext`, `sram_waddr_ext`,
   and `sram_wdata_ext`.
3. Preload kernels using `kernel_we_ext`, `kernel_waddr_ext`, and
   `kernel_wdata_ext`.
4. Drive all `cfg_*` ports, including the derived `P,Q`, and pulse `start`
   for one clock cycle.
5. Wait for the one-cycle `done` pulse, then read results from the output planes.

External buses have `ARRAY_SIZE` lanes. Input writes use the first `C` lanes;
kernel writes and logical outputs use the first `K` lanes. External write
lanes are usable while idle before the configuration is captured.

The controller first spends `C*R*S*N*P*Q` cycles building im2col, followed by
two cycles to flush the input-read and scratch-write pipeline. It then visits
`s` within `r`. Before the first tap, one PRIME cycle fetches a synchronous
kernel read, then `ARRAY_SIZE` cycles shift its weights
in descending row order into PE buffer zero. Each tap runs for
`N*P*Q+2*ARRAY_SIZE` cycles. During RUN, one read-prefetch cycle followed by
`ARRAY_SIZE` weight shifts fills the inactive PE registers with the next tap,
while activations and partial sums continue advancing with the active weights.
The remaining RUN cycles drain the current tap's physical pipeline.

After a tap finishes, the controller selects the prepared weight buffer and
spends one SWITCH_TAP cycle clearing the pipeline and prefetching the new tap's
first activation. The final tap has no next-tap preload or switch cycle.
With `T=R*S`, completion occurs this many edges after the accepted start edge:

```text
cycles = 1 + ARRAY_SIZE + C*R*S*N*P*Q + 2
         + T*(N*P*Q + 2*ARRAY_SIZE) + (T-1)
```

The added term accounts for writing all `C*R*S` matrix rows across all
`N*P*Q` output positions before compute starts.
At completion, the physical array drain has ended, all logical outputs are
committed, `busy` drops, and `done` pulses.

Starts and external input/kernel writes are ignored while busy. Holding
`start` high launches another run when idle. Synchronous active-low reset
aborts a run and clears control state while retaining memory contents. Each
run overwrites outputs on its first tap. Jobs can use different configurations
without a reset or a new hardware build. `acc_col_out` exposes live pipeline
results; final results reside in output SRAM. The testbench reads SRAM through hierarchy;
the core has no external output readback port.

## Fixtures and simulation

The project has one testbench, `sim/tb_conv_core.v`, run through `run.sh`.
The Python runner supplies the same `N,C,H,W,K,R,S`, padding, stride, and
dilation arguments to the generator and testbench. Precision remains fixed in
`gen_matrices.py` and the testbench. Set physical `ARRAY_SIZE` independently,
with `ARRAY_SIZE >= max(C,K)`. The test assumes sane configuration and complete
input and kernel files.

```bash
python3 run_case.py --seed 0
```

`run_case.py` generates tensors, then runs the simulation. It shares its argument
names and defaults with `gen_matrices.py`; every geometry value is passed to
both programs. For example:

```bash
python3 run_case.py --N 2 --C 2 --H 5 --W 6 --K 3 --R 2 --S 3 \
  --pad_i 1 --pad_j 2 --stride_i 2 --stride_j 1 --dilation_i 2 --dilation_j 1
```

Both Python scripts accept `--N`, `--C`, `--H`, `--W`, `--K`, `--R`, `--S`,
`--pad_i`, `--pad_j`, `--stride_i`, `--stride_j`, `--dilation_i`, `--dilation_j`,
`--seed`, and `--out-dir`. Their defaults are declared at the top of
`gen_matrices.py`. The runner puts tensors, simulated outputs, and the SRAM
report in `--out-dir` (default `sim`). Use `--wave-file path` for a waveform.
Run either script with `--help` to list arguments.

The generator can also be used independently:

```bash
python3 gen_matrices.py --N 2 --seed 0
bash run.sh +N=2
```

The generator uses `conv_golden.py` and writes `sim/input_tensor.txt`,
`sim/kernel_tensor.txt`, and the Python reference `sim/output_tensor.txt`.
Files use NCHW/KCRS/NKPQ order and two's-complement hexadecimal values.

The testbench reads the input and kernel files, preloads interleaved input words
and kernel SRAM, drives configuration, and pulses `start`. The core controls
weight loading, tap sequencing, double buffering, and accumulation until `done`.
The testbench checks every output against its own signed convolution reference.

| Result | Destination |
|---|---|
| Start-to-done clock cycles | Terminal; excludes reset and external preloading |
| Useful PE count and percentage | Terminal; `C*K` out of `ARRAY_SIZE*ARRAY_SIZE` |
| Output tensor in NKPQ order | `sim/output_tensor_core.txt` |
| Every address in input, output, and kernel SRAM arrays | `sim/sram_layout.txt` |
| Output comparison result | Terminal |

The SRAM report includes hexadecimal values, signed decimal values, tensor
coordinates, unused locations, and inactive arrays. Uninitialized words appear
as `x`. It shows the actual SRAM contents after completion.

Shapes and geometry can be overridden with `+N=`, `+C=`, `+K=`, `+H=`, `+W=`,
`+R=`, `+S=`, `+pad_i=`, `+pad_j=`, `+stride_i=`, `+stride_j=`,
`+dilation_i=`, and `+dilation_j=`. The testbench computes `P,Q` automatically.
Its defaults are declared at the top of the testbench. For example, with
matching tensor files:

```bash
bash run.sh +N=2
```

File paths can be overridden with `+INPUT_FILE=path`, `+KERNEL_FILE=path`,
`+OUTPUT_FILE=path`, and `+SRAM_LAYOUT_FILE=path`. A waveform is generated when
`+WAVE_FILE=path` is supplied. To reuse a compiled simulation, pass these same
arguments to `vvp sim/tb_conv_core.vvp`.

## Case sweep

`test_cases.py` runs directed boundary cases and 100 seeded random configurations
through `run_case.py`. It reads the physical array size and SRAM capacities from
the testbench and generates configurations that fit. Cases cover batches, unequal
channel counts, padding, stride, dilation, rectangular kernels, and memory limits.

```bash
python3 test_cases.py
python3 test_cases.py --cases 500 --seed 42
python3 test_cases.py --cases 0 --limit 4
```

Each case compares the simulated tensor to the generated Python golden tensor,
checks its length and cycle count, and requires an SRAM report. Results go to
`sim/case_sweep`: each case retains configuration, tensors, SRAM contents and
`run.log`. `summary.json` lists failures and checked outputs. The script continues
after failures and exits unsuccessfully if any case fails. A case times out after
120 seconds; override with `--timeout`. Use `--out-dir` to select a results folder
or `--random-only` to skip directed cases. Cases run sequentially; each invokes
the existing compilation and simulation runner.

The sweep prints each case's channel utilization from the testbench and saves
it in `summary.json` alongside cycle counts and useful/total PE counts. This is
`100*C*K/ARRAY_SIZE**2`, the fraction of PEs assigned useful channels. It
measures channel occupancy, not activity over time; loading, pipeline fill/drain,
and padded input positions do not reduce this percentage.

## TODO

1. Currently, it is assumed that input tensors and kernel tensors fit in the SRAMs.
In reality, they probably will not. So a next step is tiling. We'll have to cover:
    a. the case for when the number of channels exceed the number of PE rows,
    b. the case for when the number of kernels exceed the number of PE columns,
    c. the case for when input/output data for an input/output channel don't fit in its SRAM bank,
    d. the case for when kernels don't fit in the kernel SRAM banks
    e. proper accumulation across those cases
3. Other AI accelerator things such as:
    a. host control interface
    b. off-chip memory where entire input tensors & kernel tensors live & where final outputs go
       - need a hardware interface for this as well, a DMA.
    c. layer chaining
    d. bias, requantization, nonlinear activation, pooling, etc.

And deciding which of #2 we offload to the host

## Credits

https://github.com/kaggar11/systolic_4x4arr 
    
- Code was initially based on this. It's pretty much a Ship of Theseus thing now at this point since the only recognizable parts are the PE and the PE array buses but still worth acknowledging.

"Characterizing and Demystifying the Implicit Convolution Algorithm on Commercial Matrix-Multiplication Accelerators" by
Zhou et al.
- https://doi.org/10.48550/arXiv.2110.03901 
- Channel-first implicit im2col algorithm and TPU architecture taken from here.

# Note on AI-use

Codex and GPT-6.1 Sol was used to assist in the creation of this project.
