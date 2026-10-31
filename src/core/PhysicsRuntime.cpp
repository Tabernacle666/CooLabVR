#include "PhysicsRuntime.h"
#include "PhysicsCuda.h"
#include "PopulationCuda.h"
#include "Core.h"
#include "SessionLog.h"
#include "ConsoleSpec.h"
#include <cudamanager/PxCudaContextManager.h>
#include <extensions/PxDefaultCpuDispatcher.h>
#include <extensions/PxRigidBodyExt.h>
#include <extensions/PxD6Joint.h>
#include <cuda.h>
#include <d3d12.h>
#include <algorithm>
#include <array>
#include <atomic>
#include <cmath>
#include <cstring>
#include <map>
#include <span>
#include <vector>

namespace lab {
using namespace physx;
namespace {
void Cuda(cudaError_t result,const char* operation){if(result!=cudaSuccess){char message[512];snprintf(message,sizeof(message),"PhysX CUDA: %s: %s",operation,cudaGetErrorString(result));Fail(message);}}
void Driver(CUresult result,const char* operation){if(result!=CUDA_SUCCESS){const char* error{};cuGetErrorString(result,&error);char message[512];snprintf(message,sizeof(message),"PhysX CUDA driver: %s: %s",operation,error?error:"unknown");Fail(message);}}
void Gpu(bool result,const char* operation){if(!result)Fail(operation);}
PxVec3 V(LabVec3V1 v){return {v.x,v.y,v.z};}
PxTransform P(LabPoseV1 p){return {V(p.position),{p.orientation.x,p.orientation.y,p.orientation.z,p.orientation.w}};}
bool Finite(float v){return std::isfinite(v);}
bool Valid(LabVec3V1 v){return Finite(v.x)&&Finite(v.y)&&Finite(v.z);}
bool Valid(LabPoseV1 p){return Valid(p.position)&&P(p).isSane();}
bool PoseChanged(const PxTransform& a,const PxTransform& b){
    // Compare components, including q/-q equivalence: dot(q,q) can round below
    // one even for identical poses and must not mark untouched actors as edited.
    auto q=b.q;if(a.q.dot(q)<0)q=-q;
    return (a.p-b.p).magnitudeSquared()>1e-14f||(a.q-q).magnitudeSquared()>1e-14f;
}
bool ValidFlight(const LabFlightSettingsV1& f){
    if(f.structSize<sizeof(f))return false;
    const float values[]{f.nominalSpeed,f.maxSpeed,f.responseSeconds,f.turnIntensity,f.turnRadius,f.lightAttraction,f.comfortDistance,f.anticipationDistance,f.wander,f.vertical,f.avoidanceFailure,f.impactSeconds,f.impactMultiplier,f.mass,f.wingArea,f.liftCoefficient,f.dragCoefficient,f.wingFrequency,f.bodyRadius,f.detailDistance,f.nearDistance};
    for(float v:values)if(!Finite(v)||v<0)return false;
    return f.mass>=1e-7f&&f.mass<=.01f&&f.wingArea>=1e-8f&&f.wingArea<=.01f&&f.liftCoefficient<=8&&f.dragCoefficient<=8&&f.wingFrequency<=500&&f.responseSeconds<=2&&f.turnIntensity<=8&&f.turnRadius<=4&&f.lightAttraction<=8&&f.comfortDistance<=2&&f.anticipationDistance<=4&&f.wander<=4&&f.vertical<=4&&f.impactMultiplier<=10&&f.bodyRadius<=.1f&&f.detailDistance<=8&&f.nearDistance<=8&&f.nominalSpeed>0&&f.maxSpeed>=f.nominalSpeed&&f.maxSpeed<=12&&f.responseSeconds>=.02f&&f.turnIntensity>0&&f.turnRadius>=.02f&&f.comfortDistance>=.02f&&f.anticipationDistance>=f.comfortDistance&&f.avoidanceFailure<=1&&f.impactSeconds<=120&&f.impactMultiplier>=1&&f.mass>0&&f.wingArea>0&&f.liftCoefficient>0&&f.wingFrequency>0&&f.bodyRadius>=.001f;
}
template<class T> void Allocate(T*& p,size_t n){Cuda(cudaMalloc(reinterpret_cast<void**>(&p),n*sizeof(T)),"allocate scene buffer");}
template<class T> void Upload(cudaStream_t stream,T* device,const std::vector<T>& host){if(!host.empty())Cuda(cudaMemcpyAsync(device,host.data(),host.size()*sizeof(T),cudaMemcpyHostToDevice,stream),"upload scene descriptors");}
PxFilterFlags Filter(PxFilterObjectAttributes,PxFilterData a,PxFilterObjectAttributes,PxFilterData b,PxPairFlags& flags,const void*,PxU32){
    if(!(a.word0&b.word1)||!(b.word0&a.word1)||(a.word2&&a.word2==b.word2))return PxFilterFlag::eSUPPRESS;
    flags=PxPairFlag::eCONTACT_DEFAULT|PxPairFlag::eNOTIFY_CONTACT_POINTS;return PxFilterFlag::eDEFAULT;
}
struct Errors final:PxErrorCallback {
    std::atomic<bool> failed{};
    void reportError(PxErrorCode::Enum code,const char* message,const char* file,int line)override{
        LogEvent(0,"physics.error","code=%u file=%s line=%d message=%s",unsigned(code),file,line,message);
        switch(code){
            case PxErrorCode::eNO_ERROR:
            case PxErrorCode::eDEBUG_INFO:
            case PxErrorCode::eDEBUG_WARNING:
            case PxErrorCode::ePERF_WARNING:return;
            default:failed=true;OutputDebugStringA(message);OutputDebugStringA("\n");break;
        }
    }
};
struct SharedBuffer {
    LabGpuInteropResourceHandleV1 handle{};cudaExternalMemory_t memory{};void* pointer{};uint64_t bytes{};
    void Create(const LabGpuInteropServiceV1& interop,uint64_t size){
        bytes=size;Gpu(interop.CreateSharedBuffer(interop.serviceContext,size,&handle)!=0,"PhysX: shared DX12 buffer creation failed");
        LabGpuInteropMemoryExportV1 out{sizeof(out)};Gpu(interop.GetCudaMemoryHandle(interop.serviceContext,handle,&out)!=0,"PhysX: DX12 memory export failed");
        cudaExternalMemoryHandleDesc d{};d.type=cudaExternalMemoryHandleTypeD3D12Resource;d.handle.win32.handle=out.win32Handle;d.size=out.allocationBytes;d.flags=cudaExternalMemoryDedicated;
        auto result=cudaImportExternalMemory(&memory,&d);CloseHandle(out.win32Handle);Cuda(result,"import DX12 resource");
        cudaExternalMemoryBufferDesc b{};b.size=out.resourceBytes;Cuda(cudaExternalMemoryGetMappedBuffer(&pointer,memory,&b),"map DX12 resource");
    }
    void Destroy(const LabGpuInteropServiceV1& interop){if(pointer)Cuda(cudaFree(pointer),"unmap DX12 buffer");if(memory)Cuda(cudaDestroyExternalMemory(memory),"release DX12 import");if(handle)interop.ReleaseResource(interop.serviceContext,handle);*this={};}
};
struct SharedFence {
    LabGpuInteropFenceHandleV1 handle{};cudaExternalSemaphore_t semaphore{};
    void Create(const LabGpuInteropServiceV1& interop){
        Gpu(interop.CreateSharedFence(interop.serviceContext,0,&handle)!=0,"PhysX: shared DX12 fence creation failed");
        LabGpuInteropFenceExportV1 out{sizeof(out)};Gpu(interop.GetCudaFenceHandle(interop.serviceContext,handle,1,&out)!=0,"PhysX: DX12 fence export failed");
        cudaExternalSemaphoreHandleDesc d{};d.type=cudaExternalSemaphoreHandleTypeD3D12Fence;d.handle.win32.handle=out.win32Handle;
        auto result=cudaImportExternalSemaphore(&semaphore,&d);CloseHandle(out.win32Handle);Cuda(result,"import DX12 fence");
    }
    uint64_t Completed(const LabGpuInteropServiceV1& interop){LabGpuInteropFenceExportV1 out{sizeof(out)};Gpu(interop.GetCudaFenceHandle(interop.serviceContext,handle,0,&out)!=0,"PhysX: query DX12 fence failed");return out.completedValue;}
    void Wait(cudaStream_t stream,uint64_t value){if(value){cudaExternalSemaphoreWaitParams p{};p.params.fence.value=value;Cuda(cudaWaitExternalSemaphoresAsync(&semaphore,&p,1,stream),"wait DX12 consumer");}}
    void Signal(cudaStream_t stream,uint64_t value){cudaExternalSemaphoreSignalParams p{};p.params.fence.value=value;Cuda(cudaSignalExternalSemaphoresAsync(&semaphore,&p,1,stream),"signal CUDA producer");}
    void Destroy(const LabGpuInteropServiceV1& interop){if(semaphore)Cuda(cudaDestroyExternalSemaphore(semaphore),"release fence import");if(handle)interop.ReleaseFence(interop.serviceContext,handle);*this={};}
};
}
struct PhysicsRuntime::Impl {
    struct Owner;
    PxDefaultAllocator allocator;Errors errors;
    PxFoundation* foundation{};PxPhysics* physics{};PxCudaContextManager* cuda{};PxDefaultCpuDispatcher* dispatcher{};bool extensions{};
    uint32_t nextGeneration{1};uint64_t nextOwner{1},nextLeaseGeneration{1};
    struct Body {LabPhysicsBodyV1 handle{};PxRigidActor* actor{};PxMaterial* material{};PxConvexMesh* convex{};PxTransform initial{PxIdentity},committed{PxIdentity};uint32_t index{PhysicsInvalidIndex},collisionMask{};LabPhysicsBodyDescV1 geometry{};bool kinematic{},collisionEnabled{true};PxTransform lastTarget{PxIdentity};};
    struct Joint {LabPhysicsJointV1 handle{};PxD6Joint* joint{};LabPhysicsMotorV1 motor{};LabPhysicsD6DescV1 description{};LabPoseV1 committedFrameA{},committedFrameB{};double motorPhase{};};
    struct Scene {
        Impl& runtime;Owner& owner;LabPhysicsSceneV1 handle{};LabPhysicsSceneDescV1 desc{};PxScene* scene{};
        cudaStream_t stream{};CUevent uploadReady{},poseReady{},velocityReady{},stateReady{},forceReady{},forceDone{},torqueDone{},contactReady{};
        PxRigidDynamicGPUIndex* indices{};PxTransform *previous{},*current{};PxVec3 *velocity{},*angular{},*forces{},*torques{};
        LabPopulationEffectsV1 populationEffects{sizeof(LabPopulationEffectsV1),0,.18f,1.f,12.f,1.3f,.55f,.7f,.35f};
        LabPopulationHandsV1 populationHands{sizeof(LabPopulationHandsV1)};
        LabPopulationDescV1 population{};LabPopulationInputV1 populationInput{sizeof(LabPopulationInputV1),1};
        PopulationStateGpu* insects{};PopulationBodyGpu* populationBodies{};PopulationBodyPoseGpu* populationBodyPoses{};uint32_t* populationGrid{};PopulationSummaryGpu* populationSummary{};
        std::vector<PopulationBodyGpu> populationBodyHost;
        uint32_t insectCount{},insectCapacity{},birthGeneration{};double insectAccumulator{},populationClockOrigin{};bool populationClockStarted{};
        struct PopulationReadback {LabPopulationSnapshotV1* host{};cudaEvent_t done{};bool pending{};uint64_t sequence{};};
        std::array<PopulationReadback,3> populationReadbacks;uint32_t populationReadCursor{};uint64_t populationReadSequence{},populationPolledSequence{};
        uint32_t ConfigurePopulation(const LabPopulationDescV1&);uint32_t ResizePopulation(uint32_t);uint32_t PollPopulation(LabPopulationSnapshotV1*);
        void StepPopulation();void QueuePopulationReadback();
        PhysicsAirflowGpu* airflowDevice{};PhysicsDragGpu* dragDevice{};
        std::vector<LabPhysicsAirflowV1> airflows;std::vector<PhysicsAirflowGpu> airflowHost;std::vector<PhysicsDragGpu> dragHost;
        LabPopulationSpaceV1 populationSpace{sizeof(LabPopulationSpaceV1),0,{},{1,1,1},1};
        PhysicsVisualGpu* visualDevice{};PhysicsLightGpu* lightDevice{};PhysicsAeroGpu* aeroDevice{};PhysicsProbeGpu* probeDevice{};PhysicsActorGpu* actorDevice{};
        PxGpuContactPair* contacts{};uint32_t* contactCount{};LabPhysicsStateV1* probeOutput{};
        std::vector<Body> bodies;std::vector<Joint> joints;std::vector<PxRigidDynamicGPUIndex> indexHost;
        PxVec3 *forceHost{},*torqueHost{};
        PxTransform *editPoseHost{},*editPoseDevice{};PxRigidDynamicGPUIndex *editIndexHost{},*editIndexDevice{};PxVec3* editZeroDevice{};
        std::vector<LabPhysicsCommandV1> commands;std::vector<LabPhysicsAeroSurfaceV1> aero;
        std::vector<LabPhysicsVisualV1> visuals;std::vector<LabPhysicsLightV1> lights;std::vector<LabPhysicsBodyV1> probes;
        std::vector<PhysicsVisualGpu> visualHost;std::vector<PhysicsLightGpu> lightHost;std::vector<PhysicsAeroGpu> aeroHost;std::vector<PhysicsProbeGpu> probeHost;std::vector<PhysicsActorGpu> actorHost;
        bool paused{},edited{};
        bool topologyDirty{true},descriptorsDirty{true},started{},visible{true};uint32_t dynamicCount{};
        double populationSeconds{},accumulator{},lastTime{},simulationTime{},droppedSeconds{};uint64_t tick{},frame{};float alpha{};
        static constexpr uint32_t ContactCapacity=1024,MaxVisuals=2048,MaxLights=32;
        struct PublicationSlot {
            SharedBuffer instances,control,lighting;SharedFence producer,consumer;
            std::vector<LabGpuResourceRefV1> refs;
            uint64_t value{},leaseGeneration{};bool leased{};
        };
        std::array<PublicationSlot,3> slots;uint32_t publicationCursor{};
        struct ProbeSlot {LabPhysicsStateV1* host{};uint32_t* overflow{};cudaEvent_t done{},gpuBegin{},gpuEnd{};bool pending{};uint64_t tick{},frame{};double seconds{};uint32_t count{};};
        std::array<ProbeSlot,3> probeSlots;uint32_t probeCursor{};uint64_t lastProbeFrame{},publicationSequence{};
        struct Timing {cudaEvent_t begin{},end{};bool pending{};uint64_t frame{},tick{},value{};};
        std::array<Timing,3> timings;uint32_t timingCursor{};
        std::array<Timing,48> stepTimings;uint32_t stepTimingCursor{};
        std::array<Timing,6> publicationTimings;uint32_t publicationTimingCursor{};
        uint64_t publicationBackpressureCount{};
        double frameCommandWaitMs{},frameFetchBlockingMs{},frameTopologyWaitMs{};
        uint32_t frameUntimedSteps{};
        // Compact diagnostic, counters only; no GPU queries, waits or per-frame files.
        struct DiagnosticProfile {
            uint64_t frames{},steps{},fetchBlocked{},droppedFrames{};
            uint64_t deviceZeroSteps{},hostUploadSteps{};
            uint64_t gpuStepSamples{},gpuFrameSamples{},untimedGpuSteps{};
            double gpuStepSumMs{},gpuStepPeakMs{},gpuFrameSumMs{},gpuFramePeakMs{};
            double frameCpuMs{},stepCpuMs{},maxStepCpuMs{},contextLockMs{};
            double commandWaitMs{},fetchBlockedMs{},fetchReadyMs{},topologyWaitMs{};
            double simulateSubmitMs{},populationSubmitMs{},postFetchCpuMs{},forceInitSubmitMs{};
        } diagnostic;
        LabGpuPublicationProviderV1 provider{};std::vector<LabU32> streamMaterials;
        Scene(Impl& r,Owner& o,LabPhysicsSceneV1 h,const LabPhysicsSceneDescV1& d):runtime(r),owner(o),handle(h),desc(d){}
        void Initialize();void Destroy();
        Body* FindBody(LabPhysicsBodyV1 h){uint32_t i=uint32_t(h)-1;return h&&i<bodies.size()&&bodies[i].handle==h&&bodies[i].actor?&bodies[i]:nullptr;}
        Joint* FindJoint(LabPhysicsJointV1 h){uint32_t i=uint32_t(h)-1;return h&&i<joints.size()&&joints[i].handle==h&&joints[i].joint?&joints[i]:nullptr;}
        uint32_t CreateBody(const LabPhysicsBodyDescV1&,LabPhysicsBodyV1*);uint32_t DestroyBody(LabPhysicsBodyV1);
        uint32_t SetBodyCollisionEnabled(LabPhysicsBodyV1,bool);
        uint32_t CreateD6(const LabPhysicsD6DescV1&,LabPhysicsJointV1*);uint32_t ConfigureD6(LabPhysicsJointV1,const LabPhysicsD6DescV1&);uint32_t DestroyJoint(LabPhysicsJointV1);
        uint32_t Pause(bool);uint32_t EditSnapshot(LabPhysicsEditSnapshotV1*);uint32_t Edit(const LabPhysicsEditBatchV1&);uint32_t Translate(const LabPhysicsBodyV1*,uint32_t,LabVec3V1);uint32_t ValidateEdit(LabPhysicsEditValidationV1*);void CaptureEditPoses();void WriteEditPoses();void CommitEditPoses();
        void RefreshIndices();void RefreshDescriptors();void ReadState(bool first);void Step(float);void Advance(double,uint64_t);
        Timing* BeginTiming(std::span<Timing>,uint32_t&,uint64_t=0,uint64_t=0);
        void CollectTimings();
        uint32_t SetVisuals(const LabPhysicsVisualV1*,uint32_t,const LabPhysicsLightV1*,uint32_t);
        void DestroyPublications();uint32_t Acquire(LabGpuPublicationV1*);void Release(void*,uint64_t);
        void QueueProbe();uint32_t Poll(LabPhysicsSnapshotV1*);
    };
    struct Owner {Impl* runtime{};uint64_t id{};LabGpuInteropServiceV1 interop{};LabPhysicsServiceV1 service{};std::map<LabPhysicsSceneV1,std::unique_ptr<Scene>> scenes;};
    std::map<uint64_t,std::unique_ptr<Owner>> owners;
    uint32_t Generation(){if(nextGeneration==UINT32_MAX)Fail("PhysX handle generations exhausted");return nextGeneration++;}
    uint64_t LeaseGeneration(){if(nextLeaseGeneration==UINT64_MAX)Fail("PhysX publication lease generations exhausted");return nextLeaseGeneration++;}
    Scene* Find(Owner& o,LabPhysicsSceneV1 h){auto it=o.scenes.find(h);return it==o.scenes.end()?nullptr:it->second.get();}
    void Check(){if(errors.failed.load()||!cuda||!cuda->contextIsValid())Fail("PhysX GPU contract failed; CPU fallback is forbidden (inspect physics.error)");}
};

void PhysicsRuntime::Impl::Scene::Initialize(){
    PxSceneDesc d(runtime.physics->getTolerancesScale());d.gravity=V(desc.gravity);d.cpuDispatcher=runtime.dispatcher;d.cudaContextManager=runtime.cuda;d.filterShader=Filter;
    d.flags|=PxSceneFlag::eENABLE_GPU_DYNAMICS|PxSceneFlag::eENABLE_DIRECT_GPU_API|PxSceneFlag::eDISABLE_SLEEPING|PxSceneFlag::eENABLE_PCM;
    d.broadPhaseType=PxBroadPhaseType::eGPU;d.solverType=PxSolverType::eTGS;
    // Preallocation scales with the declared scene limit; overflows are errors,
    // never permission to drop contacts silently or substitute a CPU scene.
    d.gpuDynamicsConfig.foundLostPairsCapacity=std::max(1024u,desc.maxBodies*16);
    d.gpuDynamicsConfig.foundLostAggregatePairsCapacity=1024;
    d.gpuDynamicsConfig.totalAggregatePairsCapacity=1024;
    d.gpuDynamicsConfig.heapCapacity=16*1024*1024;d.gpuDynamicsConfig.tempBufferCapacity=4*1024*1024;
    if(!d.isValid())Fail("PhysX GPU scene descriptor is invalid");
    scene=runtime.physics->createScene(d);runtime.Check();
    if(!scene||!scene->getFlags().isSet(PxSceneFlag::eENABLE_GPU_DYNAMICS)||!scene->getFlags().isSet(PxSceneFlag::eENABLE_DIRECT_GPU_API)||!scene->getFlags().isSet(PxSceneFlag::eDISABLE_SLEEPING)||!scene->getFlags().isSet(PxSceneFlag::eENABLE_PCM)||scene->getBroadPhaseType()!=PxBroadPhaseType::eGPU||scene->getSolverType()!=PxSolverType::eTGS||scene->getCudaContextManager()!=runtime.cuda)Fail("PhysX: scene did not retain the required CUDA GPU/TGS contract");
    PxScopedCudaLock lock(*runtime.cuda);Cuda(cudaStreamCreateWithFlags(&stream,cudaStreamNonBlocking),"create physics command stream");
    for(auto* e:{&uploadReady,&poseReady,&velocityReady,&stateReady,&forceReady,&forceDone,&torqueDone,&contactReady})Driver(cuEventCreate(e,CU_EVENT_DISABLE_TIMING),"create direct GPU API event");
    Allocate(indices,desc.maxBodies);Allocate(previous,desc.maxBodies);Allocate(current,desc.maxBodies);Allocate(velocity,desc.maxBodies);Allocate(angular,desc.maxBodies);Allocate(forces,desc.maxBodies);Allocate(torques,desc.maxBodies);
    Allocate(editPoseDevice,desc.maxBodies);Allocate(editIndexDevice,desc.maxBodies);Allocate(editZeroDevice,desc.maxBodies);
    Cuda(cudaMemsetAsync(editZeroDevice,0,desc.maxBodies*sizeof(PxVec3),stream),"initialize editor zero motion");
    Cuda(cudaHostAlloc(reinterpret_cast<void**>(&editPoseHost),desc.maxBodies*sizeof(PxTransform),cudaHostAllocDefault),"allocate editor pose staging");
    Cuda(cudaHostAlloc(reinterpret_cast<void**>(&editIndexHost),desc.maxBodies*sizeof(PxRigidDynamicGPUIndex),cudaHostAllocDefault),"allocate editor index staging");
    Allocate(airflowDevice,8);Allocate(dragDevice,desc.maxBodies);
    Allocate(visualDevice,MaxVisuals);Allocate(lightDevice,MaxLights);Allocate(aeroDevice,desc.maxBodies);Allocate(probeDevice,LABOVR_PHYSICS_MAX_PROBES_V1);Allocate(actorDevice,desc.maxBodies);
    Allocate(populationBodies,desc.maxBodies);Allocate(populationSummary,1);
    for(auto& r:populationReadbacks){Cuda(cudaHostAlloc(reinterpret_cast<void**>(&r.host),sizeof(LabPopulationSnapshotV1),cudaHostAllocDefault),"allocate compact population readback");Cuda(cudaEventCreateWithFlags(&r.done,cudaEventDisableTiming),"population readback event");}
    Allocate(contacts,ContactCapacity);Allocate(contactCount,1);Allocate(probeOutput,LABOVR_PHYSICS_MAX_PROBES_V1);
    streamMaterials.reserve(MaxVisuals);bodies.reserve(desc.maxBodies);joints.reserve(desc.maxBodies*2);commands.reserve(desc.maxBodies*4);indexHost.reserve(desc.maxBodies);actorHost.reserve(desc.maxBodies);
    // Pinned command arrays avoid the staging/synchronization that pageable
    // host memory can introduce into every fixed step's async uploads. The
    // torqueDone dependency retires both uploads before these arrays are reused.
    Cuda(cudaHostAlloc(reinterpret_cast<void**>(&forceHost),desc.maxBodies*sizeof(PxVec3),cudaHostAllocDefault),"allocate pinned batched forces");
    Cuda(cudaHostAlloc(reinterpret_cast<void**>(&torqueHost),desc.maxBodies*sizeof(PxVec3),cudaHostAllocDefault),"allocate pinned batched torques");
    std::uninitialized_fill_n(forceHost,desc.maxBodies,PxVec3(0));std::uninitialized_fill_n(torqueHost,desc.maxBodies,PxVec3(0));
    for(auto& p:probeSlots){Cuda(cudaHostAlloc(reinterpret_cast<void**>(&p.host),sizeof(LabPhysicsStateV1)*LABOVR_PHYSICS_MAX_PROBES_V1,cudaHostAllocDefault),"allocate asynchronous probe readback");Cuda(cudaHostAlloc(reinterpret_cast<void**>(&p.overflow),sizeof(uint32_t),cudaHostAllocDefault),"allocate contact count readback");Cuda(cudaEventCreateWithFlags(&p.done,cudaEventDisableTiming),"create probe completion");Cuda(cudaEventCreate(&p.gpuBegin),"create GPU timing start");Cuda(cudaEventCreate(&p.gpuEnd),"create GPU timing end");}
    for(auto pool:{std::span<Timing>(timings),std::span<Timing>(stepTimings),std::span<Timing>(publicationTimings)})for(auto& t:pool){Cuda(cudaEventCreate(&t.begin),"create physics GPU span start");Cuda(cudaEventCreate(&t.end),"create physics GPU span end");}
    provider={LABOVR_GPU_ABI_V1,sizeof(provider),this,
        [](void* c,LabGpuPublicationV1* out)->LabU32{return c?static_cast<Scene*>(c)->Acquire(out):0;},
        [](void* c,void* token,LabU64 generation){if(c)static_cast<Scene*>(c)->Release(token,generation);},LABOVR_GPU_DOMAIN_MESH_SOLID_V1,0};
    provider.reserved=LABOVR_GPU_PROVIDER_REBASED_MATERIALS_V1;
    LogEvent(0,"physics.scene","scene=%llu gpu_dynamics=1 gpu_broadphase=1 direct_gpu_api=1 solver=TGS fixed_dt=%.8f capacity=%u",static_cast<unsigned long long>(handle),desc.fixedStepSeconds,desc.maxBodies);
}
void PhysicsRuntime::Impl::Scene::DestroyPublications(){
    for(auto& s:slots){if(s.leased)Fail("PhysX: destroying a publication still acquired by its client");if(s.value)s.consumer.Wait(stream,s.value);}
    Cuda(cudaStreamSynchronize(stream),"retire scene publications");
    for(auto& s:slots){s.instances.Destroy(owner.interop);s.control.Destroy(owner.interop);s.lighting.Destroy(owner.interop);s.producer.Destroy(owner.interop);s.consumer.Destroy(owner.interop);s.refs.clear();s.value=s.leaseGeneration=0;}
}
void PhysicsRuntime::Impl::Scene::Destroy(){
    if(SessionLogCompact()&&diagnostic.frames){
        const auto& p=diagnostic;
        const double invFrames=1./double(p.frames),invSteps=p.steps?1./double(p.steps):0.;
        LogEvent(0,"physics.profile.cpu",
            "frames=%llu steps=%llu steps_per_frame=%.3f fixed_dt_ms=%.3f max_substeps=%u dropped_frames=%llu dropped_s=%.6f frame_avg_ms=%.3f step_avg_ms=%.3f step_peak_ms=%.3f lock_avg_ms=%.3f",
            static_cast<unsigned long long>(p.frames),static_cast<unsigned long long>(p.steps),
            double(p.steps)*invFrames,double(desc.fixedStepSeconds)*1000.,desc.maxSubsteps,static_cast<unsigned long long>(p.droppedFrames),
            droppedSeconds,p.frameCpuMs*invFrames,p.stepCpuMs*invSteps,p.maxStepCpuMs,p.contextLockMs*invFrames);
        LogEvent(0,"physics.profile.wait",
            "fetch_blocked_steps=%llu fetch_blocked_total_ms=%.3f fetch_ready_total_ms=%.3f command_wait_total_ms=%.3f topology_wait_total_ms=%.3f",
            static_cast<unsigned long long>(p.fetchBlocked),p.fetchBlockedMs,p.fetchReadyMs,p.commandWaitMs,p.topologyWaitMs);
        LogEvent(0,"physics.profile.submit",
            "simulate_avg_ms=%.3f population_avg_ms=%.3f post_fetch_avg_ms=%.3f",
            p.simulateSubmitMs*invSteps,p.populationSubmitMs*invSteps,p.postFetchCpuMs*invSteps);
        const uint64_t forceSteps=p.deviceZeroSteps+p.hostUploadSteps;
        LogEvent(0,"physics.profile.transfer",
            "device_zero_steps=%llu host_upload_steps=%llu active_force_steps=%llu force_init_submit_avg_ms=%.4f",
            static_cast<unsigned long long>(p.deviceZeroSteps),
            static_cast<unsigned long long>(p.hostUploadSteps),
            static_cast<unsigned long long>(forceSteps),
            forceSteps?p.forceInitSubmitMs/double(forceSteps):0.);
    }
    {PxScopedCudaLock lock(*runtime.cuda);DestroyPublications();Cuda(cudaStreamSynchronize(stream),"retire physics scene");
    cudaFreeHost(forceHost);cudaFreeHost(torqueHost);cudaFreeHost(editPoseHost);cudaFreeHost(editIndexHost);cudaFree(editPoseDevice);cudaFree(editIndexDevice);cudaFree(editZeroDevice);
    if(insects)cudaFree(insects);cudaFree(populationBodies);if(populationBodyPoses)cudaFree(populationBodyPoses);if(populationGrid)cudaFree(populationGrid);cudaFree(populationSummary);for(auto& r:populationReadbacks){cudaFreeHost(r.host);cudaEventDestroy(r.done);}
    for(auto& p:probeSlots){cudaFreeHost(p.host);cudaFreeHost(p.overflow);cudaEventDestroy(p.done);cudaEventDestroy(p.gpuBegin);cudaEventDestroy(p.gpuEnd);}
    CollectTimings();
    if(SessionLogCompact()&&diagnostic.frames){
        const auto& p=diagnostic;
        LogEvent(0,"physics.profile.gpu",
            "step_samples=%llu step_untimed=%llu step_avg_span_ms=%.3f step_peak_span_ms=%.3f frame_samples=%llu frame_avg_span_ms=%.3f frame_peak_span_ms=%.3f",
            static_cast<unsigned long long>(p.gpuStepSamples),
            static_cast<unsigned long long>(p.untimedGpuSteps),
            p.gpuStepSamples?p.gpuStepSumMs/double(p.gpuStepSamples):0.,
            p.gpuStepPeakMs,
            static_cast<unsigned long long>(p.gpuFrameSamples),
            p.gpuFrameSamples?p.gpuFrameSumMs/double(p.gpuFrameSamples):0.,
            p.gpuFramePeakMs);
    }
    for(auto pool:{std::span<Timing>(timings),std::span<Timing>(stepTimings),std::span<Timing>(publicationTimings)})for(auto& t:pool){cudaEventDestroy(t.begin);cudaEventDestroy(t.end);}
    for(void* p:{static_cast<void*>(airflowDevice),static_cast<void*>(dragDevice),static_cast<void*>(indices),static_cast<void*>(previous),static_cast<void*>(current),static_cast<void*>(velocity),static_cast<void*>(angular),static_cast<void*>(forces),static_cast<void*>(torques),static_cast<void*>(visualDevice),static_cast<void*>(lightDevice),static_cast<void*>(aeroDevice),static_cast<void*>(probeDevice),static_cast<void*>(actorDevice),static_cast<void*>(contacts),static_cast<void*>(contactCount),static_cast<void*>(probeOutput)})if(p)cudaFree(p);
    for(auto e:{uploadReady,poseReady,velocityReady,stateReady,forceReady,forceDone,torqueDone,contactReady})if(e)cuEventDestroy(e);if(stream)cudaStreamDestroy(stream);}
    for(auto& j:joints)if(j.joint)j.joint->release();
    for(auto& b:bodies){if(b.actor)b.actor->release();if(b.material)b.material->release();if(b.convex)b.convex->release();}
    if(scene)scene->release();scene=nullptr;
}
uint32_t PhysicsRuntime::Impl::Scene::CreateBody(const LabPhysicsBodyDescV1& d,LabPhysicsBodyV1* out){
    if(!out||paused&&started)return 0;*out=0;
    if(d.structSize<sizeof(d)||d.kind>LAB_PHYSICS_KINEMATIC||d.shape>LAB_PHYSICS_CONVEX||!Valid(d.pose)||!Valid(d.shapePose)||!Valid(d.dimensions)||d.layer==0||!Finite(d.mass)||!Finite(d.contactOffset)||d.contactOffset<=d.restOffset||d.contactOffset<=0||!Finite(d.staticFriction)||!Finite(d.dynamicFriction)||d.staticFriction<0||d.dynamicFriction<0||!Finite(d.restitution)||d.restitution<0||d.restitution>1||!Finite(d.linearDamping)||!Finite(d.angularDamping)||d.linearDamping<0||d.angularDamping<0)return 0;
    if(d.kind!=LAB_PHYSICS_STATIC&&d.mass<=0)return 0;
    if(insectCapacity&&d.shape==LAB_PHYSICS_CONVEX)return 0;
    uint32_t slot=0;while(slot<bodies.size()&&bodies[slot].actor)++slot;if(slot>=desc.maxBodies)return 0;
    {PxScopedCudaLock lock(*runtime.cuda);Cuda(cudaStreamSynchronize(stream),"retire actor creation consumers");}
    if(slot==bodies.size())bodies.emplace_back();Body b;b.geometry=d;b.geometry.convexVertices=nullptr;b.initial=P(d.pose).getNormalized();b.committed=b.initial;b.lastTarget=b.initial;b.kinematic=d.kind==LAB_PHYSICS_KINEMATIC;b.collisionMask=d.collisionMask;
    b.material=runtime.physics->createMaterial(d.staticFriction,d.dynamicFriction,d.restitution);if(!b.material)return 0;
    PxShape* shape{};
    if(d.shape==LAB_PHYSICS_BOX&&d.dimensions.x>0&&d.dimensions.y>0&&d.dimensions.z>0)shape=runtime.physics->createShape(PxBoxGeometry(V(d.dimensions)),*b.material,true);
    if(d.shape==LAB_PHYSICS_SPHERE&&d.dimensions.x>0)shape=runtime.physics->createShape(PxSphereGeometry(d.dimensions.x),*b.material,true);
    if(d.shape==LAB_PHYSICS_CAPSULE&&d.dimensions.x>0&&d.dimensions.y>=0)shape=runtime.physics->createShape(PxCapsuleGeometry(d.dimensions.x,d.dimensions.y),*b.material,true);
    if(d.shape==LAB_PHYSICS_CONVEX&&d.convexVertices&&d.convexVertexCount>=4&&d.convexVertexCount<=64){
        PxCookingParams params(runtime.physics->getTolerancesScale());params.buildGPUData=true;PxConvexMeshDesc mesh;mesh.points.count=d.convexVertexCount;mesh.points.stride=sizeof(LabVec3V1);mesh.points.data=d.convexVertices;mesh.flags=PxConvexFlag::eCOMPUTE_CONVEX;mesh.vertexLimit=64;
        b.convex=PxCreateConvexMesh(params,mesh,runtime.physics->getPhysicsInsertionCallback());
        if(b.convex&&b.convex->isGpuCompatible())shape=runtime.physics->createShape(PxConvexMeshGeometry(b.convex),*b.material,true);
    }
    if(!shape){if(b.convex)b.convex->release();b.material->release();return 0;}
    shape->setLocalPose(P(d.shapePose));shape->setContactOffset(d.contactOffset);shape->setRestOffset(d.restOffset);shape->setSimulationFilterData(PxFilterData(d.layer,d.collisionMask,d.collisionGroup,0));
    if(d.kind==LAB_PHYSICS_STATIC)b.actor=runtime.physics->createRigidStatic(b.initial);else b.actor=runtime.physics->createRigidDynamic(b.initial);
    if(!b.actor){shape->release();if(b.convex)b.convex->release();b.material->release();return 0;}b.actor->attachShape(*shape);shape->release();
    if(d.kind!=LAB_PHYSICS_STATIC){auto* dynamic=static_cast<PxRigidDynamic*>(b.actor);Gpu(PxRigidBodyExt::setMassAndUpdateInertia(*dynamic,d.mass),"PhysX: failed body inertia calculation");if(d.inertia.x>0&&d.inertia.y>0&&d.inertia.z>0&&Valid(d.inertia))dynamic->setMassSpaceInertiaTensor(V(d.inertia));dynamic->setLinearDamping(d.linearDamping);dynamic->setAngularDamping(d.angularDamping);dynamic->setMaxAngularVelocity(d.maxAngularVelocity>0?d.maxAngularVelocity:200.f);dynamic->setSolverIterationCounts(12,4);dynamic->setSleepThreshold(0);if(b.kinematic)dynamic->setRigidBodyFlag(PxRigidBodyFlag::eKINEMATIC,true);}
    b.handle=(uint64_t(runtime.Generation())<<32)|(slot+1);scene->addActor(*b.actor);bodies[slot]=b;topologyDirty=descriptorsDirty=true;*out=b.handle;return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::DestroyBody(LabPhysicsBodyV1 h){
    auto* b=FindBody(h);if(!b||paused&&started)return 0;
    for(const auto& v:visuals)if(v.body==h)return 0;for(const auto& l:lights)if(l.body==h)return 0;
    {PxScopedCudaLock lock(*runtime.cuda);Cuda(cudaStreamSynchronize(stream),"retire body mutation consumers");}
    for(auto& j:joints)if(j.joint){PxRigidActor *a{},*other{};j.joint->getActors(a,other);if(a==b->actor||other==b->actor){j.joint->release();j={};}}
    std::erase_if(airflows,[&](const auto& f){return f.emitter==h;});std::erase_if(commands,[&](auto& c){return c.body==h;});std::erase_if(aero,[&](auto& a){return a.wing==h||a.carrier==h;});std::erase(probes,h);
    // A visible/probed body cannot be replaced with a fictitious pose. Clients
    // must detach/reconfigure its visuals before destroying that actor.
    b->actor->release();b->material->release();if(b->convex)b->convex->release();*b={};topologyDirty=descriptorsDirty=true;return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::SetBodyCollisionEnabled(LabPhysicsBodyV1 h,bool enabled){
    auto* b=FindBody(h);if(!b)return 0;if(b->collisionEnabled==enabled)return 1;
    PxScopedCudaLock lock(*runtime.cuda);Cuda(cudaStreamSynchronize(stream),"retire collision filter consumers");
    PxShape* shape{};if(b->actor->getShapes(&shape,1)!=1||b->actor->getNbShapes()!=1)return 0;
    auto filter=shape->getSimulationFilterData();filter.word1=enabled?b->collisionMask:0;
    shape->setSimulationFilterData(filter);
    Gpu(scene->resetFiltering(*b->actor),"PhysX GPU body collision filter update failed");runtime.Check();
    b->collisionEnabled=enabled;descriptorsDirty=true;return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::CreateD6(const LabPhysicsD6DescV1& d,LabPhysicsJointV1* out){
    if(!out)return 0;*out=0;if(d.structSize<sizeof(d)||!Valid(d.frameA)||!Valid(d.frameB)||d.bodyA==d.bodyB)return 0;
    auto* a=d.bodyA?FindBody(d.bodyA):nullptr;auto* b=FindBody(d.bodyB);if((d.bodyA&&!a)||!b)return 0;for(auto m:d.motion)if(m>LAB_PHYSICS_FREE)return 0;
    auto* joint=PxD6JointCreate(*runtime.physics,a?a->actor:nullptr,P(d.frameA),b->actor,P(d.frameB));if(!joint)return 0;
    uint32_t slot=0;while(slot<joints.size()&&joints[slot].joint)++slot;if(slot==joints.size())joints.emplace_back();auto& j=joints[slot];j.handle=(uint64_t(runtime.Generation())<<32)|(slot+1);j.joint=joint;if(!ConfigureD6(j.handle,d)){joint->release();j={};return 0;}*out=j.handle;return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::ConfigureD6(LabPhysicsJointV1 h,const LabPhysicsD6DescV1& d){
    auto* j=FindJoint(h);if(!j||d.structSize<sizeof(d)||!Valid(d.frameA)||!Valid(d.frameB))return 0;
    auto* a=d.bodyA?FindBody(d.bodyA):nullptr;auto* b=FindBody(d.bodyB);
    PxRigidActor *actualA{},*actualB{};j->joint->getActors(actualA,actualB);
    if((d.bodyA&&!a)||!b||(a?a->actor:nullptr)!=actualA||b->actor!=actualB)return 0;
    for(uint32_t i=0;i<6;i++)if(d.motion[i]>LAB_PHYSICS_FREE||!Finite(d.drive[i].stiffness)||!Finite(d.drive[i].damping)||!Finite(d.drive[i].maxForce)||d.drive[i].stiffness<0||d.drive[i].damping<0||d.drive[i].maxForce<0)return 0;
    if(!Finite(d.limitStiffness)||!Finite(d.limitDamping)||d.limitStiffness<0||d.limitDamping<0)return 0;
    for(uint32_t i=0;i<3;i++)if(d.motion[i]==LAB_PHYSICS_LIMITED&&(!Finite(d.linearLower[i])||!Finite(d.linearUpper[i])||d.linearUpper[i]<=d.linearLower[i]))return 0;
    if(d.motion[3]==LAB_PHYSICS_LIMITED&&(!Finite(d.twistLower)||!Finite(d.twistUpper)||d.twistUpper<=d.twistLower||d.twistLower<=-6.28f||d.twistUpper>=6.28f))return 0;
    if((d.motion[4]==LAB_PHYSICS_LIMITED||d.motion[5]==LAB_PHYSICS_LIMITED)&&(!Finite(d.swingY)||!Finite(d.swingZ)||d.swingY<=0||d.swingZ<=0||d.swingY>=3.14f||d.swingZ>=3.14f))return 0;
    const auto& slerp=d.drive[LAB_PHYSICS_DRIVE_SLERP];
    bool useSlerp=slerp.stiffness>0||slerp.damping>0;
    if(useSlerp){
        for(uint32_t i=3;i<6;i++)if(d.motion[i]==LAB_PHYSICS_LOCKED)return 0;
        if(d.drive[LAB_PHYSICS_DRIVE_SWING].stiffness||d.drive[LAB_PHYSICS_DRIVE_SWING].damping||d.drive[LAB_PHYSICS_DRIVE_TWIST].stiffness||d.drive[LAB_PHYSICS_DRIVE_TWIST].damping)return 0;
    }
    auto* joint=j->joint;joint->setLocalPose(PxJointActorIndex::eACTOR0,P(d.frameA));joint->setLocalPose(PxJointActorIndex::eACTOR1,P(d.frameB));
    for(uint32_t i=0;i<6;i++)joint->setMotion(PxD6Axis::Enum(i),PxD6Motion::Enum(d.motion[i]));
    for(uint32_t i=0;i<3;i++)if(d.motion[i]==LAB_PHYSICS_LIMITED){PxJointLinearLimitPair limit(d.linearLower[i],d.linearUpper[i],PxSpring(d.limitStiffness,d.limitDamping));joint->setLinearLimit(PxD6Axis::Enum(i),limit);}
    if(d.motion[3]==LAB_PHYSICS_LIMITED)joint->setTwistLimit(PxJointAngularLimitPair(d.twistLower,d.twistUpper,PxSpring(d.limitStiffness,d.limitDamping)));
    if(d.motion[4]==LAB_PHYSICS_LIMITED||d.motion[5]==LAB_PHYSICS_LIMITED)joint->setSwingLimit(PxJointLimitCone(d.swingY,d.swingZ,PxSpring(d.limitStiffness,d.limitDamping)));
    // Public V1 drive indices are independent of PhysX's seven drive indices.
    // In PhysX 5.9, TWIST is 3 and SLERP is 6; a cast drives the wrong axes.
    auto drive=[&](uint32_t i){const auto& v=d.drive[i];return PxD6JointDrive(v.stiffness,v.damping,v.maxForce,v.acceleration!=0);};
    joint->setAngularDriveConfig(useSlerp?PxD6AngularDriveConfig::eSLERP:PxD6AngularDriveConfig::eSWING_TWIST);
    joint->setDrive(PxD6Drive::eX,drive(LAB_PHYSICS_DRIVE_X));joint->setDrive(PxD6Drive::eY,drive(LAB_PHYSICS_DRIVE_Y));joint->setDrive(PxD6Drive::eZ,drive(LAB_PHYSICS_DRIVE_Z));
    if(useSlerp)joint->setDrive(PxD6Drive::eSLERP,drive(LAB_PHYSICS_DRIVE_SLERP));
    else{joint->setDrive(PxD6Drive::eSWING1,drive(LAB_PHYSICS_DRIVE_SWING));joint->setDrive(PxD6Drive::eSWING2,drive(LAB_PHYSICS_DRIVE_SWING));joint->setDrive(PxD6Drive::eTWIST,drive(LAB_PHYSICS_DRIVE_TWIST));}
    joint->setConstraintFlag(PxConstraintFlag::eCOLLISION_ENABLED,d.collideConnected!=0);
    j->description=d;j->committedFrameA=d.frameA;j->committedFrameB=d.frameB;
    return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::DestroyJoint(LabPhysicsJointV1 h){auto* j=FindJoint(h);if(!j)return 0;j->joint->release();*j={};return 1;}
void PhysicsRuntime::Impl::Scene::RefreshIndices(){
    indexHost.clear();for(auto& b:bodies){b.index=PhysicsInvalidIndex;if(!b.actor||!b.actor->is<PxRigidDynamic>())continue;auto index=static_cast<PxRigidDynamic*>(b.actor)->getGPUIndex();if(index==0xffffffffu)Fail("PhysX: missing rigid dynamic GPU index after simulation");b.index=uint32_t(indexHost.size());indexHost.push_back(index);}
    dynamicCount=uint32_t(indexHost.size());Upload(stream,indices,indexHost);topologyDirty=false;descriptorsDirty=true;
}
void PhysicsRuntime::Impl::Scene::RefreshDescriptors(){
    airflowHost.clear();dragHost.clear();visualHost.clear();lightHost.clear();aeroHost.clear();probeHost.clear();actorHost.clear();populationBodyHost.clear();
    for(const auto& f:airflows){auto* b=FindBody(f.emitter);if(b)airflowHost.push_back({f,b->index});}
    for(const auto& b:bodies)if(b.actor&&!b.kinematic&&b.index!=PhysicsInvalidIndex)dragHost.push_back({b.index,b.geometry});
    Upload(stream,airflowDevice,airflowHost);Upload(stream,dragDevice,dragHost);
    for(auto& v:visuals){auto* b=FindBody(v.body);if(!b)Fail("PhysX: expired visual body");visualHost.push_back({v,b->index,b->initial});}
    for(auto& l:lights){auto* b=FindBody(l.body);if(!b)Fail("PhysX: expired light body");lightHost.push_back({l,b->index,b->initial});}
    for(auto& a:aero){auto* wing=FindBody(a.wing);auto* carrier=FindBody(a.carrier);if(wing&&carrier)aeroHost.push_back({a,wing->index,carrier->index});}
    for(auto h:probes){auto* b=FindBody(h);if(b)probeHost.push_back({h,reinterpret_cast<uint64_t>(b->actor),b->index,0,b->initial});}
    for(auto& b:bodies)if(b.actor)actorHost.push_back({reinterpret_cast<uint64_t>(b.actor),b.handle});
    for(auto& b:bodies)if(b.actor){const auto& g=b.geometry;PopulationBodyGpu d{};d.initial=b.initial;d.local=P(g.shapePose);d.dimensions=V(g.dimensions);d.index=b.index;d.shape=g.shape;d.enabled=b.collisionEnabled&&(g.collisionMask&population.layer)&&(g.layer&population.collisionMask);d.hand=b.handle==populationInput.hands[0]||b.handle==populationInput.hands[1];d.kinematic=b.kinematic;d.restitution=g.restitution;d.handle=b.handle;
        d.radius=g.shape==LAB_PHYSICS_BOX?V(g.dimensions).magnitude():g.dimensions.x+(g.shape==LAB_PHYSICS_CAPSULE?g.dimensions.y:0);populationBodyHost.push_back(d);}
    Upload(stream,populationBodies,populationBodyHost);
    Upload(stream,visualDevice,visualHost);Upload(stream,lightDevice,lightHost);Upload(stream,aeroDevice,aeroHost);Upload(stream,probeDevice,probeHost);Upload(stream,actorDevice,actorHost);descriptorsDirty=false;
}
void PhysicsRuntime::Impl::Scene::ReadState(bool first){
    if(!dynamicCount)return;Driver(cuEventRecord(uploadReady,reinterpret_cast<CUstream>(stream)),"stage direct GPU indices");auto& api=scene->getDirectGPUAPI();
    Gpu(api.getRigidDynamicData(current,indices,PxRigidDynamicGPUAPIReadType::eGLOBAL_POSE,dynamicCount,uploadReady,poseReady),"PhysX direct GPU pose publication failed");
    Gpu(api.getRigidDynamicData(velocity,indices,PxRigidDynamicGPUAPIReadType::eLINEAR_VELOCITY,dynamicCount,poseReady,velocityReady),"PhysX direct GPU velocity read failed");
    Gpu(api.getRigidDynamicData(angular,indices,PxRigidDynamicGPUAPIReadType::eANGULAR_VELOCITY,dynamicCount,velocityReady,stateReady),"PhysX direct GPU angular read failed");
    Driver(cuStreamWaitEvent(reinterpret_cast<CUstream>(stream),stateReady,0),"wait grouped physical state");
    if(first)Cuda(cudaMemcpyAsync(previous,current,dynamicCount*sizeof(PxTransform),cudaMemcpyDeviceToDevice,stream),"initialize coherent previous poses");
}
PhysicsRuntime::Impl::Scene::Timing* PhysicsRuntime::Impl::Scene::BeginTiming(std::span<Timing> pool,uint32_t& cursor,uint64_t sampleTick,uint64_t value){
    for(uint32_t i=0;i<pool.size();i++){
        auto index=(cursor+i)%uint32_t(pool.size());auto& timing=pool[index];
        if(timing.pending)continue;
        timing.frame=frame;timing.tick=sampleTick;timing.value=value;timing.pending=true;
        Cuda(cudaEventRecord(timing.begin,stream),"begin physical GPU span");
        cursor=(index+1)%uint32_t(pool.size());return &timing;
    }
    return nullptr; // Profiling never adds a blocking wait to the simulation.
}
void PhysicsRuntime::Impl::Scene::CollectTimings(){
    auto collect=[&](std::span<Timing> pool,const char* stage,uint32_t kind){
        for(auto& t:pool)if(t.pending){
            auto ready=cudaEventQuery(t.end);if(ready==cudaErrorNotReady)continue;
            Cuda(ready,"query physical GPU timing");float span{};
            Cuda(cudaEventElapsedTime(&span,t.begin,t.end),"measure physical GPU span");
            // Non-blocking event harvest: spans include CUDA stream dependencies
            // and GPU scheduling gaps, not exclusively PhysX kernel execution.
            if(SessionLogCompact()){
                if(kind==1){
                    ++diagnostic.gpuStepSamples;
                    diagnostic.gpuStepSumMs+=span;
                    diagnostic.gpuStepPeakMs=std::max(diagnostic.gpuStepPeakMs,double(span));
                }else if(kind==2){
                    ++diagnostic.gpuFrameSamples;
                    diagnostic.gpuFrameSumMs+=span;
                    diagnostic.gpuFramePeakMs=std::max(diagnostic.gpuFramePeakMs,double(span));
                }
            }
            LogEvent(t.frame,stage,"scene=%llu tick=%llu fence_value=%llu gpu_span_ms=%.4f",static_cast<unsigned long long>(handle),static_cast<unsigned long long>(t.tick),static_cast<unsigned long long>(t.value),span);
            t.pending=false;
        }
    };
    collect(timings,"physics.gpu",2);
    collect(stepTimings,"physics.step.gpu",1);
    collect(publicationTimings,"physics.publication.wait",0);
}
void PhysicsRuntime::Impl::Scene::Step(float targetFraction){
    const double stepBegin=QpcNowSeconds();double commandWaitMs=0,topologyWaitMs=0,uploadSubmitMs=0,populationSubmitMs=0;
    bool forceDeviceCleared=false,forceHostUploaded=false;
    auto* timing=BeginTiming(stepTimings,stepTimingCursor,tick+1);
    if(!timing)++frameUntimedSteps;
    const bool rebuild=topologyDirty;
    if(started&&!rebuild&&dynamicCount){
        // No explicit physical force is the common case: kinematic targets,
        // airflow and aero all have their own inputs or GPU kernels. Do not
        // clear pinned CPU arrays and upload them across PCIe for zero data.
        // Keep the old host accumulation path for force/torque commands.
        for(const auto& c:commands){
            if(c.kind==LAB_PHYSICS_KINEMATIC_TARGET)continue;
            auto* b=FindBody(c.body);if(!b||b->index==PhysicsInvalidIndex)continue;
            if(!forceHostUploaded){
                std::fill_n(forceHost,dynamicCount,PxVec3(0));
                std::fill_n(torqueHost,dynamicCount,PxVec3(0));
                forceHostUploaded=true;
            }
            const float multiplier=(c.kind==LAB_PHYSICS_IMPULSE||c.kind==LAB_PHYSICS_ANGULAR_IMPULSE)?1.f/desc.fixedStepSeconds:1.f;
            if(c.kind==LAB_PHYSICS_FORCE||c.kind==LAB_PHYSICS_IMPULSE)forceHost[b->index]+=V(c.value)*multiplier;
            else torqueHost[b->index]+=V(c.value)*multiplier;
        }
        const double uploadBegin=QpcNowSeconds();
        const size_t forceBytes=size_t(dynamicCount)*sizeof(PxVec3);
        if(forceHostUploaded){
            Cuda(cudaMemcpyAsync(forces,forceHost,forceBytes,cudaMemcpyHostToDevice,stream),"upload grouped forces");
            Cuda(cudaMemcpyAsync(torques,torqueHost,forceBytes,cudaMemcpyHostToDevice,stream),"upload grouped torques");
        }else{
            // Same GPU stream orders the zeroing before insect/airflow/aero
            // kernels and before PhysX Direct GPU API consumes the arrays.
            Cuda(cudaMemsetAsync(forces,0,forceBytes,stream),"reset GPU forces");
            Cuda(cudaMemsetAsync(torques,0,forceBytes,stream),"reset GPU torques");
            forceDeviceCleared=true;
        }
        uploadSubmitMs=(QpcNowSeconds()-uploadBegin)*1000;
        const double populationBegin=SessionLogCompact()?QpcNowSeconds():0.;
        StepPopulation();
        if(populationBegin>0)populationSubmitMs+=(QpcNowSeconds()-populationBegin)*1000.;
        PhysicsApplyAirflow(stream,dragDevice,uint32_t(dragHost.size()),airflowDevice,uint32_t(airflowHost.size()),current,velocity,angular,forces,torques,float(simulationTime));Cuda(cudaGetLastError(),"rotor airflow forces");
        PhysicsApplyAero(stream,aeroDevice,uint32_t(aeroHost.size()),current,velocity,angular,forces,torques);Cuda(cudaGetLastError(),"wing aerodynamic commands");
        Driver(cuEventRecord(forceReady,reinterpret_cast<CUstream>(stream)),"publish grouped commands");auto& api=scene->getDirectGPUAPI();
        Gpu(api.setRigidDynamicData(forces,indices,PxRigidDynamicGPUAPIWriteType::eFORCE,dynamicCount,forceReady,forceDone),"PhysX direct GPU forces rejected");
        Gpu(api.setRigidDynamicData(torques,indices,PxRigidDynamicGPUAPIWriteType::eTORQUE,dynamicCount,forceDone,torqueDone),"PhysX direct GPU torques rejected");
        // PhysX simulate has no external start-event argument. One batch event
        // gates the submission, never one wait per actor or a graphics WaitIdle.
        auto ready=cuEventQuery(torqueDone);
        if(ready==CUDA_ERROR_NOT_READY){
            double waitBegin=QpcNowSeconds();Driver(cuEventSynchronize(torqueDone),"complete grouped simulation commands");
            commandWaitMs=(QpcNowSeconds()-waitBegin)*1000;
        }else Driver(ready,"query grouped simulation commands");
        Cuda(cudaMemcpyAsync(previous,current,dynamicCount*sizeof(PxTransform),cudaMemcpyDeviceToDevice,stream),"retain previous fixed-step poses");
        // forceReady follows the previous probe/visual kernels on this stream,
        // so torqueDone already retires all consumers of PhysX internal contact
        // pointers. The external previous-pose copy can overlap simulate(); the
        // next GPU state read waits on uploadReady recorded after that copy.
    }else {
        double waitBegin=QpcNowSeconds();Cuda(cudaStreamSynchronize(stream),"prepare scene topology");
        topologyWaitMs=(QpcNowSeconds()-waitBegin)*1000;
    }
    if(started&&!rebuild&&!dynamicCount){
        const double populationBegin=SessionLogCompact()?QpcNowSeconds():0.;
        StepPopulation();
        if(populationBegin>0)populationSubmitMs+=(QpcNowSeconds()-populationBegin)*1000.;
    }
    for(auto& c:commands)if(c.kind==LAB_PHYSICS_KINEMATIC_TARGET){auto* b=FindBody(c.body);if(b&&b->kinematic){auto end=P(c.target);PxQuat q=end.q;if(b->lastTarget.q.dot(q)<0)q=-q;PxTransform target(b->lastTarget.p+(end.p-b->lastTarget.p)*targetFraction,(b->lastTarget.q*(1-targetFraction)+q*targetFraction).getNormalized());static_cast<PxRigidDynamic*>(b->actor)->setKinematicTarget(target);}}
    for(auto& j:joints)if(j.joint&&j.motor.structSize){
        auto target=P(j.motor.target);auto omega=V(j.motor.angularVelocity);
        if(j.motor.frequencyHz>0){
            // Frequency changes alter the next cycle's rate, never its current
            // phase. These are D6 motor targets; PhysX alone moves the bodies.
            constexpr double tau=6.283185307179586;
            double phase=j.motorPhase+double(j.motor.phaseRadians);
            float angle=j.motor.amplitudeRadians*float(std::sin(phase));target.q=PxQuat(angle,PxVec3(1,0,0));
            omega.x=j.motor.amplitudeRadians*j.motor.frequencyHz*float(tau)*float(std::cos(phase));
            j.motorPhase=std::fmod(j.motorPhase+double(j.motor.frequencyHz)*tau*desc.fixedStepSeconds,tau);
        }
        j.joint->setDrivePosition(target,false);j.joint->setDriveVelocity(V(j.motor.linearVelocity),omega,false);
    }
    double simulateBegin=QpcNowSeconds();scene->simulate(desc.fixedStepSeconds);
    double simulateMs=(QpcNowSeconds()-simulateBegin)*1000;
    bool resultsReady=scene->checkResults(false);PxU32 error=0;
    double fetchBegin=QpcNowSeconds();
    // Serial fixed steps require completed PhysX results before another simulate
    // or direct-GPU state query. Keep that required rendezvous explicit; do not
    // request the blocking path when checkResults already establishes readiness.
    Gpu(scene->fetchResults(!resultsReady,&error)&&error==0,"PhysX GPU simulation failed; no CPU fallback allowed");
    double fetchMs=(QpcNowSeconds()-fetchBegin)*1000;runtime.Check();
    const double postFetchBegin=SessionLogCompact()?QpcNowSeconds():0.;
    if(rebuild)RefreshIndices();if(descriptorsDirty)RefreshDescriptors();ReadState(!started||rebuild);started=true;++tick;simulationTime+=desc.fixedStepSeconds;
    const double postFetchMs=postFetchBegin>0?(QpcNowSeconds()-postFetchBegin)*1000.:0.;
    if(timing)Cuda(cudaEventRecord(timing->end,stream),"end physical fixed-step GPU span");
    frameCommandWaitMs+=commandWaitMs;frameFetchBlockingMs+=resultsReady?0:fetchMs;frameTopologyWaitMs+=topologyWaitMs;
    const double stepCpuMs=(QpcNowSeconds()-stepBegin)*1000.;
    if(SessionLogCompact()){
        auto& p=diagnostic;
        ++p.steps;p.stepCpuMs+=stepCpuMs;p.maxStepCpuMs=std::max(p.maxStepCpuMs,stepCpuMs);
        p.commandWaitMs+=commandWaitMs;p.topologyWaitMs+=topologyWaitMs;
        p.fetchBlocked+=!resultsReady;
        if(resultsReady)p.fetchReadyMs+=fetchMs;else p.fetchBlockedMs+=fetchMs;
        p.simulateSubmitMs+=simulateMs;p.populationSubmitMs+=populationSubmitMs;p.postFetchCpuMs+=postFetchMs;
        p.deviceZeroSteps+=forceDeviceCleared;
        p.hostUploadSteps+=forceHostUploaded;
        p.untimedGpuSteps+=timing==nullptr;
        p.forceInitSubmitMs+=uploadSubmitMs;
    }
    LogEvent(frame,"physics.step","scene=%llu tick=%llu cpu_ms=%.4f command_upload_submit_ms=%.4f command_wait_ms=%.4f topology_wait_ms=%.4f simulate_submit_ms=%.4f fetch_ms=%.4f fetch_blocking=%u gpu_timed=%u",static_cast<unsigned long long>(handle),static_cast<unsigned long long>(tick),stepCpuMs,uploadSubmitMs,commandWaitMs,topologyWaitMs,simulateMs,fetchMs,unsigned(!resultsReady),unsigned(timing!=nullptr));
    if(started&&!rebuild)std::erase_if(commands,[](const auto& c){return c.kind==LAB_PHYSICS_IMPULSE||c.kind==LAB_PHYSICS_ANGULAR_IMPULSE;});
}
void PhysicsRuntime::Impl::Scene::Advance(double now,uint64_t inputFrame){
    double begin=QpcNowSeconds();PxScopedCudaLock lock(*runtime.cuda);frame=inputFrame;
    double contextLockMs=(QpcNowSeconds()-begin)*1000;
    frameCommandWaitMs=frameFetchBlockingMs=frameTopologyWaitMs=0;frameUntimedSteps=0;
    if(paused){lastTime=now;accumulator=0;alpha=0;commands.clear();if(descriptorsDirty&&started)RefreshDescriptors();return;}
    CollectTimings();auto* timing=BeginTiming(timings,timingCursor);
    if(insectCapacity&&!populationClockStarted){populationClockOrigin=now;populationClockStarted=true;}
    double elapsed=lastTime>0?std::max(0.,now-lastTime):double(desc.fixedStepSeconds);lastTime=now;
    const double budget=double(desc.fixedStepSeconds)*desc.maxSubsteps;
    const double droppedBefore=droppedSeconds;
    // Never carry whole overdue steps into later frames. A CPU/GPU stall
    // must not create extra PhysX fetchResults waits on the next frame.
    // Retain only the fractional remainder needed to align 72/90 Hz XR
    // frames with the fixed 120 Hz physics clock.
    const double owed=accumulator+elapsed;
    // When two steps are sufficient, keep their fractional remainder untouched.
    // Only whole extra steps are discarded; otherwise even healthy 72 Hz XR
    // would lose simulation time at every alternate frame.
    double discarded=0.;
    if(owed>=budget+double(desc.fixedStepSeconds))
        discarded=std::floor((owed-budget)/double(desc.fixedStepSeconds))*double(desc.fixedStepSeconds);
    droppedSeconds+=discarded;
    accumulator=owed-discarded;
    populationSeconds+=std::max(0.,elapsed-discarded);uint32_t steps=0;
    uint32_t planned=std::min(desc.maxSubsteps,uint32_t((accumulator+1e-9)/desc.fixedStepSeconds));
    while(accumulator+1e-9>=desc.fixedStepSeconds&&steps<desc.maxSubsteps){Step(float(steps+1)/float(std::max(1u,planned)));accumulator-=desc.fixedStepSeconds;++steps;}
    alpha=float(std::clamp(accumulator/double(desc.fixedStepSeconds),0.,1.));
    if(descriptorsDirty&&started){Cuda(cudaStreamSynchronize(stream),"retire descriptor uploads");RefreshDescriptors();}
    if(started)QueueProbe();
    if(timing)Cuda(cudaEventRecord(timing->end,stream),"end physical GPU span");
    // Continuous commands expire only after being consumed. An impulse survives
    // a display frame that had no physics tick.
    if(steps){for(const auto& c:commands)if(c.kind==LAB_PHYSICS_KINEMATIC_TARGET){if(auto* b=FindBody(c.body))b->lastTarget=P(c.target);}}
    if(steps)std::erase_if(commands,[](const auto& c){return c.kind!=LAB_PHYSICS_IMPULSE&&c.kind!=LAB_PHYSICS_ANGULAR_IMPULSE;});
    const double frameCpuMs=(QpcNowSeconds()-begin)*1000.;
    if(SessionLogCompact()){
        ++diagnostic.frames;diagnostic.droppedFrames+=droppedSeconds>droppedBefore;
        diagnostic.frameCpuMs+=frameCpuMs;diagnostic.contextLockMs+=contextLockMs;
    }
    LogEvent(frame,"physics.frame","scene=%llu tick=%llu steps=%u fixed_dt=%.8f cpu_ms=%.4f context_lock_ms=%.4f command_wait_ms=%.4f fetch_blocking_call_ms=%.4f topology_wait_ms=%.4f untimed_gpu_steps=%u frame_gpu_timed=%u publication_backpressure_total=%llu dropped_seconds=%.6f probe_count=%u readback_bytes=%u",static_cast<unsigned long long>(handle),static_cast<unsigned long long>(tick),steps,desc.fixedStepSeconds,frameCpuMs,contextLockMs,frameCommandWaitMs,frameFetchBlockingMs,frameTopologyWaitMs,frameUntimedSteps,unsigned(timing!=nullptr),static_cast<unsigned long long>(publicationBackpressureCount),droppedSeconds,uint32_t(probeHost.size()),uint32_t(probeHost.size()*sizeof(LabPhysicsStateV1)+sizeof(uint32_t)));
}
uint32_t PhysicsRuntime::Impl::Scene::SetVisuals(const LabPhysicsVisualV1* v,uint32_t n,const LabPhysicsLightV1* l,uint32_t nl){
    if(n>MaxVisuals||nl>MaxLights||(n&&!v)||(nl&&!l))return 0;
    for(uint32_t i=0;i<n;i++)if(v[i].structSize<sizeof(*v)||!FindBody(v[i].body)||v[i].mesh>=ConsoleSpec::MaxMeshes||v[i].material>=ConsoleSpec::MaxMaterials||!Valid(v[i].localPose)||!Valid(v[i].scale)||!Finite(v[i].boundingRadius)||v[i].boundingRadius<=0)return 0;
    for(uint32_t i=0;i<nl;i++)if(l[i].structSize<sizeof(*l)||!FindBody(l[i].body)||l[i].sceneLightIndex>=ConsoleSpec::MaxLights||!Valid(l[i].localPosition)||!Valid(l[i].localDirection)||!Valid(l[i].color)||!Finite(l[i].radius)||l[i].radius<=0||!Finite(l[i].power)||l[i].power<0||!Finite(l[i].outerCos)||!Finite(l[i].innerCos)||l[i].outerCos<-1||l[i].outerCos>1||l[i].innerCos<l[i].outerCos||l[i].innerCos>1)return 0;
    PxScopedCudaLock lock(*runtime.cuda);
    uint32_t publicationCapacity=n+(insectCapacity?insectCapacity+4*LAB_PHYSICS_POPULATION_DETAIL_MAX_V1+LAB_POPULATION_SHADOW_MAX_V1:0);
    bool sameLayout=n==visuals.size()&&nl==lights.size()&&!slots[0].refs.empty()&&slots[0].instances.bytes==uint64_t(publicationCapacity)*sizeof(GpuInstance);
    for(uint32_t i=0;i<nl&&sameLayout;i++)sameLayout=lights[i].sceneLightIndex==l[i].sceneLightIndex;
    for(uint32_t i=0;i<n&&sameLayout;i++)sameLayout=std::find(streamMaterials.begin(),streamMaterials.end(),v[i].material)!=streamMaterials.end();
    if(sameLayout){
        // Descriptor/material/light edits preserve the shared ring and fences.
        // Retire prior descriptor consumers once, then batch the new upload.
        Cuda(cudaStreamSynchronize(stream),"retire visual descriptor edits");
        if(n)visuals.assign(v,v+n);if(nl)lights.assign(l,l+nl);descriptorsDirty=true;return 1;
    }
    DestroyPublications();visuals.clear();lights.clear();if(n)visuals.assign(v,v+n);if(nl)lights.assign(l,l+nl);streamMaterials.clear();
    for(const auto& x:visuals)if(std::find(streamMaterials.begin(),streamMaterials.end(),x.material)==streamMaterials.end())streamMaterials.push_back(x.material);
    if(insectCapacity)for(auto mat:{population.bodyMaterial,population.headMaterial,population.wingMaterial})if(std::find(streamMaterials.begin(),streamMaterials.end(),mat)==streamMaterials.end())streamMaterials.push_back(mat);
    provider.streamMaterials=streamMaterials.data();provider.streamMaterialCount=uint32_t(streamMaterials.size());
    if(publicationCapacity)for(auto& s:slots){s.instances.Create(owner.interop,uint64_t(publicationCapacity)*sizeof(GpuInstance));s.control.Create(owner.interop,48);if(nl)s.lighting.Create(owner.interop,uint64_t(nl)*sizeof(PhysicsGpuLight));s.producer.Create(owner.interop);s.consumer.Create(owner.interop);
        auto ref=[&](uint32_t binding,const SharedBuffer& buffer,uint64_t offset,uint64_t bytes){LabGpuResourceRefV1 r{};r.binding=binding;r.kind=LABOVR_GPU_RESOURCE_BUFFER_V1;r.resourceHandle=buffer.handle;r.bytes=bytes;r.offset=offset;r.generation=handle;r.initialLayout=uint32_t(D3D12_BARRIER_LAYOUT_COMMON);s.refs.push_back(r);};
        ref(0,s.instances,0,s.instances.bytes);ref(1,s.control,0,16);ref(2,s.control,16,32);
        if(insectCapacity){ref(LAB_POPULATION_OPTICAL_BINDING_V1,s.instances,0,sizeof(GpuInstance));ref(LAB_POPULATION_SHADOW_BINDING_V1,s.instances,0,LAB_POPULATION_SHADOW_MAX_V1*sizeof(GpuInstance));ref(LAB_POPULATION_PROXY_BINDING_V1,s.instances,0,sizeof(GpuInstance));}
        for(uint32_t i=0;i<nl;i++)ref(LABOVR_GPU_MESH_BINDING_LIGHT_BASE_V1+lights[i].sceneLightIndex,s.lighting,uint64_t(i)*sizeof(PhysicsGpuLight),sizeof(PhysicsGpuLight));
    }
    descriptorsDirty=true;return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::Acquire(LabGpuPublicationV1* out){
    if(!out||out->structSize<sizeof(*out)||out->gpuAbiVersion!=LABOVR_GPU_ABI_V1||(visuals.empty()&&!insectCapacity)||!started||topologyDirty)return 0;
    PxScopedCudaLock lock(*runtime.cuda);if(descriptorsDirty)RefreshDescriptors();
    PublicationSlot* chosen{};PublicationSlot* available{};uint32_t chosenIndex{},availableIndex{};uint64_t completed{};
    for(uint32_t i=0;i<slots.size();i++){
        uint32_t index=(publicationCursor+i)%uint32_t(slots.size());auto& slot=slots[index];
        if(slot.leased)continue;
        if(!available){available=&slot;availableIndex=index;}
        uint64_t value=slot.consumer.Completed(owner.interop);
        if(value>=slot.value){chosen=&slot;chosenIndex=index;completed=value;break;}
    }
    if(!chosen&&available){chosen=available;chosenIndex=availableIndex;completed=chosen->consumer.Completed(owner.interop);}
    // CPU lease ownership and GPU completion are distinct. Release means the
    // previous consumer signal has been enqueued, so an unleased slot can be
    // reused now with a GPU wait. A pending DX12 fence is never an Acquire failure.
    if(!chosen){LogEvent(frame,"physics.publication","scene=%llu leases_exhausted=1",static_cast<unsigned long long>(handle));return 0;}
    publicationCursor=(chosenIndex+1)%uint32_t(slots.size());auto& s=*chosen;
    Timing* waitTiming=nullptr;
    if(completed<s.value){
        ++publicationBackpressureCount;waitTiming=BeginTiming(publicationTimings,publicationTimingCursor,tick,s.value);
        LogEvent(frame,"physics.publication","scene=%llu slot=%u backpressure=1 consumer_completed=%llu wait_value=%llu gpu_wait_timed=%u",static_cast<unsigned long long>(handle),chosenIndex,static_cast<unsigned long long>(completed),static_cast<unsigned long long>(s.value),unsigned(waitTiming!=nullptr));
    }
    s.consumer.Wait(stream,s.value);
    if(waitTiming)Cuda(cudaEventRecord(waitTiming->end,stream),"end GPU publication consumer wait");
    PhysicsPackVisuals(stream,visualDevice,uint32_t(visualHost.size()),lightDevice,uint32_t(lightHost.size()),previous,current,alpha,visible,static_cast<GpuInstance*>(s.instances.pointer),static_cast<uint32_t*>(s.control.pointer),static_cast<PhysicsGpuLight*>(s.lighting.pointer));Cuda(cudaGetLastError(),"pack GPU physical visuals");
    if(insectCapacity){s.refs[0].bytes=(uint64_t(visualHost.size())+insectCount+4*LAB_PHYSICS_POPULATION_DETAIL_MAX_V1+LAB_POPULATION_SHADOW_MAX_V1)*sizeof(GpuInstance);PopulationPack(stream,insects,insectCount,insectCapacity,population,populationInput,populationEffects,populationBodies,populationBodyPoses,uint32_t(populationBodyHost.size()),lightDevice,uint32_t(lightHost.size()),started?current:nullptr,visible,static_cast<GpuInstance*>(s.instances.pointer),static_cast<uint32_t*>(s.control.pointer),uint32_t(visualHost.size()),populationSummary,frame,tick,float(std::clamp((insectAccumulator+accumulator)*120.,0.,1.)),float(populationSeconds));Cuda(cudaGetLastError(),"pack compact GPU population");for(auto& ref:s.refs){if(ref.binding==LAB_POPULATION_SHADOW_BINDING_V1)ref.offset=(uint64_t(visualHost.size())+insectCount+4*LAB_PHYSICS_POPULATION_DETAIL_MAX_V1)*sizeof(GpuInstance);if(ref.binding==LAB_POPULATION_PROXY_BINDING_V1||ref.binding==LAB_POPULATION_OPTICAL_BINDING_V1){ref.offset=uint64_t(visualHost.size())*sizeof(GpuInstance);ref.bytes=uint64_t(std::max(1u,insectCount))*sizeof(GpuInstance);ref.flags=insectCount?0:1;}}QueuePopulationReadback();}
    if(s.value==UINT64_MAX)Fail("PhysX publication fence exhausted");++s.value;s.producer.Signal(stream,s.value);s.leased=true;s.leaseGeneration=runtime.LeaseGeneration();
    *out={LABOVR_GPU_ABI_V1,sizeof(*out),LABOVR_GPU_DOMAIN_MESH_SOLID_V1,0,s.refs.data(),uint32_t(visible?s.refs.size():3),0,++publicationSequence,s.producer.handle,s.value,s.consumer.handle,s.value,&s,s.leaseGeneration};return 1;
}
void PhysicsRuntime::Impl::Scene::Release(void* token,uint64_t generation){for(auto& s:slots)if(token==&s){if(generation!=s.leaseGeneration)return;if(!s.leased)Fail("PhysX GPU publication released twice");s.leased=false;return;}}
void PhysicsRuntime::Impl::Scene::QueueProbe(){
    if(probeHost.empty())return;auto& p=probeSlots[probeCursor];
    if(p.pending){auto ready=cudaEventQuery(p.done);if(ready==cudaErrorNotReady){LogEvent(frame,"physics.probe","busy=1");return;}Cuda(ready,"probe completion");}
    // Each probe ring slot has its own pinned destination, never reused while
    // its async copy is in flight. No all-body host pose copy exists.
    Cuda(cudaEventRecord(p.gpuBegin,stream),"begin physics GPU timing");Driver(cuEventRecord(uploadReady,reinterpret_cast<CUstream>(stream)),"stage contact query");
    Gpu(scene->getDirectGPUAPI().copyContactData(contacts,contactCount,ContactCapacity,uploadReady,contactReady),"PhysX GPU contact query failed");Driver(cuStreamWaitEvent(reinterpret_cast<CUstream>(stream),contactReady,0),"wait GPU contacts");
    PhysicsPackProbes(stream,probeDevice,uint32_t(probeHost.size()),current,velocity,angular,contacts,contactCount,ContactCapacity,actorDevice,uint32_t(actorHost.size()),probeOutput);Cuda(cudaGetLastError(),"compact GPU contact probes");
    Cuda(cudaMemcpyAsync(p.host,probeOutput,probeHost.size()*sizeof(LabPhysicsStateV1),cudaMemcpyDeviceToHost,stream),"copy compact behavior/audio probes");Cuda(cudaMemcpyAsync(p.overflow,contactCount,sizeof(uint32_t),cudaMemcpyDeviceToHost,stream),"copy contact count");Cuda(cudaEventRecord(p.gpuEnd,stream),"end physics GPU timing");Cuda(cudaEventRecord(p.done,stream),"publish probe completion");p.pending=true;p.tick=tick;p.frame=frame;p.seconds=simulationTime;p.count=uint32_t(probeHost.size());probeCursor=(probeCursor+1)%uint32_t(probeSlots.size());
}
uint32_t PhysicsRuntime::Impl::Scene::Poll(LabPhysicsSnapshotV1* out){
    if(!out||out->structSize<sizeof(*out)||!out->states)return 0;PxScopedCudaLock lock(*runtime.cuda);ProbeSlot* newest{};
    for(auto& p:probeSlots){if(!p.pending||p.frame<=lastProbeFrame||p.count>out->stateCapacity)continue;auto ready=cudaEventQuery(p.done);if(ready==cudaErrorNotReady)continue;Cuda(ready,"query asynchronous physical state");if(!newest||p.frame>newest->frame)newest=&p;}
    if(!newest)return 0;auto& p=*newest;std::copy_n(p.host,p.count,out->states);out->stateCount=p.count;out->simulationTick=p.tick;out->sourceFrame=p.frame;out->simulationSeconds=p.seconds;out->contactOverflow=*p.overflow>=ContactCapacity;lastProbeFrame=p.frame;
    float ms{};Cuda(cudaEventElapsedTime(&ms,p.gpuBegin,p.gpuEnd),"measure physics probe GPU cost");LogEvent(frame,"physics.probe","source_frame=%llu gpu_ms=%.4f states=%u bytes=%u contact_pairs=%u overflow=%u",static_cast<unsigned long long>(p.frame),ms,p.count,uint32_t(p.count*sizeof(LabPhysicsStateV1)+4),*p.overflow,out->contactOverflow);
    if(out->contactOverflow)Fail("PhysX GPU contact query capacity exceeded; scene must be resized");return 1;
}

void PhysicsRuntime::Impl::Scene::CaptureEditPoses(){
    if(!started)return;
    Cuda(cudaStreamSynchronize(stream),"retire consumers before editor capture");
    if(topologyDirty)Fail("PhysX: editor capture requires committed topology");
    ReadState(true);
    if(dynamicCount)Cuda(cudaMemcpyAsync(editPoseHost,current,dynamicCount*sizeof(PxTransform),cudaMemcpyDeviceToHost,stream),"bounded editor body poses");
    Cuda(cudaStreamSynchronize(stream),"complete explicit editor snapshot");
    for(auto& b:bodies)if(b.actor&&b.index!=PhysicsInvalidIndex){
        if(b.index>=dynamicCount||!editPoseHost[b.index].isSane())Fail("PhysX: invalid editor GPU pose mapping");
        b.initial=editPoseHost[b.index].getNormalized();b.committed=b.initial;
    }
}
void PhysicsRuntime::Impl::Scene::WriteEditPoses(){
    // Paused publication is an authored preview, not a mutation of PhysX contacts,
    // joint shaders, broadphase data, or CPU shadows of GPU-driven actors.
    Cuda(cudaStreamSynchronize(stream),"retire paused preview consumers");
    for(auto& b:bodies)if(b.actor&&b.index!=PhysicsInvalidIndex){
        if(b.index>=dynamicCount)Fail("PhysX: invalid editor preview index");editPoseHost[b.index]=b.initial;
    }
    if(started&&dynamicCount){
        Cuda(cudaMemcpyAsync(current,editPoseHost,dynamicCount*sizeof(PxTransform),cudaMemcpyHostToDevice,stream),"publish authored preview poses");
        Cuda(cudaMemcpyAsync(previous,current,dynamicCount*sizeof(PxTransform),cudaMemcpyDeviceToDevice,stream),"reset editor preview interpolation");
    }
    commands.clear();accumulator=0;insectAccumulator=0;alpha=0;descriptorsDirty=true;
    if(started)RefreshDescriptors();
    Cuda(cudaStreamSynchronize(stream),"complete authored preview publication");
}
void PhysicsRuntime::Impl::Scene::CommitEditPoses(){
    Cuda(cudaStreamSynchronize(stream),"retire editor preview before commit");
    uint32_t count=0;
    // Stage only changed dynamic actors. GPU indices are actor identities, not
    // vector slots; never teleport unselected hands, the fan, or other bodies.
    for(auto& b:bodies)if(b.actor&&PoseChanged(b.initial,b.committed)){
        auto* dynamic=b.actor->is<PxRigidDynamic>();
        if(dynamic&&started){
            auto index=dynamic->getGPUIndex();
            if(b.index==PhysicsInvalidIndex||b.index>=indexHost.size()||index==0xffffffffu||index!=indexHost[b.index])Fail("PhysX: editor GPU identity changed during pause");
            for(uint32_t i=0;i<count;i++)if(editIndexHost[i]==index)Fail("PhysX: duplicate editor GPU index");
            editPoseHost[count]=b.initial;editIndexHost[count++]=index;
        }
    }
    if(count){
        Cuda(cudaMemcpyAsync(editPoseDevice,editPoseHost,count*sizeof(PxTransform),cudaMemcpyHostToDevice,stream),"stage grouped authored poses");
        Cuda(cudaMemcpyAsync(editIndexDevice,editIndexHost,count*sizeof(PxRigidDynamicGPUIndex),cudaMemcpyHostToDevice,stream),"stage grouped authored identities");
        Driver(cuEventRecord(uploadReady,reinterpret_cast<CUstream>(stream)),"publish isolated edit staging");auto& api=scene->getDirectGPUAPI();
        Gpu(api.setRigidDynamicData(editPoseDevice,editIndexDevice,PxRigidDynamicGPUAPIWriteType::eGLOBAL_POSE,count,uploadReady,poseReady),"PhysX GPU authoring poses");
        Gpu(api.setRigidDynamicData(editZeroDevice,editIndexDevice,PxRigidDynamicGPUAPIWriteType::eLINEAR_VELOCITY,count,poseReady,velocityReady),"PhysX GPU clear authored velocity");
        Gpu(api.setRigidDynamicData(editZeroDevice,editIndexDevice,PxRigidDynamicGPUAPIWriteType::eANGULAR_VELOCITY,count,velocityReady,stateReady),"PhysX GPU clear authored angular velocity");
        Driver(cuStreamWaitEvent(reinterpret_cast<CUstream>(stream),stateReady,0),"wait grouped editor commit");
        Cuda(cudaStreamSynchronize(stream),"complete grouped editor commit before CPU scene updates");
    }
    // Static setters remain supported with Direct GPU API; runtime dynamic pose
    // setters do not. Apply statics once, then rebuild D6 local frames against
    // the new static poses (the extension uses static inverse poses in c2b).
    for(auto& b:bodies)if(b.actor&&PoseChanged(b.initial,b.committed)){
        if(auto* fixed=b.actor->is<PxRigidStatic>())fixed->setGlobalPose(b.initial,false);
        else if(!started)static_cast<PxRigidDynamic*>(b.actor)->setGlobalPose(b.initial,false);
        if(b.kinematic){static_cast<PxRigidDynamic*>(b.actor)->setKinematicTarget(b.initial);b.lastTarget=b.initial;}
        b.committed=b.initial;b.geometry.pose={{b.initial.p.x,b.initial.p.y,b.initial.p.z},{b.initial.q.x,b.initial.q.y,b.initial.q.z,b.initial.q.w}};
    }
    for(auto& j:joints)if(j.joint){
        j.joint->setLocalPose(PxJointActorIndex::eACTOR0,P(j.description.frameA));j.joint->setLocalPose(PxJointActorIndex::eACTOR1,P(j.description.frameB));
        j.committedFrameA=j.description.frameA;j.committedFrameB=j.description.frameB;
    }
    runtime.Check();
    if(populationBodyPoses)Cuda(cudaMemsetAsync(populationBodyPoses,0,desc.maxBodies*sizeof(PopulationBodyPoseGpu),stream),"invalidate committed collider sweep history");
    descriptorsDirty=true;if(started){ReadState(true);RefreshDescriptors();}
    Cuda(cudaStreamSynchronize(stream),"complete authored state before simulate");
    for(auto& p:probeSlots)p.pending=false;for(auto& p:populationReadbacks)p.pending=false;
}
uint32_t PhysicsRuntime::Impl::Scene::Pause(bool value){
    PxScopedCudaLock lock(*runtime.cuda);if(value==paused)return 1;
    if(value){if(started&&topologyDirty)return 0;CaptureEditPoses();paused=true;commands.clear();accumulator=0;alpha=0;edited=false;}
    else{
        if(edited){LabPhysicsEditValidationV1 v{sizeof(v)};if(!ValidateEdit(&v))return 0;CommitEditPoses();}
        else Cuda(cudaStreamSynchronize(stream),"retire pause publications before resume");
        paused=false;lastTime=0;commands.clear();accumulator=0;insectAccumulator=0;edited=false;
    }
    return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::EditSnapshot(LabPhysicsEditSnapshotV1* out){
    if(!out||out->structSize<sizeof(*out)||!out->bodies||!out->joints)return 0;
    uint32_t nb=0,nj=0;for(auto& b:bodies)nb+=b.actor!=nullptr;for(auto& j:joints)nj+=j.joint!=nullptr;
    if(nb>out->bodyCapacity||nj>out->jointCapacity||(!paused&&topologyDirty))return 0;
    PxScopedCudaLock lock(*runtime.cuda);if(!paused)CaptureEditPoses();nb=nj=0;
    for(auto& b:bodies)if(b.actor){const auto& t=b.initial;out->bodies[nb++]={b.handle,{{t.p.x,t.p.y,t.p.z},{t.q.x,t.q.y,t.q.z,t.q.w}}};}
    for(auto& j:joints)if(j.joint)out->joints[nj++]={j.handle,j.description.frameA,j.description.frameB};
    out->bodyCount=nb;out->jointCount=nj;out->simulationSeconds=simulationTime;return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::Edit(const LabPhysicsEditBatchV1& batch){
    if(!paused||batch.structSize<sizeof(batch)||batch.bodyCount>bodies.size()||batch.jointCount>joints.size()||(batch.bodyCount&&!batch.bodies)||(batch.jointCount&&!batch.joints))return 0;
    for(uint32_t i=0;i<batch.bodyCount;i++){const auto& e=batch.bodies[i];if(!FindBody(e.body)||!Valid(e.pose)||V(e.pose.position).magnitude()>64)return 0;for(uint32_t j=0;j<i;j++)if(batch.bodies[j].body==e.body)return 0;}
    for(uint32_t i=0;i<batch.jointCount;i++){const auto& e=batch.joints[i];if(!FindJoint(e.joint)||!Valid(e.frameA)||!Valid(e.frameB)||V(e.frameA.position).magnitude()>256||V(e.frameB.position).magnitude()>256)return 0;for(uint32_t j=0;j<i;j++)if(batch.joints[j].joint==e.joint)return 0;}
    PxScopedCudaLock lock(*runtime.cuda);
    std::vector<PxTransform> oldBodies;std::vector<LabPhysicsEditJointV1> oldJoints;
    oldBodies.reserve(batch.bodyCount);oldJoints.reserve(batch.jointCount);
    for(uint32_t i=0;i<batch.bodyCount;i++){auto* b=FindBody(batch.bodies[i].body);oldBodies.push_back(b->initial);b->initial=P(batch.bodies[i].pose).getNormalized();}
    for(uint32_t i=0;i<batch.jointCount;i++){const auto& e=batch.joints[i];auto* j=FindJoint(e.joint);oldJoints.push_back({e.joint,j->description.frameA,j->description.frameB});j->description.frameA=e.frameA;j->description.frameB=e.frameB;}
    LabPhysicsEditValidationV1 result{sizeof(result)};
    if(!ValidateEdit(&result)){
        for(uint32_t i=0;i<batch.bodyCount;i++)FindBody(batch.bodies[i].body)->initial=oldBodies[i];
        for(const auto& e:oldJoints){auto* j=FindJoint(e.joint);j->description.frameA=e.frameA;j->description.frameB=e.frameB;}
        return 0;
    }
    edited=false;for(const auto& b:bodies)if(b.actor&&PoseChanged(b.initial,b.committed))edited=true;
    for(const auto& j:joints)if(j.joint&&(PoseChanged(P(j.description.frameA),P(j.committedFrameA))||PoseChanged(P(j.description.frameB),P(j.committedFrameB))))edited=true;
    WriteEditPoses();return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::Translate(const LabPhysicsBodyV1* selected,uint32_t n,LabVec3V1 offset){
    if(!paused||!n||!selected||n>bodies.size()||!Valid(offset)||V(offset).magnitude()>.25f)return 0;
    std::vector<LabPhysicsEditBodyV1> edits;std::vector<LabPhysicsEditJointV1> anchors;
    auto contains=[&](LabPhysicsBodyV1 h){return h&&std::find(selected,selected+n,h)!=selected+n;};
    for(uint32_t i=0;i<n;i++){auto* b=FindBody(selected[i]);if(!b)return 0;auto t=b->initial;t.p+=V(offset);edits.push_back({b->handle,{{t.p.x,t.p.y,t.p.z},{t.q.x,t.q.y,t.q.z,t.q.w}}});}
    for(auto& j:joints)if(j.joint){const auto& d=j.description;bool a=contains(d.bodyA),b=contains(d.bodyB);if(a==b)continue;
        // Keep the connection's authored rest relation when one endpoint is
        // translated. World anchors and the other local frame move coherently.
        auto e=LabPhysicsEditJointV1{j.handle,d.frameA,d.frameB};auto other=a?FindBody(d.bodyB):FindBody(d.bodyA);
        auto& local=a?e.frameB:e.frameA;PxTransform parent=other?other->initial:PxTransform(PxIdentity),world=parent*P(local);world.p+=V(offset);world=parent.getInverse()*world;
        local={{world.p.x,world.p.y,world.p.z},{world.q.x,world.q.y,world.q.z,world.q.w}};anchors.push_back(e);
    }
    LabPhysicsEditBatchV1 batch{sizeof(batch),uint32_t(edits.size()),edits.data(),uint32_t(anchors.size()),0,anchors.data()};return Edit(batch);
}
uint32_t PhysicsRuntime::Impl::Scene::ValidateEdit(LabPhysicsEditValidationV1* out){
    if(!out||out->structSize<sizeof(*out))return 0;*out={sizeof(*out),0};
    if(!paused)return 0;out->valid=1;
    for(const auto& b:bodies)if(b.actor&&(!b.initial.isSane()||!b.initial.p.isFinite()||b.initial.p.magnitude()>64)){out->valid=0;out->bodyA=b.handle;return 0;}
    for(const auto& j:joints)if(j.joint){
        const auto& d=j.description;auto* a=d.bodyA?FindBody(d.bodyA):nullptr;auto* b=FindBody(d.bodyB);
        if((d.bodyA&&!a)||!b||!Valid(d.frameA)||!Valid(d.frameB)){out->valid=0;return 0;}
        auto wa=(a?a->initial:PxTransform(PxIdentity))*P(d.frameA),wb=b->initial*P(d.frameB),relative=wa.getInverse()*wb;
        const float axis[]{relative.p.x,relative.p.y,relative.p.z};float error=0;
        for(uint32_t i=0;i<3;i++){
            if(d.motion[i]==LAB_PHYSICS_LOCKED)error=std::max(error,PxAbs(axis[i]));
            else if(d.motion[i]==LAB_PHYSICS_LIMITED)error=std::max(error,std::max(d.linearLower[i]-axis[i],axis[i]-d.linearUpper[i]));
        }
        auto q=relative.q;if(q.w<0)q=-q;PxQuat twist(q.x,0,0,q.w);float n=twist.magnitudeSquared();
        twist=n>1e-12f?twist.getNormalized():PxQuat(PxIdentity);auto swing=q*twist.getConjugate();
        float angular[]{2*std::atan2(twist.x,twist.w),2*std::atan2(swing.y,swing.w),2*std::atan2(swing.z,swing.w)};
        float angularError=0;for(uint32_t i=0;i<3;i++){
            if(d.motion[i+3]==LAB_PHYSICS_LOCKED)angularError=std::max(angularError,PxAbs(angular[i]));
            else if(d.motion[i+3]==LAB_PHYSICS_LIMITED){
                float low=i==0?d.twistLower:-(i==1?d.swingY:d.swingZ),high=i==0?d.twistUpper:(i==1?d.swingY:d.swingZ);
                angularError=std::max(angularError,std::max(low-angular[i],angular[i]-high));
            }
        }
        if(error>.025f||angularError>.15f){out->valid=0;out->bodyA=d.bodyA;out->bodyB=d.bodyB;out->penetration=error;return 0;}
    }
    for(size_t i=0;i<bodies.size();i++)for(size_t k=i+1;k<bodies.size();k++){
        auto& a=bodies[i];auto& b=bodies[k];if(!a.actor||!b.actor||!a.collisionEnabled||!b.collisionEnabled)continue;
        if(!(a.geometry.layer&b.collisionMask)||!(b.geometry.layer&a.collisionMask)||(a.geometry.collisionGroup&&a.geometry.collisionGroup==b.geometry.collisionGroup))continue;
        bool connected=false;for(auto& j:joints)if(j.joint&&!j.description.collideConnected&&((j.description.bodyA==a.handle&&j.description.bodyB==b.handle)||(j.description.bodyA==b.handle&&j.description.bodyB==a.handle))){connected=true;break;}if(connected)continue;
        PxShape *sa{},*sb{};if(a.actor->getShapes(&sa,1)!=1||b.actor->getShapes(&sb,1)!=1)continue;PxVec3 direction;PxReal depth;
        if(PxGeometryQuery::computePenetration(direction,depth,sa->getGeometry(),a.initial*sa->getLocalPose(),sb->getGeometry(),b.initial*sb->getLocalPose())&&depth>.025f&&depth>out->penetration){out->valid=0;out->bodyA=a.handle;out->bodyB=b.handle;out->penetration=depth;}
    }
    return out->valid;
}

PhysicsRuntime::PhysicsRuntime():impl_(std::make_unique<Impl>()){}
PhysicsRuntime::~PhysicsRuntime(){Shutdown();}
void PhysicsRuntime::Initialize(ID3D12Device* device){
    auto& r=*impl_;if(r.physics||!device)Fail("PhysX initialization order: DX12 device required exactly once");Driver(cuInit(0),"initialize CUDA driver");auto luid=device->GetAdapterLuid();int count{};Driver(cuDeviceGetCount(&count),"enumerate CUDA devices");int selected=-1;
    for(int i=0;i<count;i++){char identity[8]{};unsigned int nodeMask{};Driver(cuDeviceGetLuid(identity,&nodeMask,i),"read CUDA adapter LUID");if(std::memcmp(identity,&luid,8)==0&&nodeMask){selected=i;break;}}
    if(selected<0)Fail("PhysX: no CUDA adapter matches the OpenXR DX12 adapter LUID");int major{},minor{};Driver(cuDeviceGetAttribute(&major,CU_DEVICE_ATTRIBUTE_COMPUTE_CAPABILITY_MAJOR,selected),"query CUDA architecture");Driver(cuDeviceGetAttribute(&minor,CU_DEVICE_ATTRIBUTE_COMPUTE_CAPABILITY_MINOR,selected),"query CUDA architecture");if(major!=12||minor!=0)Fail("PhysX reference build requires SM120 on the DX12/CUDA adapter");
    r.foundation=PxCreateFoundation(PX_PHYSICS_VERSION,r.allocator,r.errors);if(!r.foundation)Fail("PhysX foundation creation failed");r.physics=PxCreatePhysics(PX_PHYSICS_VERSION,*r.foundation,PxTolerancesScale(),false,nullptr);if(!r.physics)Fail("PhysX SDK creation failed");r.extensions=PxInitExtensions(*r.physics,nullptr);if(!r.extensions)Fail("PhysX extensions initialization failed");
    PxCudaContextManagerDesc d;d.deviceOrdinal=selected;r.cuda=PxCreateCudaContextManager(*r.foundation,d,PxGetProfilerCallback());if(!r.cuda)Fail("PhysX CUDA context manager creation failed");r.Check();if(r.cuda->getDevice()!=selected)Fail("PhysX CUDA context is on the wrong DX12 adapter");
    r.dispatcher=PxDefaultCpuDispatcherCreate(2);if(!r.dispatcher)Fail("PhysX CPU orchestration dispatcher creation failed");r.Check();LogEvent(0,"physics.initialize","physx=%u cuda_device=%d luid=%08x:%08x sm=%d%d workers=2",PX_PHYSICS_VERSION,selected,unsigned(luid.HighPart),unsigned(luid.LowPart),major,minor);
}
void PhysicsRuntime::Shutdown(){auto& r=*impl_;for(auto& [id,o]:r.owners)for(auto& [h,s]:o->scenes)s->Destroy();r.owners.clear();if(r.dispatcher)r.dispatcher->release();r.dispatcher=nullptr;if(r.cuda)r.cuda->release();r.cuda=nullptr;if(r.extensions)PxCloseExtensions();r.extensions=false;if(r.physics)r.physics->release();r.physics=nullptr;if(r.foundation)r.foundation->release();r.foundation=nullptr;}
uint32_t PhysicsRuntime::Impl::Scene::ConfigurePopulation(const LabPopulationDescV1& d){
    if(desc.maxBodies>LAB_PHYSICS_POPULATION_COLLIDERS_V1||insectCapacity||d.structSize<sizeof(d)||d.layer==0||d.collisionMask==0||d.capacity<1||d.capacity>LAB_PHYSICS_POPULATION_MAX_V1||d.initialCount>d.capacity||!Valid(d.spawnCenter)||!Valid(d.spawnHalfExtent)||d.spawnHalfExtent.x<0||d.spawnHalfExtent.y<0||d.spawnHalfExtent.z<0||!ValidFlight(d.flight))return 0;
    for(auto mesh:{d.proxyMesh,d.bodyMesh,d.headMesh,d.abdomenMesh,d.leftWingMesh,d.rightWingMesh})if(mesh>=ConsoleSpec::MaxMeshes)return 0;
    for(auto mat:{d.bodyMaterial,d.headMaterial,d.wingMaterial})if(mat>=ConsoleSpec::MaxMaterials)return 0;
    for(auto& b:bodies)if(b.actor&&b.geometry.shape==LAB_PHYSICS_CONVEX)return 0;
    PxScopedCudaLock lock(*runtime.cuda);population=d;populationEffects.fleeSeconds=d.flight.impactSeconds;descriptorsDirty=true;populationClockOrigin=lastTime;populationClockStarted=lastTime>0;Allocate(populationBodyPoses,desc.maxBodies);Cuda(cudaMemsetAsync(populationBodyPoses,0,desc.maxBodies*sizeof(PopulationBodyPoseGpu),stream),"initialize population collider history");Allocate(populationGrid,PopulationGridWords);insectCapacity=d.capacity;Allocate(insects,insectCapacity);insectCount=d.initialCount;
    if(descriptorsDirty)RefreshDescriptors();PopulationInitialize(stream,insects,0,insectCount,population,++birthGeneration,populationBodies,uint32_t(populationBodyHost.size()),started?current:nullptr);Cuda(cudaGetLastError(),"initialize GPU population");
    auto v=visuals;auto l=lights;SetVisuals(v.data(),uint32_t(v.size()),l.data(),uint32_t(l.size()));return 1;
}
uint32_t PhysicsRuntime::Impl::Scene::ResizePopulation(uint32_t n){
    if(!insectCapacity||n>LAB_PHYSICS_POPULATION_MAX_V1)return 0;PxScopedCudaLock lock(*runtime.cuda);
    if(n>insectCapacity){uint32_t capacity=insectCapacity;while(capacity<n)capacity=std::min(LAB_PHYSICS_POPULATION_MAX_V1,capacity*2);
        PopulationStateGpu* next{};Allocate(next,capacity);Cuda(cudaMemcpyAsync(next,insects,insectCount*sizeof(PopulationStateGpu),cudaMemcpyDeviceToDevice,stream),"grow GPU population preserving survivors");Cuda(cudaStreamSynchronize(stream),"retire population capacity");cudaFree(insects);insects=next;insectCapacity=capacity;
        auto v=visuals;auto l=lights;SetVisuals(v.data(),uint32_t(v.size()),l.data(),uint32_t(l.size()));
    }
    if(n>insectCount){if(descriptorsDirty)RefreshDescriptors();PopulationInitialize(stream,insects,insectCount,n-insectCount,population,++birthGeneration,populationBodies,uint32_t(populationBodyHost.size()),started?current:nullptr);Cuda(cudaGetLastError(),"append GPU insect batch");}
    insectCount=n;return 1;
}
void PhysicsRuntime::Impl::Scene::StepPopulation(){
    if(!insectCapacity||!visible||!populationInput.enabled)return;
    insectAccumulator+=desc.fixedStepSeconds;
    constexpr double step=1./120.;
    while(insectAccumulator+1e-9>=step){insectAccumulator-=step;
    Cuda(cudaMemsetAsync(populationGrid,0,PopulationGridWords*sizeof(uint32_t),stream),"clear population broadphase");
    PopulationStep(stream,insects,insectCount,population,populationInput,populationEffects,populationHands,populationBodies,populationBodyPoses,populationGrid,uint32_t(populationBodyHost.size()),previous,current,velocity,angular,forces,torques,lightDevice,uint32_t(lightHost.size()),airflowDevice,uint32_t(airflowHost.size()),populationSpace,float(step),desc.fixedStepSeconds,simulationTime,float(populationSeconds));Cuda(cudaGetLastError(),"advance compact GPU flight and contacts");}
}
void PhysicsRuntime::Impl::Scene::QueuePopulationReadback(){
    auto& r=populationReadbacks[populationReadCursor];if(r.pending){auto ready=cudaEventQuery(r.done);if(ready==cudaErrorNotReady)return;Cuda(ready,"population readback reuse");}
    Cuda(cudaMemcpyAsync(r.host,&populationSummary->snapshot,sizeof(LabPopulationSnapshotV1),cudaMemcpyDeviceToHost,stream),"copy bounded population diagnostics and voices");Cuda(cudaEventRecord(r.done,stream),"complete population readback");r.pending=true;r.sequence=++populationReadSequence;populationReadCursor=(populationReadCursor+1)%uint32_t(populationReadbacks.size());
}
uint32_t PhysicsRuntime::Impl::Scene::PollPopulation(LabPopulationSnapshotV1* out){
    if(!out||out->structSize<sizeof(*out))return 0;PxScopedCudaLock lock(*runtime.cuda);PopulationReadback* newest{};
    for(auto& r:populationReadbacks)if(r.pending&&r.sequence>populationPolledSequence){auto ready=cudaEventQuery(r.done);if(ready==cudaErrorNotReady)continue;Cuda(ready,"poll GPU population");if(!newest||r.sequence>newest->sequence)newest=&r;}
    if(!newest)return 0;*out=*newest->host;populationPolledSequence=newest->sequence;return 1;
}
uint64_t PhysicsRuntime::CreateOwner(const LabGpuInteropServiceV1& interop){
    auto& r=*impl_;if(!r.physics||interop.version!=1||interop.structSize<sizeof(interop))Fail("PhysX owner requires initialized Core and gpu_interop_v1");auto o=std::make_unique<Impl::Owner>();o->runtime=&r;o->id=r.nextOwner++;o->interop=interop;o->service={1,sizeof(LabPhysicsServiceV1),o.get()};
    auto& t=o->service;
    t.CreateScene=[](void* c,const LabPhysicsSceneDescV1* d,LabPhysicsSceneV1* out)->LabU32{if(out)*out=0;if(!c||!d||!out||d->structSize<sizeof(*d)||!Valid(d->gravity)||d->maxBodies<1||d->maxBodies>4096||!Finite(d->fixedStepSeconds)||d->fixedStepSeconds<1.f/1000||d->fixedStepSeconds>1.f/60||d->maxSubsteps<1||d->maxSubsteps>16)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto h=uint64_t(o.runtime->Generation())<<32|1;auto s=std::make_unique<Impl::Scene>(*o.runtime,o,h,*d);s->Initialize();o.scenes.emplace(h,std::move(s));*out=h;return 1;};
    t.DestroyScene=[](void* c,LabPhysicsSceneV1 h)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto i=o.scenes.find(h);if(i==o.scenes.end())return 0;i->second->Destroy();o.scenes.erase(i);return 1;};
    t.CreateBody=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsBodyDescV1* d,LabPhysicsBodyV1* out)->LabU32{if(!c||!d)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->CreateBody(*d,out):0;};
    t.DestroyBody=[](void* c,LabPhysicsSceneV1 h,LabPhysicsBodyV1 b)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->DestroyBody(b):0;};
    t.CreateD6=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsD6DescV1* d,LabPhysicsJointV1* out)->LabU32{if(!c||!d)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->CreateD6(*d,out):0;};
    t.ConfigureD6=[](void* c,LabPhysicsSceneV1 h,LabPhysicsJointV1 j,const LabPhysicsD6DescV1* d)->LabU32{if(!c||!d)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->ConfigureD6(j,*d):0;};
    t.DestroyJoint=[](void* c,LabPhysicsSceneV1 h,LabPhysicsJointV1 j)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->DestroyJoint(j):0;};
    t.SetMotors=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsMotorV1* m,LabU32 n)->LabU32{if(!c||(n&&!m))return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s||n>s->joints.size())return 0;for(uint32_t i=0;i<n;i++)if(m[i].structSize<sizeof(*m)||!s->FindJoint(m[i].joint)||!Valid(m[i].target)||!Valid(m[i].linearVelocity)||!Valid(m[i].angularVelocity)||!Finite(m[i].frequencyHz)||m[i].frequencyHz<0||m[i].frequencyHz>1.f/(8*s->desc.fixedStepSeconds)||!Finite(m[i].phaseRadians)||!Finite(m[i].amplitudeRadians)||std::abs(m[i].amplitudeRadians)>1.5f)return 0;for(uint32_t i=0;i<n;i++)s->FindJoint(m[i].joint)->motor=m[i];return 1;};
    t.SubmitCommands=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsCommandV1* commands,LabU32 n)->LabU32{if(!c||(n&&!commands))return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s||n>s->desc.maxBodies*4||s->commands.size()+n>s->desc.maxBodies*8)return 0;for(uint32_t i=0;i<n;i++){auto& v=commands[i];auto* b=s->FindBody(v.body);if(v.structSize<sizeof(v)||!b||v.kind>LAB_PHYSICS_KINEMATIC_TARGET||!Valid(v.value)||!Valid(v.target)||!b->actor->is<PxRigidDynamic>()||((v.kind==LAB_PHYSICS_KINEMATIC_TARGET)!=b->kinematic))return 0;}for(uint32_t i=0;i<n;i++){const auto& v=commands[i];if(v.kind!=LAB_PHYSICS_IMPULSE&&v.kind!=LAB_PHYSICS_ANGULAR_IMPULSE)std::erase_if(s->commands,[&](const auto& old){return old.body==v.body&&old.kind==v.kind;});s->commands.push_back(v);}return 1;};
    t.SetAeroSurfaces=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsAeroSurfaceV1* a,LabU32 n)->LabU32{if(!c||(n&&!a))return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s||n>s->desc.maxBodies)return 0;for(uint32_t i=0;i<n;i++){auto* wing=s->FindBody(a[i].wing);auto* carrier=s->FindBody(a[i].carrier);if(a[i].structSize<sizeof(*a)||!wing||!carrier||wing->kinematic||carrier->kinematic||!wing->actor->is<PxRigidDynamic>()||!carrier->actor->is<PxRigidDynamic>()||!Valid(a[i].liftAxis)||!Finite(a[i].liftCoefficient)||!Finite(a[i].dragCoefficient)||!Finite(a[i].maxLift)||!Finite(a[i].maxDrag)||a[i].liftCoefficient<0||a[i].dragCoefficient<0||a[i].maxLift<0||a[i].maxDrag<0)return 0;}s->aero.clear();if(n)s->aero.assign(a,a+n);s->descriptorsDirty=true;return 1;};
    t.SetVisuals=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsVisualV1* v,LabU32 n,const LabPhysicsLightV1* l,LabU32 nl)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->SetVisuals(v,n,l,nl):0;};
    t.GetVisualProvider=[](void* c,LabPhysicsSceneV1 h,LabGpuPublicationProviderV1* out)->LabU32{if(!c||!out||out->structSize<sizeof(*out))return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s)return 0;*out=s->provider;return 1;};
    t.SetVisible=[](void* c,LabPhysicsSceneV1 h,LabU32 visible)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s)return 0;s->visible=visible!=0;return 1;};
    t.SetLightPower=[](void* c,LabPhysicsSceneV1 h,LabU32 lightIndex,float power)->LabU32{if(!c||!Finite(power)||power<0)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s)return 0;for(auto& l:s->lights)if(l.sceneLightIndex==lightIndex){l.power=power;s->descriptorsDirty=true;return 1;}return 0;};
    t.SetProbes=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsBodyV1* b,LabU32 n)->LabU32{if(!c||(n&&!b)||n>LABOVR_PHYSICS_MAX_PROBES_V1)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s)return 0;for(uint32_t i=0;i<n;i++)if(!s->FindBody(b[i]))return 0;s->lastProbeFrame=s->frame;s->probes.clear();if(n)s->probes.assign(b,b+n);s->descriptorsDirty=true;return 1;};
    t.PollSnapshot=[](void* c,LabPhysicsSceneV1 h,LabPhysicsSnapshotV1* out)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->Poll(out):0;};
    t.SetBodyCollisionEnabled=[](void* c,LabPhysicsSceneV1 h,LabPhysicsBodyV1 b,LabU32 enabled)->LabU32{if(!c||enabled>1)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->SetBodyCollisionEnabled(b,enabled!=0):0;};
    t.CreatePopulation=[](void* c,LabPhysicsSceneV1 h,const LabPopulationDescV1* d)->LabU32{if(!c||!d)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->ConfigurePopulation(*d):0;};
    t.SetPopulationCount=[](void* c,LabPhysicsSceneV1 h,LabU32 n)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->ResizePopulation(n):0;};
    t.SetFlightSettings=[](void* c,LabPhysicsSceneV1 h,const LabFlightSettingsV1* f)->LabU32{if(!c||!f||!ValidFlight(*f))return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s||!s->insectCapacity||f->seed!=s->population.flight.seed)return 0;s->population.flight=*f;s->populationEffects.fleeSeconds=f->impactSeconds;return 1;};
    t.SetPopulationInput=[](void* c,LabPhysicsSceneV1 h,const LabPopulationInputV1* in)->LabU32{if(!c||!in||in->structSize<sizeof(*in)||!Valid(in->playerPosition)||!Valid(in->aimOrigin)||!Valid(in->aimDirection))return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s||!s->insectCapacity)return 0;for(auto hand:in->hands)if(hand&&!s->FindBody(hand))return 0;if(in->hands[0]!=s->populationInput.hands[0]||in->hands[1]!=s->populationInput.hands[1])s->descriptorsDirty=true;s->populationInput=*in;return 1;};
    t.SetPopulationEffects=[](void* c,LabPhysicsSceneV1 h,const LabPopulationEffectsV1* e)->LabU32{
        if(!c||!e||e->structSize<sizeof(*e))return 0;
        const float v[]{e->sweepRadius,e->impulse,e->fleeSeconds,e->avoidanceRadius,e->residualAversion,e->shadowDensity,e->shadowIntensity};
        for(float x:v)if(!Finite(x)||x<0)return 0;
        if(e->sweepRadius<.02f||e->sweepRadius>1||e->impulse>8||e->fleeSeconds>120||e->avoidanceRadius<.1f||e->avoidanceRadius>4||e->residualAversion>1||e->shadowDensity>1||e->shadowIntensity>1)return 0;
        auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s||!s->insectCapacity)return 0;s->populationEffects=*e;s->population.flight.impactSeconds=e->fleeSeconds;return 1;
    };
    t.SetPopulationHands=[](void* c,LabPhysicsSceneV1 h,const LabPopulationHandsV1* in)->LabU32{
        if(!c||!in||in->structSize<sizeof(*in))return 0;
        for(auto& v:in->hand)if(!Valid(v.position)||!Valid(v.previous)||!Valid(v.velocity)||V(v.velocity).magnitudeSquared()>400||(V(v.position)-V(v.previous)).magnitudeSquared()>.25f)return 0;
        auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s||!s->insectCapacity)return 0;s->populationHands=*in;return 1;
    };
    t.PollPopulation=[](void* c,LabPhysicsSceneV1 h,LabPopulationSnapshotV1* out)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->PollPopulation(out):0;};
    t.SetAirflows=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsAirflowV1* fields,LabU32 n)->LabU32{
        if(!c||n>8||(n&&!fields))return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s)return 0;
        for(uint32_t i=0;i<n;i++){const auto& f=fields[i];auto* b=s->FindBody(f.emitter);float norm=V(f.localDirection).magnitudeSquared();
            if(f.structSize<sizeof(f)||f.enabled>1||!b||!b->actor->is<PxRigidDynamic>()||!Valid(f.localDirection)||norm<.99f||norm>1.01f||!Finite(f.radius)||f.radius<.05f||f.radius>4||!Finite(f.length)||f.length<.1f||f.length>16||!Finite(f.speedAtReferenceRpm)||f.speedAtReferenceRpm<0||f.speedAtReferenceRpm>80||!Finite(f.referenceRpm)||f.referenceRpm<=0||!Finite(f.turbulence)||f.turbulence<0||f.turbulence>1)return 0;
        }
        if(n==s->airflows.size()&&(!n||!memcmp(fields,s->airflows.data(),n*sizeof(*fields))))return 1;
        {PxScopedCudaLock lock(*o.runtime->cuda);Cuda(cudaStreamSynchronize(s->stream),"retire airflow descriptor edits");}
        s->airflows.clear();if(n)s->airflows.assign(fields,fields+n);s->descriptorsDirty=true;return 1;
    };
    t.SetPopulationSpace=[](void* c,LabPhysicsSceneV1 h,const LabPopulationSpaceV1* v)->LabU32{
        if(!c||!v||v->structSize<sizeof(*v)||v->enabled>1||!Valid(v->center)||!Valid(v->halfExtent)||v->halfExtent.x<.1f||v->halfExtent.y<.1f||v->halfExtent.z<.1f||v->halfExtent.x>64||v->halfExtent.y>64||v->halfExtent.z>64||!Finite(v->returnStrength)||v->returnStrength<0||v->returnStrength>16)return 0;
        auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);if(!s)return 0;s->populationSpace=*v;return 1;
    };
    t.SetPaused=[](void* c,LabPhysicsSceneV1 h,LabU32 paused)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s&&paused<=1?s->Pause(paused!=0):0;};
    t.GetEditSnapshot=[](void* c,LabPhysicsSceneV1 h,LabPhysicsEditSnapshotV1* out)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->EditSnapshot(out):0;};
    t.ApplyEdit=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsEditBatchV1* batch)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?batch?s->Edit(*batch):0:0;};
    t.TranslateBodies=[](void* c,LabPhysicsSceneV1 h,const LabPhysicsBodyV1* b,LabU32 n,LabVec3V1 delta)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->Translate(b,n,delta):0;};
    t.ValidateEdit=[](void* c,LabPhysicsSceneV1 h,LabPhysicsEditValidationV1* out)->LabU32{if(!c)return 0;auto& o=*static_cast<Impl::Owner*>(c);auto* s=o.runtime->Find(o,h);return s?s->ValidateEdit(out):0;};
    auto id=o->id;r.owners.emplace(id,std::move(o));return id;
}
void PhysicsRuntime::ResetOwner(uint64_t id){auto& r=*impl_;auto i=r.owners.find(id);if(i==r.owners.end())return;for(auto& [h,s]:i->second->scenes)s->Destroy();i->second->scenes.clear();}
LabPhysicsServiceV1 PhysicsRuntime::Service(uint64_t id){auto it=impl_->owners.find(id);if(it==impl_->owners.end())Fail("PhysX owner unavailable");return it->second->service;}
void PhysicsRuntime::Advance(double now,uint64_t inputFrame){impl_->Check();for(auto& [id,o]:impl_->owners)for(auto& [h,s]:o->scenes)s->Advance(now,inputFrame);}
}
