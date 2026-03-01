# Phase 2: Pure Go Evaluator

## Overview

Build a pure Go evaluator that reads `.orion` v2 files (produced by the Python compiler), CKKS-encodes raw diagonals at load time, and runs FHE inference by walking the computation graph. No Python, no PyTorch, no skeleton network.

Key deliverables:

- `evaluator/` Go package at repo root (separate `go.mod`)
- `LoadModel(data) → *Model` — parses binary format, CKKS-encodes diagonals and biases
- `NewEvaluator(params, keys) → *Evaluator` — constructs from evaluation keys
- `eval.Forward(model, ct) → ct` — walks graph, dispatches per-node operations
- E2E tests: Python compile → Go keygen + encrypt → Go evaluate → Go decrypt → verify

Op coverage for Phase 2: `linear_transform`, `quad`, `polynomial`, `flatten`, `add`, `mult`. Bootstrap deferred.

## Context

**Existing Go code in `orionclient/`:**

- `evaluator.go` — `Evaluator` with all Lattigo arithmetic ops (Add, Mul, Rotate, Rescale, EvalPoly, EvalLinearTransform, Bootstrap)
- `lineartransform.go` — `GenerateLinearTransform()` encodes raw diagonals into Lattigo `lintrans.LinearTransformation` objects. This is the reference for how the evaluator must encode diagonals.
- `polynomial.go` — `GenerateMonomial()`, `GenerateChebyshev()` wrapping `bignum.NewPolynomial`
- `bootstrapper.go` — `loadBootstrapKey()`, `Bootstrap()`
- `params.go` — `Params` type matching Python's `CKKSParams`
- `keys.go` — `EvalKeyBundle`, `Manifest` types
- `client.go` — `Client` for keygen, encrypt, decrypt; `FromSecretKey()` restores from serialized key

**v2 binary format** (from `orion/compiled_model.py`):

```
[8B] MAGIC (ORION\x00\x02\x00)
[4B] HEADER_LEN (uint32 LE)
[NB] HEADER_JSON (UTF-8)
[4B] BLOB_COUNT (uint32 LE)
for each blob:
    [8B] BLOB_LEN (uint64 LE)
    [NB] BLOB_DATA
```

**Raw diagonal blob format:**

```
[4B]                         NUM_DIAGS (uint32 LE)
[NUM_DIAGS × 4B]             DIAG_INDICES (int32 LE, sorted ascending)
[NUM_DIAGS × max_slots × 8B] VALUES (float64 LE)
```

**Raw bias blob format:** `[max_slots × 8B]` float64 LE

**JSON header key fields:** `version`, `params`, `config`, `manifest`, `input_level`, `cost`, `graph` (with `nodes`, `edges`, `input`, `output`), `blob_count`

**Node op types and configs:** See ARCH.md section 2.5 and plan `2026-03-01-phase-1-compiled-model.md` Op Types table.

**Architecture reference:** ARCH.md sections 2.1–2.6

**Design constraints:**

- `Model` is immutable after `LoadModel()` — safe to share across goroutines
- `Evaluator` is NOT goroutine-safe (Lattigo buffers)
- Evaluator never holds secret keys — accepts eval keys from user
- No `orionclient.Evaluator` wrapping — construct Lattigo evaluators directly to avoid needing accessor methods on unexported fields
- Import `orionclient/` only for type definitions: `Params`, `EvalKeyBundle`, `Client`

**Serialization format compatibility notes:**

- Python `EvalKeys.to_bytes()` uses its own container format (`ORKEY\x00\x01\x00`) — there is **no Go parser** for this format. E2E tests must generate keys in Go using `orionclient.Client.GenerateKeys()`, not by loading Python-serialized key files.
- Python `Ciphertext.to_bytes()` prepends a Python shape header before the Go wire format — Go's `UnmarshalCiphertext()` cannot load it directly. E2E tests must encrypt in Go using `orionclient.Client`.
- Python `CompiledModel.to_bytes()` uses the `.orion` v2 container format — this IS what the Go evaluator parses. This is the only cross-language serialization boundary.

## Development Approach

- **Testing approach**: Regular (implement, then test)
- Complete each task fully before moving to the next
- Make small, focused changes
- **CRITICAL: every task MUST include new/updated tests** for code changes in that task
  - tests are not optional — they are a required part of the checklist
  - write unit tests for new functions/methods
  - write tests for error/edge cases
  - tests cover both success and error scenarios
- **CRITICAL: all tests must pass before starting next task** — no exceptions
- **CRITICAL: update this plan file when scope changes during implementation**
- Run tests after each change

## Testing Strategy

- **Unit tests**: required for every task (see Development Approach above)
- Go tests in `evaluator/` with `go test ./evaluator/...`
- **Test fixtures from Python**: Only `.orion` compiled model files + cleartext expected output JSON + raw input values JSON. Small files (< 1 MB each), safe to commit.
- **Keys and ciphertexts generated in Go**: E2E tests use `orionclient.Client` to generate keys from `model.ClientParams()` manifest and encrypt input. This avoids cross-language serialization issues and prevents committing large key files (~50-100 MB per model).
- E2E validation: Python compile → Go keygen → Go encrypt → Go evaluate → Go decrypt → compare to cleartext expected output

## Progress Tracking

- Mark completed items with `[x]` immediately when done
- Add newly discovered tasks with + prefix
- Document issues/blockers with ! prefix
- Update plan if implementation deviates from original scope
- Keep plan in sync with actual work done

## Implementation Steps

### Task 1: Set up evaluator/ Go package and generate test fixtures

Create the Go module and generate test data from Python.

- [x] Create `evaluator/` directory at repo root
- [x] Create `evaluator/go.mod`:
  - Module path: `github.com/baahl-nyu/orion/evaluator`
  - Import `github.com/baahl-nyu/orion/orionclient` and `github.com/baahl-nyu/lattigo/v6` (same versions as `orionclient/go.mod`)
  - Add `replace github.com/baahl-nyu/orion/orionclient => ../orionclient` (local dependency, not published to module proxy)
  - Add `github.com/stretchr/testify` for tests
- [x] Run `cd evaluator && go mod tidy` to generate `go.sum`
- [x] Create placeholder `evaluator/doc.go` with `package evaluator` so the module compiles
- [x] Create Python script `evaluator/testdata/generate.py` that:
  - Compiles SimpleMLP (Flatten → Linear(784,32) → Quad → Linear(32,10)) with `logn=13, logq=[29,26,26,26,26,26], h=8192, conjugate_invariant`
  - Writes `testdata/mlp.orion` (CompiledModel.to_bytes()) — the compiled model file (~26 KB)
  - Sets `torch.manual_seed(42)`, generates input `torch.randn(1,1,28,28)`, writes `testdata/mlp.input.json` (flattened float64 array as JSON list)
  - Computes cleartext expected output (float64), writes `testdata/mlp.expected.json` (float64 array)
  - Repeats for SigmoidMLP (Flatten → Linear(784,32) → Sigmoid(degree=7) → Linear(32,10)) with `logn=13, logq=[29,26,26,26,26,26,26,26], h=8192, conjugate_invariant` — writes `testdata/sigmoid.orion`, `testdata/sigmoid.input.json`, `testdata/sigmoid.expected.json`
- [x] Run the Python script to generate fixtures (use venv)
- [x] Commit generated fixtures to `evaluator/testdata/` (only `.orion`, `.input.json`, `.expected.json` files — no key or ciphertext files)
- [x] Verify `cd evaluator && go build ./...` succeeds
- [x] Run `cd evaluator && go test ./...` — must pass (no tests yet, should be no-op)

### Task 2: Binary format parser (format.go)

Parse the `.orion` v2 binary container.

- [x] Create `evaluator/format.go` with Go structs for JSON header (all with `json:"..."` struct tags matching Python's lowercase JSON keys):
  - `CompiledHeader` — `Version int`, `Params HeaderParams`, `Config HeaderConfig`, `Manifest HeaderManifest`, `InputLevel int`, `Cost HeaderCost`, `Graph HeaderGraph`, `BlobCount int`
  - `HeaderParams` — `LogN int`, `LogQ []int`, `LogP []int`, `LogScale int`, `H int`, `RingType string`, `BootLogP []int`
  - `HeaderConfig` — `Margin int`, `EmbeddingMethod string`, `FuseModules bool`
  - `HeaderManifest` — `GaloisElements []int`, `BootstrapSlots []int`, `BootLogP []int`, `NeedsRLK bool`
  - `HeaderCost` — `BootstrapCount int`, `GaloisKeyCount int`, `BootstrapKeyCount int`
  - `HeaderGraph` — `Input string`, `Output string`, `Nodes []HeaderNode`, `Edges []HeaderEdge`
  - `HeaderNode` — `Name string`, `Op string`, `Level int`, `Depth int`, `Shape map[string][]int` (nullable), `Config json.RawMessage` (kept raw for per-op parsing later), `BlobRefs map[string]int` (nullable)
  - `HeaderEdge` — `Src string`, `Dst string`
- [x] Implement `ParseContainer(data []byte) (*CompiledHeader, [][]byte, error)`:
  - Verify magic `ORION\x00\x02\x00`
  - Parse header length (uint32 LE), JSON header via `json.Unmarshal`, blob count (uint32 LE), blobs
- [x] Implement `ParseDiagonalBlob(data []byte, maxSlots int) (map[int][]float64, error)`:
  - Read NUM_DIAGS (uint32 LE), DIAG_INDICES (int32 LE), VALUES (float64 LE via `math.Float64frombits`)
  - Return `diagIndex → []float64` map
- [x] Implement `ParseBiasBlob(data []byte, maxSlots int) ([]float64, error)`:
  - Read `maxSlots` float64 LE values
- [x] Add per-op config structs and parsing helpers:
  - `LinearTransformConfig` — `BSGSRatio float64`, `OutputRotations int`
  - `PolynomialConfig` — `Coeffs []float64`, `Basis string`, `Prescale float64`, `Postscale float64`, `Constant float64`
  - `BootstrapConfig` — `InputLevel int`, `InputMin float64`, `InputMax float64`, `Prescale float64`, `Postscale float64`, `Constant float64`, `Slots int`
  - `parseLinearTransformConfig(raw json.RawMessage) (*LinearTransformConfig, error)` etc.
- [x] Write tests: `ParseContainer` on `testdata/mlp.orion` — verify version=2, node count, edge count, blob count match expected
- [x] Write tests: `ParseContainer` with wrong magic returns error
- [x] Write tests: `ParseDiagonalBlob` — load a diagonal blob from parsed mlp.orion, verify indices sorted, each diagonal has `maxSlots` values
- [x] Write tests: `ParseBiasBlob` — verify length = maxSlots
- [x] Write tests: `parseLinearTransformConfig` — verify bsgs_ratio and output_rotations parsed correctly from a real node's config
- [x] Run `go test ./evaluator/...` — must pass before task 3

### Task 3: Graph representation (graph.go)

Build the computation graph with topological ordering.

- [x] Create `evaluator/graph.go` with types:
  - `Node` — `Name string`, `Op string`, `Level int`, `Depth int`, `Shape map[string][]int`, `ConfigRaw json.RawMessage`, `BlobRefs map[string]int`
  - `Graph` — `Input string`, `Output string`, `Nodes map[string]*Node`, `Order []string`, `Inputs map[string][]string`
- [x] Implement `buildGraph(header *CompiledHeader) (*Graph, error)`:
  - Index nodes by name into `Nodes` map
  - Build `Inputs` reverse adjacency: for each edge `{src, dst}`, append `src` to `Inputs[dst]`
  - Compute topological sort (Kahn's algorithm — count in-degrees, BFS from zero-in-degree nodes)
  - Validate: all nodes reached (else cycle exists), Input node has no incoming edges, Output node exists
- [x] Write tests: `buildGraph` on parsed `testdata/mlp.orion` header — verify topo order length, input name = `flatten`, output name = `fc2`, node count = 4
- [x] Write tests: `buildGraph` with synthetic cyclic edges returns error
- [x] Write tests: `buildGraph` with edge referencing nonexistent node returns error
- [x] Write tests: `Inputs` map — verify `fc1` has exactly one predecessor (`flatten`), `act1` has exactly one predecessor (`fc1`), etc.
- [x] Run `go test ./evaluator/...` — must pass before task 4

### Task 4: Model loader (model.go)

Load a compiled model, CKKS-encode diagonals and biases at load time.

- [x] Create `evaluator/model.go` with `Model` struct:
  ```go
  type Model struct {
      header     *CompiledHeader
      params     ckks.Parameters
      graph      *Graph
      transforms map[string]map[string]lintrans.LinearTransformation // node -> ref -> LT
      biases     map[string]*rlwe.Plaintext                          // node -> bias
      polys      map[string]bignum.Polynomial                        // node -> polynomial
  }
  ```
- [x] Implement `LoadModel(data []byte) (*Model, error)`:
  1. `ParseContainer(data)` → header + blobs
  2. Convert `header.Params` to `orionclient.Params`, call `.NewCKKSParameters()` → `ckks.Parameters`
  3. Create `ckks.Encoder` (temporary, used only during loading)
  4. `buildGraph(header)` → `*Graph`
  5. For each `linear_transform` node:
     - Parse config via `parseLinearTransformConfig(node.ConfigRaw)`
     - For each `diag_{row}_{col}` blob ref: `ParseDiagonalBlob` → diagonal map → create `lintrans.Parameters` → `lintrans.NewTransformation` + `lintrans.Encode` (reference: `orionclient/lineartransform.go:28-56`)
     - For `bias` blob ref: `ParseBiasBlob` → create `ckks.NewPlaintext(params, biasLevel)`, set scale to `rlwe.NewScale(params.DefaultScale())`, `encoder.Encode(biasVec, pt)` → store `*rlwe.Plaintext`
     - Bias level = `node.Level - node.Depth` (level after LT + rescale). **Note:** the bias scale must match the ciphertext scale at that level — `params.DefaultScale()` is `2^logscale` which should match post-rescale ciphertext scale. If E2E tests show scale mismatch, adjust to use `rlwe.NewScale(params.Q()[biasLevel])` instead.
  6. For each `polynomial` node:
     - Parse config via `parsePolynomialConfig(node.ConfigRaw)`
     - If `basis == "chebyshev"`: `bignum.NewPolynomial(bignum.Chebyshev, coeffs, [2]float64{-1, 1})`
     - If `basis == "monomial"`: `bignum.NewPolynomial(bignum.Monomial, coeffs, nil)`
  7. Validate: all blob_refs resolved, all edge endpoints exist
- [x] Implement `(m *Model) ClientParams() (orionclient.Params, orionclient.Manifest, int)`:
  - Convert header params to `orionclient.Params`
  - Convert header manifest to `orionclient.Manifest` (note: manifest `GaloisElements` are `[]int` in JSON but `[]uint64` in Go Manifest — cast during conversion)
  - Return `(params, manifest, inputLevel)`
- [x] Write tests: `LoadModel` on `testdata/mlp.orion` — verify node count, LT count (2), bias count (2), polynomial count (0)
- [x] Write tests: `LoadModel` on `testdata/sigmoid.orion` — verify polynomial count (1), polynomial basis = "chebyshev", coeffs length > 0
- [x] Write tests: `ClientParams()` — verify returned params match header, manifest galois_elements non-empty, inputLevel > 0
- [x] Write tests: `LoadModel` with truncated data returns error
- [x] Run `go test ./evaluator/...` — must pass before task 5

### Task 5: Evaluator struct, constructor, and Forward skeleton (evaluator.go)

Create the evaluator with key deserialization and graph walking dispatch loop — op handlers are stubs that return errors.

- [ ] Create `evaluator/evaluator.go` with `Evaluator` struct:
  ```go
  type Evaluator struct {
      params   ckks.Parameters
      encoder  *ckks.Encoder
      eval     *ckks.Evaluator
      linEval  *lintrans.Evaluator
      polyEval *polynomial.Evaluator
  }
  ```
- [ ] Implement `NewEvaluator(p orionclient.Params, keys orionclient.EvalKeyBundle) (*Evaluator, error)`:
  - Build `ckks.Parameters` from `Params` via `p.NewCKKSParameters()`
  - Deserialize RLK, Galois keys into `rlwe.MemEvaluationKeySet` (same logic as `orionclient/evaluator.go:34-59`)
  - Create `ckks.Evaluator`, `ckks.Encoder`, `lintrans.Evaluator`, `polynomial.Evaluator`
- [ ] Implement `(e *Evaluator) Close()` — nil out all fields
- [ ] Implement `(e *Evaluator) Forward(model *Model, input *rlwe.Ciphertext) (*rlwe.Ciphertext, error)`:
  - Initialize `results map[string]*rlwe.Ciphertext`
  - Set `results[model.graph.Input] = input` (the graph's input node — for MLP this is `flatten`, the first node with no predecessors; the input ciphertext represents the already-flattened/padded data)
  - Walk `model.graph.Order`, skip input node
  - For each node: gather inputs from `model.graph.Inputs[name]`, switch on `node.Op`, dispatch to `evalXxx` method
  - Return `results[model.graph.Output]`
- [ ] Add stub op handlers that return `fmt.Errorf("op %s not yet implemented", op)` for each op type
- [ ] Write test: `NewEvaluator` + `Close` lifecycle (use `orionclient.Client` to generate minimal keys)
- [ ] Write test: `Forward` with stub ops returns "not yet implemented" error
- [ ] Run `go test ./evaluator/...` — must pass before task 6

### Task 6: Implement simple op handlers (flatten, quad, add, mult)

- [ ] Implement `evalFlatten(ct *rlwe.Ciphertext) (*rlwe.Ciphertext, error)` — return input unchanged (no-op, metadata only)
- [ ] Implement `evalQuad(ct *rlwe.Ciphertext) (*rlwe.Ciphertext, error)`:
  1. `eval.MulRelinNew(ct, ct)` → result
  2. `eval.Rescale(result, result)` → rescaled
  3. Return rescaled
- [ ] Implement `evalAdd(ct0, ct1 *rlwe.Ciphertext) (*rlwe.Ciphertext, error)`:
  1. `eval.AddNew(ct0, ct1)`
- [ ] Implement `evalMult(ct0, ct1 *rlwe.Ciphertext) (*rlwe.Ciphertext, error)`:
  1. `eval.MulRelinNew(ct0, ct1)` → result
  2. `eval.Rescale(result, result)`
  3. Return rescaled
- [ ] Write unit tests for `evalQuad`: encrypt a vector, square it, decrypt, verify against element-wise expected
- [ ] Write unit tests for `evalAdd`, `evalMult`: encrypt two vectors, combine, decrypt, verify
- [ ] Run `go test ./evaluator/...` — must pass before task 7

### Task 7: Implement evalLinearTransform

This is the most complex op — handles multi-block LTs, rescaling, bias addition, and output rotations.

- [ ] Implement `evalLinearTransform(model *Model, node *Node, ct *rlwe.Ciphertext) (*rlwe.Ciphertext, error)`:
  1. Parse config via `parseLinearTransformConfig(node.ConfigRaw)`
  2. Look up pre-encoded LTs from `model.transforms[node.Name]`
  3. For each `(ref, lt)` in the LT map:
     - `linEval.EvaluateNew(ct, lt)` → partial result
     - If multi-block: accumulate via `eval.Add`
  4. Rescale result: `eval.Rescale(result, result)`
  5. Add bias: `eval.Add(result, model.biases[node.Name])` (bias plaintext pre-encoded at correct level/scale)
  6. If `config.OutputRotations > 0`: apply output rotation loop:
     ```go
     for i := 0; i < config.OutputRotations; i++ {
         rotation := maxSlots / (1 << (i + 1))
         rotated, _ := eval.RotateNew(result, rotation)
         result, _ = eval.AddNew(result, rotated)
     }
     ```
- [ ] Write integration test: load MLP model, create client+evaluator, encrypt input, call `Forward` (which now uses real `evalLinearTransform` + `evalQuad` + `evalFlatten`), decrypt, compare to expected output from `testdata/mlp.expected.json` with tolerance ≤ 1e-3
- [ ] If bias scale mismatch causes errors: adjust bias encoding in `LoadModel` (try `rlwe.NewScale(params.Q()[biasLevel])` or match ciphertext scale dynamically)
- [ ] Run `go test ./evaluator/...` — must pass before task 8

### Task 8: Implement evalPolynomial

- [ ] Implement `evalPolynomial(model *Model, node *Node, ct *rlwe.Ciphertext) (*rlwe.Ciphertext, error)`:
  1. Parse config via `parsePolynomialConfig(node.ConfigRaw)`
  2. Look up polynomial from `model.polys[node.Name]`
  3. Apply prescale/constant (if needed):
     - If `constant != 0`: `eval.Add(ct, constant)` (scalar add)
     - If `prescale != 1`: `eval.Mul(ct, prescale)` then `eval.Rescale(ct, ct)` (scalar mul consumes a level)
  4. `polyEval.Evaluate(ct, poly, targetScale)` — target scale = `rlwe.NewScale(params.DefaultScale())`
     **Note:** Lattigo's polynomial evaluator handles level management internally. The `targetScale` parameter determines the output scale. If polynomial evaluation fails with scale errors, experiment with `rlwe.NewScale(params.Q()[expectedOutputLevel])`.
  5. Apply postscale (if needed):
     - If `postscale != 1`: `eval.Mul(ct, postscale)` then `eval.Rescale(ct, ct)`
- [ ] Write integration test `TestForwardSigmoid`: load sigmoid model, create client+evaluator, encrypt input, `Forward`, decrypt, compare to `testdata/sigmoid.expected.json` with tolerance ≤ 1e-3
- [ ] Run `go test ./evaluator/...` — must pass before task 9

### Task 9: E2E tests and edge cases

Full E2E test suite with error handling validation.

- [ ] Create shared test helper `loadModelAndEvaluate(t, modelPath, inputPath, expectedPath)` to reduce duplication between MLP and sigmoid tests:
  1. `LoadModel(os.ReadFile(modelPath))`
  2. `model.ClientParams()` → params, manifest, inputLevel
  3. `orionclient.New(params)` → client (fresh key pair)
  4. `client.GenerateKeys(manifest)` → eval key bundle
  5. `NewEvaluator(params, keys)` → evaluator
  6. Load input values from inputPath JSON, pad to maxSlots
  7. `client.Encode(inputValues, inputLevel, client.DefaultScale())` → plaintext
  8. `client.Encrypt(plaintext)` → ciphertext (single `*rlwe.Ciphertext` via `.Raw()[0]`)
  9. `evaluator.Forward(model, ciphertext)` → result
  10. `client.Decrypt(orionclient.NewCiphertext([]*rlwe.Ciphertext{result}, nil))` → plaintext
  11. `client.Decode(plaintext)` → float64 slice
  12. Load expected output from expectedPath JSON
  13. Compare first N values with `assert.InDelta` tolerance ≤ 1e-3
- [ ] Write `TestForwardMLP` using the helper with MLP testdata
- [ ] Write `TestForwardSigmoid` using the helper with sigmoid testdata (replace or extend Task 8's test)
- [ ] Write `TestMultipleEvaluatorsShareModel`:
  - Load model once
  - Create two separate clients with separate keys
  - Generate eval keys from each client
  - Create two evaluators
  - Both evaluate the same model with differently encrypted inputs
  - Both produce correct results independently
- [ ] Write `TestForwardClosedEvaluatorErrors`:
  - Close evaluator, call Forward, expect error (not panic)
- [ ] Write `TestLoadModelInvalidData`:
  - Empty data, wrong magic, truncated header — all return errors
- [ ] Run `go test ./evaluator/...` — all tests must pass

### Task 10: Verify acceptance criteria

- [ ] Verify `evaluator.LoadModel(data)` successfully parses `.orion` v2 files produced by the Python compiler
- [ ] Verify `model.ClientParams()` returns correct CKKS params, key manifest, and input level
- [ ] Verify `evaluator.NewEvaluator(params, keys)` constructs from Go-generated eval keys
- [ ] Verify `eval.Forward(model, ct)` produces correct results for MLP (tolerance ≤ 1e-3)
- [ ] Verify `eval.Forward(model, ct)` produces correct results for Sigmoid model (polynomial evaluation path)
- [ ] Verify `eval.Forward()` handles: `linear_transform`, `quad`, `polynomial`, `flatten`
- [ ] Verify multiple `Evaluator` instances sharing one `Model` work correctly
- [ ] Verify `Evaluator.Close()` releases resources
- [ ] Verify all methods return `(result, error)` — no panics on malformed input
- [ ] Run full test suite: `go test ./evaluator/...` — all pass
- [ ] Run linter: `go vet ./evaluator/...` — all issues fixed

### Task 11: [Final] Update documentation

- [ ] Update ARCH.md: mark Phase 2 acceptance checklist items as complete (those covered), note deferred items (bootstrap, add/mult E2E if no test model exercises them)
- [ ] Update CLAUDE.md if new patterns discovered

_Note: ralphex automatically moves completed plans to `docs/plans/completed/`_

## Technical Details

### Linear transform CKKS encoding (the critical path)

At `LoadModel()` time, each raw diagonal blob must be encoded into a Lattigo `lintrans.LinearTransformation`. Reference code in `orionclient/lineartransform.go:28-56`:

```go
diagonals := make(lintrans.Diagonals[float64])
for idx, vals := range diagIndices {
    diagonals[idx] = vals
}

ltparams := lintrans.Parameters{
    DiagonalsIndexList:        diagonals.DiagonalsIndexList(),
    LevelQ:                    level,
    LevelP:                    ckksParams.MaxLevelP(),
    Scale:                     rlwe.NewScale(ckksParams.Q()[level]),
    LogDimensions:             ring.Dimensions{Rows: 0, Cols: ckksParams.LogMaxSlots()},
    LogBabyStepGiantStepRatio: int(math.Log2(bsgsRatio)),
}

lt := lintrans.NewTransformation(ckksParams, ltparams)
lintrans.Encode(enc, diagonals, lt)
```

Key parameters per node:

- `level` = node.Level (from graph metadata)
- `bsgsRatio` = node.Config `bsgs_ratio` field (parsed via `parseLinearTransformConfig`)
- `LogDimensions` = `{Rows: 0, Cols: LogMaxSlots()}` (always, regardless of output_rotations)

### Output rotations (hybrid embedding)

After LT evaluation, when `output_rotations > 0`:

```go
for i := 0; i < outputRotations; i++ {
    rotation := maxSlots / (1 << (i + 1))
    rotated, _ := eval.RotateNew(ct, rotation)
    ct, _ = eval.AddNew(ct, rotated)
}
```

### Bias encoding

Bias is a plaintext at level `node.Level - node.Depth` with scale = `rlwe.NewScale(params.DefaultScale())`. Encoded at `LoadModel()` time via `encoder.Encode(biasValues, pt)`.

**Scale matching note:** After `EvalLinearTransform` + `Rescale`, the ciphertext scale is approximately `2^logscale` (the default scale). The bias plaintext scale must match. If E2E tests reveal scale mismatch (Lattigo `Add` may error or produce garbage), try:

1. `rlwe.NewScale(params.Q()[biasLevel])` — uses the actual modulus at that level
2. Match the ciphertext's post-rescale scale dynamically (would require encoding bias at eval time, not load time — last resort)

### Polynomial evaluation

For Chebyshev nodes with `prescale`/`postscale`/`constant`:

1. If `constant != 0`: `ct = ct + constant` (scalar add, no level consumed)
2. If `prescale != 1`: `ct = ct * prescale` then rescale (consumes 1 level)
3. `ct = polyEval.Evaluate(ct, poly, targetScale)` — Lattigo handles internal level management
4. If `postscale != 1`: `ct = ct * postscale` then rescale

Target scale for `polyEval.Evaluate`: use `rlwe.NewScale(params.DefaultScale())`. The polynomial evaluator produces output at this scale.

**Note:** The order of prescale/constant operations matters — `constant` shifts the input, `prescale` scales it. Together they map values into the polynomial's domain (e.g., [-1, 1] for Chebyshev). The ARCH.md specifies: first add constant, then multiply by prescale.

### Graph input node

The graph's `Input` field (e.g., `flatten` for MLP) is the first node with no incoming edges. In `Forward()`, the input ciphertext is assigned to `results[model.graph.Input]`. The input ciphertext must contain the already-padded slot values (e.g., flattened image + zero padding to `maxSlots`). The `flatten` node itself is a no-op — it passes the ciphertext through unchanged.

## Post-Completion

**Manual verification:**

- Compare Go evaluation output against Python cleartext forward (tolerance ≤ 1e-3)
- Profile `LoadModel()` time for LeNet-sized models (~370 MB `.orion`)

**Phase 3 prerequisites:**

- The Go evaluator is the foundation for Python evaluator bindings (`orion-evaluator` package)
- After Phase 2: `python/orion-evaluator/bridge/` wraps `evaluator/` via CGO
- The `evaluator/` package API (`LoadModel`, `NewEvaluator`, `Forward`) becomes the Python binding contract
