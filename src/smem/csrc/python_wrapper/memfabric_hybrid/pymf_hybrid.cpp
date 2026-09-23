/*
 * Copyright (c) Huawei Technologies Co., Ltd. 2025-2025. All rights reserved.
 * MemFabric_Hybrid is licensed under Mulan PSL v2.
 * You can use this software according to the terms and conditions of the Mulan PSL v2.
 * You may obtain a copy of Mulan PSL v2 at:
 *          http://license.coscl.org.cn/MulanPSL2
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND,
 * EITHER EXPRESS OR IMPLIED, INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT,
 * MERCHANTABILITY OR FIT FOR A PARTICULAR PURPOSE.
 * See the Mulan PSL v2 for more details.
*/
#pragma GCC diagnostic push
#pragma GCC diagnostic ignored "-Wmissing-field-initializers" // ignore pybind11 warning

#include <algorithm>
#include <iostream>
#include <Python.h>
#include <pybind11/pybind11.h>
#include <pybind11/pytypes.h>
#include <pybind11/stl.h>
#include <pybind11/functional.h>
#include <cstdint>
#include <cstddef>
#include <mutex>
#include <new>
#include <stdexcept>
#include <string>
#include "smem.h"
#include "smem_shm.h"
#include "smem_bm.h"
#include "smem_bm_sparse.h"
#include "smem_logger.h"
#include "smem_version.h"

namespace py = pybind11;

namespace {
class ShareMemory {
public:
    explicit ShareMemory(smem_shm_t hd, void *gva) noexcept : handle_{hd}, gvaAddress_{gva} {}
    virtual ~ShareMemory() noexcept
    {
        if (handle_ != nullptr) {
            smem_shm_destroy(handle_, 0);
            handle_ = nullptr;
        }
    }

    int32_t SetExternContext(const void *context, uint32_t size)
    {
        return smem_shm_set_extra_context(handle_, context, size);
    }

    uint32_t LocalRank() noexcept
    {
        return smem_shm_get_global_rank(handle_);
    }

    uint32_t RankSize() noexcept
    {
        return smem_shm_get_global_rank_size(handle_);
    }

    int32_t Barrier()
    {
        return smem_shm_control_barrier(handle_);
    }

    int32_t Destroy(uint32_t flags)
    {
        auto ret = smem_shm_destroy(handle_, flags);
        handle_ = nullptr;
        return ret;
    }

    int32_t AllGather(const char *sendBuf, uint32_t sendSize, char *recvBuf, uint32_t recvSize)
    {
        return smem_shm_control_allgather(handle_, sendBuf, sendSize, recvBuf, recvSize);
    }

    void *Address() const noexcept
    {
        return gvaAddress_;
    }

    static int Initialize(const std::string &storeURL, uint32_t worldSize, uint32_t rankId, uint16_t deviceId,
                          smem_shm_config_t &config) noexcept
    {
        return smem_shm_init(storeURL.c_str(), worldSize, rankId, deviceId, &config);
    }

    static void UnInitialize(uint32_t flags) noexcept
    {
        smem_shm_uninit(flags);
    }

    static ShareMemory *Create(uint32_t id, uint32_t rankSize, uint32_t rankId, uint64_t symmetricSize,
                               smem_shm_data_op_type dataOpType, uint32_t flags)
    {
        void *gva;
        auto handle = smem_shm_create(id, rankSize, rankId, symmetricSize, dataOpType, flags, &gva);
        if (handle == nullptr) {
            throw std::runtime_error("create shm failed!");
        }

        return new (std::nothrow) ShareMemory(handle, gva);
    }

    uint32_t QuerySupportDataOp() noexcept
    {
        return smem_shm_query_support_data_operation();
    }

    uint32_t TopologyCanReach(uint32_t remoteRank, uint32_t *reachInfo)
    {
        return smem_shm_topology_can_reach(handle_, remoteRank, reachInfo);
    }

private:
    smem_shm_t handle_;
    void *gvaAddress_;
};

class BigMemory {
public:
    explicit BigMemory(smem_bm_t hd) noexcept : handle_{hd} {}
    virtual ~BigMemory() noexcept
    {
        if (handle_ != nullptr) {
            smem_bm_destroy(handle_);
            handle_ = nullptr;
        }
    }

    int32_t Join(uint32_t flags)
    {
        return smem_bm_join(handle_, flags);
    }

    int32_t Leave(uint32_t flags)
    {
        return smem_bm_leave(handle_, flags);
    }

    uint64_t LocalMemSize(smem_bm_mem_type memType)
    {
        return smem_bm_get_local_mem_size_by_mem_type(handle_, memType);
    }

    uint64_t GetPtrByRank(uint32_t rankId, smem_bm_mem_type memType)
    {
        auto ptr = smem_bm_ptr_by_mem_type(handle_, memType, rankId);
        if (ptr == nullptr) {
            return 0;
        }

        return (uint64_t)(ptrdiff_t)ptr;
    }

    uint64_t GvaToVa(uintptr_t gva, smem_bm_mem_type memType)
    {
        void *va = nullptr;
        auto ret = smem_bm_gva_to_va(handle_, reinterpret_cast<void *>(gva), memType, &va);
        if (ret != 0) {
            return 0;
        }
        return (uint64_t)(ptrdiff_t)va;
    }

    void Destroy()
    {
        smem_bm_destroy(handle_);
        handle_ = nullptr;
    }

    int32_t PrepareHostRdmaSparse(uint64_t workspace, uint64_t workspaceBytes, uint32_t maxBlocks,
                                 uint64_t maxBlockBytes, uint32_t chunk, uint32_t timeoutMs,
                                 uint32_t gatherThreads, uint32_t scatterThreads)
    {
        smem_bm_host_rdma_sparse_options_t options{workspace, workspaceBytes, maxBlockBytes, maxBlocks,
                                                  chunk, timeoutMs, gatherThreads, scatterThreads};
        return smem_bm_prepare_host_rdma_sparse(handle_, &options);
    }

    int32_t PrepareHostRdmaSparseCase(const std::vector<uint64_t> &destinations, uint32_t count, uint64_t bytes)
    {
        if (!destinations.empty() && destinations.size() != count) {
            throw py::value_error("destination count does not match sparse case count");
        }
        return smem_bm_prepare_host_rdma_sparse_case(
            handle_, destinations.empty() ? nullptr : destinations.data(), count, bytes);
    }

    py::capsule NativeHandle() const
    {
        if (handle_ == nullptr) { throw std::runtime_error("BM has been destroyed"); }
        return py::capsule(handle_, "memfabric.smem_bm_t");
    }

    int32_t PollHostRdmaSparse(uint32_t timeoutMs)
    {
        return smem_bm_poll_host_rdma_sparse(handle_, timeoutMs);
    }

    int32_t CopyData(uint64_t src, uint64_t dest, uint64_t size, smem_bm_copy_type type, uint32_t flags,
                     uint64_t stream)
    {
        if (stream != 0) {
            flags |= SMEM_BM_FLAG_USE_EXTERNAL_STREAM;
        }
        smem_copy_params params = {(const void *)(ptrdiff_t)src, (void *)(ptrdiff_t)dest, size,
                                   reinterpret_cast<void *>(stream)};
        return smem_bm_copy(handle_, &params, type, flags);
    }

    int32_t CopyDataBatch(std::vector<uintptr_t> srcs, std::vector<uintptr_t> dsts, std::vector<size_t> sizes,
                          uint32_t count, smem_bm_copy_type type, uint32_t flags, uint64_t stream)
    {
        if (count == 0 || srcs.size() != count || dsts.size() != count || sizes.size() != count) {
            return SMEM_INVALID_PARAM;
        }
        void **ptr = new void *[count + count];
        if (ptr == nullptr) {
            throw std::runtime_error(std::string("alloc mem failed."));
        }

        if (stream != 0) {
            flags |= SMEM_BM_FLAG_USE_EXTERNAL_STREAM;
        }

        void **sources = ptr;
        void **destinations = ptr + count;
        for (uint64_t i = 0; i < count; ++i) {
            sources[i] = reinterpret_cast<void *>(srcs[i]);
            destinations[i] = reinterpret_cast<void *>(dsts[i]);
        }
        smem_batch_copy_params batch_params = {sources, destinations, sizes.data(), count,
                                               reinterpret_cast<void *>(stream), nullptr, nullptr, 0, 0};
        auto ret = smem_bm_copy_batch(handle_, &batch_params, type, flags);
        delete[] ptr;
        return ret;
    }

    int32_t CopyDataBatchWithProgress(std::vector<uintptr_t> srcs, std::vector<uintptr_t> dsts, std::vector<size_t> sizes,
                          uint32_t count, smem_bm_copy_type type, uint32_t flags, uint64_t stream,
                          uintptr_t progressSrc, uintptr_t progressDest, uint64_t progressBase,
                          uint32_t progressInterval)
    {
        if (count == 0 || srcs.size() != count || dsts.size() != count || sizes.size() != count) {
            SM_LOG_ERROR("invalid batch copy arrays, count: " << count);
            return SMEM_INVALID_PARAM;
        }
        if (progressSrc == 0 || progressDest == 0 || progressInterval == 0) {
            SM_LOG_ERROR("batch progress addresses and interval must be nonzero, count: " << count);
            return SMEM_INVALID_PARAM;
        }
        void **ptr = new void *[count + count];
        if (ptr == nullptr) {
            throw std::runtime_error(std::string("alloc mem failed."));
        }

        if (stream != 0) {
            flags |= SMEM_BM_FLAG_USE_EXTERNAL_STREAM;
        }

        void **sources = ptr;
        void **destinations = ptr + count;
        for (uint64_t i = 0; i < count; ++i) {
            sources[i] = reinterpret_cast<void *>(srcs[i]);
            destinations[i] = reinterpret_cast<void *>(dsts[i]);
        }
        smem_batch_copy_params batch_params = {sources, destinations, sizes.data(), count,
                                               reinterpret_cast<void *>(stream),
                                               reinterpret_cast<void *>(progressSrc),
                                               reinterpret_cast<void *>(progressDest), progressBase, progressInterval};
        auto ret = smem_bm_copy_batch(handle_, &batch_params, type, flags);
        delete[] ptr;
        return ret;
    }

    static int32_t Initialize(const std::string &storeURL, uint32_t worldSize, uint16_t deviceId,
                              const smem_bm_config_t &config) noexcept
    {
        worldSize_ = worldSize;
        return smem_bm_init(storeURL.c_str(), worldSize, deviceId, &config);
    }

    static void UnInitialize(uint32_t flags) noexcept
    {
        smem_bm_uninit(flags);
    }

    static uint32_t GetRankId() noexcept
    {
        return smem_bm_get_rank_id();
    }

    uint32_t GetRankIdByGva(uintptr_t gva) noexcept
    {
        void *gvaPtr = reinterpret_cast<void *>(gva);
        return smem_bm_get_rank_id_by_gva(handle_, gvaPtr);
    }

    static BigMemory *Create(uint32_t id, uint64_t localDRAMSize, uint64_t localHBMSize,
                             smem_bm_data_op_type dataOpType, uint32_t flags)
    {
        auto hd = smem_bm_create(id, worldSize_, dataOpType, localDRAMSize, localHBMSize, flags);
        if (hd == nullptr) {
            throw std::runtime_error(std::string("create bm handle failed."));
        }

        return new (std::nothrow) BigMemory{hd};
    }

    static BigMemory *Create2(uint32_t id, uint64_t localDRAMSize, uint64_t localMaxDRAMSize, uint64_t localHBMSize,
                              uint64_t localMaxHBMSize, smem_bm_data_op_type dataOpType, bool enable56BitsGva,
                              uint32_t flags, int shmFd, const std::string &tag, const std::string &tagOpInfo)
    {
        smem_bm_create_option_t option{};
        option.maxDramSize = localMaxDRAMSize;
        option.maxHbmSize = localMaxHBMSize;
        option.localDRAMSize = localDRAMSize;
        option.localHBMSize = localHBMSize;
        option.dataOpType = dataOpType;
        option.enable56BitsGva = enable56BitsGva;
        option.flags = flags;
        if (shmFd >= 0) {
            option.flags |= SMEM_BM_FLAG_CREATE_WITH_SHM;
            option.dramShmFd = shmFd;
        } else {
            option.flags &= (~SMEM_BM_FLAG_CREATE_WITH_SHM);
            option.dramShmFd = -1;
        }
        if (tag.size() >= sizeof(option.tag)) {
            SM_LOG_ERROR("BigMemory::Create2 tag is too long, id: " << id << " tag length: " << tag.size());
            throw std::invalid_argument("tag is too long");
        }
        if (tagOpInfo.size() >= sizeof(option.tagOpInfo)) {
            SM_LOG_ERROR("BigMemory::Create2 tagOpInfo is too long, id: " << id
                                                                          << " tagOpInfo length: " << tagOpInfo.size());
            throw std::invalid_argument("tag_op_info must not exceed 255 characters");
        }
        std::copy_n(tag.c_str(), tag.size() + 1U, option.tag);
        std::copy_n(tagOpInfo.c_str(), tagOpInfo.size() + 1U, option.tagOpInfo);

        auto hd = smem_bm_create2(id, &option);
        if (hd == nullptr) {
            throw std::runtime_error(std::string("create bm handle failed."));
        }

        return new (std::nothrow) BigMemory{hd};
    }

    int32_t ExtendLocalMem(smem_bm_mem_type memType, uint64_t size)
    {
        return smem_bm_extend_local_mem(handle_, memType, size);
    }

    int32_t RegisterMem(uint64_t addr, uint64_t size) noexcept
    {
        return smem_bm_register_user_mem(handle_, addr, size);
    }

    int32_t UnRegisterMem(uint64_t addr) noexcept
    {
        return smem_bm_unregister_user_mem(handle_, addr);
    }

    int32_t Wait()
    {
        return smem_bm_wait(handle_);
    }

private:
    smem_bm_t handle_;
    static uint32_t worldSize_;
};

uint32_t BigMemory::worldSize_;
struct LoggerState {
    static std::mutex mutex;
    static std::shared_ptr<py::function> py_logger;
};

std::mutex LoggerState::mutex;
std::shared_ptr<py::function> LoggerState::py_logger;

static void cpp_logger_adapter(int level, const char *msg)
{
    std::lock_guard<std::mutex> lock(LoggerState::mutex);

    if (!LoggerState::py_logger) {
        return;
    }

    py::gil_scoped_acquire acquire;
    if (Py_IsInitialized()) {
        (*(LoggerState::py_logger))(level, msg ? msg : "");
    }
}

static py::function g_py_decrypt_func;
static constexpr size_t MAX_CIPHER_LEN = 10 * 1024 * 1024;

static int py_decrypt_handler_wrapper(const char *cipherText, size_t cipherTextLen, char *plainText,
                                      size_t &plainTextLen)
{
    if (cipherText == nullptr || plainText == nullptr) {
        std::cerr << "py_decrypt_handler_wrapper: cipherText or plainText is null." << std::endl;
        return -1;
    }
    if (cipherTextLen > MAX_CIPHER_LEN || !g_py_decrypt_func || g_py_decrypt_func.is_none()) {
        std::cerr << "input cipher len is too long or decrypt func invalid." << std::endl;
        return -1;
    }
    std::string plain;
    try {
        py::str py_cipher = py::str(cipherText, cipherTextLen);
        plain = py::cast<std::string>(g_py_decrypt_func(py_cipher).cast<py::str>());
        if (plain.size() >= plainTextLen) {
            std::cerr << "output cipher len is too long" << std::endl;
            std::fill(plain.begin(), plain.end(), 0);
            return -1;
        }

        std::copy(plain.begin(), plain.end(), plainText);
        plainText[plain.size()] = '\0';
        plainTextLen = plain.size();
        std::fill(plain.begin(), plain.end(), 0);
        return 0;
    } catch (const py::error_already_set &e) {
        return -1;
    }
}

int32_t smem_set_conf_store_tls_key(std::string &tls_pk, std::string &tls_pk_pw, py::function py_decrypt_func)
{
    if (!py_decrypt_func || py_decrypt_func.is_none()) {
        return smem_set_config_store_tls_key(tls_pk.c_str(), tls_pk.size(), tls_pk_pw.c_str(), tls_pk_pw.size(),
                                             nullptr);
    }

    g_py_decrypt_func = py_decrypt_func;
    return smem_set_config_store_tls_key(tls_pk.c_str(), tls_pk.size(), tls_pk_pw.c_str(), tls_pk_pw.size(),
                                         py_decrypt_handler_wrapper);
}

int32_t smem_set_conf_store_tls_adapt(bool enable, std::string &tls_info)
{
    return smem_set_conf_store_tls(enable, tls_info.c_str(), tls_info.size());
}

void DefineSmemFunctions(py::module_ &m)
{
    m.def("initialize", &smem_init, py::call_guard<py::gil_scoped_release>(), py::arg("flags") = 0, R"(
Initialize the smem running environment.

Arguments:
    flags(int): optional flags, reserved
Returns:
    0 if successful
)");

    m.def("uninitialize", &smem_uninit, py::call_guard<py::gil_scoped_release>(), R"(
Un-Initialize the smem running environment)");

    m.def("set_log_level", &smem_set_log_level, py::call_guard<py::gil_scoped_release>(), py::arg("level"), R"(
set log print level.

Arguments:
    level(int): log level, 0:debug 1:info 2:warn 3:error)");
    m.def(
        "set_extern_logger",
        [](py::function log_fn) {
            if (!log_fn || log_fn.is_none()) {
                std::lock_guard<std::mutex> lock(LoggerState::mutex);
                LoggerState::py_logger.reset();
                auto ret = smem_set_extern_logger(nullptr);
                return ret;
            }

            {
                std::lock_guard<std::mutex> lock(LoggerState::mutex);
                LoggerState::py_logger = std::make_shared<py::function>(log_fn);
            }

            auto ret = smem_set_extern_logger(cpp_logger_adapter);
            if (ret != 0) {
                throw std::runtime_error("Failed to set logger");
            }
            return ret;
        },
        py::call_guard<py::gil_scoped_release>(), py::arg("log_fn"), R"(
Set external logger callback function

Parameters:
    log_fn (callable): Python function that accepts (int level, str message)
        level: log level
        message: log content
Returns:
    0 if successful
)");

    m.add_object("_cleanup_capsule", py::capsule([]() { LoggerState::py_logger.reset(); }));

    m.def("get_last_err_msg", &smem_get_last_err_msg, py::call_guard<py::gil_scoped_release>(), R"(
Get last error message.
Returns:
    error message string
)");

    m.def("get_and_clear_last_err_msg", &smem_get_and_clear_last_err_msg, py::call_guard<py::gil_scoped_release>(), R"(
Get and clear all error message.
Returns:
    error message string
)");

    m.def("set_conf_store_tls_key", &smem_set_conf_store_tls_key, py::call_guard<py::gil_scoped_release>(),
          py::arg("tls_pk"), py::arg("tls_pk_pw"), py::arg("py_decrypt_func"), R"(
Register a Python decrypt handler.
Parameters:
    tls_pk (string): the content of tls private key string
    tls_pk_pw (string): the content of tls private key password string
    py_decrypt_func (callable): Python function that accepts (str cipher_text) and returns (str plain_text)
        cipher_text: the encrypted text (private key password)
        plain_text: the decrypted text (private key password)
Returns:
    None
)");

    m.def("set_conf_store_tls", &smem_set_conf_store_tls_adapt, py::call_guard<py::gil_scoped_release>(),
          py::arg("enable"), py::arg("tls_info"), R"(
set the config store tls info.
Parameters:
    enable (boolean): enable config store tls or not
        tls_info (string): tls config string
Returns:
    returns zero on success. On error, none-zero is returned.
)");

    m.doc() = LIB_VERSION;
}

void DefineShmConfig(py::module_ &m)
{
    py::class_<smem_shm_config_t>(m, "ShmConfig")
        .def(py::init([]() {
                 auto config = new (std::nothrow) smem_shm_config_t;
                 smem_shm_config_init(config);
                 return config;
             }),
             py::call_guard<py::gil_scoped_release>())
        .def_readwrite("init_timeout", &smem_shm_config_t::shmInitTimeout, R"(
func smem_shm_init timeout, default 120 second.)")
        .def_readwrite("create_timeout", &smem_shm_config_t::shmCreateTimeout, R"(
func smem_shm_create timeout, default 120 second)")
        .def_readwrite("operation_timeout", &smem_shm_config_t::controlOperationTimeout, R"(
control operation timeout, i.e. barrier, allgather, topology_can_reach etc, default 120 second)")
        .def_readwrite("start_store", &smem_shm_config_t::startConfigStoreServer, R"(
whether to start config store, default true)")
        .def_readwrite("flags", &smem_shm_config_t::flags, "other flags, default 0");
}

void DefineBmConfig(py::module_ &m)
{
    py::enum_<smem_bm_mem_type>(m, "BmMemType")
        .value("LOCAL_DEVICE", SMEM_MEM_TYPE_LOCAL_DEVICE, "memory type is on local DEVICE side.")
        .value("LOCAL_HOST", SMEM_MEM_TYPE_LOCAL_HOST, "memory type is on local HOST side.")
        .value("DEVICE", SMEM_MEM_TYPE_DEVICE, "memory type is on global DEVICE side.")
        .value("HOST", SMEM_MEM_TYPE_HOST, "memory type is on global HOST side.");

    py::enum_<smem_bm_group_event_t>(m, "BmGroupEvent")
        .value("JOIN_EVENT", SMEM_GROUP_EVENT_JOIN)
        .value("LEAVE_EVENT", SMEM_GROUP_EVENT_LEAVE);

    py::enum_<smem_bm_copy_type>(m, "BmCopyType")
        .value("L2G", SMEMB_COPY_L2G, "copy data from local hbm to global space")
        .value("G2L", SMEMB_COPY_G2L, "copy data from global space to local hbm")
        .value("G2H", SMEMB_COPY_G2H, "copy data from global space to host memory")
        .value("H2G", SMEMB_COPY_H2G, "copy data from host memory to global space")
        .value("L2GH", SMEMB_COPY_L2GH, "copy data from local hbm to global host space")
        .value("GH2L", SMEMB_COPY_GH2L, "copy data from global host space to local hbm")
        .value("GH2H", SMEMB_COPY_GH2H, "copy data from global host space to host memory")
        .value("H2GH", SMEMB_COPY_H2GH, "copy data from host memory to global host space")
        .value("G2G", SMEMB_COPY_G2G, "copy data from global space to global space")
        .value("AUTO", SMEMB_COPY_AUTO,
               "copy data automatically based on the memory type of the source and destination");

    py::class_<smem_bm_config_t>(m, "BmConfig")
        .def(py::init([]() {
                 auto config = new (std::nothrow) smem_bm_config_t;
                 smem_bm_config_init(config);
                 return config;
             }),
             py::call_guard<py::gil_scoped_release>())
        .def_readwrite("init_timeout", &smem_bm_config_t::initTimeout, R"(
func smem_bm_init timeout, default 120 second)")
        .def_readwrite("create_timeout", &smem_bm_config_t::createTimeout, R"(
func smem_bm_create timeout, default 120 second)")
        .def_readwrite("operation_timeout", &smem_bm_config_t::controlOperationTimeout, R"(
control operation timeout, default 120 second)")
        .def_readwrite("start_store", &smem_bm_config_t::startConfigStoreServer, R"(
whether to start config store, default true)")
        .def_readwrite("start_store_only", &smem_bm_config_t::startConfigStoreOnly, "only start the config store")
        .def_readwrite("dynamic_world_size", &smem_bm_config_t::dynamicWorldSize, "member cannot join dynamically")
        .def_readwrite("unified_address_space", &smem_bm_config_t::unifiedAddressSpace, "unified address with SVM")
        .def_readwrite("auto_ranking", &smem_bm_config_t::autoRanking, R"(
automatically allocate rank IDs, default is false)")
        .def_readwrite("rank_id", &smem_bm_config_t::rankId, "user specified rank ID, valid for autoRanking is False")
        .def_readwrite("flags", &smem_bm_config_t::flags, "other flags, default 0")
        .def(
            "set_nic",
            [](smem_bm_config_t &config, const std::string &nic) {
                strncpy(config.hcomUrl, nic.c_str(), sizeof(config.hcomUrl) - 1);
                config.hcomUrl[sizeof(config.hcomUrl) - 1] = '\0';
            },
            py::call_guard<py::gil_scoped_release>(), py::arg("nic"));
}

void DefineShmClass(py::module_ &m)
{
    py::enum_<smem_shm_data_op_type>(m, "ShmDataOpType")
        .value("MTE", SMEMS_DATA_OP_MTE)
        .value("SDMA", SMEMS_DATA_OP_SDMA)
        .value("RDMA", SMEMS_DATA_OP_RDMA);

    m.def("initialize", &ShareMemory::Initialize, py::call_guard<py::gil_scoped_release>(), py::arg("store_url"),
          py::arg("world_size"), py::arg("rank_id"), py::arg("device_id"), py::arg("config"));
    m.def("uninitialize", &ShareMemory::UnInitialize, py::call_guard<py::gil_scoped_release>(), py::arg("flags") = 0);
    m.def("create", &ShareMemory::Create, py::call_guard<py::gil_scoped_release>(), py::arg("id"), py::arg("rank_size"),
          py::arg("rank_id"), py::arg("local_mem_size"), py::arg("data_op_type") = SMEMS_DATA_OP_MTE,
          py::arg("flags") = 0);

    py::class_<ShareMemory>(m, "ShareMemory")
        .def(
            "set_context",
            [](ShareMemory &shm, py::bytes data) {
                auto str = py::bytes(data).cast<std::string>();
                shm.SetExternContext(str.data(), str.size());
            },
            py::call_guard<py::gil_scoped_release>(), py::arg("context"), R"(
Set user extra context of shm object.

Arguments:
    context(bytes): extra context
Returns:
    0 if successful)")
        .def_property_readonly("local_rank",
                               py::cpp_function(&ShareMemory::LocalRank, py::call_guard<py::gil_scoped_release>()), R"(
Get local rank of a shm object)")
        .def_property_readonly("rank_size",
                               py::cpp_function(&ShareMemory::RankSize, py::call_guard<py::gil_scoped_release>()), R"(
Get rank size of a shm object)")
        .def("destroy", &ShareMemory::Destroy, py::call_guard<py::gil_scoped_release>(), py::arg("flags") = 0, R"(
Destroy the shm handle.)")
        .def("query_support_data_operation", &ShareMemory::QuerySupportDataOp, py::call_guard<py::gil_scoped_release>(),
             R"(
Get supported data operations)")
        .def("barrier", &ShareMemory::Barrier, py::call_guard<py::gil_scoped_release>(), R"(
Do barrier on a shm object, using control network.)")
        .def(
            "all_gather",
            [](ShareMemory &shm, py::bytes data) {
                auto str = py::bytes(data).cast<std::string>();
                auto outputSize = str.size() * shm.RankSize();
                std::string output;
                output.resize(outputSize);
                shm.AllGather(str.c_str(), str.size(), const_cast<char *>(output.data()), outputSize);
                return py::bytes(output.c_str(), outputSize);
            },
            py::call_guard<py::gil_scoped_release>(), py::arg("local_data"), R"(
Do all gather on a shm object, using control network

Arguments:
    local_data(bytes): input data
Returns:
    output data)")
        .def(
            "topology_can_reach",
            [](ShareMemory &shm, uint32_t remote_rank, uint32_t reach_info) {
                return shm.TopologyCanReach(remote_rank, &reach_info);
            },
            py::call_guard<py::gil_scoped_release>(), py::arg("remote_rank"), py::arg("reach_info"), R"(
Query the topology reachability to a remote rank

Arguments:
    remote_rank (int): Target rank ID to check
    reach_info (int): Reachability information
Returns:
    int: 0 if successful)")
        .def_property_readonly(
            "gva",
            py::cpp_function([](const ShareMemory &shm) { return (uint64_t)(ptrdiff_t)shm.Address(); },
                             py::call_guard<py::gil_scoped_release>()),
            R"(
get global virtual address created, it can be passed to kernel to data operations)");
}

void DefineBmClass(py::module_ &m)
{
    py::enum_<smem_bm_data_op_type>(m, "BmDataOpType")
        .value("SDMA", SMEMB_DATA_OP_SDMA)
        .value("HOST_RDMA", SMEMB_DATA_OP_HOST_RDMA)
        .value("HOST_URMA", SMEMB_DATA_OP_HOST_URMA)
        .value("HOST_TCP", SMEMB_DATA_OP_HOST_TCP)
        .value("DEVICE_RDMA", SMEMB_DATA_OP_DEVICE_RDMA)
        .value("DEVICE_URMA", SMEMB_DATA_OP_DEVICE_URMA)
        .value("DEVICE_UBOE", SMEMB_DATA_OP_DEVICE_UBOE)
        .value("HOST_SHM", SMEMB_DATA_OP_HOST_SHM);

    // module method
    m.def("initialize", &BigMemory::Initialize, py::call_guard<py::gil_scoped_release>(), py::arg("store_url"),
          py::arg("world_size"), py::arg("device_id"), py::arg("config"), R"(
Initialize smem big memory library.

Arguments:
    store_url(str):   configure store url for control, e.g. tcp://ip:port or tcp://[ip]:port
    world_size(int):  number of guys participating
    device_id(int):   device id
    config(BmConfig): extract config
Returns:
    0 if successful)");

    m.def("uninitialize", &BigMemory::UnInitialize, py::call_guard<py::gil_scoped_release>(), py::arg("flags") = 0, R"(
Un-initialize the smem big memory library.

Arguments:
    flags(int): optional flags, not used yet)");

    m.def("bm_rank_id", &BigMemory::GetRankId, py::call_guard<py::gil_scoped_release>(), R"(
Get the rank id, assigned during initialize.
Returns:
    rank id if successful, UINT32_MAX is returned if failed.)");

    m.def(
        "update_store_url", [](const std::string &storeURL) { return smem_bm_update_store_url(storeURL.c_str()); },
        py::call_guard<py::gil_scoped_release>(), py::arg("store_url"), R"(
Update the config store URL after smem_bm_init, used when MetaService restarts with a new IP.

Arguments:
    store_url(str): new configure store url, e.g. tcp://ip:port
Returns:
    0 if successful, negative value for error)");

    m.def("create", &BigMemory::Create, py::call_guard<py::gil_scoped_release>(), py::arg("id"),
          py::arg("local_dram_size"), py::arg("local_hbm_size") = 0, py::arg("data_op_type") = SMEMB_DATA_OP_SDMA,
          py::arg("flags") = 0, R"(
Create a big memory object locally after initialized.

Arguments:
    id(int):                     identity of the big memory object
    local_dram_size(int):        the size of local dram memory contributes to big memory object
    max_dram_size(int):          the max size of all rank DRAM memory contributes to Big Memory object
    local_hbm_size(int):         the size of local hbm memory contributes to big memory object, default 0
    max_hbm_size(int):           the max size of all rank HBM memory contributes to Big Memory object
    data_op_type(BmDataOpType):  data operation type, default SMEMB_DATA_OP_SDMA
    flags(int):                  optional flags, default 0
    shm_fd(int):                 gva used share memory dile descriptor, default -1)");

    m.def("create2", &BigMemory::Create2, py::call_guard<py::gil_scoped_release>(), py::arg("id"),
          py::arg("local_dram_size"), py::arg("max_dram_size"), py::arg("local_hbm_size") = 0,
          py::arg("max_hbm_size") = 0, py::arg("data_op_type") = SMEMB_DATA_OP_SDMA,
          py::arg("enable_56bits_gva") = false, py::arg("flags") = 0, py::arg("shm_fd") = -1, py::arg("tag") = "",
          py::arg("tag_op_info") = "", R"(
Create a big memory object locally after initialized.

Arguments:
    id(int):                     identity of the big memory object
    local_dram_size(int):        the size of local dram memory contributes to big memory object
    max_dram_size(int):          the max local dram memory size for dynamic expansion
    local_hbm_size(int):         the size of local hbm memory contributes to big memory object, default 0
    max_hbm_size(int):           the max local hbm memory size for dynamic expansion, default 0
    data_op_type(BmDataOpType):  data operation type, default SMEMB_DATA_OP_SDMA
    enable_56bits_gva(bool):     explicitly enable 56-bit GVA, default false.
                                 When (max_dram_size + max_hbm_size) * world_size > 32TB,
                                 this must be true; memfabric_hybrid does not auto-enable it.
                                 Effective max usable capacity remains 128TB.
    flags(int):                  optional flags, default 0
    shm_fd(int):                 gva shared-memory file descriptor, default -1
    tag(str):                    tag of the current rank, default ""
    tag_op_info(str):            data operation routes between tags, default "")");

    // big memory class
    py::class_<BigMemory>(m, "BigMemory")
        .def("join", &BigMemory::Join, py::call_guard<py::gil_scoped_release>(), py::arg("flags") = 0, R"(
Join to global Big Memory space actively, after this, we operate on the global space.

Arguments:
    flags(int): optional flags)")
        .def("leave", &BigMemory::Leave, py::call_guard<py::gil_scoped_release>(), py::arg("flags") = 0, R"(
Leave the global Big Memory space actively, after this, we cannot operate on the global space any more.

Arguments:
    flags(int): optional flags)")
        .def("extend_local_mem", &BigMemory::ExtendLocalMem, py::call_guard<py::gil_scoped_release>(),
             py::arg("mem_type") = SMEM_MEM_TYPE_HOST, py::arg("size"), R"(
Alloc an extend memory for rank, all alloc memory must range in reserved memory.

Arguments:
    mem_type(BmMemType): memory type, DEVICE or HOST, default is HOST
    size(int): extend memory size)")
        .def("local_mem_size", &BigMemory::LocalMemSize, py::call_guard<py::gil_scoped_release>(),
             py::arg("mem_type") = SMEM_MEM_TYPE_DEVICE, R"(
Get size of local memory that contributed to global space.

Arguments:
    mem_type(BmMemType): memory type, DEVICE or HOST, default is DEVICE
Returns:
    local memory size in bytes)")
        .def("peer_rank_ptr", &BigMemory::GetPtrByRank, py::call_guard<py::gil_scoped_release>(), py::arg("peer_rank"),
             py::arg("mem_type") = SMEM_MEM_TYPE_DEVICE,
             R"(
Get peer gva by rank id.

Arguments:
    peer_rank(int): rank id of peer
    mem_type(BmMemType): memory type, DEVICE or HOST, default is DEVICE
Returns:
    ptr of peer gva)")
        .def("gva_to_va", &BigMemory::GvaToVa, py::call_guard<py::gil_scoped_release>(), py::arg("gva"),
             py::arg("mem_type") = SMEM_MEM_TYPE_LOCAL_HOST,
             R"(
    Convert GVA (Global Virtual Address) to VA (Virtual Address).

    Arguments:
        gva(int): Global Virtual Address to convert
        mem_type(BmMemType): memory type, LOCAL_DEVICE or LOCAL_HOST, default is LOCAL_HOST
    Returns:
        Converted Virtual Address, 0 if failed)")
        .def("destroy", &BigMemory::Destroy, py::call_guard<py::gil_scoped_release>(), R"(
Destroy the big memory handle.)")
        .def_property_readonly("_native_handle", &BigMemory::NativeHandle)
        .def("prepare_host_rdma_sparse_case", &BigMemory::PrepareHostRdmaSparseCase,
             py::call_guard<py::gil_scoped_release>(), py::arg("dst_addrs"), py::arg("count"), py::arg("block_bytes"))
        .def("prepare_host_rdma_sparse", &BigMemory::PrepareHostRdmaSparse,
             py::call_guard<py::gil_scoped_release>(), py::arg("workspace_gva"), py::arg("workspace_bytes"),
             py::arg("max_blocks"), py::arg("max_block_bytes"), py::kw_only(), py::arg("progress_interval") = 128,
             py::arg("timeout_ms") = 30000, py::arg("gather_threads") = 16, py::arg("scatter_threads") = 6,
             R"(Collective preparation on both joined HOST_RDMA BM ranks. Rank 0 requests, rank 1 explicitly polls.
Reserve exclusive, 64-byte-aligned BM DRAM workspace at the same offset on both ranks.
MF_HOST_RDMA_SPARSE_MODE selects baseline/cont/gather, fixed until BM destruction.
Call once per BM. Creates no polling thread. No offload.initialize or NPU required. Returns 0 on success.
Synchronize peers after the final copy before destroying the BM.)")
        .def("poll_host_rdma_sparse", &BigMemory::PollHostRdmaSparse,
             py::call_guard<py::gil_scoped_release>(), py::arg("timeout_ms") = 0,
             R"(On prepared rank 1, process at most one sparse request on the calling thread.
Returns 1 if processed, 0 if idle, negative on error. timeout_ms=0 checks once;
positive values busy-poll with yield for at most timeout_ms while waiting for a request.
The timeout does not interrupt a request already being processed. Creates no thread.)")
        .def("get_rank_id_by_gva", &BigMemory::GetRankIdByGva, py::call_guard<py::gil_scoped_release>(), py::arg("gva"),
             R"(Get rank id of gva that belongs to.)")
        .def("register", &BigMemory::RegisterMem, py::call_guard<py::gil_scoped_release>(), py::arg("addr"),
             py::arg("size"), R"(
register user mem.)")
        .def("unregister", &BigMemory::UnRegisterMem, py::call_guard<py::gil_scoped_release>(), py::arg("addr"), R"(
unregister user mem.)")
        .def("copy_data", &BigMemory::CopyData, py::call_guard<py::gil_scoped_release>(), py::arg("src_ptr"),
             py::arg("dst_ptr"), py::arg("size"), py::arg("type"), py::arg("flags") = 0, py::arg("stream") = 0, R"(
Data operation on Big Memory object.

Arguments:
    src_ptr(int): source gva of data
    dst_ptr(int): destination gva of data
    size(int): size of data to be copied
    type(BmCopyType): copy type, L2G, G2L, G2H, H2G, G2G
    flags(int): optional flags
    stream(int): acl rt stream, default 0
Returns:
    0 if successful)")
        .def("copy_data_batch", &BigMemory::CopyDataBatch, py::call_guard<py::gil_scoped_release>(),
             py::arg("src_addrs"), py::arg("dst_addrs"), py::arg("sizes"), py::arg("count"), py::arg("type"),
             py::arg("flags") = 0, py::arg("stream") = 0, R"(cop data with batch.)")
        .def("copy_data_batch_with_progress", &BigMemory::CopyDataBatchWithProgress, py::call_guard<py::gil_scoped_release>(),
             py::arg("src_addrs"), py::arg("dst_addrs"), py::arg("sizes"), py::arg("count"), py::arg("type"),
             py::arg("flags") = 0, py::arg("stream") = 0, py::kw_only(), py::arg("progress_src"),
             py::arg("progress_dest"), py::arg("progress_base") = 0, py::arg("progress_interval"),
             R"(Copy a HOST_RDMA batch with progress notifications. Arguments match smem_batch_copy_params:
progress_src is registered local storage; progress_dest is the peer watermark array GVA.
For K links, reserve ceil(count / progress_interval) * K uint64 slots at progress_src
(count * K slots is always sufficient), and K uint64 slots at progress_dest.
Keep both allocations alive until synchronous completion. Addresses and progress_interval must be nonzero.
Watermarks are progress_base plus the completed global element index for each link.)")
        .def("wait", &BigMemory::Wait, py::call_guard<py::gil_scoped_release>(), R"(
Wait all issued async copy(s) finish.)")
        .def(
            // clang-format off
        "set_group_event_handler",
        [](BigMemory &self, const std::function<void(uint32_t, smem_bm_group_event_t)> &cb) {
            (void)self;
            (void)cb;
            PyErr_WarnEx(PyExc_DeprecationWarning,
                         "BigMemory.set_group_event_handler is deprecated. "
                         "Group events are now handled by the server-driven async scheme. "
                         "The callback will never be invoked.",
                         1);
        },
            // clang-format on
            R"(Set group event handler (DEPRECATED — no-op, callback is never invoked).)");
}
} // namespace

PYBIND11_MODULE(_pymf_hybrid, m)
{
    DefineSmemFunctions(m);

    auto shm = m.def_submodule("shm", "Share Memory Module.");
    auto bm = m.def_submodule("bm", "Big Memory Module.");

    DefineShmConfig(shm);
    DefineShmClass(shm);

    DefineBmConfig(bm);
    DefineBmClass(bm);
    bm.def("host_rdma_sparse_workspace_size", &smem_bm_host_rdma_sparse_workspace_size,
           py::arg("max_blocks"), py::arg("max_block_bytes"), py::arg("links") = 1,
           py::arg("progress_interval") = 128,
           R"(Return required workspace bytes, or 0 for invalid dimensions. Does not allocate memory.)");

}

#pragma GCC diagnostic pop
