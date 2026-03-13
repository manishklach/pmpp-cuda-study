# 044 - Batched Matrix Multiply

- Track: `Linear Algebra`
- Difficulty: `Intermediate`
- Status: `Reference-friendly`
- GitHub batch: `041-060`

## Goal

Build and study a working CUDA implementation of **Batched Matrix Multiply**.

## PMPP Ideas To Focus On

- batch dimension indexing
- independent GEMMs
- launch shape design

## Build

```powershell
nvcc -std=c++17 -O2 main.cu -o example.exe
```

## Run

```powershell
.\example.exe
```

## Validation

- The program prints `PASS` when GPU output matches the CPU reference or stays within tolerance.
- Start with the included tiny matrices before scaling up.

## What To Modify Next

- Increase batch size.
- Compare serial launches versus batched indexing.
