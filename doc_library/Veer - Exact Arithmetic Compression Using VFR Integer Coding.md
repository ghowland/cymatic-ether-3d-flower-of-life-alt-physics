# Veer: Exact Arithmetic Compression Using VFR Integer Coding

**Lossless and Lossy Data Compression Through Remainder-Preserving Range Division**

---

## Abstract

We present Veer, a data compression system built on VFR (Value, Factor, Remainder) integer arithmetic. Unlike conventional arithmetic coders that accumulate truncation error through integer division and compensate with renormalization heuristics, Veer preserves the exact remainder at every range division step, carrying it forward as input to the next division. The result is a coder whose internal range boundaries are mathematically exact throughout the entire encoding process, producing output that is provably optimal for the given frequency model. We define two modes: Veer Lossless, which achieves byte-perfect reconstruction through full VFR carry propagation, and Veer Lossy, which trades bit-depth precision for compression speed and ratio through a single configurable parameter Q. Both modes operate on arbitrary binary data — the input need not be VFR-native. The system is implemented as a command-line tool in Zig with zero external dependencies. File extension: `.ver`.

---

## 1. The Problem with Conventional Arithmetic Coding

### 1.1 How Arithmetic Coding Works

An arithmetic coder represents an entire message as a sub-interval of the range `[0, MAX)`. Each input symbol narrows the interval proportionally to that symbol's probability. After all symbols are processed, any number inside the final interval uniquely identifies the original message. The number of bits required to specify a value inside the interval is the compressed size — approximately equal to the Shannon entropy of the message.

The narrowing operation for each symbol requires two divisions:

```
range_width = high - low
new_high = low + (range_width × cum_high) / total
new_low  = low + (range_width × cum_low) / total
```

These divisions are the source of all difficulty in arithmetic coding.

### 1.2 The Truncation Problem

Integer division truncates. `7 / 3 = 2` in integer arithmetic, not `2.333...`. The fractional part `0.333...` is discarded. In a single division, this is negligible. But an arithmetic coder performs two divisions per symbol. A file with 1 million bytes requires 2 million divisions. Each division truncates. The errors accumulate.

The consequence: after thousands of symbols, the encoder's range boundaries have drifted from their mathematically correct positions. The range may be slightly too wide (wasting bits) or slightly too narrow (risking ambiguity). Conventional coders manage this through renormalization — periodically emitting settled top bits and shifting the range to use the full integer width. Each renormalization is a correction that approximately recovers precision. The corrections work in practice but are not exact. They introduce sub-bit distortions that, summed over millions of symbols, produce output that is slightly longer than the theoretical optimum.

### 1.3 The Carry Propagation Problem

When the top bits of `low` and `high` nearly match but have not yet converged, conventional arithmetic coders enter an underflow state. The coder cannot emit bits because the range straddles a bit boundary. Conventional solutions (bit-stuffing, carry counters) add bookkeeping complexity and additional opportunities for precision loss.

### 1.4 What VFR Changes

VFR arithmetic preserves the exact remainder of every integer division:

```
7 / 3 = [quotient: 2, remainder: 1]
```

The quotient narrows the range (same as conventional). The remainder carries forward as exact input to the next division. No information is discarded. No truncation occurs. After 2 million divisions, the range boundaries are mathematically exact — identical to what infinite-precision rational arithmetic would produce, but computed entirely with fixed-width integers plus a small carry value.

---

## 2. VFR Arithmetic Coding

### 2.1 State

The coder state at any point during encoding or decoding is:

```
low:        i64     range lower bound
high:       i64     range upper bound
carry_low:  i32     remainder from last low-boundary division
carry_high: i32     remainder from last high-boundary division
total:      i32     sum of all symbol frequencies
reciprocal: i64     precomputed reciprocal of total: (1 << 32) / total
```

The carries are the VFR remainders. They are small — always in the range `[0, total - 1]`. For a byte-level alphabet with adaptive frequencies, total never exceeds 65,536, so each carry fits in an i16. We use i32 for headroom during intermediate computation.

### 2.2 Encoding One Symbol

Given a symbol with cumulative frequency range `[cum_low, cum_high)` out of `total`:

```
range_width = high - low

; Compute new high boundary with VFR carry
product_high = range_width × cum_high + carry_high × cum_high
quotient_high = (product_high × reciprocal) >> 32
remainder_high = product_high - quotient_high × total
new_high = low + quotient_high

; Compute new low boundary with VFR carry
product_low = range_width × cum_low + carry_low × cum_low
quotient_low = (product_low × reciprocal) >> 32
remainder_low = product_low - quotient_low × total
new_low = low + quotient_low

; Update state
low = new_low
high = new_high
carry_low = remainder_low
carry_high = remainder_high
```

The carries from the previous symbol participate in the current division through the terms `carry_high × cum_high` and `carry_low × cum_low`. This is the exact fractional contribution that conventional coding discards. By including it, the range boundaries after N symbols are identical to what exact rational arithmetic would produce.

### 2.3 Why Reciprocal Multiply Instead of Division

The VFR processor has no division instruction. Division is replaced by multiplication by a precomputed reciprocal:

```
; Precompute once when frequency table is built:
reciprocal = (1 << 32) / total

; Use for every division:
quotient = (product × reciprocal) >> 32
remainder = product - quotient × total
```

Two multiplies and one subtract replace one division. On VFR hardware, multiply is single-cycle (DSP48). On conventional CPUs, this is also faster than division. The reciprocal is exact for the given total. The remainder is computed exactly by back-multiplication.

### 2.4 Renormalization

When the top bits of `low` and `high` match, they can be emitted:

```
while top_bit(low) == top_bit(high):
    emit(top_bit(low))
    low = (low << 1) & RANGE_MASK
    high = ((high << 1) | 1) & RANGE_MASK
```

During renormalization, the carries are preserved. They are not affected by the bit shift because they represent the fractional remainder of the division, not the range position. The carries continue to feed into the next symbol's division after renormalization, maintaining exact precision across the shift.

Underflow handling (when low and high straddle but their second bits differ) uses the standard bit-stuffing approach. The carry values do not participate in underflow handling — they are orthogonal to the bit-emission process.

### 2.5 Decoding One Symbol

The decoder maintains the same state as the encoder plus a `value` register holding the current bits from the compressed stream:

```
value:      i64     current compressed bits
low:        i64     range lower bound
high:       i64     range upper bound
carry_low:  i32     remainder from last low division
carry_high: i32     remainder from last high division
```

To decode one symbol:

```
range_width = high - low

; Find which symbol's sub-range contains 'value'
; Compute: target = ((value - low) × total) / range_width
; Use this to index into the cumulative frequency table

for each symbol in frequency table:
    ; Compute sub-range with VFR carries (same as encoder)
    product_high = range_width × sym.cum_high + carry_high × sym.cum_high
    quotient_high = (product_high × reciprocal_range) >> 32
    test_high = low + quotient_high

    product_low = range_width × sym.cum_low + carry_low × sym.cum_low
    quotient_low = (product_low × reciprocal_range) >> 32
    test_low = low + quotient_low

    if value >= test_low AND value < test_high:
        emit(symbol)
        low = test_low
        high = test_high
        carry_low = product_low - quotient_low × total
        carry_high = product_high - quotient_high × total
        break
```

The decoder performs identical divisions with identical carries as the encoder. The ranges match exactly. There is no drift between encoder and decoder. Symbol identification is unambiguous.

### 2.6 Optimized Symbol Lookup

The linear scan over all symbols is O(alphabet_size) per symbol. For byte-level coding (alphabet size 256), this is acceptable but not ideal. A precomputed lookup table indexed by the top bits of the scaled value reduces to O(1) average case:

```
; Build lookup table (once per frequency table update):
; For each possible top-8-bit value, store which symbol it maps to
lookup_table: [256]u8

; Decode with lookup:
scaled = ((value - low) × total) / range_width
candidate = lookup_table[scaled >> (PRECISION - 8)]

; Verify candidate (may need to check adjacent symbols due to rounding)
; Then do exact VFR range computation for the confirmed symbol
```

This reduces decoding to one table lookup plus one exact VFR range computation per symbol.

---

## 3. Frequency Modeling

### 3.1 Static Model (Mode 1, Maximum Compression)

For lossless maximum compression, the encoder makes two passes over the input:

**Pass 1:** Count byte frequencies.

```
freq: [256]u32    ; frequency of each byte value 0-255
total: u32        ; sum of all frequencies

For each byte in input:
    freq[byte] += 1
    total += 1
```

**Pass 2:** Build cumulative frequency table.

```
cum_freq: [257]u32    ; cumulative frequency, cum_freq[0] = 0

cum_freq[0] = 0
for i in 0..256:
    cum_freq[i + 1] = cum_freq[i] + freq[i]

; Symbol i has range [cum_freq[i], cum_freq[i+1]) out of total
```

The frequency table is stored in the `.ver` file header so the decoder can reconstruct it.

### 3.2 Adaptive Model (Mode 1, Improved Compression)

Instead of a static table, update frequencies as symbols are encoded. Both encoder and decoder update identically, so the table stays synchronized without transmitting it.

```
; Initialize all frequencies to 1 (uniform)
freq: [256]u32 = [1] ** 256
total: u32 = 256

; After encoding/decoding each symbol:
freq[symbol] += 1
total += 1

; Rebuild cumulative table (or update incrementally)

; Rescale when total exceeds threshold (prevent overflow):
if total > 65536:
    for i in 0..256:
        freq[i] = (freq[i] + 1) >> 1    ; halve, keep minimum 1
    total = sum(freq)
```

Adaptive modeling eliminates the need to store the frequency table in the file header (saving 1 KB) and adapts to local patterns in the data (improving compression on non-uniform files). The rescaling step is the only place where precision is reduced, and it affects only the frequency model, not the range arithmetic.

### 3.3 Context Modeling (Mode 1, Maximum Compression)

For maximum compression, use order-1 context: the frequency table depends on the previous byte.

```
context_freq: [256][256]u32    ; freq[prev_byte][current_byte]
context_total: [256]u32        ; total for each context

; After encoding/decoding symbol with previous byte as context:
context_freq[prev_byte][symbol] += 1
context_total[prev_byte] += 1
```

This means each byte is encoded using a frequency table specific to what byte preceded it. English text compresses dramatically better because `t` after `_` (space) has very different frequency than `t` after `x`. Binary data benefits because many file formats have strong byte-to-byte correlations.

Memory cost: 256 × 256 × 4 bytes = 256 KB for the context tables. Acceptable on any modern system. On VFR hardware, this fits in shared BRAM.

Higher-order contexts (order-2, order-3) use more memory but compress better. Order-2 uses 16 MB. Diminishing returns beyond order-2 for most data.

---

## 4. Mode 1: Veer Lossless

### 4.1 Algorithm

```
ENCODE:
  1. Read entire input file into memory
  2. Build frequency model (static, adaptive, or context — configurable)
  3. Initialize coder state: low=0, high=MAX, carry_low=0, carry_high=0
  4. For each input byte:
     a. Look up cumulative frequency range for this byte
     b. Narrow range with VFR carry propagation (Section 2.2)
     c. Renormalize and emit bits as top bits converge
  5. Flush remaining bits
  6. Write .ver file: header + compressed bitstream

DECODE:
  1. Read .ver file header
  2. Reconstruct frequency model (from header or adaptive initialization)
  3. Initialize coder state: low=0, high=MAX, carry_low=0, carry_high=0
  4. Read initial bits into value register
  5. For each output byte:
     a. Determine which symbol's range contains current value
     b. Emit the symbol
     c. Narrow range with VFR carry propagation (identical to encoder)
     d. Renormalize and read new bits
  6. Write output file
```

### 4.2 Correctness Guarantee

The decoder performs the same sequence of VFR divisions as the encoder with the same carry values. The ranges match exactly at every step. The decoded symbol is unambiguous. The output is byte-for-byte identical to the input.

This is provable: given that the carries are exact and the reciprocal multiply produces the correct quotient and remainder for all values in the range `[0, MAX × total)`, the encoder and decoder state machines are identical. No drift, no ambiguity, no correction needed.

### 4.3 Expected Compression

Veer Lossless achieves compression within 1-2 bits of the Shannon entropy for static modeling, and within 0.1-0.5 bits for adaptive context modeling. The VFR carry propagation means the output is exactly optimal for the frequency model used — no truncation padding.

```
Data type          Static model    Adaptive order-0    Adaptive order-1
─────────          ────────────    ────────────────    ────────────────
English text       4.5:1           5.0:1               6.5:1
Zig source code    3.5:1           4.0:1               5.5:1
PNG image data     1.05:1          1.1:1               1.15:1
WAV audio          1.3:1           1.5:1               1.8:1
Random bytes       1.00:1          1.00:1              1.00:1
Sparse data        8:1+            10:1+               12:1+
```

PNG and other already-compressed formats see minimal improvement because they've already removed redundancy. Raw data (text, source code, uncompressed images, audio) compresses well. Sparse data (lots of zeros, like VFR R channels) compresses extremely well.

---

## 5. Mode 2: Veer Lossy

### 5.1 The Q Parameter

Q is an integer from 1 to 8 representing how many bits of each input byte to preserve. Q=8 is lossless. Q<8 discards the bottom `(8-Q)` bits of every byte before compression.

```
Q=8:  keep all 8 bits    lossless          256 unique values
Q=7:  keep top 7 bits    lose 1 bit        128 unique values
Q=6:  keep top 6 bits    lose 2 bits        64 unique values
Q=5:  keep top 5 bits    lose 3 bits        32 unique values
Q=4:  keep top 4 bits    lose 4 bits        16 unique values
```

### 5.2 Algorithm

```
ENCODE:
  1. Read input file
  2. For each byte: reduced = byte >> (8 - Q)
  3. Arithmetic-code the reduced stream (alphabet size = 2^Q instead of 256)
  4. Write .ver file with Q in header

DECODE:
  1. Read .ver header, extract Q
  2. Arithmetic-decode the reduced stream
  3. For each decoded value: restored = value << (8 - Q)
  4. Write output file
```

The restored bytes have their bottom bits zeroed. For image data, this is equivalent to reducing color depth. For audio, it's equivalent to reducing bit depth. For text, it corrupts characters (not useful — text should always use Q=8).

### 5.3 Why Lossy Is Faster

The alphabet shrinks from 256 to `2^Q` symbols. At Q=4, only 16 symbols. The frequency table is 16 entries instead of 256. Symbol lookup is faster. The cumulative frequency range is wider per symbol, meaning the range narrows more slowly, meaning fewer renormalization steps, meaning fewer output bits and fewer division operations.

```
Q=8: 256 symbols, ~8 bits per symbol, ~2M divisions for 1MB file
Q=6:  64 symbols, ~6 bits per symbol, ~1.5M divisions for 1MB file
Q=4:  16 symbols, ~4 bits per symbol, ~1M divisions for 1MB file
```

Fewer divisions means faster encoding and decoding. Smaller output means less I/O. The speedup compounds: fewer symbols to code AND each symbol codes faster AND the output is smaller.

### 5.4 Expected Compression and Quality

```
Q     Compression ratio    Quality loss            Speed vs Q=8
      (typical image)      (perceptual)
─     ─────────────────    ────────────            ────────────
8     2.5:1                none (lossless)         1.0x
7     3.0:1                imperceptible           1.2x
6     4.0:1                slight banding          1.5x
5     5.5:1                visible banding         2.0x
4     8.0:1                posterized              2.5x
```

For images, Q=6 or Q=7 is the sweet spot — visually near-identical at significantly better compression and speed. For audio, Q=6 is roughly equivalent to reducing from 16-bit to 12-bit depth — audible to trained ears, acceptable for game audio. For arbitrary binary data, lossy mode is only appropriate when the consumer tolerates approximate values.

---

## 6. File Format

### 6.1 Extension

`.ver` — Veer compressed file.

### 6.2 Header

```
Offset  Size    Field               Description
──────  ────    ─────               ───────────
0       4       magic               "VEER" (0x56454552)
4       1       version             format version (1)
5       1       mode                0 = lossless, 1 = lossy
6       1       q_value             Q parameter (1-8, always 8 for lossless)
7       1       model_type          0 = static, 1 = adaptive, 2 = context order-1
8       8       original_size       original file size in bytes (u64)
16      4       checksum            CRC-32 of original file
20      4       compressed_size     compressed data size in bytes (u32)
24      varies  freq_table          frequency table (static model only)
```

For static model: the frequency table follows the header. 256 entries × 4 bytes = 1,024 bytes.

For adaptive model: no frequency table stored. The decoder initializes uniform and adapts identically to the encoder.

For context model: 256 bytes indicating which contexts are active, followed by tables for active contexts only (sparse storage).

### 6.3 Compressed Data

After the header (and optional frequency table), the compressed bitstream follows as a packed byte array. The bitstream is the output of the arithmetic coder.

### 6.4 Footer

```
Offset  Size    Field               Description
──────  ────    ─────               ───────────
0       4       end_marker          0x00000000
4       4       carry_low_final     final carry_low value (for verification)
8       4       carry_high_final    final carry_high value (for verification)
```

The final carries are stored for verification. A correct decoder will arrive at these exact carry values after decoding the last symbol. If the decoder's carries don't match, the file is corrupt.

---

## 7. Zig Implementation

### 7.1 Core Data Structures

```zig
const VeerHeader = packed struct {
    magic: u32,             // "VEER"
    version: u8,            // 1
    mode: u8,               // 0=lossless, 1=lossy
    q_value: u8,            // 1-8
    model_type: u8,         // 0=static, 1=adaptive, 2=context
    original_size: u64,     // bytes
    checksum: u32,          // CRC-32 of original
    compressed_size: u32,   // bytes of compressed data
};

const VeerFooter = packed struct {
    end_marker: u32,        // 0x00000000
    carry_low_final: i32,   // final VFR carry
    carry_high_final: i32,  // final VFR carry
};

const FrequencyTable = struct {
    freq: [256]u32,
    cum_freq: [257]u32,
    total: u32,
    reciprocal: u64,        // (1 << 32) / total

    fn init() FrequencyTable {
        var ft: FrequencyTable = undefined;
        for (0..256) |i| {
            ft.freq[i] = 1;
        }
        ft.total = 256;
        ft.buildCumulative();
        return ft;
    }

    fn buildCumulative(self: *FrequencyTable) void {
        self.cum_freq[0] = 0;
        for (0..256) |i| {
            self.cum_freq[i + 1] = self.cum_freq[i] + self.freq[i];
        }
        self.total = self.cum_freq[256];
        self.reciprocal = (@as(u64, 1) << 32) / @as(u64, self.total);
    }

    fn update(self: *FrequencyTable, symbol: u8) void {
        self.freq[symbol] += 1;
        self.total += 1;

        // Rescale if approaching overflow
        if (self.total > 65536) {
            for (0..256) |i| {
                self.freq[i] = (self.freq[i] + 1) >> 1;
            }
            self.buildCumulative();
        } else {
            // Incremental cumulative update
            for (symbol + 1..257) |i| {
                self.cum_freq[i] += 1;
            }
            self.reciprocal = (@as(u64, 1) << 32) / @as(u64, self.total);
        }
    }
};
```

### 7.2 VFR Arithmetic Coder State

```zig
const RANGE_BITS: u6 = 32;
const RANGE_MAX: i64 = @as(i64, 1) << RANGE_BITS;
const RANGE_HALF: i64 = RANGE_MAX >> 1;
const RANGE_QUARTER: i64 = RANGE_MAX >> 2;

const VeerCoder = struct {
    low: i64,
    high: i64,
    carry_low: i32,
    carry_high: i32,

    // Output state (encoder)
    pending_bits: u32,
    output: std.ArrayList(u8),
    bit_buffer: u8,
    bit_count: u3,

    // Input state (decoder)
    value: i64,
    input: []const u8,
    input_pos: usize,
    input_bit: u3,

    fn init() VeerCoder {
        return .{
            .low = 0,
            .high = RANGE_MAX - 1,
            .carry_low = 0,
            .carry_high = 0,
            .pending_bits = 0,
            .output = undefined,
            .bit_buffer = 0,
            .bit_count = 0,
            .value = 0,
            .input = undefined,
            .input_pos = 0,
            .input_bit = 0,
        };
    }
};
```

### 7.3 Encode Symbol

```zig
fn encodeSymbol(
    coder: *VeerCoder,
    ft: *FrequencyTable,
    symbol: u8,
) void {
    const range_width = coder.high - coder.low + 1;
    const cum_high = @as(i64, ft.cum_freq[symbol + 1]);
    const cum_low = @as(i64, ft.cum_freq[symbol]);
    const total = @as(i64, ft.total);

    // VFR division for high boundary
    const product_high = range_width * cum_high +
                         @as(i64, coder.carry_high) * cum_high;
    const quotient_high = @intCast(i64, @as(u64, @intCast(u64, product_high)) *
                          ft.reciprocal >> 32);
    const remainder_high = @intCast(i32, product_high - quotient_high * total);

    // VFR division for low boundary
    const product_low = range_width * cum_low +
                        @as(i64, coder.carry_low) * cum_low;
    const quotient_low = @intCast(i64, @as(u64, @intCast(u64, product_low)) *
                         ft.reciprocal >> 32);
    const remainder_low = @intCast(i32, product_low - quotient_low * total);

    // Update range
    coder.high = coder.low + quotient_high - 1;
    coder.low = coder.low + quotient_low;
    coder.carry_high = remainder_high;
    coder.carry_low = remainder_low;

    // Renormalize
    renormalize(coder);
}
```

### 7.4 Renormalization

```zig
fn renormalize(coder: *VeerCoder) void {
    while (true) {
        if (coder.high < RANGE_HALF) {
            // Top bits both 0
            emitBit(coder, 0);
            emitPendingBits(coder, 1);
        } else if (coder.low >= RANGE_HALF) {
            // Top bits both 1
            emitBit(coder, 1);
            emitPendingBits(coder, 0);
            coder.low -= RANGE_HALF;
            coder.high -= RANGE_HALF;
        } else if (coder.low >= RANGE_QUARTER and
                   coder.high < 3 * RANGE_QUARTER) {
            // Underflow: straddle
            coder.pending_bits += 1;
            coder.low -= RANGE_QUARTER;
            coder.high -= RANGE_QUARTER;
        } else {
            break;
        }

        // Shift range
        coder.low = coder.low << 1;
        coder.high = (coder.high << 1) | 1;

        // Carries are NOT shifted — they represent the fractional
        // remainder of the division, independent of range position
    }
}

fn emitBit(coder: *VeerCoder, bit: u1) void {
    coder.bit_buffer = (coder.bit_buffer << 1) | bit;
    coder.bit_count += 1;
    if (coder.bit_count == 8) {
        coder.output.append(coder.bit_buffer) catch unreachable;
        coder.bit_buffer = 0;
        coder.bit_count = 0;
    }
}

fn emitPendingBits(coder: *VeerCoder, bit: u1) void {
    while (coder.pending_bits > 0) {
        emitBit(coder, bit);
        coder.pending_bits -= 1;
    }
}
```

### 7.5 Decode Symbol

```zig
fn decodeSymbol(
    coder: *VeerCoder,
    ft: *FrequencyTable,
) u8 {
    const range_width = coder.high - coder.low + 1;
    const total = @as(i64, ft.total);

    // Scale value into frequency space for initial symbol guess
    const scaled = ((coder.value - coder.low + 1) * total - 1) / range_width;

    // Find symbol via cumulative frequency lookup
    var symbol: u8 = 0;
    while (ft.cum_freq[symbol + 1] <= @intCast(u32, scaled)) {
        symbol += 1;
    }

    // Verify with exact VFR range computation
    const cum_high = @as(i64, ft.cum_freq[symbol + 1]);
    const cum_low = @as(i64, ft.cum_freq[symbol]);

    const product_high = range_width * cum_high +
                         @as(i64, coder.carry_high) * cum_high;
    const quotient_high = @intCast(i64, @as(u64, @intCast(u64, product_high)) *
                          ft.reciprocal >> 32);
    const remainder_high = @intCast(i32, product_high - quotient_high * total);

    const product_low = range_width * cum_low +
                        @as(i64, coder.carry_low) * cum_low;
    const quotient_low = @intCast(i64, @as(u64, @intCast(u64, product_low)) *
                         ft.reciprocal >> 32);
    const remainder_low = @intCast(i32, product_low - quotient_low * total);

    // Update range (identical to encoder)
    coder.high = coder.low + quotient_high - 1;
    coder.low = coder.low + quotient_low;
    coder.carry_high = remainder_high;
    coder.carry_low = remainder_low;

    // Renormalize and read new bits
    decodeRenormalize(coder);

    return symbol;
}

fn decodeRenormalize(coder: *VeerCoder) void {
    while (true) {
        if (coder.high < RANGE_HALF) {
            // Top bits both 0 — shift
        } else if (coder.low >= RANGE_HALF) {
            // Top bits both 1
            coder.value -= RANGE_HALF;
            coder.low -= RANGE_HALF;
            coder.high -= RANGE_HALF;
        } else if (coder.low >= RANGE_QUARTER and
                   coder.high < 3 * RANGE_QUARTER) {
            // Underflow
            coder.value -= RANGE_QUARTER;
            coder.low -= RANGE_QUARTER;
            coder.high -= RANGE_QUARTER;
        } else {
            break;
        }

        coder.low = coder.low << 1;
        coder.high = (coder.high << 1) | 1;
        coder.value = (coder.value << 1) | readBit(coder);
    }
}

fn readBit(coder: *VeerCoder) i64 {
    if (coder.input_pos >= coder.input.len) return 0;

    const bit = (coder.input[coder.input_pos] >> (7 - @as(u3, coder.input_bit))) & 1;
    coder.input_bit += 1;
    if (coder.input_bit == 0) { // wrapped around from 7
        coder.input_pos += 1;
    }
    return @as(i64, bit);
}
```

### 7.6 Lossy Preprocessing

```zig
fn applyLossyEncode(data: []u8, q: u8) void {
    const shift = 8 - q;
    for (data) |*byte| {
        byte.* = byte.* >> @intCast(u3, shift);
    }
}

fn applyLossyDecode(data: []u8, q: u8) void {
    const shift = 8 - q;
    for (data) |*byte| {
        byte.* = byte.* << @intCast(u3, shift);
    }
}
```

### 7.7 CRC-32

```zig
const CRC32_TABLE: [256]u32 = blk: {
    var table: [256]u32 = undefined;
    for (0..256) |i| {
        var crc: u32 = @intCast(u32, i);
        for (0..8) |_| {
            if (crc & 1 == 1) {
                crc = (crc >> 1) ^ 0xEDB88320;
            } else {
                crc = crc >> 1;
            }
        }
        table[i] = crc;
    }
    break :blk table;
};

fn crc32(data: []const u8) u32 {
    var crc: u32 = 0xFFFFFFFF;
    for (data) |byte| {
        crc = CRC32_TABLE[(crc ^ byte) & 0xFF] ^ (crc >> 8);
    }
    return crc ^ 0xFFFFFFFF;
}
```

### 7.8 Top-Level Encode

```zig
fn encode(
    input_data: []const u8,
    mode: u8,
    q_value: u8,
    model_type: u8,
    allocator: std.mem.Allocator,
) ![]u8 {
    var data = try allocator.dupe(u8, input_data);
    defer allocator.free(data);

    // Apply lossy reduction if Q < 8
    if (mode == 1 and q_value < 8) {
        applyLossyEncode(data, q_value);
    }

    // Build frequency model
    var ft = FrequencyTable.init();
    if (model_type == 0) {
        // Static: count all frequencies first
        for (data) |byte| {
            ft.freq[byte] += 1;
        }
        ft.buildCumulative();
    }
    // Adaptive and context models start uniform and update per-symbol

    // Initialize coder
    var coder = VeerCoder.init();
    coder.output = std.ArrayList(u8).init(allocator);

    // Encode each byte
    for (data) |byte| {
        encodeSymbol(&coder, &ft, byte);
        if (model_type >= 1) {
            ft.update(byte);
        }
    }

    // Flush
    flushEncoder(&coder);

    // Build output file
    var output = std.ArrayList(u8).init(allocator);

    // Write header
    const header = VeerHeader{
        .magic = 0x56454552,
        .version = 1,
        .mode = mode,
        .q_value = q_value,
        .model_type = model_type,
        .original_size = input_data.len,
        .checksum = crc32(input_data),
        .compressed_size = @intCast(u32, coder.output.items.len),
    };
    try output.appendSlice(std.mem.asBytes(&header));

    // Write frequency table (static model only)
    if (model_type == 0) {
        try output.appendSlice(std.mem.sliceAsBytes(&ft.freq));
    }

    // Write compressed data
    try output.appendSlice(coder.output.items);

    // Write footer
    const footer = VeerFooter{
        .end_marker = 0,
        .carry_low_final = coder.carry_low,
        .carry_high_final = coder.carry_high,
    };
    try output.appendSlice(std.mem.asBytes(&footer));

    return output.toOwnedSlice();
}
```

### 7.9 Top-Level Decode

```zig
fn decode(
    ver_data: []const u8,
    allocator: std.mem.Allocator,
) ![]u8 {
    // Read header
    const header = @ptrCast(*const VeerHeader, ver_data[0..@sizeOf(VeerHeader)]);

    if (header.magic != 0x56454552) return error.InvalidFile;

    // Locate compressed data
    var data_offset: usize = @sizeOf(VeerHeader);

    // Read frequency table if static model
    var ft = FrequencyTable.init();
    if (header.model_type == 0) {
        const freq_bytes = ver_data[data_offset..data_offset + 1024];
        @memcpy(std.mem.sliceAsBytes(&ft.freq), freq_bytes);
        ft.buildCumulative();
        data_offset += 1024;
    }

    // Initialize coder
    var coder = VeerCoder.init();
    coder.input = ver_data[data_offset..data_offset + header.compressed_size];
    coder.input_pos = 0;
    coder.input_bit = 0;

    // Read initial value
    coder.value = 0;
    for (0..RANGE_BITS) |_| {
        coder.value = (coder.value << 1) | readBit(&coder);
    }

    // Decode each byte
    var output = try allocator.alloc(u8, header.original_size);
    for (0..header.original_size) |i| {
        output[i] = decodeSymbol(&coder, &ft);
        if (header.model_type >= 1) {
            ft.update(output[i]);
        }
    }

    // Apply lossy expansion if Q < 8
    if (header.mode == 1 and header.q_value < 8) {
        applyLossyDecode(output, header.q_value);
    }

    // Verify footer carries
    const footer_offset = data_offset + header.compressed_size;
    const footer = @ptrCast(*const VeerFooter,
        ver_data[footer_offset..footer_offset + @sizeOf(VeerFooter)]);
    if (footer.carry_low_final != coder.carry_low or
        footer.carry_high_final != coder.carry_high) {
        return error.CarryMismatch;
    }

    // Verify checksum for lossless mode
    if (header.mode == 0) {
        if (crc32(output) != header.checksum) {
            return error.ChecksumMismatch;
        }
    }

    return output;
}
```

---

## 8. Command-Line Interface

### 8.1 Usage

```
veer compress <input> <output.ver> [-q Q] [-m model]
veer decompress <input.ver> <output>
veer verify <input> [-q Q] [-m model]
veer info <input.ver>
```

### 8.2 Commands

**compress:** Encode input file to `.ver` format.

```
veer compress photo.png photo.ver              lossless, adaptive model
veer compress photo.png photo.ver -q 6         lossy Q=6, adaptive model
veer compress data.bin data.ver -m static      lossless, static model
veer compress book.txt book.ver -m context     lossless, context model (best compression)
```

**decompress:** Decode `.ver` file to original format.

```
veer decompress photo.ver restored.png
veer decompress data.ver restored.bin
```

**verify:** Compress and decompress in memory, verify match. Does not produce output files. For lossless mode, verifies byte-for-byte identity. For lossy mode, reports maximum per-byte error.

```
veer verify photo.png
veer verify photo.png -q 6
```

Output:

```
Veer verify: photo.png
  Original size:    2,458,832 bytes
  Compressed size:    983,211 bytes
  Ratio:            2.50:1
  Mode:             lossless
  Model:            adaptive
  CRC-32 match:     YES
  Carry match:      YES
  Result:           PASS
```

For lossy:

```
Veer verify: photo.png -q 6
  Original size:    2,458,832 bytes
  Compressed size:    614,208 bytes
  Ratio:            4.00:1
  Mode:             lossy (Q=6)
  Model:            adaptive
  Max byte error:   3
  Mean byte error:  1.2
  Result:           PASS (lossy)
```

**info:** Display `.ver` file header information without decompressing.

```
veer info photo.ver
```

Output:

```
Veer file: photo.ver
  Magic:            VEER
  Version:          1
  Mode:             lossless
  Q value:          8
  Model:            adaptive
  Original size:    2,458,832 bytes
  Compressed size:  983,211 bytes
  Ratio:            2.50:1
  CRC-32:           0xA3B7C921
  Final carry low:  1,847
  Final carry high: 3,092
```

---

## 9. Verification Strategy

### 9.1 Proving Correctness

The key claim of Veer is that VFR carry propagation produces exact range boundaries, resulting in provably optimal compression with perfect reconstruction. Verification:

**Test 1: Round-trip identity.** Compress and decompress files of varying sizes (1 byte to 100 MB) and types (text, binary, images, random). Verify byte-for-byte identity via CRC-32 and bitwise comparison. Any single-bit difference is a failure.

**Test 2: Carry chain verification.** After decoding, the decoder's final carry values must exactly match the encoder's final carry values stored in the footer. Any mismatch indicates precision loss in the range arithmetic.

**Test 3: Comparison with conventional coder.** Implement a conventional arithmetic coder (same frequency model, no VFR carries) alongside Veer. Compress the same files. Compare output sizes. Veer output should be equal to or smaller than conventional output on every input, because VFR carries prevent the sub-bit truncation waste that conventional coders accumulate.

**Test 4: Worst-case inputs.** Construct adversarial inputs: files with maximally skewed distributions (one symbol 99.99% frequency), files with perfectly uniform distributions, files with alternating patterns designed to maximize underflow states. Verify round-trip identity on all.

**Test 5: Lossy quality verification.** For lossy mode, compress images at Q=8 through Q=4. Verify that Q=8 produces identical output. Verify that Q<8 produces output with maximum per-byte error exactly equal to `2^(8-Q) - 1`. Verify visual quality at each Q level.

### 9.2 Benchmark Suite

```
File                    Size        Type            Purpose
────                    ────        ────            ───────
zeros_1mb.bin           1 MB        all zeros       best case (maximum compression)
random_1mb.bin          1 MB        random bytes    worst case (incompressible)
english_100kb.txt       100 KB      English prose   natural language
zig_source_500kb.zig    500 KB      Zig source      structured code
photo_5mb.bmp           5 MB        raw bitmap      image data
audio_10mb.wav          10 MB       raw PCM audio   signal data
mixed_50mb.bin          50 MB       mixed content   general purpose
tiny_11b.txt            11 bytes    "ABRACADABRA"   minimum viable test
```

Each file is compressed with all three model types (static, adaptive, context) and all Q values (4-8). Round-trip verified. Compression ratios and encode/decode speeds recorded.

---

## 10. Implementation Size Estimate

```
Module                      Lines    Purpose
──────                      ─────    ───────
veer_coder.zig              200      VFR arithmetic encode/decode
frequency_table.zig         100      Static, adaptive, context models
veer_format.zig             80       Header/footer read/write, CRC-32
lossy.zig                   30       Q-parameter shift encode/decode
main.zig                    120      CLI parsing, file I/O, commands
tests.zig                   150      Round-trip tests, carry verification
──────────────────────────────────────────────────
Total:                      ~680 lines of Zig
```

Zero external dependencies. Zig standard library only. Single compilation unit: `zig build-exe veer.zig`.

---

## 11. Summary

| Property | Specification |
|---|---|
| Name | Veer |
| File extension | `.ver` |
| Mode 1 | Lossless — byte-perfect reconstruction |
| Mode 2 | Lossy — configurable Q parameter (1-8 bits preserved) |
| Core algorithm | Arithmetic coding with VFR remainder carry propagation |
| Frequency models | Static, adaptive, context order-1 |
| Division method | Reciprocal multiply (no hardware division) |
| Precision | Mathematically exact range boundaries (no truncation drift) |
| Carry verification | Final carry values stored in footer, verified on decode |
| Checksum | CRC-32 of original file |
| Implementation | ~680 lines of Zig, zero dependencies |
| CLI commands | compress, decompress, verify, info |

---

*Veer: Exact Arithmetic Compression Using VFR Integer Coding*
*A constituent specification of the Q-Foundational Stack*

