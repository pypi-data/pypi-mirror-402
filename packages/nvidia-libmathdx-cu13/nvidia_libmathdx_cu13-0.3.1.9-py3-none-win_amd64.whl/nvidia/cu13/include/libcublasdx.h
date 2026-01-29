// Copyright (c) 2024-2026, NVIDIA CORPORATION & AFFILIATES.  All rights reserved.
//
// NVIDIA CORPORATION and its licensors retain all intellectual property
// and proprietary rights in and to this software, related documentation
// and any modifications thereto.  Any use, reproduction, disclosure or
// distribution of this software and related documentation without an express
// license agreement from NVIDIA CORPORATION is strictly prohibited.

// libmathdx's API is subject to change.
// Please contact Math-Libs-Feedback@nvidia.com for usage feedback.

#ifndef MATHDX_LIBCUBLASDX_H
#define MATHDX_LIBCUBLASDX_H

#include <stddef.h>
#include <limits.h>

#include "libcommondx.h"

#if defined(__cplusplus)
extern "C" {
#endif /* __cplusplus */

/**
 * @brief Returns the major.minor.patch version of cuBLASDx
 *
 * @param[out] major The major version
 * @param[out] minor The minor version
 * @param[out] patch The patch version
 * @return `COMMONDX_SUCCESS`
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetVersion(int* major,
                                                                   int* minor,
                                                                   int* patch) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief A handle to a cuBLASDx descriptor.
 *
 * Equivalent to `using GEMM = ...` in cuBLASDx CUDA C++.
 */
typedef long long int cublasdxDescriptor;

/**
 * @brief A handle to an opaque device tensor.
 */
typedef long long int cublasdxTensor;

/**
 * @brief A handle to a device function.
 * A device function operators on tensors described by \ref cublasdxTensor
 */
typedef long long int cublasdxDeviceFunction;

/**
 * @brief Sentinel value used to mark runtime-provided shapes/strides.
 *
 * Pass \ref LIBMATHDX_RUNTIME in \ref cublasdxCreateTensorStrided
 * to indicate that the corresponding dimension or stride will be provided at runtime.
 */
#define LIBMATHDX_RUNTIME LLONG_MIN

/**
 * @brief Special pipeline depth requesting the maximal supported depth.
 *
 * When creating pipelines with \ref cublasdxCreateDevicePipeline pass
 * \ref LIBMATHDX_MAX_PIPELINE_DEPTH to select the maximum depth based
 * on available shared memory.
 */
#define LIBMATHDX_MAX_PIPELINE_DEPTH 0

/**
 * @brief Sentinel handle indicating that no descriptor is provided.
 *
 * Some APIs accept \ref LIBMATHDX_NONE in lieu of a \ref cublasdxDescriptor to operate
 * without a descriptor.
 */
#define LIBMATHDX_NONE LLONG_MIN

/**
 * @brief A handle to an opaque device pipeline.
 */
 typedef long long int cublasdxPipeline;

/**
 * @brief Type of cublasDx API
 *
 * Handling problems with default or custom/dynamic leading dimensions.
 * Check cublasdx::LeadingDimension operator documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/operators.html#leadingdimension-operator)
 */
typedef enum cublasdxApi_t {
    /**
     * Use API for problems with default leading dimensions.
     * Function API is defined by its signature:
     * `void (value_type_c* alpha, value_type_a* smem_a, value_type_b* smem_b, value_type_c* beta, value_type_c*
     * smem_c)` where
     *     - `smem_a`, `smem_b` and `smem_c` are pointers to value of type given by the \ref CUBLASDX_TRAIT_VALUE_TYPE
     * a, b, and c trait. `smem_a`, `smem_b` and `smem_c` must be shared memory pointers.
     *     - `alpha` and `beta` are pointers to value of type \ref CUBLASDX_TRAIT_VALUE_TYPE c.
     *
     * Note that complex numbers must be over-aligned.
     *
     * The function is `extern "C"` and the symbol name can be queried using \ref CUBLASDX_TRAIT_SYMBOL_NAME.
     * See https://docs.nvidia.com/cuda/cublasdx/api/methods.html#shared-memory-api and in
     * particular the `Pointer API` section.
     */
    CUBLASDX_API_SMEM = 0,
    /** Use API for problems with custom / dynamic leading dimensions.
     * Function API is defined by its signature:
     * `void (value_type_c alpha, value_type_a* smem_a, unsigned* lda, value_type_b *smem_b, unsigned* ldb,
     * value_type_c* beta, value_type_c* smem_c, unsigned *ldc)` where
     *     - `smem_a`, `smem_b` and `smem_c` are pointers to value of type given by the \ref CUBLASDX_TRAIT_VALUE_TYPE
     * a, b, and c trait. `smem_a`, `smem_b` and `smem_c` must be shared memory pointers.
     *     - `alpha` and `beta` are pointers to value of type \ref CUBLASDX_TRAIT_VALUE_TYPE c trait.
     *     - `lda`, `ldb` and `ldc` are pointers to unsigned 32 bits integer (`unsigned`)
     *
     * Note that complex numbers must be over-aligned.
     *
     * The function is `extern "C"` and the symbol name can be queried using \ref CUBLASDX_TRAIT_SYMBOL_NAME.
     * See https://docs.nvidia.com/cuda/cublasdx/api/methods.html#shared-memory-api and in
     * particular the `Pointer API, which allows providing runtime/dynamic leading dimensions for matrices A, B,
     * and C` section.
     */
    CUBLASDX_API_SMEM_DYNAMIC_LD = 1,
    /** Use Tensor API.
     * Function API is defined by the input and output tensors specified
     * when calling \ref cublasdxCreateDeviceFunction.
     * The device functions are `extern "C"`. 
     * Tensors are trivial and passed by value. Scalars are `void*`.
     */
    CUBLASDX_API_TENSORS = 2,
} cublasdxApi;

/**
 * @brief Type of device pipeline
 */
typedef enum cublasdxDevicePipelineType_t {
    /**
     * A suggested device pipeline.
     */
    CUBLASDX_DEVICE_PIPELINE_SUGGESTED = 0,
} cublasdxDevicePipelineType;
    

/**
 * @brief Type of tile pipeline
 */
typedef enum cublasdxTilePipelineType_t {
    /**
     * A tile pipeline.
     */
     CUBLASDX_TILE_PIPELINE_DEFAULT = 0,
} cublasdxTilePipelineType;
    

/**
 * @brief Type of block size strategy used in device pipeline and tile pipeline creation. This enum affects register usage
 * in pipelining GEMM kernels and should be considered for different architectures.
 */
typedef enum cublasdxBlockSizeStrategy_t {  
    /**
     * A heuristic block size strategy where cuBLASDx will pick the "best" strategy using internal heuristics.
     */
    CUBLASDX_BLOCK_SIZE_STRATEGY_HEURISTIC = 0,
    /**
     * A fixed block size strategy where cuBLASDx will use the user-specified block size.
     */
    CUBLASDX_BLOCK_SIZE_STRATEGY_FIXED = 1,
} cublasdxBlockSizeStrategy;


/**
 * @brief Type of computation data
 *
 * Check cubladx::Type operator documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/operators.html#type-operator)
 */
typedef enum cublasdxType_t {
    /** Use for real matmuls */
    CUBLASDX_TYPE_REAL = 0,
    /** Use for complex matmuls */
    CUBLASDX_TYPE_COMPLEX = 1,
} cublasdxType;

/**
 * @brief Memory space
 */
typedef enum cublasdxMemorySpace_t {
    /** Register (aka stack) memory space */
    CUBLASDX_MEMORY_SPACE_RMEM = 0,
    /** Shared memory space */
    CUBLASDX_MEMORY_SPACE_SMEM = 1,
    /** Global memory space */
    CUBLASDX_MEMORY_SPACE_GMEM = 2,
    /** Unspecified, aka any of the above or any other memory space (like Tensor memory - TMEM) */
    CUBLASDX_MEMORY_SPACE_ANY = 3,
} cublasdxMemorySpace;

/**
 * @brief Tensor transpose mode
 *
 * The transpose mode depends on cubladx::TransposeMode operator
 * which is deprecated since cublasDx 0.2.0 and might be removed in future
 * versions of mathDx libraries
 *
 * Check cubladx::TransposeMode operator documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/operators.html#transposemode-operator)
 */
typedef enum cublasdxTransposeMode_t {
    /** Use matrix as-is in the matmul */
    CUBLASDX_TRANSPOSE_MODE_NON_TRANSPOSED = 0,
    /** Use transposed matrix in the matmul */
    CUBLASDX_TRANSPOSE_MODE_TRANSPOSED = 1,
    /** Use transposed and conjugate matrix in the matmul */
    CUBLASDX_TRANSPOSE_MODE_CONJ_TRANSPOSED = 2,
} cublasdxTransposeMode;

/**
 * @brief Data arrangement mode
 *
 * Defines data arrangements in tensors' taking part in the calculation.
 *
 * Check cubladx::TransposeMode operator documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/operators.html#arrangement-operator)
 */
typedef enum cublasdxArrangement_t {
    /** Data is considered column-major */
    CUBLASDX_ARRANGEMENT_COL_MAJOR = 0,
    /** Data is considered row-major */
    CUBLASDX_ARRANGEMENT_ROW_MAJOR = 1,
} cublasdxArrangement;

/**
 * @brief BLAS function
 *
 * Sets the BLAS function that will be executed.
 *
 * Check cubladx::Function operator documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/operators.html#function-operator)
 */
typedef enum cublasdxFunction_t {
    /** Matrix-multiply */
    CUBLASDX_FUNCTION_MM = 0,
} cublasdxFunction;

/**
 * @brief cublasDx operators
 *
 * The set of supported cublasDx operators.
 *
 * Check cublaDx description operator documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/operators.html#function-operator)
 *
 * Check cublasDx execution operator documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/operators.html#execution-operators)
 */
typedef enum cublasdxOperatorType_t {
    /** Operator data type: \ref cublasdxFunction_t.
     * Operator definition: required */
    CUBLASDX_OPERATOR_FUNCTION = 0,
    /** Operator data type: long long int * 3.
     * Expected content: `<M, N, K>` problem sizes.
     * Operator definition: required */
    CUBLASDX_OPERATOR_SIZE = 1,
    /** Operator data type: \ref cublasdxType_t.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_TYPE = 2,
    /** Operator data type: \ref commondxPrecision_t * 3.
     * Expected content: `<A, B, C>` precisions.
     * Operator definition: required */
    CUBLASDX_OPERATOR_PRECISION = 3,
    /** Operator data type: long long int.
     * Expected content: 700 (Volta), 800 (Ampere), ....
     * Operator definition: required */
    CUBLASDX_OPERATOR_SM = 4,
    /** Operator data type: \ref commondxExecution_t.
     * Operator definition: required */
    CUBLASDX_OPERATOR_EXECUTION = 5,
    /** Operator data type: long long int * 3.
     * Expected content: <x, y, z> block dimensions.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_BLOCK_DIM = 6,
    /** Operator data type: long long int * 3.
     * Expected content: <LDA, LDB, LDC> leading dimensions.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_LEADING_DIMENSION = 7,
    /** Operator data type: \ref cublasdxTransposeMode_t * 2.
     * Expected content: <A, B> transpose modes.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_TRANSPOSE_MODE = 8,
    /** Operator data type: \ref cublasdxApi_t.
     * Operator definition: required */
    CUBLASDX_OPERATOR_API = 9,
    /** Operator data type: \ref cublasdxArrangement_t * 3.
     * Expected content: <A, B, C> data arrangements.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_ARRANGEMENT = 10,
    /** Operator data type: long long int * 3.
     * Expected content: <AAlign, BAlign, CAlign> tensors' alignments.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_ALIGNMENT = 11,
    /** Operator data type: long long int.
     * Expected content: 1, to enable cublasdx::experimental::StaticBlockDim.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_STATIC_BLOCK_DIM = 12,
    /** Operator data type: long long int.
     * Expected content: 1, to enable cublasdx::EnableInputStreaming.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_ENABLE_INPUT_STREAMING = 13,
    /** Operator data type: long long int.
     * Expected content: 1, to enable cublasdx::WithPipeline.
     * Operator definition: optional */
    CUBLASDX_OPERATOR_WITH_PIPELINE = 14,
} cublasdxOperatorType;

/**
 * @brief cublasDx traits
 *
 * The set of supported types of traits that can be accessed from finalized sources
 * that use cublasDx.
 *
 * Check cublasDx Execution Block Traits documentation for more details
 * (https://docs.nvidia.com/cuda/cublasdx/api/traits.html#block-traits)
 */
typedef enum cublasdxTraitType_t {
    /** Trait data type: \ref commondxValueType_t * 3.
     * Expected content: <A, B, C> types.
     */
    CUBLASDX_TRAIT_VALUE_TYPE = 0,
    /** Trait data type: long long int * 3.
     * Expected content: <M, N, K> problem sizes.
     */
    CUBLASDX_TRAIT_SIZE = 1,
    /** Trait data type: long long int.
     * Expected content: multiplication result of block dimensions (x * y * z).
     */
    CUBLASDX_TRAIT_BLOCK_SIZE = 2,
    /** Trait data type: long long int * 3.
     * Expected content: <x, y, z> block dimension.
     */
    CUBLASDX_TRAIT_BLOCK_DIM = 3,
    /** Trait data type: long long int * 3.
     * Expected content: <LDA, LDB, LDC> leading dimensions.
     */
    CUBLASDX_TRAIT_LEADING_DIMENSION = 4,
    /** Trait data type: C-string
     */
    CUBLASDX_TRAIT_SYMBOL_NAME = 5,
    /** Trait data type: \ref cublasdxArrangement_t * 3.
     * Expected content: <A, B, C> data arrangements.
     */
    CUBLASDX_TRAIT_ARRANGEMENT = 6,
    /** Trait data type: long long int * 3.
     * Expected content: <AAlign, BAlign, CAlign> tensors' alignments, in bytes.
     */
    CUBLASDX_TRAIT_ALIGNMENT = 7,
    /** Trait data type: long long int * 3.
     * Expected content: <LDA, LDB, LDC>.
     */
    CUBLASDX_TRAIT_SUGGESTED_LEADING_DIMENSION = 8,
    /** Trait data type: long long int * 3.
     * Expected content: <X, Y, Z>.
     */
    CUBLASDX_TRAIT_SUGGESTED_BLOCK_DIM = 9,
    /** Trait data type: long long int.
     * Expected content: the product of three elements in block dimension.
     */
    CUBLASDX_TRAIT_MAX_THREADS_PER_BLOCK = 10,
} cublasdxTraitType;

/**
 * @brief cuBLASDx desired tensor type
 *
 * Tensor types are opaque (layout is unspecified), non-owning, and defined by
 * - Memory space (global, shared or register memory)
 * - Size & alignment (in bytes)
 *
 * Tensor's representation in-memory and in-device depends on their memory space.
 * Shared & register tensors are defined as
 *
 * \code
 * struct tensor {
 *   void* ptr;
 * }
 * \endcode
 *
 * where `ptr` points to the associated data.
 *
 * Global memory tensors have an associated runtime leading dimension (64b signed integer), and their
 * representation is
 *
 * \code
 * struct tensor {
 *   void* ptr;
 *   long long int strides[1];
 * }
 * \endcode
*
 * where `ptr` points to the associated data and `strides[0]` is the leading dimension.
 *
 * In either case, `ptr` must point to some storage (with appropriate size and alignment,
 * see below) and is not owning. The user is expected to keep memory allocated beyond
 * any use of the tensor. `strides[1]` should be a signed, 64bit integer (`long long`) equal to the leading dimension of the
 * global memory tensor. The leading dimension is the number of *elements* between two successive rows or
 * columns (not bytes), depending on the context.
 *
 * All tensor APIs take their argument by value (not by pointer) and expect the struct to be passed
 * as-is on the stack.
 *
 * Each opaque tensor type is uniquely identified by a unique ID and name, see \ref cublasdxTensorTrait_t .
 */
typedef enum cublasdxTensorType_t {
    /**
     * A shared memory tensor for `A`, in simple row or column layout
     * In memory representation: `struct { void* ptr; }` with `ptr` a shared
     * memory pointer.
     * Corresponds to cuBLASDx `make_tensor(..., get_layout_smem_a());`
     **/
    CUBLASDX_TENSOR_SMEM_A = 0,
    /**
     * A shared memory tensor for `B`, in simple row or column layout.
     * In memory representation: `struct { void* ptr; }` with `ptr` a shared
     * memory pointer.
     * Corresponds to cuBLASDx `make_tensor(..., get_layout_smem_b());`
     **/
    CUBLASDX_TENSOR_SMEM_B = 1,
    /**
     * A shared memory tensor for `C`, in simple row or column layout.
     * In memory representation: `struct { void* ptr; }` with `ptr` a shared
     * memory pointer.
     * Corresponds to cuBLASDx `make_tensor(..., get_layout_smem_c());`
     **/
    CUBLASDX_TENSOR_SMEM_C = 2,
    /**
     * A shared memory tensor for `A`, in unspecified (could be swizzled, 
     * padded, etc) layout.
     * In memory representation: `struct { void* ptr; }` with `ptr` a shared
     * memory pointer.
     * Corresponds to cuBLASDx `make_tensor(..., suggest_layout_smem_a());`
     **/
    CUBLASDX_TENSOR_SUGGESTED_SMEM_A = 3,
    /**
     * A shared memory tensor for `B`, in unspecified (could be swizzled, 
     * padded, etc) layout.
     * In memory representation: `struct { void* ptr; }` with `ptr` a shared
     * memory pointer.
     * Corresponds to cuBLASDx `make_tensor(..., suggest_layout_smem_b());`
     **/
    CUBLASDX_TENSOR_SUGGESTED_SMEM_B = 4,
    /**
     * A shared memory tensor for `C`, in unspecified (could be swizzled, 
     * padded, etc) layout.
     * In memory representation: `struct { void* ptr; }` with `ptr` a shared
     * memory pointer.
     * Corresponds to cuBLASDx `make_tensor(..., suggest_layout_smem_c());`
     **/
    CUBLASDX_TENSOR_SUGGESTED_SMEM_C = 5,
    /**
     * A register tensor for `C`, in unspecified layout.
     * In memory representation: `struct { void* ptr; }` with ptr a stack
     * (aka local or thread-private) memory pointer.
     * Corresponds to cuBLASDx `suggest_accumulator().make_accumulator_fragment();`
     **/
    CUBLASDX_TENSOR_SUGGESTED_RMEM_C = 6,
    /**
     * A global memory view for `A` (typically a tile of a larger matrix)
     * in row or column-major format, with a runtime leading dimension.
     * In memory representation: `struct { void* ptr; long long int[1] strides; }`
     * with `ptr` a global memory pointer and `strides[0]` the leading dimension.
     * Corresponds to cuBLASDx `make_tensor(a, get_layout_gmem_a(lda));`
     **/
    CUBLASDX_TENSOR_GMEM_A = 7,
    /**
     * A global memory view for `B` (typically a tile of a larger matrix)
     * in row or column-major format, with a runtime leading dimension.
     * In memory representation: `struct { void* ptr; long long int[1] strides; }`
     * with `ptr` a global memory pointer and `strides[0]` the leading dimension.
     * Corresponds to cuBLASDx `make_tensor(a, get_layout_gmem_b(ldb));`
     **/
    CUBLASDX_TENSOR_GMEM_B = 8,
    /**
     * A global memory view for `C` (typically a tile of a larger matrix)
     * in row or column-major format, with a runtime leading dimension.
     * In memory representation: `struct { void* ptr; long long int[1] strides; }`
     * with `ptr` a global memory pointer and `strides[0]` the leading dimension.
     * Corresponds to cuBLASDx `make_tensor(a, get_layout_gmem_c(ldc));`
     **/
    CUBLASDX_TENSOR_GMEM_C = 9,
    /**
     * An opaque, stateful accumulator for `C`, in unspecified layout and
     * in an unspecified memory space. Must be explicitly initialized and
     * destroyed. 
     * In memory representation: `struct { void* ptr; }` with ptr a stack
     * (aka local or thread-private) memory pointer pointing to an opaque state.
     * `ptr` should not be assumed to point to any specific data.
     * Corresponds to cuBLASDx `suggest_accumulator();`
     **/
    CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C = 10,
    /**
     * A register tensor for `C`, in unspecified layout.
     * In memory representation: `struct { void* ptr; }` with ptr a stack
     * (aka local, aka thread-private) memory pointer.
     * Corresponds to cuBLASDx `get_accumulator().make_accumulator_fragment();`
     **/
    CUBLASDX_TENSOR_RMEM_C = 11,
    /**
     * An opaque, stateful accumulator for `C`, in unspecified layout and
     * in an unspecified memory space. Must be explicitly initialized and
     * destroyed. 
     * In memory representation: `struct { void* ptr; }` where ptr is a stack
     * (aka local or thread-private) memory pointer pointing to an opaque state.
     * `ptr` should not be assumed to point to any specific data.
     * Corresponds to cuBLASDx `get_accumulator();`
     **/
    CUBLASDX_TENSOR_ACCUMULATOR_C = 12,
} cublasdxTensorType;

/**
 * @brief Tensor options
 *
 */
typedef enum cublasdxTensorOption_t {
    /**
     * The alignment of the underlying storage, in bytes.
     * Trait data type: long long int.
     */
    CUBLASDX_TENSOR_OPTION_ALIGNMENT_BYTES = 0,
} cublasdxTensorOption;

/**
 * @brief Tensor traits, used to query informations
 */
typedef enum cublasdxTensorTrait_t {
    /**
     * The size of the underlying storage, in bytes.
     * Trait data type: long long int.
     */
    CUBLASDX_TENSOR_TRAIT_STORAGE_BYTES = 0,
    /**
     * The alignment of the underlying storage, in bytes.
     * Trait data type: long long int.
     */
    CUBLASDX_TENSOR_TRAIT_ALIGNMENT_BYTES = 1,
    /**
     * The tensor type UID. Tensor types with the same UID
     * are identical and can be passed through various cuBLASDx
     * device functions. UIDs are only well defined within a process.
     * Note: This trait has been deprecated. use `CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME` instead
     * to identify device tensors.
     * Trait data type: long long int.
     */
    CUBLASDX_TENSOR_TRAIT_UID = 2,
    /**
     * A human readable but unspecified C-string representing the opaque tensor type name.
     * Names are stable and unique per tensor type,
     * and tensor types with the same name can be used interchangeably.
     * Opaque names are not C++ type name identifiers.
     * Trait data type: C-string.
     */
    CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME = 4,
    /**
     * The logical number of elements owned by the tensor.
     * Note this is not related to the size in memory. 
     * Trait data type: int.
     */
    CUBLASDX_TENSOR_TRAIT_LOGICAL_SIZE = 5,
    /**
     * Returns the memory space of the underlying data of this tensor.
     * Trait data type: cublasdxMemorySpace.
     */
    CUBLASDX_TENSOR_TRAIT_MEMORY_SPACE = 6,
} cublasdxTensorTrait;


/** 
 * @brief Pipeline traits, used to query informations
 */
typedef enum cublasdxPipelineTrait_t {
    /**
     * The size of the underlying storage, in bytes.
     * Trait data type: long long int.
     */
    CUBLASDX_PIPELINE_TRAIT_STORAGE_BYTES = 0,
    /**
     * The alignment of the underlying storage, in bytes.
     * Trait data type: long long int.
     */
    CUBLASDX_PIPELINE_TRAIT_STORAGE_ALIGNMENT_BYTES = 1,
    /**
     * The size of the buffer memory, in bytes.
     * Trait data type: long long int.
     */
    CUBLASDX_PIPELINE_TRAIT_BUFFER_SIZE = 2,
    /**
     * The alignment of the buffer memory, in bytes.
     * Trait data type: long long int.
     */
    CUBLASDX_PIPELINE_TRAIT_BUFFER_ALIGNMENT_BYTES = 3,
    /**
     * A human readable but unspecified C-string representing the opaque pipeline type name.
     * Names are stable and unique per pipeline type,
     * and pipeline types with the same name can be used interchangeably.
     * Opaque names are not C++ type name identifiers.
     * Trait data type: C-string.
     */
    CUBLASDX_PIPELINE_TRAIT_OPAQUE_NAME = 4,
    /**
     * The block dimension of the pipeline.
     * Trait data type: dim3.
     */
    CUBLASDX_PIPELINE_TRAIT_BLOCK_DIM = 5,
} cublasdxPipelineTrait;		


/**
 * @brief Device function traits, used to query informations
 */
typedef enum cublasdxDeviceFunctionTrait_t {
    /**
     * The symbol name of the device function.
     * Trait data type: C-string
     */
    CUBLASDX_DEVICE_FUNCTION_TRAIT_SYMBOL = 1,
} cublasdxDeviceFunctionTrait;

/**
 * @brief Device function options
 */
typedef enum cublasdxDeviceFunctionOption_t {
    /**
     * Specify an optional symbol name for the device function.
     * Trait data type: const char*
     */
    CUBLASDX_DEVICE_FUNCTION_OPTION_SYMBOL_NAME = 0,
    /**
     * Specify an optional alignment for copy and copy_fragment functions.
     * Default is taken from the input tensors.
     * Trait data type: long long int.
     */
    CUBLASDX_DEVICE_FUNCTION_OPTION_COPY_ALIGNMENT = 1,
    /**
     * Specify a callback for the device function. This option is only supported for epilogue device function, and is required.
     * The callback function signature is strictly defined as `callback(<internal_tensor_type> accumulator, void* user_data)`.
     * `<internal_tensor_type>` details can be found in \ref CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C and \ref CUBLASDX_TENSOR_ACCUMULATOR_C .
     * Trait data type: const char*
     */
    CUBLASDX_DEVICE_FUNCTION_OPTION_CALLBACK = 2,
    /**
     * Specify the number of threads for the operation. 
     * This option is only supported for copy functions without BLAS descriptors (aka using \ref LIBMATHDX_NONE ).
     * Trait data type: long long int.
     */
    CUBLASDX_DEVICE_FUNCTION_OPTION_NUM_THREADS = 3,
} cublasdxDeviceFunctionOption;

/**
 * @brief Device functions supported by the library
 */
typedef enum cublasdxDeviceFunctionType_t {
    /**
     * Execute the device function (matmul).
     *
     * When the input is a tile pipeline, and the output is a accumulator tensor,
     * the device function API is `execute(tile_pipeline, C)` 
     * which computes `C += A x B`. 
     *
     * When the output is a register tensor, the device function API is
     * `execute(A, B, C)` which computes `C += A x B`.
     *
     * When the output is a shared memory tensor, the device function API is
     * `execute(alpha, A, B, beta, C)` which computes
     * `C = alpha A x B + beta C`.
     *
     * `A`, `B` and `C` are tensors, while alpha and beta are scalars 
     * with the same type of `C` (passed by `void*` pointers), and tile_pipeline is
     * a reference to tiles of A and B.
     *
     * Different `execute` generated from distinct `cublasdxDescriptor`
     * are generally different and cannot be used interchangeably, even
     * with an identical set of input and output tensors.
     *
     * \ref cublasdxCreateDeviceFunction must be called with three tensors:
     *     - `tile_pipeline`, an instance of
     *           - \ref CUBLASDX_TILE_PIPELINE_DEFAULT
     *     - `A`, an instance of
     *           - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_A
     *           - \ref CUBLASDX_TENSOR_SMEM_A
     *     - `B`, an instance of
     *           - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_B
     *           - \ref CUBLASDX_TENSOR_SMEM_B
     *     - `C`, an instance of
     *           - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_C
     *           - \ref CUBLASDX_TENSOR_SMEM_C
     *           - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *           - \ref CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C
     *           - \ref CUBLASDX_TENSOR_ACCUMULATOR_C
     *
     * The resulting function has the following device API:
     *     - `void execute(void* alpha, TA A, TB B, void* beta, TC C)` when `C` is a shared memory tensor,
     *     - `void execute(TA A, TB B, TC C)` when `C` is a register memory tensors.
     *     - `void execute(TP tile_pipeline, TC C)` when `C` is an accumulator tensor. 
     *
     * The names for `TA`, `TB`, `TC` and `TP` can be retreived using \ref CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME .
     *
     */
    CUBLASDX_DEVICE_FUNCTION_EXECUTE = 0,
    /**
     * Copies from one tensor to another. `copy(S, D)` copies
     * from `S` to `D`.
     *
     * Different `copy` generated from distinct `cublasdxDescriptor`
     * are in general different and cannot be used interchangeably, even
     * with identical input and output tensors.
     *
     * \ref cublasdxCreateDeviceFunction must be called with two tensors:
     *     - `S`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_A
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_B
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_C
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C
     *          - \ref CUBLASDX_TENSOR_GMEM_A
     *          - \ref CUBLASDX_TENSOR_GMEM_B
     *          - \ref CUBLASDX_TENSOR_GMEM_C
     *     - `D`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_A
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_B
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_C
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *          - \ref CUBLASDX_TENSOR_GMEM_A
     *          - \ref CUBLASDX_TENSOR_GMEM_B
     *          - \ref CUBLASDX_TENSOR_GMEM_C
     *
     * `S` and `D` can be in different memory spaces but must correspond to the
     * same A, B or C matrix.
     *
     * The resulting function has one of the following device API: 
     *
     *     - `void copy(TS S, TD D)` if a BLAS descriptor is provided,
     *     - `void copy(int* tid, TS S, TD D)` if \ref LIBMATHDX_NONE is used in lieu of a BLAS descriptor.
     *       In this case, `tid` should be the thread ID (e.g. `threadIdx.x`).
     *
     * The names for `TS` and `TD` can be retreived using \ref CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME .
     *
     */
    CUBLASDX_DEVICE_FUNCTION_COPY = 1,
    /**
     * Wait on all previously issued copies to complete.
     * `wait_all()` waits on all previously issued copies to complete.
     *
     * Different `wait_all` from distinct `cublasdxDescriptor` are
     * identical and may used interchangeably. They will have the same
     * symbol name and implementation.
     *
     * \ref cublasdxCreateDeviceFunction must be called without any tensors.
     *
     * The resulting function has the following device API: `void copy_wait()`
     *
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     *
     */
    CUBLASDX_DEVICE_FUNCTION_COPY_WAIT = 2,
    /**
     * Zeroes out a tensor. `clear(C)` zeroes out `C`.
     *
     * Different `clear` generated from distinct `cublasdxDescriptor`
     * are in general different and cannot be used interchangeably, even
     * with identical input and output tensors.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensors:
     *     - `C`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C
     *
     * The resulting function has the following device API: `void clear(TC C)`
     *
     * The name for `TC` can be retreived using \ref CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME .
     *
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     *
     */
    CUBLASDX_DEVICE_FUNCTION_CLEAR = 3,
    /**
     * Computes `D = alpha * C + beta * D`.
     *
     * The `cublasdxDescriptor` maybe me \ref LIBMATHDX_NONE and is effectively ignored.
     *
     * \ref cublasdxCreateDeviceFunction must be called with two tensors:
     *     - `C`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *     - `D`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *
     * The resulting function has the following device API:
     *     - `void axpby(void* alpha, TC C, void* beta, TD D)` where `C` and `D` are tensors
     *       and `alpha`, `beta` are pointers to scalars, where `alpha` has type of `TC` and
     *       `beta` the type of `TD`.
     *
     * The name for `TC` and `TD` can be retreived using \ref CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME .
     */
    CUBLASDX_DEVICE_FUNCTION_AXPBY = 4,
    /**
     * Iterates over a 2D tensor.
     *
     * Supports iterative logical access to different layouts in underlying CuTe Tensor.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `A`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_A
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_B
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_C
     *          - \ref CUBLASDX_TENSOR_SMEM_A
     *          - \ref CUBLASDX_TENSOR_SMEM_B
     *          - \ref CUBLASDX_TENSOR_SMEM_C
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *
     * The resulting function has the following device API:
     *     - `void map_idx2crd(T A, int* lin_idx, int* i, int* j, void* ptr)` where input `A` is a tensor
     *       and  input `lin_idx`, output `i`, output `j`, and output `ptr` are pointers of type, int, int, int,
     *       and void respectively.
     * 
     * The arguement defitions are as follows:
     *     - `T A` is the tensor to iterate over.
     *     - `int* lin_idx` is the provided linearized index.
     *     - `int* i` is the returned row index value for the physical tensor element stored in `ptr`.
     *     - `int* j` is the returned column index value for the physical tensor element stored in `ptr`.
     *     - `void* ptr` is the pointer to the physical tensor element.
     * 
     * The name for `T` can be retreived using \ref CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME .
     * 
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     *
     * The following six functions are based on this link:
     * https://docs.nvidia.com/cuda/cublasdx/api/other_tensors.html#partitioner
     */ 
    CUBLASDX_DEVICE_FUNCTION_MAP_IDX2CRD = 5,
    /**
     * Iterates over a 2D tensor.
     *
     * Supports iterative logical access to different layouts in underlying implicit CuTe Tensor.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `A`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *
     * The resulting function has the following device API:
     *     - `void map_idx2crd_partitioner(int* lin_idx, int* i, int* j)` where 
     *       input `lin_idx`, output `i`, and output `j` are pointers of type, int, int, int, respectively.
     *
     * The argument definitions are as follows:
     *     - `int* lin_idx` is the provided linearized index.
     *     - `int* i` is the returned row index value for the physical tensor element stored in `ptr`.
     *     - `int* j` is the returned column index value for the physical tensor element stored in `ptr`.
     *
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     *
     * The name for `T` can be retreived using \ref CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME .
     */
    CUBLASDX_DEVICE_FUNCTION_MAP_IDX2CRD_PARTITIONER = 6,
    /**
     * Random access to a specific location in a 2D tensor.
     *
     * Supports random logical access to different layouts in underlying CuTe tensor.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `A`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_A
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_B
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_SMEM_C
     *          - \ref CUBLASDX_TENSOR_SMEM_A
     *          - \ref CUBLASDX_TENSOR_SMEM_B
     *          - \ref CUBLASDX_TENSOR_SMEM_C
     *
     * The resulting function has the following device API:
     *     - `void map_crd2idx(T A, int* i, int* j, int* lin_idx, void* ptr)` where input `A` is a tensor
     *       and input `i`, input `j`, output `lin_idx`, and output `ptr` are pointers of type, int, int, int,
     *       and void respectively.
     *
     * The argument definitions are as follows:
     *     - `T A` is the tensor to iterate over.
     *     - `int* i` is the provided row index value.
     *     - `int* j` is the provided column index value.
     *     - `int* lin_idx` is the returned linearized index offset for the physical tensor element stored in `ptr`.
     *     - `void* ptr` is the pointer to the physical tensor element.
     *
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     *
     * The name for `T` can be retreived using \ref CUBLASDX_TENSOR_TRAIT_OPAQUE_NAME .
     */
    CUBLASDX_DEVICE_FUNCTION_MAP_CRD2IDX = 7,
    /**
     * Returns true if the current thread is part of the GEMM execution.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `A`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *
     * The resulting function has the following device API:
     *     - `void is_thread_active(void* yes_or_no)` where output `yes_or_no` is a pointer of type int.
     *
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     *
     */
    CUBLASDX_DEVICE_FUNCTION_IS_THREAD_ACTIVE = 8,
    /**
     * Returns true if any threads within the active BlockDim set of threads are predicated, ie if it does not participate in the GEMM calculations.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `A`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *
     * The resulting function has the following device API:
     *     - `void is_predicated(void* yes_or_no)` where output `yes_or_no` is a pointer of type int.
     *
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     *
     */
    CUBLASDX_DEVICE_FUNCTION_IS_PREDICATED = 9,
    /**
     * Determines if memory access is in bounds.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `A`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_RMEM_C
     *
     * The resulting function has the following device API:
     *     - `void is_index_in_bounds(int* lin_idx, void* yes_or_no)` where input `lin_idx` and output `yes_or_no`
     *        are pointers of type int.
     *
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     */
    CUBLASDX_DEVICE_FUNCTION_IS_INDEX_IN_BOUNDS = 10,
    /**
     * Initialize an opaque stateful tensor.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `C`, an instance of
     *          - \ref CUBLASDX_DEVICE_PIPELINE_SUGGESTED
     *          - \ref CUBLASDX_TILE_PIPELINE_DEFAULT
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C
     *          - \ref CUBLASDX_TENSOR_ACCUMULATOR_C
     *
     * The resulting function has the following device API:
     *     - `void create(T)` where `T` is the tensor to initialize.
     *     - `void create(DP, TA, TB)` where `DP` is the device pipeline, `TA` is the tensor A, and `TB` is the tensor B.
     *     - `void create(DP, TP, char* smem, int* idx, int* idy)` where `DP` is the device pipeline, `TP` is the tile pipeline, 
     *       `smem` is the shared memory pointer, `idx` is offset(s) in the first dimension, 
     *       `idy` is offset(s) in the second dimension. The dimension count is determined by the tensor rank. 
     */
    CUBLASDX_DEVICE_FUNCTION_CREATE = 11,
    /**
     * Destroys an opaque stateful tensor.
     *
     * \ref cublasdxCreateDeviceFunction must be called with one tensor:
     *     - `C`, an instance of
     *          - \ref CUBLASDX_DEVICE_PIPELINE_SUGGESTED
     *          - \ref CUBLASDX_TILE_PIPELINE_DEFAULT
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C
     *          - \ref CUBLASDX_TENSOR_ACCUMULATOR_C
     *
     * The resulting function has the following device API:
     *     - `void destroy(T)` where `T` is the tensor to destroy.
     */
    CUBLASDX_DEVICE_FUNCTION_DESTROY = 12,
    /**
     * Resets an opaque stateful tile pipeline.
     *
     * \ref cublasdxCreateDeviceFunction must be called with either one or two pipelines:
     *     - `DP`, an instance of
     *          - \ref CUBLASDX_DEVICE_PIPELINE_SUGGESTED
     *     - `TP`, an instance of
     *          - \ref CUBLASDX_TILE_PIPELINE_DEFAULT
     * 
     * The resulting function has the following device APIs depending on the number of pipelines:
     *     - `void reset(DP, TP, int* idx, int* idy)` where `DP` is the device pipeline, `TP` is the tile pipeline, 
     *       `idx` is offsets in the first dimension, and `idy` is offsets in the second dimension. 
     *       This function is only valid for 3D input tensors.
     *
     *     - `void reset(TP)` where `TP` is the tile pipeline. This function is only valid for 2D input tensors.
     */
    CUBLASDX_DEVICE_FUNCTION_RESET = 13,
    /**
     * Epilogue callback function for cublasdx pipelining API. 
     *
     * \ref cublasdxCreateDeviceFunction must be called with one pipeline, one accumulator tensor:
     *     - `pipeline`, an instance of
     *          - \ref CUBLASDX_TILE_PIPELINE_DEFAULT
     *     - `accumulator_tensor`, an instance of
     *          - \ref CUBLASDX_TENSOR_SUGGESTED_ACCUMULATOR_C
     *          - \ref CUBLASDX_TENSOR_ACCUMULATOR_C
     *
     * The resulting function has the following device API:
     *     - `void epilogue(TP, TC, void*)` where `TP` is the pipeline, `TC` is the accumulator tensor, and `void*` is any user required
     *       external state to be passed to the callback function. If no external state is required, `void*` can be `NULL`.
     *       The callback function is expected to be defined by the user and passed as a C-string to \ref cublasdxSetDeviceFunctionOptionStr.
     * 
     * \ref LIBMATHDX_NONE may be used in lieu of a BLAS descriptor, and has the same effect.
     * 
     */
    CUBLASDX_DEVICE_FUNCTION_EPILOGUE = 14,
} cublasdxDeviceFunctionType;

/**
 * @brief Creates a cuBLASDx descriptor
 *
 * @param[out] handle A pointer to a handle
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxCreateDescriptor(cublasdxDescriptor* handle)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Sets a C-string option on a cuBLASDx descriptor.
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] option An option to set the descriptor to.
 * @param[in] value A pointer to a C-string. Cannot be `NULL`.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetOptionStr(cublasdxDescriptor handle,
                                                                     commondxOption option,
                                                                     const char* value) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Sets one or more C-string options on a cuBLASDx descriptor.
 *
 * @param[in] code A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] option An option to set the descriptor to.
 * @param[in] count The number of options.
 * @param[in] values A pointer to an array of `count` C-strings.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetOptionStrs(commondxCode code,
                                                                      commondxOption option,
                                                                      size_t count,
                                                                      const char** values) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Set an operator on a cuBLASDx descriptor to an integer value
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] op An operator to set the descriptor to.
 * @param[in] value The operator's value
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetOperatorInt64(cublasdxDescriptor handle,
                                                                         cublasdxOperatorType op,
                                                                         long long int value) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Set an operator on a cuBLASDx descriptor to an integer array
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] op An option to set the descriptor to.
 * @param[in] count The size of the operator array, as indicated by the \ref cublasdxOperatorType_t documentation
 * @param[in] array A pointer to an array containing the operator's value. Must point to at least `count` elements.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL
cublasdxSetOperatorInt64s(cublasdxDescriptor handle, cublasdxOperatorType op, size_t count, const long long int* array)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Create a tensor handle.
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] tensor_type The tensor type to bind to the handle
 * @param[out] tensor A valid tensor handle
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxCreateTensor(cublasdxDescriptor handle,
                                                                     cublasdxTensorType tensor_type,
                                                                     cublasdxTensor* tensor) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Create a tensor handle for a N-dimensional strided tensor.
 *
 * The resulting tensor has the following in-memory, on-device representation
 *
 * \code
 * struct tensor {
 *   void* ptr;
 *   long long int shapes[n_runtime_shapes];
 *   long long int strides[n_runtime_strides];
 * }
 * \endcode
 *
 * where
 *
 * - `ptr` points to the data in the appropriate memory space,
 * - `shapes[n_runtime_shapes]` is an array holding the runtime (aka not static) shapes,
 * - `strides[n_runtime_strides]` is an array holding the runtime (aka not static) shapes.
 *
 * Runtime shapes and strides are marked by passing \ref LIBMATHDX_RUNTIME in \p shape and \p stride .
 * Static shapes and strides should be specified as-is in \p shape and \p stride and should not be
 * provided again at runtime.
 *
 * @param[in] memory_space The memory space for the tensor.
 * @param[in] value_type The datatype of the individual elements.
 * @param[in] ptr A pointer to the data. Currently, only `NULL` is supported.
 * @param[in] rank The rank of of tensor.
 * @param[in] shape An array of size `rank` indicating the tensor shape. \ref LIBMATHDX_RUNTIME can be used to indicate a runtime shape.
 * @param[in] stride An array of size `rank` indicating the tensor stride. \ref LIBMATHDX_RUNTIME can be used to indicate a runtime stride.
 * @param[out] tensor The tensor handle
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxCreateTensorStrided(cublasdxMemorySpace memory_space,
                                                                            commondxValueType value_type,
                                                                            void* ptr,
                                                                            long long int rank,
                                                                            long long int* shape,
                                                                            long long int* stride,
                                                                            cublasdxTensor* tensor) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Create an opaque tensor with a identical layout (smem/gmem) or partitioner (rmem), but with a different datatype.
 *
 * The resulting tensor in-memory and on-device representation is identical to `input`'s representation, 
 * except that the memory pointer must point to data of the appropriate type.
 *
 * @param[in] input An opaque tensors
 * @param[in] value_type The new datatype
 * @param[out] output The output tensor
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxMakeTensorLike(cublasdxTensor input,
                                                                       commondxValueType value_type,
                                                                       cublasdxTensor* output) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Destroys a tensor handle created using \ref cublasdxCreateTensor or \ref cublasdxMakeTensorLike.
 *
 * @param[in] tensor The tensor to destroy.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxDestroyTensor(cublasdxTensor tensor) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Destroys a pipeline handle created using \ref cublasdxCreateDevicePipeline or \ref cublasdxCreateTilePipeline.
 *
 * @param[in] pipeline The pipeline to destroy.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxDestroyPipeline(cublasdxPipeline pipeline) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Create a device pipeline handle.
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] device_pipeline_type The type of the device pipeline
 * @param[in] pipeline_depth The depth of the pipeline. If \ref LIBMATHDX_MAX_PIPELINE_DEPTH is passed, the pipeline depth will be set to the maximal depth based on available shared memory.
 * @param[in] block_size_strategy The block size strategy to use, fixed (you use the number of threads specified) or heuristic (cuBLASDx can use more threads if needed)
 * @param[in] tensor_a The tensor handle for global matrix A
 * @param[in] tensor_b The tensor handle for global matrix B
 * @param[out] device_pipeline A valid device pipeline handle
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxCreateDevicePipeline(cublasdxDescriptor handle,
    cublasdxDevicePipelineType device_pipeline_type,
    long long int pipeline_depth,
    cublasdxBlockSizeStrategy block_size_strategy,
    cublasdxTensor tensor_a,
    cublasdxTensor tensor_b,
    cublasdxPipeline* device_pipeline) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Create a tile pipeline handle.
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] tile_pipeline_type The type of the tile pipeline
 * @param[in] device_pipeline The device pipeline handle this tile pipeline is associated with
 * @param[out] tile_pipeline A valid tile pipeline handle   
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxCreateTilePipeline(cublasdxDescriptor handle,
    cublasdxTilePipelineType tile_pipeline_type,
    cublasdxPipeline device_pipeline,
    cublasdxPipeline* tile_pipeline) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Set an option on a tensor.
 * This must be called before the tensor is finalized.
 *
 * @param[in] tensor A cuBLASDx tensor, output of \ref cublasdxCreateTensor.
 * @param[in] option The option to set on the tensor.
 * @param[in] value A value for the option.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetTensorOptionInt64(cublasdxTensor tensor,
                                                                             cublasdxTensorOption option,
                                                                             long long int value)
    LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Set an option on a tensor.
 * This must be called before the tensor is finalized.
 *
 * @param[in] tensor A cuBLASDx tensor, output of \ref cublasdxCreateTensor.
 * @param[in] option The commondx option to set on the tensor.
 * @param[in] value A C-string value to set on the tensor.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetTensorOptionStr(cublasdxTensor tensor,
                                                                           commondxOption option,
                                                                           const char* value) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Set an option on a pipeline.
 * This must be called before the pipeline is finalized.
 *
 * @param[in] pipeline A cuBLASDx pipeline, output of \ref cublasdxCreateDevicePipeline or \ref cublasdxCreateTilePipeline.
 * @param[in] option The commondx option to set on the pipeline.
 * @param[in] value A C-string value to set on the pipeline.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetPipelineOptionStr(cublasdxPipeline pipeline,
                                                                              commondxOption option,
                                                                              const char* value) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Set one or more options on a tensor.
 * This must be called before the tensor is finalized.
 *
 * @param[in] tensor A cuBLASDx tensor, output of \ref cublasdxCreateTensor.
 * @param[in] option The commondx option to set on the tensor.
 * @param[in] count The number of options to set.
 * @param[in] values A pointer to an array of `count` C-strings.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetTensorOptionStrs(cublasdxTensor tensor,
                                                                             commondxOption option,
                                                                             size_t count, 
                                                                             const char** values) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Set one or more options on a pipeline.
 * This must be called before the pipeline is finalized.
 *
 * @param[in] pipeline A cuBLASDx pipeline, output of \ref cublasdxCreateDevicePipeline or \ref cublasdxCreateTilePipeline.
 * @param[in] option The commondx option to set on the pipeline.
 * @param[in] count The number of options to set.
 * @param[in] values A pointer to an array of `count` C-strings.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxSetPipelineOptionStrs(cublasdxPipeline pipeline,
                                                                               commondxOption option,
                                                                               size_t count,
                                                                               const char** values) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Finalize the tensors. This is required before traits can be queried.
 *
 * @param[in] count The number of tensors to finalized
 * @param[out] array The array of tensors
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxFinalizeTensors(size_t count, const cublasdxTensor* array) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Finalize the pipelines. This is required before traits can be queried.
 *
 * @param[in] count The number of pipelines to finalized
 * @param[out] array The array of pipelines
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxFinalizePipelines(size_t count, const cublasdxPipeline* array) LIBMATHDX_API_NOEXCEPT;


 /**
  * @brief Finalize both tensors and pipelines. This is required before traits can be queried. Internally calls \ref cublasdxFinalizeTensors and \ref cublasdxFinalizePipelines.
  *
  * @param[in] countTensors The number of tensors to finalized
  * @param[out] tensors The array of tensors
  * @param[in] countPipelines The number of pipelines to finalized
  * @param[out] pipelines The array of pipelines
  * @return `COMMONDX_SUCCESS` on success, or an error code.
  */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxFinalize(size_t countTensors, const cublasdxTensor* tensors, size_t countPipelines, const cublasdxPipeline* pipelines) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Query an integer trait value from a finalized tensor
 *
 * @param[in] tensor A finalized tensor handle, output of \ref cublasdxCreateTensor
 * @param[in] trait The trait to query
 * @param[out] value The trait value
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTensorTraitInt64(cublasdxTensor tensor,
                                                                            cublasdxTensorTrait trait,
                                                                            long long int* value)
    LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Query an integer trait value from a finalized pipeline
 *
 * @param[in] pipeline A finalized pipeline handle, output of \ref cublasdxCreateDevicePipeline or \ref cublasdxCreateTilePipeline
 * @param[in] trait The trait to query
 * @param[out] value The trait value
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetPipelineTraitInt64(cublasdxPipeline pipeline,
    cublasdxPipelineTrait trait,
    long long int* value)
LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns an array trait's value from a finalized pipeline
 *
 * @param[in] pipeline A finalized pipeline handle, output of \ref cublasdxCreateDevicePipeline or \ref cublasdxCreateTilePipeline
 * @param[in] trait The trait to query
 * @param[in] count The number of values to query
 * @param[out] array The array of trait values. Must point to exactly `count` elements of type `long long int`.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetPipelineTraitInt64s(cublasdxPipeline pipeline,
    cublasdxPipelineTrait trait,
    size_t count,
    long long int* array)
LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Query an C-string trait's size from a finalized tensor
 *
 * @param[in] tensor A finalized tensor handle, output of \ref cublasdxCreateTensor
 * @param[in] trait The trait to query
 * @param[out] size The C-string size (including the `\0`)
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTensorTraitStrSize(cublasdxTensor tensor,
                                                                              cublasdxTensorTrait trait,
                                                                              size_t* size) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Query an C-string trait's size from a finalized pipeline
 *
 * @param[in] pipeline A finalized pipeline handle, output of \ref cublasdxCreateDevicePipeline or \ref cublasdxCreateTilePipeline
 * @param[in] trait The trait to query
 * @param[out] size The C-string size (including the `\0`)
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetPipelineTraitStrSize(cublasdxPipeline pipeline,
    cublasdxPipelineTrait trait,
    size_t* size) LIBMATHDX_API_NOEXCEPT;                                                                             

/**
 * @brief Query a C-string trait value from a finalized tensor
 *
 * @param[in] tensor A finalized tensor handle, output of \ref cublasdxCreateTensor
 * @param[in] trait The trait to query
 * @param[in] size The C-string size, as returned by \ref cublasdxGetTensorTraitStrSize
 * @param[out] value The C-string trait value
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTensorTraitStr(cublasdxTensor tensor,
                                                                          cublasdxTensorTrait trait,
                                                                          size_t size,
                                                                          char* value) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Query a C-string trait value from a finalized pipeline
 *
 * @param[in] pipeline A finalized pipeline handle, output of \ref cublasdxCreateDevicePipeline or \ref cublasdxCreateTilePipeline
 * @param[in] trait The trait to query
 * @param[in] size The C-string size, as returned by \ref cublasdxGetPipelineTraitStrSize
 * @param[out] value The C-string trait value
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetPipelineTraitStr(cublasdxPipeline pipeline,
    cublasdxPipelineTrait trait,
    size_t size,
    char* value) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Create a device function from a set of tensor
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor or LIBMATHDX_NONE if no descriptor is required.
 * @param[in] device_function_type The device function to create.
 * @param[in] count The number of input & output tensors to the device function.
 * @param[in] array The array of input & output tensors.
 * @param[out] device_function The device function.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL
cublasdxCreateDeviceFunction(cublasdxDescriptor handle,
                           cublasdxDeviceFunctionType device_function_type,
                           size_t count,
                           const cublasdxTensor* array,
                           cublasdxDeviceFunction* device_function) LIBMATHDX_API_NOEXCEPT;

/**  
 * @brief Destroys a device function handle.
 *
 * @param[in] device_function A cuBLASDx device function, output of \ref cublasdxCreateDeviceFunction.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxDestroyDeviceFunction(cublasdxDeviceFunction device_function) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Binds (aka create) a device function from a set of tensor
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] device_function_type The device function to create
 * @param[in] tensor_count The number of input & output tensors to the device function
 * @param[in] tensors The array of input & output tensors
 * @param[in] pipeline_count The number of pipelines to the device function
 * @param[in] pipelines The array of pipelines
 * @param[out] device_function The device function
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
 LIBMATHDX_API commondxStatusType LIBMATHDX_CALL
 cublasdxCreateDeviceFunctionWithPipelines(cublasdxDescriptor handle,
                            cublasdxDeviceFunctionType device_function_type,
                            size_t tensor_count,
                            const cublasdxTensor* tensors,
                            size_t pipeline_count,
                            const cublasdxPipeline* pipelines,
                            cublasdxDeviceFunction* device_function) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Finalize (aka codegen) a set of device function into a code handle
 *
 * After this, LTOIR can be extracted from `code` using \ref commondxGetCodeLTOIR
 *
 * @param[out] code A code handle, output from \ref commondxCreateCode
 * @param[in] count The number of device functions to codegen
 * @param[in] array The array of device functions
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxFinalizeDeviceFunctions(commondxCode code,
                                                                                size_t count,
                                                                                const cublasdxDeviceFunction* array)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Query a device function C-string trait value size
 *
 * @param[in] device_function A device function handle, output from \ref cublasdxFinalizeDeviceFunctions
 * @param[in] trait The trait to query the device function
 * @param[out] size The size of the trait value C-string, including the `\0`
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL
cublasdxGetDeviceFunctionTraitStrSize(cublasdxDeviceFunction device_function,
                                      cublasdxDeviceFunctionTrait trait,
                                      size_t* size) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Query a device function C-string trait value
 *
 * @param[in] device_function A device function handle, output from \ref cublasdxFinalizeDeviceFunctions
 * @param[in] trait The trait to query the device function
 * @param[in] size The size of the trait value C-string as returned by \ref cublasdxGetDeviceFunctionTraitStrSize
 * @param[out] value The trait value as a C-string. Must point to at least `size` bytes.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL
cublasdxGetDeviceFunctionTraitStr(cublasdxDeviceFunction device_function,
                                  cublasdxDeviceFunctionTrait trait,
                                  size_t size,
                                  char* value) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Set an integer option on a device function.
 *
 * @param[in] function A device function handle.
 * @param[in] option The option to set on the device function.
 * @param[in] opt The value for the option.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL
cublasdxSetDeviceFunctionOptionInt64(cublasdxDeviceFunction function,
                                     cublasdxDeviceFunctionOption option,
                                     long long int opt) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Set a string option on a device function.
 *
 * @param[in] function A device function handle.
 * @param[in] option The option to set on the device function.
 * @param[in] opt The string value for the option. Must be a null terminated C-string.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */

LIBMATHDX_API commondxStatusType LIBMATHDX_CALL
cublasdxSetDeviceFunctionOptionStr(cublasdxDeviceFunction function,
                                   cublasdxDeviceFunctionOption option,
                                   const char* opt) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns the LTOIR size, in bytes
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[out] lto_size The size of the LTOIR.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetLTOIRSize(cublasdxDescriptor handle,
                                                                     size_t* lto_size) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns the LTOIR
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] size The size, in bytes, of the LTOIR, as returned by \ref cublasdxGetLTOIRSize
 * @param[out] lto A pointer to at least `size` bytes containing the LTOIR
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetLTOIR(cublasdxDescriptor handle,
                                                                 size_t size,
                                                                 void* lto) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns the size of a C-string trait
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] trait The trait to query the size of
 * @param[out] size The size of the C-string value, including the `\0`.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTraitStrSize(cublasdxDescriptor handle,
                                                                        cublasdxTraitType trait,
                                                                        size_t* size) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns a C-string trait's value
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] trait The trait to query on the descriptor
 * @param[in] size The size of the C-string (including the `\0`)
 * @param[out] value The C-string trait value. Must point to at least `size` bytes.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTraitStr(cublasdxDescriptor handle,
                                                                    cublasdxTraitType trait,
                                                                    size_t size,
                                                                    char* value) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns an integer trait's value
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] trait A trait to query the handle for
 * @param[out] value The trait value.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTraitInt64(cublasdxDescriptor handle,
                                                                      cublasdxTraitType trait,
                                                                      long long int* value) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns an array trait's value
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] trait A trait to query handle for
 * @param[in] count The number of elements in the trait array, as indicated in the \ref cublasdxTraitType_t
 * documentation.
 * @param[out] array A pointer to at least count integers. As output, an array filled with the trait value.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTraitInt64s(cublasdxDescriptor handle,
                                                                       cublasdxTraitType trait,
                                                                       size_t count,
                                                                       long long int* array) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Returns an array trait's value, when the elements are commondxValueType values
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @param[in] trait A trait to query handle for
 * @param[in] count The number of elements in the trait array, as indicated in the \ref cublasdxTraitType_t
 * documentation.
 * @param[out] array A pointer to at least count commondxValueType. As output, an array filled with the trait value.
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxGetTraitCommondxDataTypes(cublasdxDescriptor handle,
                                                                                  cublasdxTraitType trait,
                                                                                  size_t count,
                                                                                  commondxValueType* array)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert an operator enum to a human readable C-string
 *
 * @param[in] op The operator enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxOperatorTypeToStr(cublasdxOperatorType op) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a trait enum to a human readable C-string
 *
 * @param[in] trait The trait enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxTraitTypeToStr(cublasdxTraitType trait) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Fill an instance of commondxCode with the code from the cuBLASDx descriptor
 *
 * @param[out] code A commondxCode code
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxFinalizeCode(commondxCode code,
                                                                     cublasdxDescriptor handle) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Destroy a cuBLASDx descriptor
 *
 * @param[in] handle A cuBLASDx descriptor, output of \ref cublasdxCreateDescriptor
 * @return `COMMONDX_SUCCESS` on success, or an error code.
 */
LIBMATHDX_API commondxStatusType LIBMATHDX_CALL cublasdxDestroyDescriptor(cublasdxDescriptor handle)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert an API enum to a human readable C-string
 *
 * @param[in] api The API enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxApiToStr(cublasdxApi api) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a type enum to a human readable C-string
 *
 * @param[in] type The type enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxTypeToStr(cublasdxType type) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a transpose mode enum to a human readable C-string
 *
 * @param[in] mode The transpose mode enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxTransposeModeToStr(cublasdxTransposeMode mode) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert an arrangement enum to a human readable C-string
 *
 * @param[in] arrangement The arrangement enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxArrangementToStr(cublasdxArrangement arrangement)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a function enum to a human readable C-string
 *
 * @param[in] function The function enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxFunctionToStr(cublasdxFunction function) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a tensor type enum to a human readable C-string
 *
 * @param[in] type The tensor type enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxTensorTypeToStr(cublasdxTensorType type) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a block size strategy enum to a human readable C-string
 *
 * @param[in] strategy The block size strategy enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxBlockSizeStrategyToStr(cublasdxBlockSizeStrategy strategy) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a device pipeline type enum to a human readable C-string
 *
 * @param[in] type The device pipeline type enum to convert
 * @return The C-string
 */
 LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxDevicePipelineTypeToStr(cublasdxDevicePipelineType type) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a tile pipeline type enum to a human readable C-string
 *
 * @param[in] type The tile pipeline type enum to convert
 * @return The C-string
 */
 LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxTilePipelineTypeToStr(cublasdxTilePipelineType type) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Convert a tensor option enum to a human readable C-string
 *
 * @param[in] option The tensor option enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxTensorOptionToStr(cublasdxTensorOption option) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a tensor trait enum to a human readable C-string
 *
 * @param[in] trait The tensor trait enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxTensorTraitToStr(cublasdxTensorTrait trait) LIBMATHDX_API_NOEXCEPT;


/**
 * @brief Convert a pipeline trait enum to a human readable C-string
 *
 * @param[in] trait The pipeline trait enum to convert
 * @return The C-string
 */
 LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxPipelineTraitToStr(cublasdxPipelineTrait trait) LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a device function trait enum to a human readable C-string
 *
 * @param[in] trait The device function trait enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxDeviceFunctionTraitToStr(cublasdxDeviceFunctionTrait trait)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a device function option enum to a human readable C-string
 *
 * @param[in] option The device function option enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxDeviceFunctionOptionToStr(cublasdxDeviceFunctionOption option)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a device function type enum to a human readable C-string
 *
 * @param[in] type The device function type enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxDeviceFunctionTypeToStr(cublasdxDeviceFunctionType type)
    LIBMATHDX_API_NOEXCEPT;

/**
 * @brief Convert a memory space enum to a human readable C-string
 *
 * @param[in] memory_space The memory space enum to convert
 * @return The C-string
 */
LIBMATHDX_API const char* LIBMATHDX_CALL cublasdxMemorySpaceToStr(cublasdxMemorySpace memory_space) 
    LIBMATHDX_API_NOEXCEPT;

#if defined(__cplusplus)
} // extern "C"
#endif /* __cplusplus */

#endif // MATHDX_LIBCUBLASDX_H
