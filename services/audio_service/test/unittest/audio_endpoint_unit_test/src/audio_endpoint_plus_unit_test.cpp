/*
 * Copyright (c) 2024-2026 Huawei Device Co., Ltd.
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 *     http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 */

#include "audio_endpoint_plus_unit_test.h"
#include "pa_adapter_manager.h"
#include "accesstoken_kit.h"
#include "audio_device_info.h"
#include "audio_endpoint.h"
#include "audio_errors.h"
#include "audio_info.h"
#include "audio_process_config.h"
#include "audio_server.h"
#include "audio_service.h"
#include "audio_stream_info.h"
#include "policy_handler.h"
#include "audio_endpoint.cpp"
#include "audio_endpoint_sink_adapter.cpp"
#include "audio_system_manager.h"
#include "audio_utils.h"

using namespace testing::ext;

namespace OHOS {
namespace AudioStandard {
namespace {
    static int64_t WAIT_TIME_HALF_MILLISECOND = 500000; // 0.5ms
    static int64_t WAIT_TIME_EIGHT_MILLISECOND = 8000000; // 8ms
    constexpr uint64_t TEST_ENDPOINT_ID = 123;
}
class MockAudioProcessStream : public IAudioProcessStream {
public:
    // Pure virtual methods
    MOCK_METHOD(std::shared_ptr<OHAudioBufferBase>, GetStreamBuffer, (), (override));
    MOCK_METHOD(AudioStreamInfo, GetStreamInfo, (), (override));
    MOCK_METHOD(uint32_t, GetAudioSessionId, (), (override));
    MOCK_METHOD(AudioStreamType, GetAudioStreamType, (), (override));
    MOCK_METHOD(StreamUsage, GetUsage, (), (override));
    MOCK_METHOD(SourceType, GetSource, (), (override));

    MOCK_METHOD(void, SetInnerCapState, (bool isInnerCapped, int32_t innerCapId), (override));
    MOCK_METHOD(bool, GetInnerCapState, (int32_t innerCapId), (override));

    using RetTypeUnorderedMap = std::unordered_map<int32_t, bool>;
    MOCK_METHOD(RetTypeUnorderedMap, GetInnerCapState, (), (override));

    MOCK_METHOD(AppInfo, GetAppInfo, (), (override));
    MOCK_METHOD(BufferDesc&, GetConvertedBuffer, (), (override));
    MOCK_METHOD(bool, GetMuteState, (), (override));
    MOCK_METHOD(AudioProcessConfig, GetAudioProcessConfig, (), (override));
    MOCK_METHOD(void, WriteDumpFile, (void* buffer, size_t bufferSize), (override));

    MOCK_METHOD(int32_t, SetDefaultOutputDevice, (int32_t defaultOutputDevice, bool skipForce), (override));
    MOCK_METHOD(int32_t, SetSilentModeAndMixWithOthers, (bool on), (override));

    MOCK_METHOD(uint32_t, GetSpanSizeInFrame, (), (override));
    MOCK_METHOD(uint32_t, GetByteSizePerFrame, (), (override));

    MOCK_METHOD(StreamStatus, GetStreamInServerStatus, (), (override));

    // Non-pure virtual methods (with default implementations in interface)
    MOCK_METHOD(void, EnableStandby, (), (override));

    // Time and state control
    MOCK_METHOD(std::time_t, GetStartMuteTime, (), (override));
    MOCK_METHOD(void, SetStartMuteTime, (std::time_t time), (override));

    MOCK_METHOD(bool, GetSilentState, (), (override));
    MOCK_METHOD(void, SetSilentState, (bool state), (override));

    MOCK_METHOD(void, AddMuteFrameSize, (int64_t muteFrameCnt), (override));
    MOCK_METHOD(void, AddNormalFrameSize, (), (override));
    MOCK_METHOD(void, AddNoDataFrameSize, (), (override));

    MOCK_METHOD(StreamStatus, GetStreamStatus, (), (override));

    // Audio-Haptics sync
    MOCK_METHOD(int32_t, SetAudioHapticsSyncId, (int32_t audioHapticsSyncId), (override));
    MOCK_METHOD(bool, PrepareRingBuffer, (uint64_t curRead, RingBufferWrapper& ringBuffer,
        int32_t &audioHapticsSyncId), (override));
    MOCK_METHOD(void, PrepareStreamDataBuffer,
        (size_t spanSizeInByte, RingBufferWrapper &ringBuffer, AudioStreamData &streamData), (override));
    MOCK_METHOD(void, DfxOperationAndCalcMuteFrame, (BufferDesc &bufferDesc), (override));
};

void AudioEndpointPlusUnitTest::SetUpTestCase(void)
{
    // input testsuit setup step，setup invoked before all testcases
}

void AudioEndpointPlusUnitTest::TearDownTestCase(void)
{
    // input testsuit teardown step，teardown invoked after all testcases
}

void AudioEndpointPlusUnitTest::SetUp(void)
{
    // input testcase setup step，setup invoked before each testcases
}

void AudioEndpointPlusUnitTest::TearDown(void)
{
    // input testcase teardown step，teardown invoked after each testcases
}

static const size_t BIGNUMBER = 2808348670;
static const size_t NUMFIVE = 5;
#ifdef SUPPORT_OLD_ENGINE
static constexpr uint32_t MORE_SESSIONID = MAX_STREAMID + 1;
static const int32_t CAPTURER_FLAG = 10;
static const uint32_t SESSIONID = 123456;
#endif

constexpr int32_t DEFAULT_STREAM_ID = 10;

static AudioProcessConfig InitServerProcessConfig()
{
    AudioProcessConfig config;
    config.appInfo.appUid = DEFAULT_STREAM_ID;
    config.streamInfo.format = SAMPLE_S32LE;
    config.streamInfo.samplingRate = SAMPLE_RATE_48000;
    config.streamInfo.channels = STEREO;
    config.streamInfo.channelLayout = AudioChannelLayout::CH_LAYOUT_STEREO;
    config.audioMode = AudioMode::AUDIO_MODE_RECORD;
    config.streamType = AudioStreamType::STREAM_MUSIC;
    config.deviceType = DEVICE_TYPE_USB_HEADSET;
    return config;
}

static sptr<AudioProcessInServer> CreateAudioProcessInServer()
{
    AudioService *audioServicePtr = AudioService::GetInstance();
    AudioDeviceDescriptor deviceInfo(AudioDeviceDescriptor::DEVICE_INFO);
    AudioStreamInfo audioStreamInfo;
    audioStreamInfo.samplingRate = SAMPLE_RATE_48000;
    audioStreamInfo.channelLayout = CH_LAYOUT_STEREO;
    AudioProcessConfig serverConfig = InitServerProcessConfig();
    sptr<AudioProcessInServer> processStream = AudioProcessInServer::Create(serverConfig, audioServicePtr);
    uint32_t spanSizeInFrame = 1000;
    uint32_t totalSizeInFrame = spanSizeInFrame;
    processStream->ConfigProcessBuffer(totalSizeInFrame, spanSizeInFrame, audioStreamInfo);
    return processStream;
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_001
 * @tc.desc  : Test AudioEndpointInner::CheckStandBy()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->endpointStatus_.store(AudioEndpoint::EndpointStatus::RUNNING);

    audioEndpointInner->CheckStandBy();
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_002
 * @tc.desc  : Test AudioEndpointInner::CheckStandBy()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_002, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->endpointStatus_.store(AudioEndpoint::EndpointStatus::IDEL);

    audioEndpointInner->CheckStandBy();
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_003
 * @tc.desc  : Test AudioEndpointInner::CheckAllBufferReady()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_003, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    int64_t checkTime = 0;
    uint64_t curWritePos = 0;

    auto result = audioEndpointInner->CheckAllBufferReady(checkTime, curWritePos);
    EXPECT_EQ(result, true);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_004
 * @tc.desc  : Test AudioEndpointInner::CheckAllBufferReady()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_004, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    int64_t checkTime = 0;
    uint64_t curWritePos = 0;
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    std::shared_ptr<OHAudioBufferBase> processBuffer = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    BasicBufferInfo basicBufferInfo;
    processBuffer->basicBufferInfo_ = &basicBufferInfo;
    processBuffer->basicBufferInfo_->streamStatus.store(StreamStatus::STREAM_RUNNING);
    uint64_t readFrame = 0;
    processBuffer->SetCurReadFrame(readFrame);
    int64_t lastTime = 0;
    processBuffer->SetLastWrittenTime(lastTime);
    uint64_t pos = 0;
    processBuffer->basicBufferInfo_->basePosInFrame.store(pos);
    AudioProcessConfig config = {};
    config.privacyType = AudioPrivacyType::PRIVACY_TYPE_PUBLIC;
    sptr<AudioProcessInServer> audioProcess = AudioProcessInServer::Create(config, AudioService::GetInstance());
    audioEndpointInner->processList_.push_back(audioProcess);
    audioEndpointInner->processBufferList_.push_back(processBuffer);
    AudioService *g_audioServicePtr = AudioService::GetInstance();
    sptr<AudioProcessInServer> processStream = AudioProcessInServer::Create(clientConfig, g_audioServicePtr);
    audioEndpointInner->processList_.push_back(processStream);
    auto result = audioEndpointInner->CheckAllBufferReady(checkTime, curWritePos);
    EXPECT_EQ(result, true);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_CheckAllBufferReady_001
 * @tc.desc  : Test AudioEndpointInner::CheckAllBufferReady()
 */
HWTEST_F(AudioEndpointPlusUnitTest, CheckAllBufferReady_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    int64_t checkTime = 0;
    uint64_t curWritePos = 0;
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    std::shared_ptr<OHAudioBufferBase> processBuffer = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    BasicBufferInfo basicBufferInfo;
    processBuffer->basicBufferInfo_ = &basicBufferInfo;
    processBuffer->basicBufferInfo_->streamStatus.store(StreamStatus::STREAM_RUNNING);
    uint64_t readFrame = 0;
    processBuffer->SetCurReadFrame(readFrame);
    int64_t lastTime = 0;
    processBuffer->SetLastWrittenTime(lastTime);
    uint64_t pos = 0;
    processBuffer->basicBufferInfo_->basePosInFrame.store(pos);
    AudioProcessConfig config = {};
    config.privacyType = AudioPrivacyType::PRIVACY_TYPE_PUBLIC;
    sptr<AudioProcessInServer> audioProcess = AudioProcessInServer::Create(config, AudioService::GetInstance());
    audioEndpointInner->processList_.push_back(audioProcess);
    audioEndpointInner->processBufferList_.push_back(processBuffer);
    AudioService *g_audioServicePtr = AudioService::GetInstance();
    sptr<AudioProcessInServer> processStream = AudioProcessInServer::Create(clientConfig, g_audioServicePtr);
    processStream->keepRunning_ = true;
    audioEndpointInner->processList_.push_back(processStream);
    auto result = audioEndpointInner->CheckAllBufferReady(checkTime, curWritePos);
    EXPECT_EQ(result, true);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_CheckAllBufferReady_002
 * @tc.desc  : Test AudioEndpointInner::CheckAllBufferReady()
 */
HWTEST_F(AudioEndpointPlusUnitTest, CheckAllBufferReady_002, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    int64_t checkTime = 0;
    uint64_t curWritePos = 0;
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    std::shared_ptr<OHAudioBufferBase> processBuffer = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    BasicBufferInfo basicBufferInfo;
    processBuffer->basicBufferInfo_ = &basicBufferInfo;
    processBuffer->basicBufferInfo_->streamStatus.store(StreamStatus::STREAM_STARTING);
    audioEndpointInner->processBufferList_.push_back(processBuffer);
    AudioService *g_audioServicePtr = AudioService::GetInstance();
    sptr<AudioProcessInServer> processStream = AudioProcessInServer::Create(clientConfig, g_audioServicePtr);
    processStream->keepRunning_ = true;
    audioEndpointInner->processList_.push_back(processStream);
    bool ret = audioEndpointInner->CheckAllBufferReady(checkTime, curWritePos);
    EXPECT_EQ(ret, true);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_005
 * @tc.desc  : Test AudioEndpointInner::CheckAllBufferReady()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_005, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    int64_t checkTime = 0;
    uint64_t curWritePos = 0;
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    std::shared_ptr<OHAudioBufferBase> processBuffer = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    BasicBufferInfo basicBufferInfo;
    processBuffer->basicBufferInfo_ = &basicBufferInfo;
    processBuffer->basicBufferInfo_->streamStatus.store(StreamStatus::STREAM_STARTING);
    audioEndpointInner->processBufferList_.push_back(processBuffer);
    AudioService *g_audioServicePtr = AudioService::GetInstance();
    sptr<AudioProcessInServer> processStream = AudioProcessInServer::Create(clientConfig, g_audioServicePtr);
    audioEndpointInner->processList_.push_back(processStream);
    bool ret = audioEndpointInner->CheckAllBufferReady(checkTime, curWritePos);
    EXPECT_EQ(ret, true);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_006
 * @tc.desc  : Test AudioEndpointInner::MixToDupStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_006, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData audioStreamData;
    srcDataList.push_back(audioStreamData);
    audioEndpointInner->dupBuffer_ = std::make_unique<uint8_t []>(1);
    EXPECT_NE(nullptr, audioEndpointInner->dupBuffer_);

    audioEndpointInner->MixToDupStream(srcDataList, 1);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_007
 * @tc.desc  : Test AudioEndpointInner::MixToDupStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_007, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData audioStreamData;
    audioStreamData.isInnerCapeds[1] = true;
    srcDataList.push_back(audioStreamData);
    audioEndpointInner->dupBuffer_ = std::make_unique<uint8_t []>(1);
    EXPECT_NE(nullptr, audioEndpointInner->dupBuffer_);

    audioEndpointInner->MixToDupStream(srcDataList, 1);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_008
 * @tc.desc  : Test AudioEndpointInner::ProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_008, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData dstData;
    dstData.bufferDesc.buffer = new uint8_t[1] {1};
    dstData.bufferDesc.bufLength = 1;
    dstData.bufferDesc.dataLength = 1;

    audioEndpointInner->ProcessData(srcDataList, dstData);
    EXPECT_EQ(dstData.bufferDesc.buffer[0], 0);

    AudioStreamData audioStreamData;
    audioStreamData.streamInfo.format = AudioSampleFormat::SAMPLE_S24LE;
    audioStreamData.streamInfo.channels = AudioChannel::CHANNEL_3;
    srcDataList.push_back(audioStreamData);

    audioEndpointInner->ProcessData(srcDataList, dstData);
    audioEndpointInner->endpointType_ = AudioEndpoint::TYPE_VOIP_MMAP;
    audioEndpointInner->ProcessData(srcDataList, dstData);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_009
 * @tc.desc  : Test AudioEndpointInner::ProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_009, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData dstData;
    AudioStreamData audioStreamData;
    audioStreamData.streamInfo.format = AudioSampleFormat::SAMPLE_S16LE;
    audioStreamData.streamInfo.channels = AudioChannel::CHANNEL_3;
    srcDataList.push_back(audioStreamData);

    audioEndpointInner->ProcessData(srcDataList, dstData);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_010
 * @tc.desc  : Test AudioEndpointInner::ProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_010, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData dstData;
    AudioStreamData audioStreamData;
    audioStreamData.streamInfo.format = AudioSampleFormat::SAMPLE_S16LE;
    audioStreamData.streamInfo.channels = AudioChannel::STEREO;
    audioStreamData.bufferDesc.bufLength = 1;
    dstData.bufferDesc.bufLength = 2;
    srcDataList.push_back(audioStreamData);

    audioEndpointInner->ProcessData(srcDataList, dstData);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_011
 * @tc.desc  : Test AudioEndpointInner::ProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_011, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData dstData;
    AudioStreamData audioStreamData;
    audioStreamData.streamInfo.format = AudioSampleFormat::SAMPLE_S16LE;
    audioStreamData.streamInfo.channels = AudioChannel::STEREO;
    audioStreamData.bufferDesc.bufLength = 1;
    dstData.bufferDesc.bufLength = 1;
    audioStreamData.bufferDesc.dataLength = 1;
    dstData.bufferDesc.dataLength = 2;
    srcDataList.push_back(audioStreamData);

    audioEndpointInner->ProcessData(srcDataList, dstData);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_012
 * @tc.desc  : Test AudioEndpointInner::ProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_012, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData dstData;
    AudioStreamData audioStreamData;
    audioStreamData.streamInfo.format = AudioSampleFormat::SAMPLE_S16LE;
    audioStreamData.streamInfo.channels = AudioChannel::STEREO;
    audioStreamData.bufferDesc.bufLength = 1;
    dstData.bufferDesc.bufLength = 1;
    audioStreamData.bufferDesc.dataLength = 1;
    dstData.bufferDesc.dataLength = 1;
    srcDataList.push_back(audioStreamData);

    audioEndpointInner->ProcessData(srcDataList, dstData);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_013
 * @tc.desc  : Test AudioEndpointInner::ProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_013, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData audioStreamData;
    audioStreamData.streamInfo.format = AudioSampleFormat::SAMPLE_S16LE;
    audioStreamData.streamInfo.channels = AudioChannel::STEREO;
    audioStreamData.bufferDesc.bufLength = 1;
    audioStreamData.bufferDesc.dataLength = 1;
    srcDataList.push_back(audioStreamData);

    PolicyHandler policyHandler;
    audioEndpointInner->ProcessData(srcDataList, audioStreamData);
    policyHandler.deviceType_ = DEVICE_TYPE_NEARLINK;
    audioEndpointInner->ProcessData(srcDataList, audioStreamData);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_014
 * @tc.desc  : Test AudioEndpointInner::ProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_014, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    audioEndpointInner->isExistLoopback_ = true;

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> srcDataList;
    AudioStreamData audioStreamData;
    audioStreamData.streamInfo.format = AudioSampleFormat::SAMPLE_S16LE;
    audioStreamData.streamInfo.channels = AudioChannel::STEREO;
    audioStreamData.bufferDesc.bufLength = 1;
    audioStreamData.bufferDesc.dataLength = 1;
    srcDataList.push_back(audioStreamData);

    PolicyHandler policyHandler;
    audioEndpointInner->ProcessData(srcDataList, audioStreamData);
    policyHandler.deviceType_ = DEVICE_TYPE_NEARLINK;
    audioEndpointInner->ProcessData(srcDataList, audioStreamData);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_018
 * @tc.desc  : Test AudioEndpointInner::GetAllReadyProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_018, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::vector<AudioStreamData> audioDataList;
    AudioStreamData audioStreamData;
    audioDataList.push_back(audioStreamData);

    std::function<void()> moveClientIndex;
    audioEndpointInner->GetAllReadyProcessData(audioDataList, moveClientIndex);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_019
 * @tc.desc  : Test AudioEndpointInner::GetPredictNextReadTime()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_019, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t posInFrame = 0;
    audioEndpointInner->dstSpanSizeInframe_ = 1;

    audioEndpointInner->GetPredictNextReadTime(posInFrame);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_020
 * @tc.desc  : Test AudioEndpointInner::GetPredictNextReadTime()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_020, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t posInFrame = 400;
    audioEndpointInner->dstSpanSizeInframe_ = 1;

    audioEndpointInner->GetPredictNextReadTime(posInFrame);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_021
 * @tc.desc  : Test AudioEndpointInner::GetPredictNextReadTime()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_021, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t posInFrame = 401;
    audioEndpointInner->dstSpanSizeInframe_ = 1;
    audioEndpointInner->readTimeModel_.isConfiged = true;
    audioEndpointInner->readTimeModel_.sampleRate_ = 1000;
    audioEndpointInner->posInFrame_.store(13);
    audioEndpointInner->stopUpdateThread_ = true;

    audioEndpointInner->GetPredictNextReadTime(posInFrame);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_022
 * @tc.desc  : Test AudioEndpointInner::GetPredictNextReadTime()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_022, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t posInFrame = 401;
    audioEndpointInner->dstSpanSizeInframe_ = 1;
    audioEndpointInner->readTimeModel_.isConfiged = true;
    audioEndpointInner->readTimeModel_.sampleRate_ = 1000;
    audioEndpointInner->posInFrame_.store(0);

    audioEndpointInner->GetPredictNextReadTime(posInFrame);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_023
 * @tc.desc  : Test AudioEndpointInner::GetPredictNextReadTime()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_023, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t posInFrame = 401;
    audioEndpointInner->dstSpanSizeInframe_ = 1;
    audioEndpointInner->readTimeModel_.isConfiged = false;
    audioEndpointInner->readTimeModel_.sampleRate_ = 1000;

    audioEndpointInner->GetPredictNextReadTime(posInFrame);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_024
 * @tc.desc  : Test AudioEndpointInner::CheckPlaySignal()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_024, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint8_t buffer = 1;
    size_t bufferSize = 1;
    audioEndpointInner->latencyMeasEnabled_ = false;

    audioEndpointInner->CheckPlaySignal(&buffer, bufferSize);
}
#ifdef AUDIO_ENDPOINT_INNER_UNIT_TEST_DIFF
/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_025
 * @tc.desc  : Test AudioEndpointInner::CheckPlaySignal()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_025, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint8_t buffer = 1;
    size_t bufferSize = BIGNUMBER;
    audioEndpointInner->dstStreamInfo_.format = AudioSampleFormat::SAMPLE_S16LE;
    audioEndpointInner->signalDetectAgent_ = std::make_shared<SignalDetectAgent>();
    audioEndpointInner->signalDetectAgent_->signalDetected_ = true;
    audioEndpointInner->signalDetectAgent_->dspTimestampGot_ = false;
    audioEndpointInner->latencyMeasEnabled_ = true;

    EXPECT_NE(nullptr, audioEndpointInner->signalDetectAgent_);

    audioEndpointInner->CheckPlaySignal(&buffer, bufferSize);
}
#endif
/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_026
 * @tc.desc  : Test AudioEndpointInner::CheckPlaySignal()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_026, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint8_t buffer = 1;
    size_t bufferSize = BIGNUMBER;
    audioEndpointInner->dstStreamInfo_.format = AudioSampleFormat::SAMPLE_S16LE;
    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_8000;
    audioEndpointInner->dstStreamInfo_.channels = AudioChannel::STEREO;
    audioEndpointInner->signalDetectAgent_ = std::make_shared<SignalDetectAgent>();
    audioEndpointInner->signalDetectAgent_->signalDetected_ = false;
    audioEndpointInner->signalDetectAgent_->dspTimestampGot_ = false;
    audioEndpointInner->latencyMeasEnabled_ = true;

    EXPECT_NE(nullptr, audioEndpointInner->signalDetectAgent_);

    audioEndpointInner->CheckPlaySignal(&buffer, bufferSize);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_027
 * @tc.desc  : Test AudioEndpointInner::CheckPlaySignal()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_027, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint8_t buffer = 1;
    size_t bufferSize = BIGNUMBER;
    audioEndpointInner->dstStreamInfo_.format = AudioSampleFormat::SAMPLE_S16LE;
    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_8000;
    audioEndpointInner->dstStreamInfo_.channels = AudioChannel::STEREO;
    audioEndpointInner->signalDetectAgent_ = std::make_shared<SignalDetectAgent>();
    audioEndpointInner->signalDetectAgent_->signalDetected_ = true;
    audioEndpointInner->signalDetectAgent_->dspTimestampGot_ = true;
    audioEndpointInner->latencyMeasEnabled_ = true;

    EXPECT_NE(nullptr, audioEndpointInner->signalDetectAgent_);

    audioEndpointInner->CheckPlaySignal(&buffer, bufferSize);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_032
 * @tc.desc  : Test AudioEndpointInner::CheckRecordSignal()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_032, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint8_t* buffer = new uint8_t[NUMFIVE];
    size_t bufferSize = NUMFIVE;
    audioEndpointInner->latencyMeasEnabled_ = true;
    audioEndpointInner->signalDetectAgent_ = std::make_shared<SignalDetectAgent>();
    EXPECT_NE(nullptr, audioEndpointInner->signalDetectAgent_);
    audioEndpointInner->signalDetected_ = true;

    audioEndpointInner->CheckRecordSignal(buffer, bufferSize);
    delete[] buffer;
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_033
 * @tc.desc  : Test AudioEndpointInner::CheckRecordSignal()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_033, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint8_t* buffer = new uint8_t[NUMFIVE];
    size_t bufferSize = NUMFIVE;
    audioEndpointInner->latencyMeasEnabled_ = true;
    audioEndpointInner->signalDetectAgent_ = std::make_shared<SignalDetectAgent>();
    EXPECT_NE(nullptr, audioEndpointInner->signalDetectAgent_);
    audioEndpointInner->signalDetected_ = false;

    audioEndpointInner->CheckRecordSignal(buffer, bufferSize);
    delete[] buffer;
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_035
 * @tc.desc  : Test AudioEndpointInner::PrepareNextLoop()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_035, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t curWritePos = 0;
    int64_t wakeUpTime = 0;
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t spanSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    audioEndpointInner->dstAudioBuffer_ = std::make_shared<OHAudioBuffer>(bufferHolder, totalSizeInFrame,
        spanSizeInFrame, byteSizePerFrame);
    audioEndpointInner->dstAudioBuffer_->ohAudioBufferBase_.basicBufferInfo_ =
        std::make_shared<BasicBufferInfo>().get();

    std::function<void()> moveClientIndex;
    auto result = audioEndpointInner->PrepareNextLoop(curWritePos, wakeUpTime, moveClientIndex);
    EXPECT_EQ(result, false);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_036
 * @tc.desc  : Test AudioEndpointInner::GetMaxAmplitude()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_036, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    auto result = audioEndpointInner->GetMaxAmplitude();

    EXPECT_EQ(audioEndpointInner->startUpdate_, true);
    EXPECT_NEAR(result, 0.0, 0.001);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_037
 * @tc.desc  : Test AudioEndpointInner::ProcessToDupStream()
 */
#ifdef HAS_FEATURE_INNERCAPTURER
#ifdef SUPPORT_OLD_ENGINE
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_037, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    AudioStreamData dstStreamData;
    dstStreamData.isInnerCapeds[1] = true;
    const std::vector<AudioStreamData> audioDataList = {dstStreamData};
    audioEndpointInner->endpointType_ = AudioEndpoint::EndpointType::TYPE_VOIP_MMAP;

    EXPECT_EQ(audioDataList.size(), 1);

    audioEndpointInner->dupBufferSize_ = 3;

    PaAdapterManager *adapterManager = new PaAdapterManager(DUP_PLAYBACK);
    adapterManager->InitPaContext();
    AudioProcessConfig config;
    config.appInfo.appUid = CAPTURER_FLAG;
    config.appInfo.appPid = CAPTURER_FLAG;
    config.streamInfo.format = SAMPLE_S32LE;
    config.streamInfo.samplingRate = SAMPLE_RATE_48000;
    config.streamInfo.channels = STEREO;
    config.streamInfo.channelLayout = AudioChannelLayout::CH_LAYOUT_STEREO;
    config.audioMode = AudioMode::AUDIO_MODE_PLAYBACK;
    config.streamType = AudioStreamType::STREAM_MUSIC;
    config.deviceType = DEVICE_TYPE_USB_HEADSET;
    config.originalSessionId = MORE_SESSIONID;
    config.innerCapId = 1;
    uint32_t sessionId = SESSIONID;
    setuid(AUDIO_ID);
    AudioPlaybackCaptureConfig checkConfig;
    int32_t checkInnerCapId = 0;
    AudioSystemManager::GetInstance()->CheckCaptureLimit(checkConfig, checkInnerCapId);
    pa_stream *stream = adapterManager->InitPaStream(config, sessionId, false);
    auto &info = audioEndpointInner->fastCaptureInfos_[1];
    info.dupStream = adapterManager->CreateRendererStream(config, stream);
    audioEndpointInner->ProcessToDupStream(audioDataList, dstStreamData, 1);
    AudioSystemManager::GetInstance()->ReleaseCaptureLimit(1);
    EXPECT_EQ(dstStreamData.bufferDesc.bufLength, audioDataList[0].bufferDesc.bufLength);
}
#endif
#endif
/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_039
 * @tc.desc  : Test AudioEndpointInner::GetAllReadyProcessData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_039, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    AudioStreamData dstStreamData;
    std::vector<AudioStreamData> audioDataList = {dstStreamData};
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    std::shared_ptr<OHAudioBufferBase> processBuffer = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    EXPECT_NE(processBuffer, nullptr);

    processBuffer->basicBufferInfo_ = std::make_shared<BasicBufferInfo>().get();
    EXPECT_NE(processBuffer->basicBufferInfo_, nullptr);

    audioEndpointInner->processBufferList_.push_back(processBuffer);
    MockAudioProcessStream mockProcessStream;
    audioEndpointInner->processList_.push_back(&mockProcessStream);

    std::function<void()> moveClientIndex;
    audioEndpointInner->GetAllReadyProcessData(audioDataList, moveClientIndex);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_040
 * @tc.desc  : Test AudioEndpointInner::WaitAllProcessReady()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_040, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t curWritePos = 0;

    audioEndpointInner->WaitAllProcessReady(curWritePos);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_WaitAllReady_001
 * @tc.desc  : Test AudioEndpointInner::WaitAllProcessReady() will wait between 1~5ms
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_WaitAllReady_001, TestSize.Level1)
{
    AudioProcessConfig clientConfig = {};
    auto endpoint = std::make_shared<AudioEndpointInner>(AudioEndpoint::TYPE_MMAP, 0, clientConfig.audioMode);

    ASSERT_NE(endpoint, nullptr);

    endpoint->readTimeModel_.ConfigSampleRate(SAMPLE_RATE_48000);
    uint64_t curWritePos = 0;
    endpoint->readTimeModel_.ResetFrameStamp(curWritePos, ClockTime::GetCurNano());
    int64_t time = ClockTime::GetCurNano();
    endpoint->WaitAllProcessReady(curWritePos);
    time = ClockTime::GetCurNano() - time;
    EXPECT_GE(time, WAIT_TIME_HALF_MILLISECOND);
    time = ClockTime::GetCurNano();
    curWritePos = 1200; // 25ms
    endpoint->WaitAllProcessReady(curWritePos);
    time = ClockTime::GetCurNano() - time;
    EXPECT_GE(WAIT_TIME_EIGHT_MILLISECOND, time);
}

/*
 * @tc.name  : Test CheckJank API
 * @tc.type  : FUNC
 * @tc.number: CheckJank_001
 * @tc.desc  : Test AudioEndpointInner::CheckJank()
 */
HWTEST_F(AudioEndpointPlusUnitTest, CheckJank_001, TestSize.Level1)
{
    AudioProcessConfig clientConfig = {};
    auto endpoint = std::make_shared<AudioEndpointInner>(AudioEndpoint::TYPE_MMAP, 0, clientConfig.audioMode);

    uint32_t totalSizeInFrame = 8;
    uint32_t spanSizeInFrame = 2;
    uint32_t byteSizePerFrame = 4;
    endpoint->dstAudioBuffer_ = std::make_shared<OHAudioBuffer>(AUDIO_SERVER_SHARED, totalSizeInFrame,
        spanSizeInFrame, byteSizePerFrame);
    EXPECT_NE(endpoint->dstAudioBuffer_, nullptr);
    endpoint->syncInfoSize_ = 0;
    endpoint->CheckJank(0);

    endpoint->syncInfoSize_ = 8;
    endpoint->dstSpanSizeInframe_ = 0;
    endpoint->CheckJank(0);

    endpoint->isStarted_ = true;
    endpoint->CheckJank(0);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_041
 * @tc.desc  : Test AudioEndpointInner::ProcessToEndpointDataHandle()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_041, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t spanSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    audioEndpointInner->dstAudioBuffer_ = std::make_shared<OHAudioBuffer>(bufferHolder, totalSizeInFrame,
        spanSizeInFrame, byteSizePerFrame);
    EXPECT_NE(audioEndpointInner->dstAudioBuffer_, nullptr);

    audioEndpointInner->dstAudioBuffer_->ohAudioBufferBase_.basicBufferInfo_ =
        std::make_shared<BasicBufferInfo>().get();
    EXPECT_NE(audioEndpointInner->dstAudioBuffer_->ohAudioBufferBase_.basicBufferInfo_, nullptr);

    uint64_t curWritePos = 0;
    std::function<void()> moveClientIndex;
    auto result = audioEndpointInner->ProcessToEndpointDataHandle(curWritePos, moveClientIndex);
    EXPECT_EQ(result, false);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_042
 * @tc.desc  : Test AudioEndpointInner::WriteMuteDataSysEvent()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_042, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;

    std::shared_ptr<OHAudioBufferBase> processBuffer1 = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    sptr<AudioProcessInServer> audioProcess1 = AudioProcessInServer::Create(clientConfig, AudioService::GetInstance());
    size_t len = 10;
    std::unique_ptr<int8_t[]> buffer1 = std::make_unique<int8_t[]>(len);
    for (size_t i = 0; i < len; ++i) {
        buffer1[i] = static_cast<int8_t>(i);
    }
    BufferDesc bufferDesc1 = {reinterpret_cast<uint8_t *>(buffer1.get()), len, len};
    bufferDesc1.buffer[0] = 1;
    bufferDesc1.buffer[1] = 1;
    audioEndpointInner->processList_.push_back(audioProcess1);
    audioEndpointInner->processBufferList_.push_back(processBuffer1);
    audioEndpointInner->WriteMuteDataSysEvent(bufferDesc1.buffer, bufferDesc1.bufLength, 0);
    EXPECT_EQ(false, audioEndpointInner->processList_[0]->GetSilentState());
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_043
 * @tc.desc  : Test AudioEndpointInner::GetEndpointType()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_043, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    AudioEndpoint::EndpointType endpointType = audioEndpointInner->GetEndpointType();
    EXPECT_EQ(endpointType, AudioEndpoint::TYPE_MMAP);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_044
 * @tc.desc  : Test AudioEndpointInner::GetBuffer()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_044, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    std::shared_ptr<OHAudioBufferBase> buffer = audioEndpointInner->GetBuffer();
    EXPECT_EQ(buffer, nullptr);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_045
 * @tc.desc  : Test AudioEndpointInner::GetDeviceInfo()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_045, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    AudioDeviceDescriptor audioDeviceDescriptor = audioEndpointInner->GetDeviceInfo();
    EXPECT_EQ(audioDeviceDescriptor.descriptorType_, AudioDeviceDescriptor::DEVICE_INFO);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_046
 * @tc.desc  : Test AudioEndpointInner::GetDeviceRole()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_046, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->deviceInfo_.deviceRole_ = DeviceRole::INPUT_DEVICE;
    DeviceRole deviceRole = audioEndpointInner->GetDeviceRole();
    EXPECT_EQ(deviceRole, DeviceRole::INPUT_DEVICE);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_047
 * @tc.desc  : Test AudioEndpointInner::GetStatus()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_047, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    AudioEndpoint::EndpointStatus endpointStatus = audioEndpointInner->GetStatus();
    EXPECT_EQ(endpointStatus, AudioEndpoint::EndpointStatus::INVALID);
}

/*
 * @tc.name  : Test MockCallbacks API
 * @tc.type  : FUNC
 * @tc.number: MockCallbacks_049
 * @tc.desc  : Test MockCallbacks::OnStatusUpdate()
 */
HWTEST_F(AudioEndpointPlusUnitTest, MockCallbacks_049, TestSize.Level1)
{
    uint32_t streamIndex = 0;
    auto mockCallbacks = std::make_shared<MockCallbacks>(streamIndex);

    ASSERT_NE(mockCallbacks, nullptr);

    IOperation operation = IOperation::OPERATION_STARTED;
    mockCallbacks->OnStatusUpdate(operation);
}

/*
 * @tc.name  : Test MockCallbacks API
 * @tc.type  : FUNC
 * @tc.number: MockCallbacks_050
 * @tc.desc  : Test MockCallbacks::OnWriteData()
 */
HWTEST_F(AudioEndpointPlusUnitTest, MockCallbacks_050, TestSize.Level1)
{
    uint32_t streamIndex = 0;
    auto mockCallbacks = std::make_shared<MockCallbacks>(streamIndex);

    ASSERT_NE(mockCallbacks, nullptr);

    size_t length = 8;
    int32_t ret = mockCallbacks->OnWriteData(length);
    EXPECT_EQ(ret, SUCCESS);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_051
 * @tc.desc  : Test AudioEndpointInner::RecordReSyncPosition()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_051, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->spanDuration_ = -999;
    audioEndpointInner->RecordReSyncPosition();
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_052
 * @tc.desc  : Test AudioEndpointInner::LinkProcessStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_052, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    sptr<AudioProcessInServer> processStream = CreateAudioProcessInServer();
    audioEndpointInner->endpointStatus_ = AudioEndpoint::STARTING;
    int32_t ret = audioEndpointInner->LinkProcessStream(processStream);
    EXPECT_EQ(ret, SUCCESS);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_053
 * @tc.desc  : Test AudioEndpointInner::LinkProcessStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_053, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    sptr<AudioProcessInServer> processStream = CreateAudioProcessInServer();
    audioEndpointInner->endpointStatus_ = AudioEndpoint::RUNNING;
    int32_t ret = audioEndpointInner->LinkProcessStream(processStream);
    EXPECT_EQ(ret, SUCCESS);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_054
 * @tc.desc  : Test AudioEndpointInner::LinkProcessStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_054, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    sptr<AudioProcessInServer> processStream = CreateAudioProcessInServer();
    audioEndpointInner->endpointStatus_ = AudioEndpoint::IDEL;
    audioEndpointInner->isDeviceRunningInIdel_ = true;
    int32_t ret = audioEndpointInner->LinkProcessStream(processStream);
    EXPECT_EQ(ret, SUCCESS);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_055
 * @tc.desc  : Test AudioEndpointInner::LinkProcessStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_055, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    sptr<AudioProcessInServer> processStream = CreateAudioProcessInServer();
    audioEndpointInner->endpointStatus_ = AudioEndpoint::IDEL;
    audioEndpointInner->isDeviceRunningInIdel_ = false;
    int32_t ret = audioEndpointInner->LinkProcessStream(processStream);
    EXPECT_EQ(ret, SUCCESS);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_056
 * @tc.desc  : Test AudioEndpointInner::CheckStandBy()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_056, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->endpointStatus_ = AudioEndpoint::EndpointStatus::STARTING;
    audioEndpointInner->CheckStandBy();
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_057
 * @tc.desc  : Test AudioEndpointInner::LinkProcessStreamExt()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_057, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    sptr<AudioProcessInServer> processStream = CreateAudioProcessInServer();
    std::shared_ptr<OHAudioBufferBase> processBuffer;

    audioEndpointInner->LinkProcessStreamExt(processStream, processBuffer);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_058
 * @tc.desc  : Test AudioEndpointInner::GetDeviceHandleInfo()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_058, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    uint64_t frames = 0;
    int64_t nanoTime = 0;
    audioEndpointInner->deviceInfo_.deviceRole_ = DeviceRole::OUTPUT_DEVICE;
    audioEndpointInner->fastRenderId_ = HDI_INVALID_ID;
    bool ret = audioEndpointInner->GetDeviceHandleInfo(frames, nanoTime);
    EXPECT_EQ(ret, false);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: AudioEndpointInner_059
 * @tc.desc  : Test AudioEndpointInner::IsBufferDataInsufficient()
 */
HWTEST_F(AudioEndpointPlusUnitTest, AudioEndpointInner_059, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);

    ASSERT_NE(audioEndpointInner, nullptr);

    bool ret = audioEndpointInner->IsBufferDataInsufficient(0, 1);
    EXPECT_EQ(ret, true);

    ret = audioEndpointInner->IsBufferDataInsufficient(1, 1);
    EXPECT_EQ(ret, false);

    ret = audioEndpointInner->IsBufferDataInsufficient(-1, 1);
    EXPECT_EQ(ret, false);

    ret = audioEndpointInner->IsBufferDataInsufficient(ERROR, std::numeric_limits<int32_t>::max());
    EXPECT_EQ(ret, false);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: IsInvalidBuffer_001
 * @tc.desc  : Test AudioEndpointInner::IsInvalidBuffer()
 */
HWTEST_F(AudioEndpointPlusUnitTest, IsInvalidBuffer_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    uint8_t buffer[1] = {1};
    bool result = audioEndpointInner->IsInvalidBuffer(buffer, sizeof(buffer), SAMPLE_U8);
    EXPECT_FALSE(result);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: IsInvalidBuffer_002
 * @tc.desc  : Test AudioEndpointInner::IsInvalidBuffer()
 */
HWTEST_F(AudioEndpointPlusUnitTest, IsInvalidBuffer_002, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    uint8_t buffer[1] = {0};
    bool result = audioEndpointInner->IsInvalidBuffer(buffer, sizeof(buffer), SAMPLE_U8);
    EXPECT_TRUE(result);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: IsInvalidBuffer_003
 * @tc.desc  : Test AudioEndpointInner::IsInvalidBuffer()
 */
HWTEST_F(AudioEndpointPlusUnitTest, IsInvalidBuffer_003, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    int16_t buffer[1] = {1};
    bool result = audioEndpointInner->IsInvalidBuffer(reinterpret_cast<uint8_t*>(buffer), sizeof(buffer), SAMPLE_S16LE);
    EXPECT_FALSE(result);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: IsInvalidBuffer_004
 * @tc.desc  : Test AudioEndpointInner::IsInvalidBuffer()
 */
HWTEST_F(AudioEndpointPlusUnitTest, IsInvalidBuffer_004, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    int16_t buffer[1] = {0};
    bool result = audioEndpointInner->IsInvalidBuffer(reinterpret_cast<uint8_t*>(buffer), sizeof(buffer), SAMPLE_S16LE);
    EXPECT_TRUE(result);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: IsInvalidBuffer_005
 * @tc.desc  : Test AudioEndpointInner::IsInvalidBuffer()
 */
HWTEST_F(AudioEndpointPlusUnitTest, IsInvalidBuffer_005, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointnIner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    uint8_t buffer[1] = {0};
    bool result = audioEndpointnIner->IsInvalidBuffer(buffer, sizeof(buffer), static_cast<AudioSampleFormat>(-1));
    EXPECT_FALSE(result);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: CheckAudioHapticsSync_001
 * @tc.desc  : Test AudioEndpointInner::CheckAudioHapticsSync()
 */
HWTEST_F(AudioEndpointPlusUnitTest, CheckAudioHapticsSync_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointnIner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    audioEndpointnIner->audioHapticsSyncId_ = 1;
    audioEndpointnIner->fastRenderId_ = 1;
    audioEndpointnIner->dstSpanSizeInframe_ = 100;
    std::shared_ptr<IAudioRenderSink> sink = nullptr;
    HdiAdapterManager::GetInstance().DoSetSinkPrestoreInfo(sink, HDI_ID_TYPE_PRIMARY);
    audioEndpointnIner->CheckAudioHapticsSync(10);
    EXPECT_EQ(audioEndpointnIner->audioHapticsSyncId_, 0);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: CheckAudioHapticsSync_002
 * @tc.desc  : Test AudioEndpointInner::CheckAudioHapticsSync()
 */
HWTEST_F(AudioEndpointPlusUnitTest, CheckAudioHapticsSync_002, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointnIner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    audioEndpointnIner->audioHapticsSyncId_ = 1;
    audioEndpointnIner->fastRenderId_ = 1;
    audioEndpointnIner->dstSpanSizeInframe_ = 100;

    HdiAdapterManager::GetInstance().DoSetSinkPrestoreInfo(nullptr, HDI_ID_TYPE_PRIMARY);

    audioEndpointnIner->CheckAudioHapticsSync(10);

    EXPECT_NE(audioEndpointnIner->audioHapticsSyncId_, 1);
}

/*
 * @tc.name  : Test IsNearlinkAbsVolSupportStream API
 * @tc.type  : FUNC
 * @tc.number: IsNearlinkAbsVolSupportStream_001
 * @tc.desc  : Test AudioEndpointInner::IsNearlinkAbsVolSupportStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, IsNearlinkAbsVolSupportStream_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointnIner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    EXPECT_FALSE(audioEndpointnIner->IsNearlinkAbsVolSupportStream(DEVICE_TYPE_NEARLINK, STREAM_MUSIC));

    EXPECT_TRUE(audioEndpointnIner->IsNearlinkAbsVolSupportStream(DEVICE_TYPE_NEARLINK, STREAM_VOICE_CALL));
}

/*
 * @tc.name  : Test CheckSyncInfo API
 * @tc.type  : FUNC
 * @tc.number: CheckSyncInfo_001
 * @tc.desc  : Test AudioEndpointInner::CheckSyncInfo()
 */
HWTEST_F(AudioEndpointPlusUnitTest, CheckSyncInfo_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointnIner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    audioEndpointnIner->dstSpanSizeInframe_ = 0;
    audioEndpointnIner->CheckSyncInfo(100);
    EXPECT_EQ(audioEndpointnIner->dstSpanSizeInframe_, 0);
}

/*
 * @tc.name  : Test ProcessToDupStream API
 * @tc.type  : FUNC
 * @tc.number: ProcessToDupStream_001
 * @tc.desc  : Test AudioEndpointInner::ProcessToDupStream()
 */
HWTEST_F(AudioEndpointPlusUnitTest, ProcessToDupStream_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointnIner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    std::vector<AudioStreamData> audioDataList;
    AudioStreamData dstStreamData;
    int32_t innerCapId = 1;

    audioEndpointnIner->ProcessToDupStream(audioDataList, dstStreamData, innerCapId);
    EXPECT_EQ(innerCapId, 1);
}

/*
 * @tc.name  : Test ProcessToDupStream API
 * @tc.type  : FUNC
 * @tc.number: HandleDisableFastCap_001
 * @tc.desc  : Test AudioEndpointInner::HandleDisableFastCap()
 */
HWTEST_F(AudioEndpointPlusUnitTest, ProcessToDupStream_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);
    CaptureInfo captureInfo;
    
    EXPECT_EQ(audioEndpointInner->HandleDisableFastCap(captureInfo), SUCCESS);
}

/*
 * @tc.name  : Test SetMuteForSwitchDevice API
 * @tc.type  : FUNC
 * @tc.number: SetMuteForSwitchDevice_001
 * @tc.desc  : check SetMuteForSwitchDevice result
 */
HWTEST_F(AudioEndpointUnitTest, SetMuteForSwitchDevice_001, TestSize.Level1)
{
    std::shared_ptr<AudioEndpointInner> audioEndpointInner = CreateOutputEndpointInner(AudioEndpoint::TYPE_MMAP);
    audioEndpointInner->SetMuteForSwitchDevice(false);
    EXPECT_EQ(audioEndpointInner->SetMuteForSwitchDevice, false);
    
    audioEndpointInner->SetMuteForSwitchDevice(true);
    EXPECT_EQ(audioEndpointInner->SetMuteForSwitchDevice, true);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: GetAllReadyProcessDataSub_001
 * @tc.desc  : Test AudioEndpointInner::GetAllReadyProcessDataSub()
 */
HWTEST_F(AudioEndpointPlusUnitTest, GetAllReadyProcessDataSub_001, TestSize.Level4)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, TEST_ENDPOINT_ID, clientConfig.audioMode);

    auto processBuffer = std::make_shared<OHAudioBufferBase>(AudioBufferHolder::AUDIO_CLIENT, 0, 0);
    audioEndpointInner->processBufferList_.push_back(processBuffer);
    AudioStreamData dstStreamData;
    std::vector<AudioStreamData> audioDataList = {dstStreamData};
    BasicBufferInfo bufferInfo;
    processBuffer->basicBufferInfo_ = &bufferInfo;

    MockAudioProcessStream processServer;
    audioEndpointInner->processList_.push_back(&processServer);

    std::function<void()> moveClientIndex;
    EXPECT_CALL(processServer, PrepareRingBuffer(_, _, _)).WillOnce(Return(true));
    audioEndpointInner->GetAllReadyProcessDataSub(0, audioDataList, 0, moveClientIndex);

    EXPECT_CALL(processServer, PrepareRingBuffer(_, _, _)).WillOnce(Return(false));
    EXPECT_CALL(processServer, GetStreamStatus()).WillOnce(Return(StreamStatus::STREAM_RUNNING));
    EXPECT_CALL(processServer, AddNoDataFrameSize())
        .Times(1)
        .WillOnce(Return());
    audioEndpointInner->GetAllReadyProcessDataSub(0, audioDataList, 0, moveClientIndex);

    audioEndpointInner->SetMuteForSwitchDevice(true);
    EXPECT_CALL(processServer, PrepareRingBuffer(_, _, _)).WillOnce(Return(false));
    EXPECT_CALL(processServer, GetStreamStatus()).WillOnce(Return(StreamStatus::STREAM_RUNNING));
    EXPECT_CALL(processServer, AddNoDataFrameSize())
        .Times(1)
        .WillOnce(Return());
    audioEndpointInner->GetAllReadyProcessDataSub(0, audioDataList, 0, moveClientIndex);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: NotifyStreamChange_001
 * @tc.desc  : Test AudioEndpointInner::NotifyStreamChange() for playback
 */
HWTEST_F(AudioEndpointPlusUnitTest, NotifyStreamChange_001, TestSize.Level4)
{
    auto testEndpoint = std::make_shared<AudioEndpointInner>(
        AudioEndpoint::TYPE_MMAP, TEST_ENDPOINT_ID, AUDIO_MODE_PLAYBACK);

    // Call config to init sink
    AudioProcessConfig config = {};
    AudioDeviceDescriptor deviceInfo(AudioDeviceDescriptor::DEVICE_INFO);
    deviceInfo.deviceRole_ = DeviceRole::OUTPUT_DEVICE;
    AudioStreamInfo audioStreamInfo = { SAMPLE_RATE_48000, ENCODING_PCM, SAMPLE_S16LE, STEREO, CH_LAYOUT_STEREO };
    deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    std::string adapterName = "";
    bool isUltraFast = false;
    AudioEndpointConfig endpointConfig = {
        .deviceInfo = deviceInfo,
        .streamInfo = audioStreamInfo,
        .adapterName = adapterName,
        .audioMode = config.audioMode,
        .streamType = config.streamType,
        .isUltraFast = isUltraFast
    };
    testEndpoint->Config(endpointConfig);

    MockAudioProcessStream mockProcessStream;
    EXPECT_CALL(mockProcessStream, GetUsage()).WillOnce(Return(StreamUsage::STREAM_USAGE_MUSIC));
    testEndpoint->NotifyStreamChange(STREAM_CHANGE_TYPE_ADD, &mockProcessStream, RENDERER_PREPARED);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: NotifyStreamChange_002
 * @tc.desc  : Test AudioEndpointInner::NotifyStreamChange() for record
 */
HWTEST_F(AudioEndpointPlusUnitTest, NotifyStreamChange_002, TestSize.Level4)
{
    auto testEndpoint = std::make_shared<AudioEndpointInner>(
        AudioEndpoint::TYPE_MMAP, TEST_ENDPOINT_ID, AUDIO_MODE_RECORD);

    // Call config to init source
    AudioProcessConfig config = {};
    AudioDeviceDescriptor deviceInfo(AudioDeviceDescriptor::DEVICE_INFO);
    deviceInfo.deviceRole_ = DeviceRole::INPUT_DEVICE;
    AudioStreamInfo audioStreamInfo = { SAMPLE_RATE_48000, ENCODING_PCM, SAMPLE_S16LE, STEREO, CH_LAYOUT_STEREO };
    deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    std::string adapterName = "";
    bool isUltraFast = false;
    AudioEndpointConfig endpointConfig = {
        .deviceInfo = deviceInfo,
        .streamInfo = audioStreamInfo,
        .adapterName = adapterName,
        .audioMode = config.audioMode,
        .streamType = config.streamType,
        .isUltraFast = isUltraFast
    };
    testEndpoint->Config(endpointConfig);

    MockAudioProcessStream mockProcessStream;
    EXPECT_CALL(mockProcessStream, GetSource()).WillOnce(Return(SourceType::SOURCE_TYPE_MIC));
    testEndpoint->NotifyStreamChange(STREAM_CHANGE_TYPE_ADD, &mockProcessStream, RENDERER_PREPARED);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSourceAttr_001
 * @tc.desc  : Test AudioEndpointInner::InitSourceAttr()
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSourceAttr_001, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    IAudioSourceAttr attr;
    AudioDeviceDescriptor deviceInfo(AudioDeviceDescriptor::DEVICE_INFO);
    deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    deviceInfo.deviceType_ = DEVICE_TYPE_USB_ARM_HEADSET;
    attr = audioEndpointInner->InitSourceAttr(deviceInfo);
    EXPECT_EQ(attr.adapterName, "usb");

    deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    deviceInfo.deviceType_ = DEVICE_TYPE_MIC;
    attr = audioEndpointInner->InitSourceAttr(deviceInfo);
    EXPECT_EQ(attr.adapterName, "primary");

    deviceInfo.networkId_ = REMOTE_NETWORK_ID;
    attr = audioEndpointInner->InitSourceAttr(deviceInfo);
    EXPECT_EQ(attr.adapterName, "remote");
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_001
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with local network and USB device
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_001, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    // Set up dstStreamInfo_ for testing
    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_USB_ARM_HEADSET;
    endpointConfig.adapterName = "";
    endpointConfig.isUltraFast = false;
    audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);
    EXPECT_EQ(attr.adapterName, "usb");
    EXPECT_EQ(attr.sampleRate, SAMPLE_RATE_48000);
    EXPECT_EQ(attr.channel, STEREO);
    EXPECT_EQ(attr.format, SAMPLE_S16LE);
    EXPECT_EQ(attr.deviceNetworkId, LOCAL_NETWORK_ID);
    EXPECT_EQ(attr.deviceType, static_cast<int32_t>(DEVICE_TYPE_USB_ARM_HEADSET));
    EXPECT_EQ(attr.audioStreamFlag, AUDIO_FLAG_MMAP);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_002
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with local network and speaker device
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_002, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_SPEAKER;
    endpointConfig.adapterName = "";
    endpointConfig.isUltraFast = false;
    audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);
    EXPECT_EQ(attr.adapterName, "primary");
    EXPECT_EQ(attr.deviceNetworkId, LOCAL_NETWORK_ID);
    EXPECT_EQ(attr.deviceType, static_cast<int32_t>(DEVICE_TYPE_SPEAKER));
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_003
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with remote network
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_003, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = "remote_network_id";
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_BLUETOOTH_A2DP;
    endpointConfig.adapterName = "";
    endpointConfig.isUltraFast = false;
    audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);
    EXPECT_EQ(attr.adapterName, "remote");
    EXPECT_EQ(attr.deviceNetworkId, "remote_network_id");
    EXPECT_EQ(attr.deviceType, static_cast<int32_t>(DEVICE_TYPE_BLUETOOTH_A2DP));
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_004
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with DP adapter
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_004, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_SPEAKER;
    endpointConfig.adapterName = "dp";
    endpointConfig.isUltraFast = false;
    audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);
    EXPECT_EQ(attr.adapterName, "dp");
    EXPECT_EQ(attr.pin, AUDIO_PIN_OUT_DP);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_005
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with ultra fast enabled
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_005, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_SPEAKER;
    endpointConfig.adapterName = "";
    endpointConfig.isUltraFast = true;
    audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);

    // Calculate expected period for ultra fast
    int32_t expectedPeriod = static_cast<int32_t>(
        static_cast<float>(static_cast<int32_t>(SAMPLE_RATE_48000) * STEREO * GetFormatByteSize(SAMPLE_S16LE)) *
        ULTRA_FAST_PERIOD_TIME_IN_MS / static_cast<float>(MILLISECOND_PER_SECOND));

    EXPECT_EQ(attr.period, expectedPeriod);
    EXPECT_GT(attr.period, 0);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_006
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with VOIP_MMAP endpoint type
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_006, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_SPEAKER;
    endpointConfig.adapterName = "";
    endpointConfig.isUltraFast = false;
    audioEndpointInner->endpointType_ = AudioEndpoint::TYPE_VOIP_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);
    EXPECT_EQ(attr.audioStreamFlag, AUDIO_FLAG_VOIP_FAST);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_007
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with different stream formats
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_007, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    // Test different formats
    struct FormatTestCase {
        AudioSampleFormat format;
        int expectedByteSize;
    };
    std::vector<FormatTestCase> testCases = {
        {SAMPLE_S16LE, 2},
        {SAMPLE_S24LE, 3},
        {SAMPLE_S32LE, 4},
    };

    for (const auto& testCase : testCases) {
        audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
        audioEndpointInner->dstStreamInfo_.channels = STEREO;
        audioEndpointInner->dstStreamInfo_.format = testCase.format;

        AudioEndpointConfig endpointConfig;
        endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
        endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_SPEAKER;
        endpointConfig.adapterName = "";
        endpointConfig.isUltraFast = true;
        audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

        IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);

        EXPECT_EQ(attr.format, testCase.format);

        // Verify period calculation for ultra fast
        int32_t expectedPeriod = static_cast<int32_t>(
            static_cast<float>(static_cast<int32_t>(SAMPLE_RATE_48000) * STEREO * testCase.expectedByteSize) *
            ULTRA_FAST_PERIOD_TIME_IN_MS / static_cast<float>(MILLISECOND_PER_SECOND));

        EXPECT_EQ(attr.period, expectedPeriod);
    }
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_008
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with address from device info
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_008, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_BLUETOOTH_A2DP;
    endpointConfig.adapterName = "";
    endpointConfig.isUltraFast = false;
    endpointConfig.deviceInfo.macAddress_ = "00:11:22:33:44:55";
    audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);
    EXPECT_EQ(attr.address, "00:11:22:33:44:55");
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_009
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with DP adapter and ultra fast
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_009, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
    audioEndpointInner->dstStreamInfo_.channels = STEREO;
    audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

    AudioEndpointConfig endpointConfig;
    endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
    endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_SPEAKER;
    endpointConfig.adapterName = "dp";
    endpointConfig.isUltraFast = true;
    audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

    IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);

    // Should have both DP adapter and ultra fast period
    EXPECT_EQ(attr.adapterName, "dp");
    EXPECT_EQ(attr.pin, AUDIO_PIN_OUT_DP);
    int32_t sampleRate = 48000;
    int32_t expectedPeriod = static_cast<int32_t>(
        static_cast<float>(sampleRate * STEREO * GetFormatByteSize(SAMPLE_S16LE)) *
        ULTRA_FAST_PERIOD_TIME_IN_MS / static_cast<float>(MILLISECOND_PER_SECOND));

    EXPECT_EQ(attr.period, expectedPeriod);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: InitSinkAttr_010
 * @tc.desc  : Test AudioEndpointInner::InitSinkAttr() with different channel counts
 */
HWTEST_F(AudioEndpointPlusUnitTest, InitSinkAttr_010, TestSize.Level2)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    clientConfig.audioMode = AUDIO_MODE_PLAYBACK;

    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    // Test different channel counts
    struct ChannelTestCase {
        AudioChannel channels;
        int expectedChannelCount;
    };
    std::vector<ChannelTestCase> testCases = {
        {MONO, 1},
        {STEREO, 2},
    };

    for (const auto& testCase : testCases) {
        audioEndpointInner->dstStreamInfo_.samplingRate = SAMPLE_RATE_48000;
        audioEndpointInner->dstStreamInfo_.channels = testCase.channels;
        audioEndpointInner->dstStreamInfo_.format = SAMPLE_S16LE;

        AudioEndpointConfig endpointConfig;
        endpointConfig.deviceInfo.networkId_ = LOCAL_NETWORK_ID;
        endpointConfig.deviceInfo.deviceType_ = DEVICE_TYPE_SPEAKER;
        endpointConfig.adapterName = "";
        endpointConfig.isUltraFast = true;
        audioEndpointInner->endpointType_= AudioEndpoint::TYPE_MMAP;

        IAudioSinkAttr attr = audioEndpointInner->InitSinkAttr(endpointConfig);

        EXPECT_EQ(attr.channel, testCase.channels);

        // Verify period calculation includes channel count
        int32_t expectedPeriod = static_cast<int32_t>(static_cast<float>(static_cast<int32_t>(SAMPLE_RATE_48000) *
            testCase.expectedChannelCount * GetFormatByteSize(SAMPLE_S16LE)) * ULTRA_FAST_PERIOD_TIME_IN_MS /
            static_cast<float>(MILLISECOND_PER_SECOND));

        EXPECT_EQ(attr.period, expectedPeriod);
    }
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: CalculateVolume_006
 * @tc.desc  : Test CalculateVolume function with STREAM_SYSTEM_ENFORCED and valid volume
 */
 HWTEST_F(AudioEndpointPlusUnitTest, CalculateVolume_006, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    AudioStreamData dstStreamData;
    std::vector<AudioStreamData> audioDataList = {dstStreamData};
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    std::shared_ptr<OHAudioBufferBase> processBuffer = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    EXPECT_NE(processBuffer, nullptr);

    MockAudioProcessStream mockProcessStream;
    processBuffer->basicBufferInfo_ = std::make_shared<BasicBufferInfo>().get();
    EXPECT_NE(processBuffer->basicBufferInfo_, nullptr);
    EXPECT_CALL(mockProcessStream, GetAudioStreamType())
    .WillOnce(Return(STREAM_SYSTEM_ENFORCED));

    audioEndpointInner->processBufferList_.push_back(processBuffer);
    audioEndpointInner->processList_.push_back(&mockProcessStream);
    audioEndpointInner->deviceInfo_.networkId_ = LOCAL_NETWORK_ID;
    audioEndpointInner->deviceInfo_.deviceType_ = DEVICE_TYPE_SPEAKER;
    VolumeUtils::enforcedToneVolume_ = 0.5f;
    int32_t targetVolume = static_cast<int32_t>(VolumeUtils::enforcedToneVolume_ * SHARED_VOLUME_MAX);
    AudioEndpointInner::VolumeResult result = audioEndpointInner->CalculateVolume(0);
    EXPECT_EQ(result.volumeStart, targetVolume);
}

/*
 * @tc.name  : Test AudioEndpointInner API
 * @tc.type  : FUNC
 * @tc.number: CalculateVolume_007
 * @tc.desc  : Test CalculateVolume function with STREAM_SYSTEM_ENFORCED and invalid volume
 */
 HWTEST_F(AudioEndpointPlusUnitTest, CalculateVolume_007, TestSize.Level1)
{
    AudioEndpoint::EndpointType type = AudioEndpoint::TYPE_MMAP;
    uint64_t id = 123;
    AudioProcessConfig clientConfig = {};
    auto audioEndpointInner = std::make_shared<AudioEndpointInner>(type, id, clientConfig.audioMode);
    ASSERT_NE(audioEndpointInner, nullptr);

    AudioStreamData dstStreamData;
    std::vector<AudioStreamData> audioDataList = {dstStreamData};
    AudioBufferHolder bufferHolder = AudioBufferHolder::AUDIO_CLIENT;
    uint32_t totalSizeInFrame = 0;
    uint32_t byteSizePerFrame = 0;
    std::shared_ptr<OHAudioBufferBase> processBuffer = std::make_shared<OHAudioBufferBase>(bufferHolder,
        totalSizeInFrame, byteSizePerFrame);
    EXPECT_NE(processBuffer, nullptr);

    MockAudioProcessStream mockProcessStream;
    processBuffer->basicBufferInfo_ = std::make_shared<BasicBufferInfo>().get();
    EXPECT_NE(processBuffer->basicBufferInfo_, nullptr);
    EXPECT_CALL(mockProcessStream, GetAudioStreamType())
    .WillOnce(Return(STREAM_SYSTEM_ENFORCED));

    audioEndpointInner->processBufferList_.push_back(processBuffer);
    audioEndpointInner->processList_.push_back(&mockProcessStream);
    audioEndpointInner->deviceInfo_.networkId_ = LOCAL_NETWORK_ID;
    audioEndpointInner->deviceInfo_.deviceType_ = DEVICE_TYPE_SPEAKER;
    VolumeUtils::enforcedToneVolume_ = -1.0f;
    int32_t targetVolume = -1;
    AudioEndpointInner::VolumeResult result = audioEndpointInner->CalculateVolume(0);
    EXPECT_NE(result.volumeStart, targetVolume);
}
} // namespace AudioStandard
} // namespace OHOS
