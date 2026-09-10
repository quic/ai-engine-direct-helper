//==============================================================================
//
// Copyright (c) 2023, Qualcomm Innovation Center, Inc. All rights reserved.
// 
// SPDX-License-Identifier: BSD-3-Clause
//
//==============================================================================
#pragma once

#include <memory>
#include <queue>
#include <map>
#include <atomic>
#include <condition_variable>
#include <mutex>
#include "IOTensor.hpp"
#include "DynamicLoadUtil.hpp"
#include "Lora.hpp"

// zw: For supporting BackendExtensions.
#include "HTP/QnnHtpPerfInfrastructure.h"
#include "HTP/QnnHtpDevice.h"


#include "QnnDevice.h"
#ifdef __linux__
#include <unistd.h>  // issue#97: pid_t for fork-safety guard
#endif

bool disableDcvs(QnnHtpDevice_PerfInfrastructure_t perfInfra, const std::vector<uint32_t>& contextIds);
bool enableDcvs(QnnHtpDevice_PerfInfrastructure_t perfInfra, const std::vector<uint32_t>& contextIds);
bool boostPerformance(QnnHtpDevice_PerfInfrastructure_t perfInfra, std::string perfProfile,
                       const std::vector<uint32_t>& contextIds);
bool resetPerformance(QnnHtpDevice_PerfInfrastructure_t perfInfra, const std::vector<uint32_t>& contextIds);
uint32_t getPowerConfigId();
std::vector<uint32_t> getAllPowerConfigIds();

namespace qnn {
namespace tools {
namespace qnn_app {

struct RunTimeAppKeys {
    std::string backendLibKey{ "NetRunBackendLibKeyDefault" };
    std::string backendHandlerKey{ "NetRunBackendHandlerDefault" };
    std::string modelLibKey{ "NetRunModelKeyDefault" };
    std::string loggerKey{ "NetRunLoggerKeyDefault" };
    std::string deviceKey{ "NetRunDeviceKeyDefault" };
    std::string contextKey{ "NetRunContextKeyDefault" };
};

enum class StatusCode {
  SUCCESS,
  FAILURE,
  FAILURE_INPUT_LIST_EXHAUSTED,
  FAILURE_SYSTEM_ERROR,
  FAILURE_SYSTEM_COMMUNICATION_ERROR,
  QNN_FEATURE_UNSUPPORTED
};

struct MultiCoreDeviceConfig_t {
  uint32_t deviceId{0};
  std::vector<uint32_t> coreIdVec{};
  const uint32_t coreType{0}; /* default to QNN_HTP_CORE_TYPE_NSP */
};
class QnnInferenceEngine {
 public:
  QnnInferenceEngine(QnnFunctionPointers qnnFunctionPointers,
               std::string inputListPaths,
               std::string opPackagePaths,
               void *backendHandle,
               std::string outputPath                  = s_defaultOutputPath,
               bool debug                              = false,
               iotensor::OutputDataType outputDataType = iotensor::OutputDataType::FLOAT_ONLY,
               iotensor::InputDataType inputDataType   = iotensor::InputDataType::FLOAT,
               ProfilingLevel profilingLevel           = ProfilingLevel::OFF,
               bool dumpOutputs                        = false,
               std::string cachedBinaryPath            = "",
               std::string saveBinaryName              = "",
               const std::vector<LoraAdapter>& lora_adapters = std::vector<LoraAdapter>(),
			    std::string dlcPath                     = "",
				MultiCoreDeviceConfig_t multiCoreDeviceConfig = {});

  // @brief Print a message to STDERR then return a nonzero
  //  exit status.
  int32_t reportError(const std::string &err);

  StatusCode initialize();

  StatusCode initializeBackend();

  StatusCode createContext();

  StatusCode composeGraphs();

  StatusCode finalizeGraphs();

  StatusCode executeGraphs();

  StatusCode registerOpPackages();

  StatusCode createFromBinary();

  StatusCode saveBinary();

  StatusCode freeContext();

  StatusCode terminateBackend();

  StatusCode freeGraphs();  // zw.
  StatusCode initializeProfiling();

  std::string getBackendBuildId();

  StatusCode isDevicePropertySupported();

  StatusCode isFinalizeDeserializedGraphSupported();

  StatusCode createDevice();

  StatusCode contextApplyBinarySection(QnnContext_SectionType_t section);
  bool binaryUpdates();
  void update_m_lora_adapters(std::vector<LoraAdapter>& lora_adapters);

  StatusCode applyBinarySection(
      std::string graphName,
      std::string binaryPath,
      QnnContext_SectionType_t sectionType,
      bool useMmap,
      ProfilingLevel profilingLevel,
      ProfilingOption profilingOption);

  StatusCode initializeProfileHandle(
      const QNN_INTERFACE_VER_TYPE* qnnInterfaceHandle,
      ProfilingLevel profilingLevel,
      Qnn_ProfileHandle_t* profileHandle,
      const uint64_t numMaxEvents);

  StatusCode initializeProfileConfigOption(
      const QNN_INTERFACE_VER_TYPE* qnnInterfaceHandle,
      ProfilingOption profilingOption,
      Qnn_ProfileHandle_t profileHandle);

  StatusCode terminateProfileHandle(
      const QNN_INTERFACE_VER_TYPE* qnnInterfaceHandle, Qnn_ProfileHandle_t profileHandle);

  StatusCode addGraphsToContext(
      qnn_wrapper_api::GraphInfo_t** graphInfos, uint32_t numGraphs);

  StatusCode addGraphToContext(
      qnn_wrapper_api::GraphInfo_t* graphInfo);

  StatusCode freeDevice();

  StatusCode verifyFailReturnStatus(Qnn_ErrorHandle_t errCode);

// improve performance.
  StatusCode setupInputAndOutputTensors();
  StatusCode tearDownInputAndOutputTensors();

// zw.
  StatusCode executeGraphsBuffers(std::vector<uint8_t*>& inputBuffers,
                                  std::vector<uint8_t*>& outputBuffers, std::vector<size_t>& outputSize,
                                  std::string perfProfile, size_t graphIndex = 0, size_t share_memory_size = 0);
  // issue#24
  std::vector<std::vector<size_t>> getInputShapes(size_t graphIdx = 0);
  std::vector<std::string> getInputDataType(size_t graphIdx = 0);
  std::vector<std::vector<size_t>> getOutputShapes(size_t graphIdx = 0);
  std::vector<std::string> getOutputDataType(size_t graphIdx = 0);
  std::string getGraphName(size_t graphIdx = 0);
  std::vector<std::string> getInputName(size_t graphIdx = 0);
  std::vector<std::string> getOutputName(size_t graphIdx = 0);
  uint64_t getProfilingEvent(uint32_t eventType);
  qnn_wrapper_api::GraphInfo_t **m_graphsInfo{nullptr};
  uint32_t m_graphsCount{0};


  StatusCode initializeLog();
  StatusCode setLogLevel(QnnLog_Level_t logLevel);

  void setIsGpu(bool isGpu) { m_isGpu = isGpu; }
  void setIsCpu(bool isCpu) { m_runInCpu = isCpu; }
  void setEnabledGraphs(const std::vector<std::string>& graphNames) { m_enabledGraphs = graphNames; }

  StatusCode initializePerformance();
  StatusCode destroyPerformance();

  /// Unified, idempotent teardown.  Releases all QNN resources in the
  /// correct dependency order (tensors → performance → graphs → context →
  /// device → profile → backend → log → DLC).  Safe to call multiple
  /// times — only the first call does work.  The destructor delegates to
  /// this, so explicit callers and the destructor share ONE code path,
  /// eliminating double-free risks.
  StatusCode shutdown() noexcept;

  virtual ~QnnInferenceEngine() noexcept;

 private:
  StatusCode extractBackendProfilingInfo(Qnn_ProfileHandle_t profileHandle);

  StatusCode extractProfilingSubEvents(QnnProfile_EventId_t profileEventId);

  StatusCode extractProfilingEvent(QnnProfile_EventId_t profileEventId);

  StatusCode composeGraphsFromDlc();
  StatusCode getDevicePlatformInfo(const QnnDevice_PlatformInfo_t *&platformInfoPtr);
  StatusCode setupDeviceConfig(QnnDevice_Config_t* devConfigPtr, MultiCoreDeviceConfig_t* multicoreConfigPtr);
  StatusCode setupContextConfigs();
  static const std::string s_defaultOutputPath;

  QnnFunctionPointers m_qnnFunctionPointers;
  std::vector<std::string> m_inputListPaths;
  std::vector<std::vector<std::vector<std::string>>> m_inputFileLists;
  std::vector<std::unordered_map<std::string, uint32_t>> m_inputNameToIndex;
  std::vector<std::string> m_opPackagePaths;
  std::string m_outputPath;
  std::string m_saveBinaryName;
  std::string m_cachedBinaryPath;

  std::vector<LoraAdapter> m_lora_adapters;

  QnnBackend_Config_t **m_backendConfig = nullptr;
  Qnn_ContextHandle_t m_context         = nullptr;
  QnnContext_Config_t **m_contextConfig = nullptr;
  std::vector<std::string> m_enabledGraphs;
  std::vector<int> m_enabledGraphIndex;
  // Memory needs to be maintained.
  std::vector<const char *> m_enabledGraphCstr;
  QnnContext_Config_t m_enabledGraphsCfg;
  std::vector<QnnContext_Config_t *> m_contextConfigPtrs;
  bool m_debug;
  iotensor::OutputDataType m_outputDataType;
  iotensor::InputDataType m_inputDataType;
  ProfilingLevel m_profilingLevel;
  bool m_dumpOutputs;
  //qnn_wrapper_api::GraphInfo_t **m_graphsInfo;
  //uint32_t m_graphsCount;
  iotensor::IOTensor m_ioTensor;
  bool m_isBackendInitialized;
  bool m_isContextCreated;
  Qnn_ProfileHandle_t m_profileBackendHandle              = nullptr;
  qnn_wrapper_api::GraphConfigInfo_t **m_graphConfigsInfo = nullptr;
  uint32_t m_graphConfigsInfoCount;
  Qnn_LogHandle_t m_logHandle         = nullptr;
  Qnn_BackendHandle_t m_backendHandle = nullptr;
  // INTENTIONAL process-wide shared handle.  `freeDevice()` is a no-op under
  // AISW-149462 because per-engine release can invalidate concurrent models;
  // process termination owns final reclamation.  See freeDevice() before
  // changing this to per-engine state.
  inline static Qnn_DeviceHandle_t m_deviceHandle = nullptr;
  RunTimeAppKeys m_runTimeAppKeys;
  uint64_t m_numMaxEvents = std::numeric_limits<uint64_t>::max();
  std::vector<qnn_wrapper_api::GraphInfo_t*> m_graphInfoPtrList;
  bool m_useMmap;
  ProfilingOption m_profilingOption;

  uint32_t m_powerConfigId = 1;
  std::vector<uint32_t> m_powerConfigIds;
  bool m_isPerformanceInitialized{false};
  QnnHtpDevice_PerfInfrastructure_t m_perfInfra = {nullptr};
  bool m_runInCpu = true;
  bool m_isGpu = false;

  // issue#24
  std::map<size_t, std::vector<std::vector<size_t>>> m_inputShapes;
  std::map<size_t, std::vector<std::string>> m_inputDataType_s;
  std::map<size_t, std::vector<std::vector<size_t>>> m_outputShapes;
  std::map<size_t, std::vector<std::string>> m_outputDataType_s;
  std::map<size_t, std::string> m_graphName;
  std::map<size_t,  std::vector<std::string>> m_inputName;
  std::map<size_t, std::vector<std::string>> m_outputName;

  std::string m_dlcPath;
  QnnSystemDlc_Handle_t m_dlcHandle = nullptr;
  Qnn_LogHandle_t m_dlcLogHandle = nullptr;

  std::vector<Qnn_Tensor_t*> m_inputTensors;
  std::vector<Qnn_Tensor_t*> m_outputTensors;
  MultiCoreDeviceConfig_t m_multiCoreDeviceConfig = {};

#ifdef __linux__
  // issue#97: PID of the process that created this engine instance. Used to
  // detect inherited instances in fork()ed children and skip teardown.
  pid_t m_creatorPid{-1};
#endif

  /// Concurrent-safe shutdown guards. The first teardown result is retained
  /// and returned by subsequent calls rather than being reported as success.
  std::atomic<bool> m_shutdownStarted{false};
  std::atomic<StatusCode> m_shutdownResult{StatusCode::FAILURE};
  std::mutex m_shutdownMutex;
  std::condition_variable m_shutdownCv;
  bool m_shutdownComplete{false};
};
}  // namespace qnn_app
}  // namespace tools
}  // namespace qnn

