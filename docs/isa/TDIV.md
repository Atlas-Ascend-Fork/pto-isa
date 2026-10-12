# TDIV


## Tile Operation Diagram

![TDIV tile operation](../figures/isa/TDIV.svg)

## Introduction

Elementwise division of two tiles.

## Math Interpretation

For each element `(i, j)` in the valid region:

$$ \mathrm{dst}_{i,j} = \frac{\mathrm{src0}_{i,j}}{\mathrm{src1}_{i,j}} $$

## C++ Intrinsic

Declared in `include/pto/common/pto_instr.hpp`:

```cpp
template <auto PrecisionType = DivAlgorithm::DEFAULT, typename TileDataDst, typename TileDataSrc0,
          typename TileDataSrc1, typename... WaitEvents>
PTO_INST RecordEvent TDIV(TileDataDst &dst, TileDataSrc0 &src0, TileDataSrc1 &src1, WaitEvents &... events);
```

`PrecisionType` has the following values available:

* `DivAlgorithm::DEFAULT`: On A2/A3, TDIV uses the hardware `vdiv` instruction and is already the high-precision mode. Passing `DivAlgorithm::DEFAULT` is also the high-precision version. On A5 this is the faster, lower-precision path.
* `DivAlgorithm::HIGH_PRECISION`: High-precision algorithm, but slower. On A2/A3 this selects the same hardware `vdiv` instruction as `DivAlgorithm::DEFAULT`. On A5 this selects the high-precision algorithm.

## Constraints

- **Implementation checks (A2A3)**:
    - `TileData::DType` must be one of: `half`, `float`.
    - Tile layout must be row-major (`TileData::isRowMajor`).
    - Tile location must be vector (`TileData::Loc == TileType::Vec`).
    - Static valid bounds: `TileData::ValidRow <= TileData::Rows` and `TileData::ValidCol <= TileData::Cols`.
    - Runtime: `src0`, `src1` and `dst` tiles should have the same `validRow/validCol`.
- **Implementation checks (A5)**:
    - `TileData::DType` must be one of: `int32_t`, `uint32_t`, `int64_t`, `uint64_t`, `float`, `int16_t`, `uint16_t`, `half`.
    - Tile layout must be row-major (`TileData::isRowMajor`).
    - Tile location must be vector (`TileData::Loc == TileType::Vec`).
    - Static valid bounds: `TileData::ValidRow <= TileData::Rows` and `TileData::ValidCol <= TileData::Cols`.
    - Runtime: `src0`, `src1` and `dst` tiles should have the same `validRow/validCol`.
- **Valid region**:
    - The op uses `dst.GetValidRow()` / `dst.GetValidCol()` as the iteration domain;.
- **Division-by-zero**:
    - Behavior is target-defined.
- **Precision**
    - On A2/A3, TDIV uses the hardware `vdiv` instruction and is already the high-precision mode. Passing `DivAlgorithm::DEFAULT` from the TDIV interface is also the high-precision version.
    - On A2/A3, `DivAlgorithm::HIGH_PRECISION` uses the same hardware `vdiv` instruction.
    - On A5, `DivAlgorithm::HIGH_PRECISION` selects the high-precision algorithm. `DivAlgorithm::DEFAULT` is the faster, lower-precision path.

## Examples

### Auto

```cpp
#include <pto/pto-inst.hpp>

using namespace pto;

void example_auto() {
  using TileT = Tile<TileType::Vec, float, 16, 16>;
  TileT src0, src1, dst;
  TDIV(dst, src0, src1);
}
```

### Manual

```cpp
#include <pto/pto-inst.hpp>

using namespace pto;

void example_manual() {
  using TileT = Tile<TileType::Vec, float, 16, 16>;
  TileT src0, src1, dst;
  TASSIGN(src0, 0x1000);
  TASSIGN(src1, 0x2000);
  TASSIGN(dst,  0x3000);
  TDIV(dst, src0, src1);
}
```
