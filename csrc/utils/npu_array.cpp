/******************************************************************************
 * Copyright (c) 2025 AISS Group at Harbin Institute of Technology. All Rights Reserved.
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 * http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 *****************************************************************************/

#include <asnumpy/dtypes/dtype_table.hpp>
#include <asnumpy/utils/npu_array.hpp>
#include <asnumpy/utils/status_handler.hpp>
#include <cstddef>

/**
 * @brief Constructor that creates an NPUArray with specified shape and data type.
 *
 * Creates an array (aclTensor) stored on NPU by calling aclCreateTensor,
 * and initializes its shape and data type.
 *
 * @param shape Vector containing array dimensions, defining the array shape.
 * @param dtype np.dtype defining the data type of array elements.
 * @throws std::runtime_error If memory allocation fails or data type is not supported.
 */
NPUArray::NPUArray(const std::vector<int64_t>& shape, py::dtype dtype) {
    this->shape = shape;
    this->dtype = dtype;
    this->aclDtype = GetACLDataType(dtype);
    tensorSize = GetShapeSize(shape);
    auto tensorByteSize = this->tensorSize * GetDataTypeSize(this->aclDtype);
    this->devicePtr = nullptr;
    if (tensorByteSize > 0) {
        auto error = aclrtMalloc(&this->devicePtr, tensorByteSize, ACL_MEM_MALLOC_HUGE_FIRST);
        ACL_RT_CHECK(error, "aclrtMalloc");
    }
    this->strides.resize(this->shape.size());
    auto currentStride = 1;
    for (int64_t i = this->shape.size() - 1; i >= 0; i--) {
        this->strides[i] = currentStride;
        currentStride *= this->shape[i];
    }
    tensorPtr =
        aclCreateTensor(this->shape.data(), this->shape.size(), GetACLDataType(this->dtype), this->strides.data(), 0,
                        ACL_FORMAT_ND, this->shape.data(), this->shape.size(), this->devicePtr);
}

/**
 * @brief Constructor that creates an NPUArray with specified shape and ACL data type.
 *
 * Creates an array (aclTensor) stored on NPU by calling aclCreateTensor,
 * and initializes its shape and ACL data type directly.
 * This constructor bypasses NumPy dtype conversion for better performance.
 *
 * @param shape Vector containing array dimensions, defining the array shape.
 * @param acl_type ACL data type constant.
 * @throws std::runtime_error If memory allocation fails or data type is not supported.
 */
NPUArray::NPUArray(const std::vector<int64_t>& shape, aclDataType acl_type) {
    this->shape = shape;
    this->aclDtype = acl_type;
    this->tensorSize = GetShapeSize(shape);
    auto tensorByteSize = this->tensorSize * GetDataTypeSize(this->aclDtype);

    // use ACL type directly; do not create NumPy dtype
    // for compatibility, create an empty py::dtype object
    this->dtype = GetPyDtype(acl_type);

    this->devicePtr = nullptr;
    if (tensorByteSize > 0) {
        auto error = aclrtMalloc(&this->devicePtr, tensorByteSize, ACL_MEM_MALLOC_HUGE_FIRST);
        ACL_RT_CHECK(error, "aclrtMalloc");
    }
    this->strides.resize(this->shape.size());
    auto currentStride = 1;
    for (int64_t i = this->shape.size() - 1; i >= 0; i--) {
        this->strides[i] = currentStride;
        currentStride *= this->shape[i];
    }
    tensorPtr = aclCreateTensor(this->shape.data(), this->shape.size(), acl_type, this->strides.data(), 0,
                                ACL_FORMAT_ND, this->shape.data(), this->shape.size(), this->devicePtr);
}

/**
 * @brief Copy constructor - deep copy.
 *
 * Creates a new NPUArray with the same content as the given NPUArray.
 * The new object owns its own memory space and is completely independent of the original.
 *
 * @param other The NPUArray to copy from.
 */
NPUArray::NPUArray(const NPUArray& other) {
    this->shape = other.shape;
    this->dtype = other.dtype;
    this->aclDtype = other.aclDtype;
    this->tensorSize = other.tensorSize;
    this->strides = other.strides;
    auto tensorByteSize = this->tensorSize * GetDataTypeSize(this->aclDtype);
    this->devicePtr = nullptr;
    if (tensorByteSize > 0) {
        auto error = aclrtMalloc(&this->devicePtr, tensorByteSize, ACL_MEM_MALLOC_HUGE_FIRST);
        ACL_RT_CHECK(error, "aclrtMalloc");
        this->tensorPtr = aclCreateTensor(this->shape.data(), this->shape.size(), this->aclDtype, this->strides.data(),
                                          0, ACL_FORMAT_ND, this->shape.data(), this->shape.size(), this->devicePtr);
        void* srcPtr = nullptr;
        error = aclGetRawTensorAddr(other.tensorPtr, &srcPtr);
        ACL_RT_CHECK(error, "aclGetRawTensorAddr");
        if (!srcPtr) {
            throw std::runtime_error("[npu_array.cpp](NPUArray) aclGetRawTensorAddr returned null pointer");
        }
        error = aclrtMemcpy(this->devicePtr, tensorByteSize, srcPtr, tensorByteSize, ACL_MEMCPY_DEVICE_TO_DEVICE);
        ACL_RT_CHECK(error, "aclrtMemcpy");
        error = aclrtSynchronizeDevice();
        ACL_RT_CHECK(error, "aclrtSynchronizeDevice");
    } else {
        // zero-size array; pass nullptr as data pointer when creating tensor
        this->tensorPtr = aclCreateTensor(this->shape.data(), this->shape.size(), this->aclDtype, this->strides.data(),
                                          0, ACL_FORMAT_ND, this->shape.data(), this->shape.size(), nullptr);
    }
}

/**
 * @brief Move constructor.
 *
 * Transfers ownership of resources from the given NPUArray to the new object.
 * The original object is left in an invalid state.
 *
 * @param other The NPUArray to move from.
 */
NPUArray::NPUArray(NPUArray&& other) noexcept {
    this->tensorPtr = other.tensorPtr;
    this->shape = std::move(other.shape);
    this->dtype = other.dtype;
    this->aclDtype = other.aclDtype;
    this->tensorSize = other.tensorSize;
    this->strides = std::move(other.strides);
    this->devicePtr = other.devicePtr;
    other.tensorPtr = nullptr;
    other.devicePtr = nullptr;
}

/**
 * @brief Copy assignment operator.
 *
 * Implements deep copy assignment, ensuring the current object is completely independent of the right-hand object.
 *
 * @param other The NPUArray to copy from.
 * @return Reference to this NPUArray.
 */
NPUArray& NPUArray::operator=(const NPUArray& other) {
    if (this != &other) {
        // release old resources
        if (this->tensorPtr) {
            aclDestroyTensor(this->tensorPtr);
            this->tensorPtr = nullptr;
        }
        if (this->devicePtr) {
            aclrtFree(this->devicePtr);
            this->devicePtr = nullptr;
        }
        this->shape = other.shape;
        this->dtype = other.dtype;
        this->aclDtype = other.aclDtype;
        this->tensorSize = other.tensorSize;
        this->strides = other.strides;

        auto tensorByteSize = this->tensorSize * GetDataTypeSize(this->aclDtype);
        this->devicePtr = nullptr;
        if (tensorByteSize > 0) {
            auto error = aclrtMalloc(&this->devicePtr, tensorByteSize, ACL_MEM_MALLOC_HUGE_FIRST);
            ACL_RT_CHECK(error, "aclrtMalloc");
            this->tensorPtr =
                aclCreateTensor(this->shape.data(), this->shape.size(), this->aclDtype, this->strides.data(), 0,
                                ACL_FORMAT_ND, this->shape.data(), this->shape.size(), this->devicePtr);
            void* srcPtr = nullptr;
            error = aclGetRawTensorAddr(other.tensorPtr, &srcPtr);
            ACL_RT_CHECK(error, "aclGetRawTensorAddr");
            if (!srcPtr) {
                throw std::runtime_error("[npu_array.cpp](operator=) aclGetRawTensorAddr returned null pointer");
            }
            error = aclrtMemcpy(this->devicePtr, tensorByteSize, srcPtr, tensorByteSize, ACL_MEMCPY_DEVICE_TO_DEVICE);
            ACL_RT_CHECK(error, "aclrtMemcpy");
            error = aclrtSynchronizeDevice();
            ACL_RT_CHECK(error, "aclrtSynchronizeDevice");
        } else {
            // zero-size array; pass nullptr as data pointer when creating tensor
            this->tensorPtr =
                aclCreateTensor(this->shape.data(), this->shape.size(), this->aclDtype, this->strides.data(), 0,
                                ACL_FORMAT_ND, this->shape.data(), this->shape.size(), nullptr);
        }
    }
    return *this;
}

/**
 * @brief Move assignment operator.
 *
 * Transfers ownership of resources from the given NPUArray to the current object.
 * The original object is left in an invalid state.
 *
 * @param other The NPUArray to move from.
 * @return Reference to this NPUArray.
 */
NPUArray& NPUArray::operator=(NPUArray&& other) noexcept {
    if (this != &other) {
        // release old resources
        if (this->tensorPtr) {
            aclDestroyTensor(this->tensorPtr);
            this->tensorPtr = nullptr;
        }
        if (this->devicePtr) {
            aclrtFree(this->devicePtr);
            this->devicePtr = nullptr;
        }
        this->tensorPtr = other.tensorPtr;
        this->devicePtr = other.devicePtr;
        this->shape = std::move(other.shape);
        this->dtype = other.dtype;
        this->aclDtype = other.aclDtype;
        this->tensorSize = other.tensorSize;
        this->strides = std::move(other.strides);
        this->devicePtr = other.devicePtr;
        other.tensorPtr = nullptr;
        other.devicePtr = nullptr;
    }
    return *this;
}

/**
 * @brief Destructor that releases resources occupied by NPUArray.
 */
NPUArray::~NPUArray() {
    if (this->tensorPtr) {
        auto error = aclDestroyTensor(this->tensorPtr);
        this->tensorPtr = nullptr;
    }
    if (this->devicePtr) {
        auto error = aclrtFree(this->devicePtr);
        this->devicePtr = nullptr;
    }
}

/**
 * @brief Static method to create NPUArray from NumPy array.
 *
 * Creates an NPUArray from a NumPy array and copies data
 * from host memory to NPU device memory.
 *
 * @param host_data Input NumPy array.
 * @return NPUArray The created NPUArray.
 * @throws std::runtime_error If getting tensor data pointer fails or data copy fails.
 */
NPUArray NPUArray::FromNumpy(py::array hostData) {
    py::buffer_info info = hostData.request();
    auto tensorByteSize = info.size * info.itemsize;
    auto result = NPUArray(info.shape, hostData.dtype());
    if (tensorByteSize == 0)
        return result;
    void* rawDataPtr = nullptr;
    auto error = aclGetRawTensorAddr(result.tensorPtr, &rawDataPtr);
    ACL_RT_CHECK(error, "aclGetRawTensorAddr");
    if (!rawDataPtr) {
        throw std::runtime_error("[npu_array.cpp](FromNumpy) aclGetRawTensorAddr returned null pointer");
    }
    error = aclrtMemcpy(rawDataPtr, tensorByteSize, info.ptr, tensorByteSize, ACL_MEMCPY_HOST_TO_DEVICE);
    ACL_RT_CHECK(error, "aclrtMemcpy");
    error = aclrtSynchronizeStream(nullptr);
    ACL_RT_CHECK(error, "aclrtSynchronizeStream");
    return result;
}

/**
 * @brief Convert NPUArray to NumPy array.
 *
 * Copies data from NPU device memory to host memory and returns a NumPy array.
 *
 * @return py::array The converted NumPy array.
 * @throws std::runtime_error If getting tensor data pointer fails or data copy fails.
 * @throws std::runtime_error If tensor size doesn't match NumPy array size.
 */
py::array NPUArray::ToNumpy() const {
    auto tensorByteSize = this->tensorSize * GetDataTypeSize(this->aclDtype);

    // create result array
    py::array result(this->dtype, this->shape);
    py::buffer_info info = result.request();
    if (tensorByteSize == 0)
        return result;

    // The host buffer is sized from `dtype`, the device buffer from `aclDtype`. dtype_table keeps
    // those in exact correspondence, so a mismatch means that invariant is broken. Check before
    // any copy: this guard previously sat in only one branch, which is how a float16 array came to
    // be written as 4-byte floats into a 2-byte-per-element buffer.
    if (static_cast<int64_t>(info.size * info.itemsize) != static_cast<int64_t>(tensorByteSize))
        throw std::runtime_error(
            fmt::format("[npu_array.cpp](ToNumpy) size mismatch: host buffer is {} bytes for dtype '{}', but the "
                        "device tensor is {} bytes for aclDataType '{}'",
                        info.size * info.itemsize, py::str(this->dtype).cast<std::string>(), tensorByteSize,
                        asnumpy::dtypes::Name(this->aclDtype)));

    void* rawDataPtr = nullptr;
    auto error = aclGetRawTensorAddr(this->tensorPtr, &rawDataPtr);
    ACL_RT_CHECK(error, "aclGetRawTensorAddr");
    if (!rawDataPtr) {
        throw std::runtime_error("[npu_array.cpp](ToNumpy) aclGetRawTensorAddr returned null pointer");
    }

    // Every supported dtype has an identical host and device representation (NumPy float16 and
    // ACL_FLOAT16 are both IEEE-754 binary16), so a raw copy is exact for all of them.
    error = aclrtMemcpy(info.ptr, tensorByteSize, rawDataPtr, tensorByteSize, ACL_MEMCPY_DEVICE_TO_HOST);
    ACL_RT_CHECK(error, "aclrtMemcpy");

    return result;
}

/**
 * @brief Helper function to calculate total size of array.
 *
 * Calculates the total number of elements for a given shape.
 *
 * @param shape Vector containing array dimensions, defining the array shape.
 * @return int64_t Total number of elements in the array.
 * @throws std::runtime_error If any dimension in shape is less than or equal to 0.
 */
int64_t NPUArray::GetShapeSize(const std::vector<int64_t>& shape) {
    int64_t shapeSize = 1;
    for (auto i : shape) {
        if (i < 0) {
            throw std::runtime_error("[npu_array.cpp](GetShapeSize) Shape Dimensions Must Be Non-Negative!");
        }
        shapeSize *= i;
    }
    return shapeSize;
}

/**
 * @brief Helper function to convert py::dtype to aclDataType.
 *
 * Thin delegation to asnumpy::dtypes::AclFromNumpy, which owns the mapping. Do not reintroduce
 * mapping logic here: the table is the single source of truth.
 *
 * @param dtype Input py::dtype.
 * @return aclDataType The converted aclDataType.
 * @throws std::invalid_argument If the dtype is big-endian, structured, or has no ACL equivalent.
 *         Surfaces to Python as ValueError.
 */
aclDataType NPUArray::GetACLDataType(py::dtype dtype) { return asnumpy::dtypes::AclFromNumpy(dtype); }

/**
 * @brief Helper function to convert aclDataType to py::dtype.
 *
 * Thin delegation to asnumpy::dtypes::NumpyFromAcl. Exact inverse of GetACLDataType over the
 * supported set.
 *
 * @param acl_type Input aclDataType.
 * @return py::dtype The converted py::dtype.
 * @throws std::invalid_argument If `acl_type` has no NumPy equivalent (bf16, fp8/6/4, int4,
 *         uint1, complex32). Surfaces to Python as ValueError.
 */
py::dtype NPUArray::GetPyDtype(aclDataType acl_type) { return asnumpy::dtypes::NumpyFromAcl(acl_type); }

/**
 * @brief Helper function to get byte size corresponding to aclDataType.
 *
 * Thin delegation to asnumpy::dtypes::ItemSize. Defined for unsupported ACL types too, so
 * byte-size math stays available for diagnostics.
 *
 * @param dataType Input aclDataType.
 * @return int64_t Byte size of the data type.
 * @throws std::invalid_argument If `dataType` is unknown. Surfaces to Python as ValueError.
 */
int64_t NPUArray::GetDataTypeSize(aclDataType dataType) { return asnumpy::dtypes::ItemSize(dataType); }

std::vector<int64_t> GetBroadcastShape(const NPUArray& a, const NPUArray& b) {
    const std::vector<int64_t>& shapeA = a.shape;
    const std::vector<int64_t>& shapeB = b.shape;

    size_t ndimA = shapeA.size();
    size_t ndimB = shapeB.size();
    size_t ndimOut = std::max(ndimA, ndimB);

    std::vector<int64_t> result(ndimOut, 1);

    for (size_t i = 0; i < ndimOut; ++i) {
        int64_t dimA = (i < ndimA) ? shapeA[ndimA - 1 - i] : 1;
        int64_t dimB = (i < ndimB) ? shapeB[ndimB - 1 - i] : 1;

        if (dimA == dimB || dimA == 1 || dimB == 1) {
            result[ndimOut - 1 - i] = (dimA == 1) ? dimB : dimA;
        } else {
            throw std::invalid_argument("[npu_array.cpp](GetBroadcastShape) shapes are not broadcastable. "
                                        "dimA=" +
                                        std::to_string(dimA) + " dimB=" + std::to_string(dimB) + " at axis -" +
                                        std::to_string(i + 1));
        }
    }

    return result;
}
