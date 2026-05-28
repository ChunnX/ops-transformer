/**
 * Copyright (c) 2025 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */
 
#include "aclnn/aclnn_base.h"
#include "aclnn/acl_meta.h"
#include "gtest/gtest.h"
#include <memory>
#include <vector>
#include <cstdlib>
#include "opdev/common_types.h"
#include "opdev/data_type_utils.h"
#include "opdev/format_utils.h"
#include "op_dfx_internal.h"
#include "opdev/make_op_executor.h"
#include "depends/dump/dump_stub.h"
#include "utils/file_faker.h"

using namespace std;
using namespace op;

#define INIT_ACL_TENSOR_ARRAY(tensors, ...)  aclTensor* tensors[] = {__VA_ARGS__}

class AclOpApiTest : public testing::Test {
protected:
    static void SetUpTestCase()
    {
        NnopbaseSetStubFiles(OP_API_COMMON_UT_SRC_DIR);
        std::cout << "AclOpApiTest SetUp" << std::endl;
    }
public:
    bool ShapeEq(const op::Shape &shape, const vector<int64_t> &value)
    {
        if (shape.GetDimNum() != value.size()) {
            return false;
        }

        for (size_t i = 0; i < value.size(); i++) {
            if (shape.GetDim(i) != value[i]) {
                return false;
            }
        }

        return true;
    }
};

#define CHECK_TENSOR(tensorName, viewShape, storageShape, dataType, strides, viewOffset, format, tensorData)                   \
    vector<int64_t> _viewShape = viewShape;                                                                                    \
    vector<int64_t> _storageShape = storageShape;                                                                              \
    auto tensorName = aclCreateTensor(_viewShape.data(),                                                                       \
                                      _viewShape.size(),                                                                       \
                                      dataType,                                                                                \
                                      strides,                                                                                 \
                                      viewOffset,                                                                              \
                                      format,                                                                                  \
                                      _storageShape.data(),                                                                    \
                                      _storageShape.size(),                                                                    \
                                      tensorData);                                                                             \
    ASSERT_NE(tensorName, nullptr);                                                                                            \
    std::unique_ptr<aclTensor> uniqueTensor(tensorName);                                                                       \
    EXPECT_TRUE(ShapeEq(tensorName->GetViewShape(), viewShape));                                                               \
    op::Shape expectStorageShape({1});                                                                                         \
    EXPECT_TRUE(ShapeEq(tensorName->GetStorageShape(), storageShape));                                                         \
    EXPECT_EQ(tensorName->GetDataType(), op::ToOpDataType(dataType));                                                          \
    EXPECT_EQ(tensorName->GetViewFormat(), op::ToOpFormat(format));                                                            \
    EXPECT_EQ(tensorName->GetStorageAddr(), tensorData);                                                                       \
    EXPECT_EQ(tensorName->GetData(), static_cast<char *>(tensorData) + viewOffset * op::TypeSize(op::ToOpDataType(dataType))); \
    EXPECT_EQ(tensorName->IsFromWorkspace(), false);                                                                           \
    EXPECT_EQ(tensorName->GetViewOffset(), viewOffset);                                                                        \
    EXPECT_EQ(tensorName->GetStorageAddr(), tensorData);                                                                       \
    EXPECT_EQ(tensorName->GetStorageFormat(), op::Format::FORMAT_ND);                                                          \
    EXPECT_EQ(tensorName->GetPlacement(), TensorPlacement::kOnDeviceHbm);                                                      \
    EXPECT_EQ(tensorName->IsView(), false);

TEST_F(AclOpApiTest, CreateEmptyViewTensor)
{
    std::vector<int64_t> strides = {1};
    CHECK_TENSOR(a, { 0 }, { 1 }, aclDataType::ACL_FLOAT, strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    EXPECT_EQ(a->GetStorageFormat(), op::Format::FORMAT_ND);
    EXPECT_EQ(a->GetViewStrides(), op::Strides({1}));
}

TEST_F(AclOpApiTest, CreateEmptyStorageTensor)
{
    std::vector<int64_t> strides = {1};
    CHECK_TENSOR(a, { 0 }, { 0 }, aclDataType::ACL_FLOAT, strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    EXPECT_EQ(a->GetViewStrides(), op::Strides({1}));
}

TEST_F(AclOpApiTest, CreateContiguousTensor001)
{
    std::vector<int64_t> strides = {2, 1};
    CHECK_TENSOR(a, std::vector<int64_t>({4, 2}), std::vector<int64_t>({8}), aclDataType::ACL_FLOAT,
                 strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    EXPECT_EQ(a->GetViewStrides(), op::Strides({2, 1}));
}

TEST_F(AclOpApiTest, CreateContiguousTensor002)
{
    CHECK_TENSOR(a, std::vector<int64_t>({1, 4, 2}), std::vector<int64_t>({8}), aclDataType::ACL_FLOAT,
                 nullptr, 0, aclFormat::ACL_FORMAT_ND, nullptr);
    EXPECT_EQ(a->GetViewStrides(), op::Strides({8, 2, 1}));
}

TEST_F(AclOpApiTest, CreateContiguousTensor003)
{
    vector<float> values(8, 3.0);
    CHECK_TENSOR(a, std::vector<int64_t>({1, 4, 2}), std::vector<int64_t>({16}), aclDataType::ACL_FLOAT,
                 nullptr, 3, aclFormat::ACL_FORMAT_ND, static_cast<void *>(values.data()));
    EXPECT_EQ(a->GetViewStrides(), op::Strides({8, 2, 1}));
}

TEST_F(AclOpApiTest, CreateUnContiguousTensor001)
{
    std::vector<int64_t> strides = {8, 1};
    CHECK_TENSOR(a, std::vector<int64_t>({4, 2}), std::vector<int64_t>({32}), aclDataType::ACL_FLOAT,
                 strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    EXPECT_EQ(a->GetViewStrides(), op::Strides({8, 1}));
}

#define CHECK_SCALAR(scalarName, value, valueType, dataType)                                  \
    valueType scalarName##valueType = value;                                                  \
    std::unique_ptr<aclScalar> scalarName(aclCreateScalar(&scalarName##valueType, dataType)); \
    ASSERT_NE(scalarName.get(), nullptr);                                                           \
    ASSERT_NE(scalarName->GetData(), nullptr);                                                \
    ASSERT_EQ(scalarName->Size(), sizeof(valueType));                                         \
    EXPECT_EQ(memcmp(scalarName->GetData(), &scalarName##valueType, sizeof(valueType)), 0);   \
    EXPECT_EQ(scalarName->GetDataType(), op::ToOpDataType(dataType));

TEST_F(AclOpApiTest, CreateScalar)
{
    CHECK_SCALAR(fpScalar, 3.2, float, aclDataType::ACL_FLOAT);
    CHECK_SCALAR(fp16Scalar, 3.2, fp16_t, aclDataType::ACL_FLOAT16);
    CHECK_SCALAR(int8Scalar, 3, int8_t, aclDataType::ACL_INT8);
    CHECK_SCALAR(int16Scalar, 3, int16_t, aclDataType::ACL_INT16);
    CHECK_SCALAR(uint16Scalar, 3, uint16_t, aclDataType::ACL_UINT16);
    CHECK_SCALAR(uint8Scalar, 3, uint8_t, aclDataType::ACL_UINT8);
    CHECK_SCALAR(int32Scalar, 3, int32_t, aclDataType::ACL_INT32);
    CHECK_SCALAR(int64Scalar, 3, int64_t, aclDataType::ACL_INT64);
    CHECK_SCALAR(uint32Scalar, 3, uint32_t, aclDataType::ACL_UINT32);
    CHECK_SCALAR(uint64Scalar, 3, uint64_t, aclDataType::ACL_UINT64);
    CHECK_SCALAR(boolScalar, 1, bool, aclDataType::ACL_BOOL);
    CHECK_SCALAR(doubleScalar, 3, double, aclDataType::ACL_DOUBLE);
    using complex64 = std::complex<float>;
    using complex128 = std::complex<double>;
    CHECK_SCALAR(complex64Scalar, complex64(3.2, 3.2), complex64, aclDataType::ACL_COMPLEX64);
    CHECK_SCALAR(complex128Scalar, complex128(3.2, 3.2), complex128, aclDataType::ACL_COMPLEX128);

    std::string stringScalar = "zyx";
    auto nullScalar = aclCreateScalar(&stringScalar, aclDataType::ACL_STRING);
    EXPECT_EQ(nullScalar, nullptr);
}

#define CHECK_ARRAY(arrayName, value, count, valueType, arrayType)                        \
    std::unique_ptr<acl##arrayType##Array> arrayName(aclCreate##arrayType##Array(value,   \
                                                                                 count)); \
    ASSERT_NE(arrayName.get(), nullptr);                                                        \
    if (value != nullptr && count != 0) {                                                 \
        ASSERT_NE(arrayName->GetData(), nullptr);                                         \
        EXPECT_EQ(memcmp(arrayName->GetData(), value, count * sizeof(valueType)), 0);     \
        EXPECT_EQ(arrayName->Size(), count);                                              \
    } else {                                                                              \
        EXPECT_EQ(arrayName->GetData(), nullptr);                                         \
        EXPECT_EQ(arrayName->Size(), 0);                                                  \
    }

TEST_F(AclOpApiTest, CreateArray)
{
    int64_t intValue[] = {1, 2, 3};
    CHECK_ARRAY(intArray1, intValue, 3UL, int64_t, Int);
    int64_t *nullInt = nullptr;
    CHECK_ARRAY(intArray2, nullInt, 0UL, int64_t, Int);
    CHECK_ARRAY(intArray3, intValue, 0UL, int64_t, Int);

    float fpValue[] = {1, 2, 3};
    float *nullFloat = nullptr;
    CHECK_ARRAY(floatArray1, fpValue, 3UL, float, Float);
    CHECK_ARRAY(floatArray2, nullFloat, 0UL, float, Float);
    CHECK_ARRAY(floatArray3, fpValue, 0UL, float, Float);

    bool boolValue[] = {true, false, true};
    bool *nullBool = nullptr;
    CHECK_ARRAY(boolArray1, boolValue, 3UL, bool, Bool);
    CHECK_ARRAY(boolArray2, nullBool, 0UL, bool, Bool);
    CHECK_ARRAY(boolArray3, boolValue, 0UL, bool, Bool);
}

TEST_F(AclOpApiTest, CreateTensorList)
{
    aclTensor *list1[] = {nullptr, nullptr, nullptr};
    auto aclTensorList1 = aclCreateTensorList(list1, 0);
    ASSERT_NE(aclTensorList1, nullptr);
    EXPECT_EQ(aclTensorList1->GetData(), nullptr);
    EXPECT_EQ(aclTensorList1->Size(), 0);
    aclDestroyTensorList(aclTensorList1);

    std::vector<int64_t> shape = {1, 2, 3};
    aclTensor *list2[] = {aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr),
                          aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr),
                          aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr)};
    auto aclTensorList2 = aclCreateTensorList(list2, 3);
    ASSERT_NE(aclTensorList2, nullptr);
    ASSERT_NE(aclTensorList2->GetData(), nullptr);
    EXPECT_EQ(aclTensorList2->Size(), 3);
    aclDestroyTensorList(aclTensorList2);
}

TEST_F(AclOpApiTest, aclDestroyTensor)
{
    std::vector<int64_t> shape = {1, 2, 3};
    aclTensor *tensorNull = aclCreateTensor(nullptr, shape.size(), aclDataType::ACL_FLOAT, nullptr,
                                            0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    EXPECT_EQ(tensorNull, nullptr);
    EXPECT_EQ(aclDestroyTensor(tensorNull), OK);
    aclTensor *tensorNull1 = aclCreateTensor(nullptr, 0, aclDataType::ACL_FLOAT, nullptr, 0,
                                             aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    EXPECT_NE(tensorNull1, nullptr);
    EXPECT_EQ(aclDestroyTensor(tensorNull1), OK);
    aclTensor *tensorNull2 = aclCreateTensor(nullptr, shape.size(), aclDataType::ACL_FLOAT, nullptr, 0,
                                            aclFormat::ACL_FORMAT_ND, nullptr, shape.size(), nullptr);
    EXPECT_EQ(tensorNull2, nullptr);
    EXPECT_EQ(aclDestroyTensor(tensorNull2), OK);
    aclTensor *tensorNull3 = aclCreateTensor(nullptr, 0, aclDataType::ACL_FLOAT, nullptr, 0, 
                                             aclFormat::ACL_FORMAT_ND, nullptr, 0, nullptr);
    EXPECT_NE(tensorNull3, nullptr);
    EXPECT_EQ(aclDestroyTensor(tensorNull3), OK);

    aclTensor *tensor = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                        nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    EXPECT_EQ(aclDestroyTensor(tensor), OK);
    EXPECT_EQ(aclDestroyTensor(nullptr), OK);
}

TEST_F(AclOpApiTest, aclDestroyScalar)
{
    EXPECT_EQ(aclCreateScalar(nullptr, aclDataType::ACL_FLOAT), nullptr);

    float fpValue = 3.2;
    auto *value = aclCreateScalar(&fpValue, aclDataType::ACL_FLOAT);
    EXPECT_EQ(aclDestroyScalar(value), OK);
    EXPECT_EQ(aclDestroyScalar(nullptr), OK);
    EXPECT_EQ(aclDestroyScalarList(nullptr), OK);
}

TEST_F(AclOpApiTest, aclIntArray)
{
    int64_t values[] = {3, 4, 5};
    auto *value = aclCreateIntArray(values, sizeof(values) / sizeof(values[0]));
    EXPECT_EQ(aclDestroyIntArray(value), OK);
    EXPECT_EQ(aclDestroyIntArray(nullptr), OK);
}

TEST_F(AclOpApiTest, aclFloatArray)
{
    float values[] = {3, 4, 5};
    auto *value = aclCreateFloatArray(values, sizeof(values) / sizeof(values[0]));
    EXPECT_EQ(aclDestroyFloatArray(value), OK);
    EXPECT_EQ(aclDestroyFloatArray(nullptr), OK);
}

TEST_F(AclOpApiTest, aclBoolArray)
{
    bool values[] = {true, false, true};
    auto *value = aclCreateBoolArray(values, sizeof(values) / sizeof(values[0]));
    EXPECT_EQ(aclDestroyBoolArray(value), OK);
    EXPECT_EQ(aclDestroyBoolArray(nullptr), OK);
}

TEST_F(AclOpApiTest, aclDestroyTensorList)
{
    aclTensor *list1[] = {nullptr, nullptr, nullptr};
    auto aclTensorList1 = aclCreateTensorList(list1, 0);
    aclDestroyTensorList(aclTensorList1);

    std::vector<int64_t> shape = {1, 2, 3};
    aclTensor *list2[] = {aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr),
                          aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr),
                          aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr)};
    auto aclTensorList2 = aclCreateTensorList(list2, 3);
    aclDestroyTensorList(aclTensorList2);

    EXPECT_EQ(aclDestroyTensorList(nullptr), OK);
}

TEST_F(AclOpApiTest, aclGetViewShape)
{
    EXPECT_NE(aclGetViewShape(nullptr, nullptr, nullptr), OK);
    std::vector<int64_t> strides = {8, 1};
    CHECK_TENSOR(a, std::vector<int64_t>({4, 2}), std::vector<int64_t>({32}), aclDataType::ACL_FLOAT,
                 strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    int64_t *view_dims = nullptr;
    uint64_t view_dim_num = 0;
    EXPECT_EQ(aclGetViewShape(a, &view_dims, &view_dim_num), OK);
    EXPECT_NE(view_dims, nullptr);
    EXPECT_EQ(view_dim_num, 2);
    EXPECT_EQ(view_dims[0], 4);
    EXPECT_EQ(view_dims[1], 2);
    delete[]view_dims;
}

TEST_F(AclOpApiTest, aclnnInit)
{
    bool flag = false;
    EXPECT_EQ(aclnnInit(nullptr), OK);
    EXPECT_EQ(op::internal::systemConfig.GetEnableDebugKernelFlag(flag), OK);
    EXPECT_EQ(flag, false);

    EXPECT_EQ(aclnnInit((std::string(OP_API_COMMON_UT_SRC_DIR) + "/conf/op_api/not_exit.json").c_str()), OK);
    EXPECT_EQ(op::internal::systemConfig.GetEnableDebugKernelFlag(flag), OK);
    EXPECT_EQ(flag, false);

    EXPECT_EQ(aclnnInit((std::string(OP_API_COMMON_UT_SRC_DIR) + "/conf/op_api/op_debug_config.json").c_str()), OK);
    EXPECT_EQ(op::internal::systemConfig.GetEnableDebugKernelFlag(flag), OK);
    EXPECT_EQ(flag, true);

    EXPECT_EQ(op::internal::systemConfig.SetEnableDebugKernelFlag(false), OK);
    setenv("NPU_COLLECT_PATH", "on", 1); // does overwrite
    EXPECT_EQ(aclnnInit(nullptr), OK);
    EXPECT_EQ(op::internal::systemConfig.GetEnableDebugKernelFlag(flag), OK);
    EXPECT_EQ(flag, true);
}

TEST_F(AclOpApiTest, aclnnFinalize)
{
    EXPECT_EQ(aclnnFinalize(), OK);
}

TEST_F(AclOpApiTest, aclGetViewStrides)
{
    EXPECT_NE(aclGetViewStrides(nullptr, nullptr, nullptr), OK);
    std::vector<int64_t> strides = {8, 1};
    CHECK_TENSOR(a, std::vector<int64_t>({4, 2}), std::vector<int64_t>({32}), aclDataType::ACL_FLOAT,
                 strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    int64_t *viewStrides = nullptr;
    uint64_t viewStridesNum = 0;
    EXPECT_EQ(aclGetViewStrides(a, &viewStrides, &viewStridesNum), OK);
    EXPECT_NE(viewStrides, nullptr);
    EXPECT_EQ(viewStridesNum, 2);
    EXPECT_EQ(viewStrides[0], 8);
    EXPECT_EQ(viewStrides[1], 1);
    delete[]viewStrides;
}

TEST_F(AclOpApiTest, aclGetViewOffset)
{
    EXPECT_NE(aclGetViewOffset(nullptr, nullptr), OK);
    std::vector<int64_t> strides = {8, 1};
    CHECK_TENSOR(a, std::vector<int64_t>({4, 2}), std::vector<int64_t>({32}), aclDataType::ACL_FLOAT,
                 strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    int64_t offset = 0;
    EXPECT_EQ(aclGetViewOffset(a, &offset), OK);
    EXPECT_EQ(offset, 0);
}

TEST_F(AclOpApiTest, aclGetFormat)
{
    EXPECT_NE(aclGetFormat(nullptr, nullptr), OK);
    std::vector<int64_t> strides = {8, 1};
    CHECK_TENSOR(a, std::vector<int64_t>({4, 2}), std::vector<int64_t>({32}), aclDataType::ACL_FLOAT,
                 strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    aclFormat formatRes = aclFormat::ACL_FORMAT_UNDEFINED;
    EXPECT_EQ(aclGetFormat(a, &formatRes), OK);
    EXPECT_EQ(formatRes, aclFormat::ACL_FORMAT_ND);
}

TEST_F(AclOpApiTest, aclGetDataType)
{
    EXPECT_NE(aclGetFormat(nullptr, nullptr), OK);
    std::vector<int64_t> strides = {8, 1};
    CHECK_TENSOR(a, std::vector<int64_t>({4, 2}), std::vector<int64_t>({32}), aclDataType::ACL_FLOAT,
                 strides.data(), 0, aclFormat::ACL_FORMAT_ND, nullptr);
    aclDataType dataType = aclDataType::ACL_DT_UNDEFINED;
    EXPECT_EQ(aclGetDataType(a, &dataType), OK);
    EXPECT_EQ(dataType, aclDataType::ACL_FLOAT);
}

TEST_F(AclOpApiTest, aclGetIntArraySize)
{
    EXPECT_NE(aclGetIntArraySize(nullptr, nullptr), OK);
    int64_t values[] = {3, 4, 5};
    auto *value = aclCreateIntArray(values, sizeof(values) / sizeof(values[0]));
    uint64_t size = 0;
    EXPECT_EQ(aclGetIntArraySize(value, &size), OK);
    EXPECT_EQ(size, 3);
    EXPECT_EQ(aclDestroyIntArray(value), OK);
}

TEST_F(AclOpApiTest, aclGetFloatArraySize)
{
    EXPECT_NE(aclGetFloatArraySize(nullptr, nullptr), OK);
    float values[] = {3.0, 4.0, 5.0};
    auto *value = aclCreateFloatArray(values, sizeof(values) / sizeof(values[0]));
    uint64_t size = 0;
    EXPECT_EQ(aclGetFloatArraySize(value, &size), OK);
    EXPECT_EQ(size, 3);
    EXPECT_EQ(aclDestroyFloatArray(value), OK);
}

TEST_F(AclOpApiTest, aclGetBoolArraySize)
{
    EXPECT_NE(aclGetBoolArraySize(nullptr, nullptr), OK);
    bool values[] = {true, true, true};
    auto *value = aclCreateBoolArray(values, sizeof(values) / sizeof(values[0]));
    uint64_t size = 0;
    EXPECT_EQ(aclGetBoolArraySize(value, &size), OK);
    EXPECT_EQ(size, 3);
    EXPECT_EQ(aclDestroyBoolArray(value), OK);
}

TEST_F(AclOpApiTest, aclGetTensorListSize)
{
    EXPECT_NE(aclGetTensorListSize(nullptr, nullptr), OK);
    std::vector<int64_t> shape = {1, 2, 3};
    aclTensor *list2[] = {aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr),
                          aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr),
                          aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                          nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr)};
    auto aclTensorList2 = aclCreateTensorList(list2, 3);
    ASSERT_NE(aclTensorList2, nullptr);
    ASSERT_NE(aclTensorList2->GetData(), nullptr);
    EXPECT_EQ(aclTensorList2->Size(), 3);

    uint64_t size = 0;
    EXPECT_EQ(aclGetTensorListSize(aclTensorList2, &size), OK);
    EXPECT_EQ(size, 3);

    aclDestroyTensorList(aclTensorList2);
}

TEST_F(AclOpApiTest, aclUpdateTensorAddr)
{
    auto uniqueExecutor = CREATE_EXECUTOR();
    aclOpExecutor *executor = nullptr;
    uniqueExecutor.ReleaseTo(&executor);
    std::vector<int64_t> shape = {1, 2, 3};
    aclTensor *input1 = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                        nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    aclTensor *input2 = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                        nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    aclTensor *list1[] = {input1, input2};
    auto aclTensorList1 = aclCreateTensorList(list1, 2);
    int *ptr1 = new int;
    void *addr = reinterpret_cast<void *>(ptr1);
    aclnnStatus ret = AclSetInputTensorAddr(executor, 0, input1, addr);
    EXPECT_EQ(ret, ACL_SUCCESS);
    EXPECT_EQ(input1->GetStorageAddr(), addr);

    int *ptr2 = new int;
    addr = reinterpret_cast<void *>(ptr2);
    ret = AclSetOutputTensorAddr(executor, 0, input1, addr);
    EXPECT_EQ(ret, ACL_SUCCESS);
    EXPECT_EQ(input1->GetStorageAddr(), addr);

    int *ptr3 = new int;
    addr = reinterpret_cast<void *>(ptr3);
    ret = AclSetDynamicInputTensorAddr(executor, 0, 0, aclTensorList1, addr);
    EXPECT_EQ(ret, ACL_SUCCESS);
    EXPECT_EQ(input1->GetStorageAddr(), addr);

    int *ptr4 = new int;
    void *addr2 = reinterpret_cast<void *>(ptr4);
    ret = AclSetDynamicOutputTensorAddr(executor, 0, 1, aclTensorList1, addr2);
    EXPECT_EQ(ret, ACL_SUCCESS);
    EXPECT_EQ(input1->GetStorageAddr(), addr);
    EXPECT_EQ(input2->GetStorageAddr(), addr2);

    delete ptr1;
    delete ptr2;
    delete ptr3;
    delete ptr4;
    aclDestroyTensorList(aclTensorList1);
}

TEST_F(AclOpApiTest, aclUpdateRawTensorAddr)
{
    aclTensor *testTensor = nullptr;
    int *ptr = new int;
    void *setAddr = static_cast<void *>(ptr);
    void *getAddr = nullptr;
    EXPECT_NE(aclSetRawTensorAddr(testTensor, setAddr), OK);
    EXPECT_NE(aclGetRawTensorAddr(testTensor, &getAddr), OK);

    std::vector<int64_t> shape = {1, 2, 3};
    testTensor = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT, nullptr, 0,
        aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    EXPECT_EQ(aclGetRawTensorAddr(testTensor, &getAddr), OK);
    EXPECT_EQ(getAddr, nullptr);
    EXPECT_EQ(aclSetRawTensorAddr(testTensor, setAddr), OK);
    EXPECT_EQ(aclGetRawTensorAddr(testTensor, &getAddr), OK);
    EXPECT_EQ(getAddr, setAddr);
    delete ptr;
}

TEST_F(AclOpApiTest, aclSetAclOpExecutorRepeatable)
{
    bool oriCacheHasFull = op::internal::GetThreadLocalContext().cacheHasFull_;
    op::internal::GetThreadLocalContext().cacheHasFull_ = false;
    op::internal::GetThreadLocalContext().hashKey_ = 0;
    op::internal::GetThreadLocalContext().cacheHashKey_ = (uint8_t *)"hello1";
    op::internal::GetThreadLocalContext().cacheHashKeyLen_ = 6;
    std::vector<int64_t> shape = {1, 2, 3};
    aclTensor *input1 = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                        nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    aclTensor *input2 = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                        nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    op::internal::GetThreadLocalContext().cachedStorageList_.clear();
    op::internal::GetThreadLocalContext().cachedStorageList_.push_back(input1->GetStorage());
    op::internal::GetThreadLocalContext().cachedStorageList_.push_back(input2->GetStorage());
    auto uniqueExecutor = CREATE_EXECUTOR();
    aclOpExecutor *executor = nullptr;
    uniqueExecutor.ReleaseTo(&executor);
    executor->AddTensorRelation(input1, input2);
    aclnnStatus ret = aclSetAclOpExecutorRepeatable(executor);
    EXPECT_EQ(ret, ACL_SUCCESS);

    // check addr update with relation
    int *ptr = new int;
    void *addr = reinterpret_cast<void *>(ptr);
    ret = AclSetInputTensorAddr(executor, 0, input1, addr);
    EXPECT_EQ(ret, ACL_SUCCESS);
    executor->UpdateStorageAddr();
    EXPECT_EQ(input2->GetStorageAddr(), addr);

    op::internal::OpExecCache *cache = executor->GetOpExecCache();
    op::internal::OpExecCacheWrap *cacheWrap = op::internal::CreateCacheWrap(cache);
    aclOpExecutor *fakeExecutor = reinterpret_cast<aclOpExecutor*>(cacheWrap);
    ret = aclSetAclOpExecutorRepeatable(fakeExecutor);
    EXPECT_EQ(ret, ACLNN_ERR_INNER);
    ret = aclDestroyAclOpExecutor(fakeExecutor);
    EXPECT_EQ(ret, ACL_SUCCESS);
    auto storageList = cache->GetStorageRelation();

    executor->FinalizeCache();

    ret = aclDestroyAclOpExecutor(executor);
    EXPECT_EQ(ret, ACL_SUCCESS);
    op::internal::GetThreadLocalContext().hashKey_ = 0;
    op::internal::GetThreadLocalContext().cacheHashKey_ = nullptr;
    op::internal::GetThreadLocalContext().cacheHashKeyLen_ = 0;
    op::internal::GetThreadLocalContext().cacheHasFull_ = oriCacheHasFull;
    op::internal::GetThreadLocalContext().cachedStorageList_.clear();
    aclDestroyTensor(input1);
    aclDestroyTensor(input2);
    delete ptr;
}

class RepeatRunDump : public Adx::DumpStub {
  public:
    uint64_t AdumpGetDumpSwitch(Adx::DumpType type) {
        return 0;
    }
};

TEST_F(AclOpApiTest, RepeatRunWithCache)
{
    bool oriCacheHasFull = op::internal::GetThreadLocalContext().cacheHasFull_;
    op::internal::GetThreadLocalContext().cacheHasFull_ = false;
    op::internal::GetThreadLocalContext().hashKey_ = 0;
    op::internal::GetThreadLocalContext().cacheHashKey_ = (uint8_t *)"hello1";
    op::internal::GetThreadLocalContext().cacheHashKeyLen_ = 6;

    RepeatRunDump dumpStub;
    Adx::DumpStub::GetInstance()->Install(&dumpStub);

    auto uniqueExecutor = CREATE_EXECUTOR();
    aclOpExecutor *executor = nullptr;
    uniqueExecutor.ReleaseTo(&executor);
    auto cache = executor->GetOpExecCache();
    ASSERT_NE(cache, nullptr);
    cache->SetUse();
    aclnnStatus ret = aclSetAclOpExecutorRepeatable(executor);
    EXPECT_EQ(ret, ACL_SUCCESS);
    ret = executor->RepeatRunWithCache(nullptr, nullptr);
    EXPECT_EQ(ret, ACL_SUCCESS);
    ret = aclDestroyAclOpExecutor(executor);
    EXPECT_EQ(ret, ACL_SUCCESS);

    Adx::DumpStub::GetInstance()->UnInstall();

    op::internal::GetThreadLocalContext().hashKey_ = 0;
    op::internal::GetThreadLocalContext().cacheHashKey_ = nullptr;
    op::internal::GetThreadLocalContext().cacheHashKeyLen_ = 0;
    op::internal::GetThreadLocalContext().cacheHasFull_ = oriCacheHasFull;
    op::internal::GetThreadLocalContext().cachedStorageList_.clear();
}

TEST_F(AclOpApiTest, RepeatRunWithCacheWithDFX)
{
    bool oriCacheHasFull = op::internal::GetThreadLocalContext().cacheHasFull_;
    op::internal::GetThreadLocalContext().cacheHasFull_ = false;
    op::internal::GetThreadLocalContext().hashKey_ = 0;
    op::internal::GetThreadLocalContext().cacheHashKey_ = (uint8_t *)"hello1";
    op::internal::GetThreadLocalContext().cacheHashKeyLen_ = 6;

    auto uniqueExecutor = CREATE_EXECUTOR();
    aclOpExecutor *executor = nullptr;
    uniqueExecutor.ReleaseTo(&executor);
    auto cache = executor->GetOpExecCache();
    ASSERT_NE(cache, nullptr);
    cache->SetUse();
    aclnnStatus ret = aclSetAclOpExecutorRepeatable(executor);
    EXPECT_EQ(ret, ACL_SUCCESS);
    ret = executor->RepeatRunWithCache(nullptr, nullptr);
    EXPECT_NE(ret, ACL_SUCCESS);
    ret = aclDestroyAclOpExecutor(executor);
    EXPECT_EQ(ret, ACL_SUCCESS);

    op::internal::GetThreadLocalContext().hashKey_ = 0;
    op::internal::GetThreadLocalContext().cacheHashKey_ = nullptr;
    op::internal::GetThreadLocalContext().cacheHashKeyLen_ = 0;
    op::internal::GetThreadLocalContext().cacheHasFull_ = oriCacheHasFull;
    op::internal::GetThreadLocalContext().cachedStorageList_.clear();
}

TEST_F(AclOpApiTest, DumpOpTensors)
{
    aclrtStream stream = (aclrtStream)0x1234;
    aclnnStatus ret = aclDumpOpTensors(nullptr, nullptr, nullptr, 0, 0, nullptr);
    EXPECT_EQ(ret, ACLNN_ERR_PARAM_NULLPTR);
    ret = aclDumpOpTensors("opType", nullptr, nullptr, 0, 0, nullptr);
    EXPECT_EQ(ret, ACLNN_ERR_PARAM_NULLPTR);
    ret = aclDumpOpTensors("opType", "opName", nullptr, 0, 0, stream);
    EXPECT_EQ(ret, ACLNN_ERR_PARAM_NULLPTR);
    std::vector<int64_t> shape = {1, 2, 3};
    aclTensor *input1 = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                        nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    aclTensor *input2 = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                        nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    aclTensor *output1 = aclCreateTensor(shape.data(), shape.size(), aclDataType::ACL_FLOAT,
                                         nullptr, 0, aclFormat::ACL_FORMAT_ND, shape.data(), shape.size(), nullptr);
    INIT_ACL_TENSOR_ARRAY(tensors, input1, input2, output1);
    EXPECT_EQ(ret, ACLNN_ERR_PARAM_NULLPTR);
    ret = aclDumpOpTensors("opType", "opName", tensors, 2, 1, stream);
    EXPECT_EQ(ret, ACLNN_SUCCESS);
    aclDestroyTensor(input1);
    aclDestroyTensor(input2);
    aclDestroyTensor(output1);
}