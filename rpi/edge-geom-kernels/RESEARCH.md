# Edge Geometry kernels, natively — research (2026-10-18)

Job module `jobmod_6d1c65171899` (image 209), loaded at LS 0x4000..0xF6B0, is
Edge Geometry: per mesh segment it decompresses vertexes and indexes, skins,
culls and compresses for the RSX. In the city profile it is the largest SPU
cost. This note covers the hot functions, what they compute, and the host
kernels in `work/port/edge_kernels_native.c` that replace them.

Words only, no game bytes: the module image, its listing and any LS dump stay
out of the repo (`work/runs/edge/` is untracked).

| LS | profile self | what | native | speedup (harness) |
|---|---|---|---|---|
| 0xD0A8 | 3.2% | skinning (+0x6E98 renormalise, 0.66%) | yes | 4.5-6.5x on 64..256 vertices |
| 0xA798 | 1.25% | triangle culling (+0xA3C8, 0.9%) | yes | 2.2-3.1x (whole call) |
| 0xA3C8 | 0.9% | transform for culling | yes | 3.5-4x |
| 0x4448 | 1.7% (14.2% of SPU time in Nov 2026, merged chunks) | vertex decompression, special formats | yes (section 5), opt-in | 4-6x on 64..300 vertices |
| 0x9C20 | 0.65% (5.5% in Nov 2026) | inner loop of vertex compression, format 1 | yes, as the chunk 0x99E8 (section 6), opt-in | 2.4-3.3x for the whole of 0x9780 |
| 0xC7B8 | 0.64% (2.7% of the module's samples, Oct 2026) | index decompression, the compressed triangle lists | yes (section 6.1), opt-in | 1.7-2.9x |

All numbers are best-of-N on the harness, lifted code built with the port's
SPU flags (`-O2 -march=x86-64-v4`), same machine, `nice -n 19`.

## 1. Method

### 1.1 The harness (`work/runs/edge/harness/`)

- `lifted.o` is the module's `spu_recomp.c` compiled with the port's SPU
  flags. `hrt.c` is a minimal runtime: function registry, `spu_drain_call`,
  `spu_indirect_branch`, and channel/stop stubs that flag a fault (only the
  error paths, which print through the mailbox at 0xE6C0, reach them).
  `hrt_call_lifted` calls a lifted function the way `brsl $r0` does (link
  0x3FFF0) and drains it.
- One test per kernel (`t_skin.c`, `t_xf.c`, `t_cull.c`): build a random but
  realistic LS (the module image at 0x4000, random bytes elsewhere, a job
  context with the fields the kernel reads, realistic matrices, positions,
  normals, triangles), run the lifted function on one copy and the native
  kernel on another, then compare **the whole LS and r0, r1, r80..r127**.
  Volatile registers are counted but not compared (section 1.4). The third
  argument is a float mutation rate in 1/1000: that share of the floats is
  replaced by 0, -0, denormals, FLT_MAX, exponent-255 values or random bits.
- `b_*.c` time one case (best of N runs); `t_replay.c` replays captured
  states (section 7.3); `mut.py` is the mutation check (section 7.2);
  `live.py` lists the volatile registers a caller reads after a call returns;
  `skin_v1.c` is the first, plain version of the skinning kernel (per vertex,
  through the u128 helpers) that pinned the semantics.
- Build: `./mk.sh skin xf cull replay`, `./mkb.sh skin`; `t_skin N 1 MUT SEED`.

### 1.2 The native-entry contract

`spu_native_entry` runs at the top of the lifted function, with the caller's
registers in `ctx->gpr`; a kernel that returns 1 has done the function's work
and the lift returns through `SPU_RET` (pc = r0). So a kernel must leave LS
and the registers as the function's epilogue would: these are compiled
functions with the standard ABI, so they save r80+ below the stack pointer,
store the link and the back chain, keep locals in their frame, and restore
r0 and r80+ from LS on the way out. The kernels write those stack slots too
(identical bytes), and reload r0/r80+ from LS at the end, as the epilogue does.

A kernel returns 0 **before writing anything** when the lifted function has
to run: the job's error paths (mailbox prints), a custom transform callback
(SPU code of the game's, section 4), unaligned or overlapping buffers (an
overlap guard checks every read and written span), sizes the job would loop
on forever (zero vertexes).

### 1.3 Floats

The lift computes every SPU float op through `runtime/spu/spu_helpers.h`.
The runtime defines `SPU_FP_DAZ`, and every entry into SPU code sets DAZ in
MXCSR (`spu_fp_enter`): the helpers then let the hardware read an exponent-0
operand as zero, as the SPU does, and test only for exponent 255. Tested over
1M random cases with denormals, signs and magnitudes mixed, **under that
caller MXCSR**: with MXCSR = round-toward-zero + flush-to-zero +
denormals-are-zero, a plain x86 `mul`/`fmadd`/`fmsub` gives the helper's
result exactly, after making exponent-0 results +0, as long as no operand has
exponent 255 and nothing overflows.

(The first version of the harness ran at the default MXCSR, where the helpers
take denormal operands at their value; the kernels followed that and differed
in game on the padding vertexes past the count, whose positions are garbage.
The harness now sets the SPU threads' MXCSR in `hrt_init`; section 7.4.)

So the fast paths run under that MXCSR and:

- check what each batch reads from the LS against a magnitude bound (the
  kernels' arithmetic is short and fixed, so a bound on inputs bounds every
  intermediate below FLT_MAX: skinning 2^18 (cofactors and renormalisation
  are the deepest: |s| < 3*(96 B^3)^2), the cull transform 2^60 plus a result
  check after the division by w, the cull 2^29 for valid triangles so the
  snapped coordinates stay int32);
- make outputs +0 where their exponent is 0. A zero's sign never reaches a
  nonzero value in these kernels (no division by a zero, compares treat both
  zeros alike), so intermediate zero signs do not matter;
- reproduce the integer estimate instructions (`frest`, `frsqest`, `fi`)
  bit for bit from the helpers' formulas; `fi(s, frsqest(s))` is folded into
  one step with two derived 64-entry tables;
- send a batch that fails the bound to an exact path: per vertex (or per
  group of four), the job's own lane layout, through the same helpers as the
  lift, at the caller's MXCSR.

The fast functions are `noinline` and MXCSR is written only outside them (the
compiler does not order float arithmetic against `ldmxcsr`; it cannot move it
out of a call).

### 1.4 Registers the callers see

Each kernel has one caller in the module (0x597C for 0xD0A8, 0x59EC for
0xA798, 0xAD40 for 0xA3C8). `live.py` from each return address: no volatile
register is read before it is written, except 0xA798's r3, the return value,
which the kernel sets exactly (the full quadword: a splat of the index count).
The callees met on the way (0xE200, 0x6E08, 0x64A8) take only r3/r4. So the
harness compares r0, r1, r3 where it is a result, and r80..r127.

## 2. 0xD0A8: skinning

Called once per segment, `r3` = the job context S (on the job's stack),
`r4` = matrix palette, `r5` = number of matrices, `r6` = per-vertex bone
indexes and weights.

### 2.1 Context fields it uses

- S+0 byte 0: flags. Bit 4: skip skinning entirely. Bit 7 must be set (the
  job's "skinning without an extra uniform table" error otherwise). Low
  nibble: which of the 16 uniform-table pointers at S+0x10 is the scratch.
- S+6 low nibble: skinning type. 1..3 are four-bone (no scaling, uniform,
  non-uniform), 4..6 the same with one bone. 0 or r5 = 0: return at once.
- S+7: matrix format. 0: 3x4 rows (48 bytes), 1: 4x4 rows (first three used),
  2: 4x4 columns, 3+: already in the job's layout.
- S+8: vertex count (u16). S+0x5C: positions. S+0x60: the "S60" stream;
  S+0x64..0x80: two lists of four stream pointers (normals, tangents...).
- S+0x58 (output): min(r4, r6), the first free byte.

### 2.2 What it does

1. Converts the palette in place to the job's layout: three quads per matrix
   holding the diagonal, the two off-diagonal rotations and the translation in
   lane 3 (q0 = (m00, m11, m22, t0), q1 = (m01, m12, m20, t1), q2 = (m02, m10,
   m21, t2)). With that layout a transform is three fmas on rotated copies of
   the vector (yzx, zxy), no transpose.
2. Builds the stream table on its stack: S60 first (when the type is not
   non-uniform), then each non-null pointer of the two lists, compacted. More
   than three: the job's "NYI" error.
3. Works in chunks: four vertices with the default scratch on its stack, or
   floor(n/3) rounded down to 4 in the extra uniform table (n = count rounded
   up to 4).
4. Per vertex: four-bone types blend `w_k * M[i_k]` row by row
   (fm, then fma for bones 1..3; weights are bytes, `cuflt` then `fm` by
   1/255; bytes alternate weight/index), one-bone types take the matrix as is.
   The matrix goes to the scratch with lane 3 replaced by 1, 0, 0; the
   position becomes `fma(zxy(p), C, fma(yzx(p), B, fma(p, A, T)))` in place.
5. Non-uniform types with S60 set transform S60 by the cofactor matrix
   (three `fms` of rotated products of A, B, C, then the same three-fma
   transform), the other streams by A, B, C without translation.
6. Types other than 1 and 4 renormalise every transformed stream (0x6E98):
   `v * (r, r, r, 1)` with `r = fi(s, frsqest(s))`, `s = z*z + (y*y + x*x)`,
   on the count rounded up to 8 (so up to 7 extra vectors are normalised).

The padding vertexes (count rounded up to 4) carry garbage indexes and
weights; they are transformed and written like the others. Their indexes can
point far past the palette (into the index stream and beyond), so the blend's
read span is checked against the written buffers only, not against the
palette conversion. A bone of weight 0 contributes nothing whatever matrix it
names (checked against the helpers: fm(+0, x) = +0 and fma(+0, x, a) =
fma(+0, 0, a) for every x), so the fast path gives it a zero matrix and only
weighted bones count for the palette range and its checks.

Everything is per vertex and in place; the job's loops are software pipelined
but read ahead only, so with the buffers disjoint (guarded) the native order is
free. The kernel fuses steps 4-5 per four vertices (matrices stay in
registers; they are still written to the scratch, chunk by chunk, so its final
contents match), and runs 6 as its own pass over 16 vectors at a time with one
estimate per 16. A zero vector, whose `s` is 0 and factor an exponent-255
value, gives (+0, +0, +0, w) on the SPU and does so in the fast path too.

## 3. 0xA3C8: transform for culling

`r3` = S. Positions (S+0x5C, rounded up to 4) go through the world matrix
(S+0xB0, 3x4) times the viewport info's 4x4 matrix (S+0xF0; the product is
taken in the prologue with the helpers), are divided by w (`frest`, `fi`, one
Newton step `fma(fnms(r, w, 1), r, r)`, and the sign of w xored back in, so it
is x/|w|), then scaled and offset (S+0x130, S+0x140). The scratch gets per
vertex (sx, sy, code, 0), code the outcode bits:
bit 7 sx > x1, 6 x0 > sx, 5 sy > y1, 4 y0 > sy, 3 sz > far, 2 near > sz,
1 w > 0 (x0, y0, x1 = x0 + w, y1 = y0 + h from the u16 scissor at S+0xE0,
near/far the smaller/larger of the two depth floats at S+0xE8). Compares are
SPU `fcgt` (both zeros equal). The job's loop is pipelined two deep; its fill
iterations store at offset 0 and are overwritten, except with 0 vertexes,
where the kernel falls back.

## 4. 0xA798: triangle culling

`r3` = S, `r4` = cull mode, `r5` = first vertex of the records.

- r4 = 0: S+0x58 = S+0x50 (unless S+0xC is -1), return the u16 at S+0x1A0.
- Otherwise: S+0x194 non-zero is a custom transform (the job calls game code:
  fall back); else 0xA3C8, then the triangles. A mode byte of 5 at S+0x150, or
  r4 outside 1..3, keeps none.
- Index count: u16 at S+0x1A0 (n/3 triangles). Records at the scratch +
  16*r5 + 16*index.
- Per triangle: valid = no vertex has bit 2 and all have bit 1; outside = the
  three codes share a bit of 7..2; area = (bx-ax)(cy-ay) - (by-ay)(cx-ax) (one
  `fms`), its sign flipped by the mode (r4 = 2: no flip) and by the index
  flavour (S+6 high nibble 0 or 2); the corners snapped to int
  (`cflts(fma(x, s, 0.5))`, s = 2 for mode bytes 3/4) cover no pixel centre
  when all three x or all three y are equal. Cull =
  (valid and covers none) or outside or (r4 = 2/3 and valid and front-facing).
  The last bit comes from an `fnms` on masks whose low bit is c | (a & b); the
  kernel takes the truth table from the helper at start and checks it.
- Survivors are compacted in place, four triangles per step: the step's 0..24
  kept bytes are stored as three quads at the output pointer, the first merged
  with what precedes the pointer in its quad, the next two shifted views
  (zeros past the kept bytes). A quad that would go past the rounded buffer
  end goes to the job's stack frame instead (sp' + 48 / + 64). The pipeline's
  two empty steps store zeros at the start first. The kernel reproduces those
  stores byte for byte; reads come from a copy of the original buffer (the job
  reads each group before any store can reach it).
- Then the u16 at S+0x1A0 = 3 * kept, S+0x58 = the end rounded to 16, r3 =
  3 * kept.

## 5. 0x4448: vertex decompression

`r3` = S, `r4` = the segment's format info T, `r5` = the stream descriptor D.
The function checks the format pair on the aligned quads: primary format at
D+44 with byte 0 = 2, byte 11 = 1 and byte 19 = 2, and the secondary at D+0x30
either null or with byte 0 = 1 and byte 11 = 3. Any other pair takes the
generic attribute loop 0xAD48 (indirect jumps per attribute format), which
stays lifted: the native kernel falls back for it. The special pair has two
inline loops (0x4A30, 9 bytes per vertex at D+20; 0x4D18, 3 bytes per vertex at
D+24), which `--merge-chunks` folds into the 0x4448 symbol; they are its self
time.

What it does, pinned by `t_dec` with 0 differences (section 7.1):

- Takes the first free uniform table slots (bytes at S+0x170 equal to 0) in
  order and gives them ids 1, 2 and, with a secondary format, 3; the pointer of
  slot i is the word at S+0x10+4i. S+0x5C, S+0x60 and S+0x64 get the three
  pointers (U1, U2, U3), S+0x54 and S+0x58 the input pointer P (the second
  through the tail call to 0x64A8). The usual frame: r80..r82 at sp-0x10..-0x30,
  r0 at sp+0x10, the back chain at sp-0x50.
- Works on n2 = the count (S+8) rounded up to two; a count of 0 would make the
  loops run about 2^27 times, so the kernel falls back.
- Position of vertex i (record P+9i): v_c = u16 BE at bytes 2c..2c+1 plus the
  int32 X[c] (four words at the pointer D+40, each read like rotqby does),
  b = the byte at T+0x1B, position_c = fa(csflt(v_c >> (16-b), 155),
  cuflt(v_c << (16+b), 123)) (arithmetic and logical shifts with the SPU's
  count rules), lane 3 = 1.0. Stored at U1+16i for every i < n2.
- Unit vector, from three bytes t0 t1 t2 (bytes 6..8 of the primary record, or
  the secondary record): a = the top 10 bits, b = the next 10, sel = the low
  nibble. m = fma(K1, 1.0|a, K2) and the same for b (the 10 bits enter as the
  mantissa of 1.0; K1 = 0x46352E7C, K2 = 0xC6353150, so m is within +-0.7072).
  s = fs(1.0, fa(ma^2, mb^2)), h = fm(s, fi(s, frsqest(s))). The vertices go in
  pairs (A, B) in one quad (ma_A, mb_A, ma_B, mb_B); entry sel of the table at
  0xF380 is both a selb source and a shuffle mask: its sign bits give h's sign,
  its words with the top bit cleared place (h, ma, mb) in lanes 0..2, and its
  lane 3 is the vector's w (+-1.0). Vertex B uses the same mask plus 8 in bytes
  0..11 (its lanes 2 and 3). Entries 0..11 are three axes x two signs x two
  handednesses; 12..15 run into the job's error strings.
- The unit-vector loops are pipelined one pair deep: their first iteration
  stores two zero quads at U2+16*n2 (and U3+16*n2), past the vectors.

The native kernel (`edge_dec_core`):

- falls back for the generic formats, a zero count, fewer free slots than
  needed, overlaps between any written span (the outputs, S+0x50..0x6F,
  S+0x170, the frame) and anything read (P, P2, X, D, S, T, the format
  quads, the module), or spans past the LS;
- runs the positions and the unit vectors four vertices per AVX-512 register
  (one quad each, the output layout), the records gathered with four 16-byte
  loads and a pshufb; the positions need no bound (integers in, normal
  singles or +0 out), and the unit vectors were checked against the exact path
  on all 2^24 inputs (`t_uv`). A group with a selector of 12..15 is redone
  pair by pair through the helpers; b > 16 takes the exact positions;
- compares the table at 0xF380 with its own copy on every call.

## 6. 0x99E8: vertex compression, output format 1

0x9780 is the compression function: it returns at once when S byte 0 has bit 4
set or the count is 0, stores the output pointer O (S+0x58, read by 0x6498) at
S+0x54, and jumps through the table at 0x991C on the output format S+4 (0x9950,
0x99E8, 0x9D18, 0x9FD8, 0x98B0; above 4 a callback at S+0xA4). Each case ends at
0x98B0, which advances S+0x58 by the vertex size (0x83C8: 12, 20, 24, 24, 0)
times the count, rounded to 16, and returns O.

Case 1 (0x99E8, loop 0x9C18/0x9C20) writes 20 bytes per vertex at O: the three
floats of the position stream (slot id 1) as they are, then one X11Y11Z10 word
for each of the streams with ids 2 and 3: per component
i = cflts(fma(scale, v, bias), 142), scale = (0x3F7FE000, 0x3F7FE000,
0x3F7FC000) at 0xE920, bias = (0xBA000000, 0xBA000000, 0xBA800000) at 0xE930,
and the word is (i_z & 0xFFC00000) | (i_y >> 21) << 11 | i_x >> 21 (the shuffles
at F070 and the rotm by (5, 2, 0) before them amount to this). It runs on
n2 = the count rounded up to two (r33). The output loop does two vertices per
step at any alignment: four quads at O+40k, the first merged with what the LS
holds before O+40k; past the last vertex the last step leaves the pattern
(n, t, 0, 0) of the last vertex's packed words, repeated from O+40k+32, up to
the end of its fourth quad.

The kernel is an entry with a continuation (section 8): it reads the
registers 0x9780 set up (r81 = S, r82 = O, r33 = n2, r26..r44 masks and
constants) and checks they hold what 0x9780 puts there; it falls back when an
id is missing from the slots, the output overlaps a stream (with the job's
read-ahead), S's pointer table or slots or the module, or a span leaves the LS.
No register the chunk writes is read later: r80 is overwritten at 0x98C0 first,
r2..r79 are dead (`live.py 98B0`). The fast path does four vertices per
register; a group with an exponent-255 component goes the exact way.

### 6.1 0xC7B8: index decompression

0xD030 (from 0x59BC, just before the cull) calls it when the index format
(S byte 3, high nibble) is 2 or 3, with r3 = S and r4 = B, the word at D+8.
It rewrites B in place as the u16 triangle list. T = the u16 at S+0x1A0 times
0xAAAB, as `mpy` does it (signed 16-bit operands, low 16 bits kept): the count
divided by three. B holds a header (N0 u16, a bias u16, L u16, c byte), L
bytes of flags (one per vertex reference, most significant bit first), CB =
(2T + 7) / 8 bytes of 2-bit triangle codes, then N0 values of c bits. Four
loops, each over the result of the previous one:

1. The values, unpacked to u16 at OUT = B + 16-aligned(8 + L + CB), 32 at a
   time, so 32 * ceil(N0 / 32) of them (the last from the bits that follow).
   It runs backwards and in place; with c <= 15 it never reads a byte it has
   written (value i ends below BS + 2i + 2, the stores above it start at
   OUT + 2i + 2 >= BS + 2i + 2). Then a delta per quad lane: v[q] = raw[q] -
   bias + v[q - 1], halfwords mod 2^16. c = 0 stores ceil(N0 / 8) zero quads
   instead of unpacking (and the delta runs over the whole blocks, the rest
   of them as the LS holds it). The loop's byte offset is a 16-bit `mpy`
   product, which wraps past N0 = 32 * 32768 / (4c): the kernel stops at
   8192.
2. The vertex list at LIST = B + 16-aligned(6T): 16 * ceil(L / 2) entries
   (a padding byte when L is odd: the first code byte), a set flag takes the
   next value, a clear one the next number of a counter from 0.
3. The codes, copied in whole quads to CODES = the end of the list.
4. The triangles, 8 per 16 code bits, 3 quads per group at B + 48g for
   every group (up to 7 past T, from the bits and entries that follow).
   Code 3 takes three new entries; 0, 1 and 2 take one, n, and an edge of
   the previous triangle p (zeros before the first): (p0, p2, n), (p2, p1,
   n), (p1, p0, n). The loop is pipelined one group deep (its first group,
   from zeros, is stored at B and overwritten), and it loads group g after
   storing the groups up to g - 2. Tables at 0xEC40/0xED40 drive it, two
   triangles per shuffle.

The tail call to 0x64A8 stores the end, B + 48 * groups, at S+0x58. Nothing
else is written, and no register past r79 (the callers read r80, r81, r1).

The kernel (`edge_idx_core`) does the four loops on host-order copies and
stores each buffer as the job leaves it: loop 2 eight entries per flag byte
(a pshufb from a 256-entry table, the counter's offsets, a blend), loop 4 two
triangles per two-source permute of (previous pair, next entries), the same
idea as the job's tables. It falls back, before writing anything, for B, S
or the stack off a quad boundary, c above 15, an empty flag stream, no
triangle, N0 > 8192, a span past the LS or reaching S's words, the stack or
the module, and where a loop could read what it has itself written: loop 2's
values (with its read-ahead) against the list it stores, loop 3's source
against its destination. Loop 4 cannot meet that (each triangle takes an
entry, so group g reads from LIST + 16g on, past B + 48(g - 1) as 6T > 4T),
and loop 1 is the backwards argument above. It checks a hash of the module's
data at 0xEB70..0xF000 (the masks and constants the lift loads) once, then a
compare with the copy it took.

## 7. Results

### 7.1 Differential tests

All of these report **0 differences** (whole LS, r0/r1/r80-r127, and r3
for the cull):

- skinning: 2000 cases x 4 runs (no mutation; 0.3% and 3% special floats;
  another seed), types 1..6, formats 0..3, 1..400 vertexes, 0..3 streams, S60
  on/off; ~15% of cases take the job's error paths and correctly fall back.
- cull transform: 1000 cases x 3 runs (0, 0.3%, 3% mutation).
- cull: 3000 + 2000 x 2 cases (0, 0.3%, 3%), modes 0..5, r4 0..6, r5 0..7,
  0..700 triangles, records from the native/lifted transform.
- replay of 50 dumped states through `t_replay` (checks the capture path).
- **real states from the game** (section 7.4): 400 skinning and 400 cull
  entry states captured in the city, plus the 8 states of the in-game
  compare differences: all native, 0 differences.

- **0x4448 and 0x99E8** (Nov 2026, harness in `~/tools/wt/edge-native-test`, and
  with the later tests `t_idx`, `b_idx`, `mut_idx.py` in `~/tools/wt/edge-more-test`:
  `extract.py` cuts the lifted module down to the functions the tests reach and
  adds the hooks as `lift_spu.py` does, `mk.sh dec enc uv`):
  - `t_uv`: all 2^24 unit vectors, fast against exact, 0 differences;
  - `t_dec N SEED`: random states (1..300 vertices, b mostly 0..16 and
    sometimes any byte, X at any alignment, random slots, with and without
    the secondary stream), 0 differences on 3000 + 3000 cases; `SANE=1` keeps
    the selectors below 12, as meshes do (2000 cases, 0 differences);
  - `t_enc N SEED MUT`: the whole of 0x9780 with and without the native
    chunk, O at any alignment, duplicate and missing slot ids, MUT special
    floats per 1000 (0, 3, 30, 300): 0 differences on 3000 x 3 + 1000 cases;
  - `mut.py`: 22 single changes, 19 caught; the 3 others are equivalent on the
    real input domain (s is never 0 or negative on the 10-bit grid; the tail
    group's mask only guards the zero quads the job writes after it).
- **The first in-game run of 0x4448** (compare mode, the city and the heavy
  area, Nov 2026): differ 0 on millions of calls, but 18% of them fell back.
  The job lays the uniform tables out back to back, 16 bytes times the count
  rounded up to 8 apart (0x7198, loop 0x7330), so with a count of 0 or 7 mod 8
  the two zero quads past the normals are the first two tangents, and the
  overlap guard refused it. The two loops run one after the other (0x4A30:
  positions, normals and the normals' zero quads, interleaved; then 0x4D18:
  the tangents and theirs), so the kernel now tags each span with its loop,
  lets spans of different loops overlap, and writes them in the job's order.
  `t_dec` with `LAYOUT=1` (the job's layout, counts of 0 and 7 mod 8 often):
  the old guard falls back on 1054 of 3000 cases, the new kernel on none, 0
  differences; `LAYOUT=2` shuffles the tables so the zero quads can land on
  the positions too, which must still fall back (a mutant that lets them
  overlap differs on 48 of 1500). The stats line now names the fallback
  reasons (generic formats, zero count, no free slot, overlap).
- **0xC7B8** (`t_idx N SEED`, `CHAOS=1`): streams as an encoder writes them
  (1..2000 triangles, any mix of codes, flags and c, B anywhere on a quad,
  tiny segments), and with `CHAOS=1` random header fields, counts and a B off
  a quad: 0 differences on 3000 x 2 + 4000 x 3 + 3000 + 4000 x 3 (chaos)
  cases. Before the N0 limit, chaos found the wrap of the unpack offset
  (N0 > 32768). `mut_idx.py`: 18 single changes, 17 caught; the survivor is
  a guard no real call reaches (loop 3's source against its destination,
  kept as a cheap check).
- `mut.py` after the layout change: 24 single changes (two new: the
  positions' phase, the zero quads' order), 22 caught. The tail group's mask
  is caught now, since the zero quads are written before the vectors; the
  two survivors are the known equivalents (s is never 0 on the grid, h is
  positive).

### 7.2 Mutation check

`mut.py` applies 44 single changes to the kernels (operand order, a lane, a
bit, a constant, a dropped store, the bound, the rounding of an estimate, the
pixel-snap offset, the slow paths, the zero-weight rule, DAZ in the fast
MXCSR, ...) and expects a test to fail. **All 44 are caught** (run at the
game's MXCSR). Survivors on the way were two equivalent mutants (a
commutative product; `cvtps` under the RZ MXCSR is `cvtt`), replaced, and
generator gaps that were closed: scissor origin always 0, depth bounds never
+-0 or denormal, no vectors small enough that s underflows to 0, and no -0
positions/translations (needed to see the +0 canonicalisation of positions).
The exact skin path is reached by the 3% mutation run.

### 7.3 Speed (best of 300 runs, hot LS)

- skinning, 256 vertexes: type 1 no streams 5.3 -> 0.78 us (6.7x); type 2,
  three streams 11.5 -> 1.9 us (6.0x); type 3, two streams and S60 13.0 -> 2.0
  us (6.6x); type 4 (one bone) one stream 3.0 -> 0.57 (5.2x). 4..12 vertexes:
  3.5-6.5x (fixed costs).
- cull transform: 8 vertexes 2.6x, 32+ 3.5-4.1x.
- cull, whole call (transform included): 150..600 triangles 2.2-3.1x;
  segments that keep nothing (mode 5) 3.5-4x.

In the randomised runs, which start from a cold LS copy, the totals are 4.5x
(skin), 3.6x (transform) and 2.8x (cull).

- 0x4448, best of 500, realistic selectors: 64 vertices 1.35 -> 0.35 us
  (3.9x), 128: 2.46 -> 0.59 us (4.2x), 256: 4.88 -> 1.04 us (4.7x); without
  the secondary stream 4.1-5.1x. A selector of 12..15 in every group makes it
  as slow as the lift (exact pairs), which meshes should never do; the stats
  line counts those groups.
- 0x9780 as a whole (its fixed part stays lifted): 64 vertices 0.80 -> 0.34 us,
  128: 1.48 -> 0.51 us, 256: 2.83 -> 0.86 us.
- 0xC7B8 (`b_idx SEED`, best of 300): 14..29 triangles 0.20 -> 0.08-0.12 us,
  106: 0.36 -> 0.21 us, 554: 1.33 -> 0.53 us, 1607: 3.06 -> 1.06 us; over the
  random cases 1.7-2x. The lifted code is efficient here (2.5 ns per
  triangle, eight at a time through the job's tables); a scalar kernel was
  slower than it until loops 2 and 4 went SIMD.

### 7.4 First in-game run, and what it found

Compare mode in the city: skinning fell back on every call (3.93M), the
cull differed on 143 of 3.98M calls (1-2 quads at the end of the transform's
records). Replaying the captures:

- Skinning: the overlap guard put the palette conversion and the blend's
  reads in one span; real meshes put the index stream right after the
  palette and the padding vertexes name matrices far past it. Fixed as in
  section 2. All 400 captured calls now run native: 4.3x on them.
- Cull: the 8 dumped states replayed identical offline, so the difference was
  in the environment: DAZ (section 1.3). With the harness at the game's
  MXCSR, the previous build differs on 8 of 8 dumps and the fixed one (DAZ in
  the fast paths' MXCSR) on none. Those quads are the records of the padding
  vertexes; they are real LS writes the job's next steps can read, so they had
  to be exact, not excluded. 2.6x on the 400 captured calls.

## 8. Integration

- `work/port/edge_kernels_native.c`; it needs `-march=x86-64-v4` (AVX-512
  F/BW/VL/DQ; it checks the CPU at start and turns itself off otherwise):
  add it to the SPU_SOURCES list in `work/port/CMakeLists.txt` next to
  `ec5f_native.c` and `job2025_native.c`, which gives it the lifted code's
  flags (the exact paths call the same helpers as the lift, so they must be
  built the same way).
- `work/tools/lift_spu.py`:
  `NATIVE_ENTRIES["jobmod_6d1c65171899_eA2A0"] = [0xD0A8, 0xA3C8, 0xA798, 0x4448, (0x99E8, 0x98B0), 0xC7B8]`.
  A pair is an entry with a continuation: when the kernel reports the work
  done, the lifted chunk transfers to 0x98B0 instead of returning.
- `PS3RECOMP_NATIVE_EDGE`: 1 (default) on, 0 off, 2 compare: the kernel runs
  on a copy of LS and registers, then the lifted function on the real ones,
  and the whole LS plus r0, r1, r80..r127 are compared. Every 10 s:
  `[edge] <kernel> (0x...): calls, native, lifted; compared, differ; native
  us, lifted us per compared call`. The first 8 differences are logged with
  their LS range; `PS3RECOMP_EDGE_DUMP=dir` also writes the input state of
  each (128 registers then the LS) for `t_replay`.
- `PS3RECOMP_NATIVE_EDGE_DEC` (0x4448), `PS3RECOMP_NATIVE_EDGE_ENC`
  (0x99E8) and `PS3RECOMP_NATIVE_EDGE_IDX` (0xC7B8): the same values, off
  unless set, until a compare run in the game shows no difference.
  `PS3RECOMP_EDGE_DEC_LAYOUT=0` puts back the strict overlap guard of
  0x4448 (no spans of different loops may overlap), the kill switch for the
  layout change of section 7.1; on by default within the kernel's switch. In compare mode the chunk runs lifted up to its
  continuation, and r80 is left out of the comparison. The stats line adds the
  groups the exact path redid.
- `PS3RECOMP_EDGE_CAPTURE=dir[,count[,every]]` writes input states of real
  calls (default 32 per kernel, every 997th call) for `t_replay dir`.

## 9. Open

- 0x4448 and 0x99E8 compared clean in the game (differ 0); their defaults
  are still opt-in. 0xC7B8 and the new 0x4448 guard have no in-game run yet.
- 0x4448's generic path (0xAD48) and the other compression formats (0x9950,
  0x9D18, 0x9FD8) stay lifted, on purpose: in the October city profile
  (`perf/spu_syms_all.txt`) 0xAD48 has no sample at all, its per-format
  handlers (0xE3xx-0xE5xx) 0.05% together and 0x9950 0.00%, 0x9D18 and
  0x9FD8 none, against 2.64% for 0x4448. So the 0x4448 fallbacks the game
  shows are most likely the layout overlap above (a quarter of the segments
  with tangents, which fits 18%), not these formats; the next run's stats
  line says which reason each one had.
- The cull fast path is bound by gathering 48 records per 16 triangles and by
  the in-place stores; an AoS formulation (area and snap tests on whole
  record quads) would cut the transposes.
- The exact paths are 2x slower than the lift; they only run for batches
  with exponent-255 or huge values.
