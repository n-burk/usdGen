#include "rootFrames.h"

#include <algorithm>
#include <cmath>
#include <limits>
#include <utility>

namespace usdGen::gpu {
namespace {

constexpr int kBadShape = 1;
constexpr int kNonFinite = 2;
constexpr int kBadTopology = 3;
constexpr int kBadRoot = 4;
constexpr int kBadAuthoredFrame = 5;
constexpr float kEpsilon = 1.0e-6f;

__device__ void SetError(int* error, int code) { atomicCAS(error, 0, code); }
__device__ bool Finite(float x) { return isfinite(x); }
__device__ bool Finite(double x) { return isfinite(x); }
__device__ bool Finite(float2 v) { return Finite(v.x) && Finite(v.y); }
__device__ bool Finite(float3 v) { return Finite(v.x) && Finite(v.y) && Finite(v.z); }
__device__ float3 Add(float3 a, float3 b) { return make_float3(a.x+b.x, a.y+b.y, a.z+b.z); }
__device__ float3 Sub(float3 a, float3 b) { return make_float3(a.x-b.x, a.y-b.y, a.z-b.z); }
__device__ float3 Mul(float3 a, float s) { return make_float3(a.x*s, a.y*s, a.z*s); }
__device__ float Dot(float3 a, float3 b) { return a.x*b.x+a.y*b.y+a.z*b.z; }
__device__ float3 Cross(float3 a, float3 b) {
    return make_float3(a.y*b.z-a.z*b.y, a.z*b.x-a.x*b.z, a.x*b.y-a.y*b.x);
}
__device__ bool Normalize(float3 in, float3* out) {
    float const lengthSquared = Dot(in, in);
    if (!Finite(lengthSquared) || lengthSquared < kEpsilon*kEpsilon) return false;
    *out = Mul(in, rsqrtf(lengthSquared));
    return Finite(*out);
}

__device__ float3 Interpolate(float3 const* v, uint32_t const* indices,
                              uint32_t begin, uint32_t count, float u, float w) {
    if (count == 3) {
        float const a = 1.0f - u - w;
        return Add(Add(Mul(v[indices[begin]], a), Mul(v[indices[begin+1]], u)),
                   Mul(v[indices[begin+2]], w));
    }
    float const a = (1.0f-u)*(1.0f-w), b = u*(1.0f-w);
    float const c = u*w, d = (1.0f-u)*w;
    return Add(Add(Mul(v[indices[begin]], a), Mul(v[indices[begin+1]], b)),
               Add(Mul(v[indices[begin+2]], c), Mul(v[indices[begin+3]], d)));
}

__device__ float3 DpDu(float3 const* v, uint32_t const* indices,
                        uint32_t begin, uint32_t count, float u, float w) {
    float3 const p0 = v[indices[begin]], p1 = v[indices[begin+1]], p2 = v[indices[begin+2]];
    if (count == 3) return Sub(p1, p0);
    float3 const p3 = v[indices[begin+3]];
    return Add(Mul(Sub(p1, p0), 1.0f-w), Mul(Sub(p2, p3), w));
}

__device__ float3 GeometricNormal(float3 const* v, uint32_t const* indices,
                                   uint32_t begin, uint32_t count) {
    float3 const p0 = v[indices[begin]], p1 = v[indices[begin+1]], p2 = v[indices[begin+2]];
    float3 n = Cross(Sub(p1, p0), Sub(p2, p0));
    if (count == 4) {
        float3 const p3 = v[indices[begin+3]];
        n = Add(n, Cross(Sub(p2, p0), Sub(p3, p0)));
    }
    return n;
}

__device__ float3 AuthoredNormal(DeviceView<const float3> normals,
                                 RootFrameNormalDomain domain, size_t curve,
                                 uint32_t faceBegin, uint32_t faceCount,
                                 uint32_t face, uint32_t const* indices,
                                 float u, float v) {
    switch (domain) {
    case RootFrameNormalDomain::Constant: return normals.data[0];
    case RootFrameNormalDomain::Uniform: return normals.data[face];
    case RootFrameNormalDomain::Vertex: return Interpolate(normals.data, indices, faceBegin, faceCount, u, v);
    case RootFrameNormalDomain::FaceVarying: {
        float3 const* n = normals.data + faceBegin;
        uint32_t local[] = {0, 1, 2, 3};
        return Interpolate(n, local, 0, faceCount, u, v);
    }
    default: return make_float3(0, 0, 0);
    }
}

__device__ bool ValidAuthoredFrame(double const* m, float3* origin, float3* t,
                                   float3* b, float3* n) {
    for (int i = 0; i != 16; ++i) if (!Finite(m[i])) return false;
    // GfMatrix4d is row-major and applies row vectors: rows are transformed
    // local basis directions and row 3 is the translated origin.
    if (m[3] != 0.0 || m[7] != 0.0 || m[11] != 0.0 || m[15] != 1.0) return false;
    double const tx=m[0], ty=m[1], tz=m[2], bx=m[4], by=m[5], bz=m[6], nx=m[8], ny=m[9], nz=m[10];
    double const tolerance = 1.0e-8;
    double const tt=tx*tx+ty*ty+tz*tz, bb=bx*bx+by*by+bz*bz, nn=nx*nx+ny*ny+nz*nz;
    double const tb=tx*bx+ty*by+tz*bz, tn=tx*nx+ty*ny+tz*nz, bn=bx*nx+by*ny+bz*nz;
    double const handed = (ty*bz-tz*by)*nx + (tz*bx-tx*bz)*ny + (tx*by-ty*bx)*nz;
    if (fabs(tt-1.0) > tolerance || fabs(bb-1.0) > tolerance || fabs(nn-1.0) > tolerance ||
        fabs(tb) > tolerance || fabs(tn) > tolerance || fabs(bn) > tolerance ||
        handed < 1.0-tolerance) return false;
    *t = make_float3(float(tx), float(ty), float(tz));
    *b = make_float3(float(bx), float(by), float(bz));
    *n = make_float3(float(nx), float(ny), float(nz));
    *origin = make_float3(float(m[12]), float(m[13]), float(m[14]));
    return Finite(*t) && Finite(*b) && Finite(*n) && Finite(*origin);
}

__global__ void ValidateInput(
    DeviceView<const float3> vertices, DeviceView<const uint32_t> offsets,
    size_t faceCount, DeviceView<const uint32_t> indices,
    DeviceView<const int32_t> rootPrim, DeviceView<const float2> rootUV,
    DeviceView<const float3> normals, RootFrameNormalDomain normalDomain,
    DeviceView<const double> authoredFrames, int* error) {
    if (blockIdx.x == 0 && threadIdx.x == 0) {
        size_t expectedNormals = 0;
        if (!offsets.data || offsets.size != faceCount + 1 || offsets.data[0] != 0 ||
            offsets.data[faceCount] != indices.size) SetError(error, kBadTopology);
        if (normalDomain == RootFrameNormalDomain::Constant) expectedNormals = 1;
        else if (normalDomain == RootFrameNormalDomain::Uniform) expectedNormals = faceCount;
        else if (normalDomain == RootFrameNormalDomain::Vertex) expectedNormals = vertices.size;
        else if (normalDomain == RootFrameNormalDomain::FaceVarying) expectedNormals = indices.size;
        if ((normalDomain == RootFrameNormalDomain::None && normals.size != 0) ||
            (normalDomain != RootFrameNormalDomain::None && normals.size != expectedNormals) ||
            (authoredFrames.size && authoredFrames.size != rootPrim.size * 16))
            SetError(error, kBadShape);
    }
    size_t work = vertices.size;
    if (indices.size > work) work = indices.size;
    if (faceCount > work) work = faceCount;
    if (normals.size > work) work = normals.size;
    if (rootPrim.size > work) work = rootPrim.size;
    for (size_t i = size_t(blockIdx.x)*blockDim.x+threadIdx.x; i < work;
         i += size_t(blockDim.x)*gridDim.x) {
        if (i < vertices.size && !Finite(vertices.data[i])) SetError(error, kNonFinite);
        if (i < normals.size && !Finite(normals.data[i])) SetError(error, kNonFinite);
        if (i < indices.size && indices.data[i] >= vertices.size) SetError(error, kBadTopology);
        if (i < faceCount) {
            uint32_t const begin = offsets.data[i], end = offsets.data[i+1];
            if (end < begin || end > indices.size || (end - begin != 3 && end - begin != 4))
                SetError(error, kBadTopology);
        }
        if (i < rootPrim.size && (!Finite(rootUV.data[i]) || rootPrim.data[i] < 0 ||
            size_t(rootPrim.data[i]) >= faceCount)) SetError(error, kBadRoot);
        if (i < authoredFrames.size && !Finite(authoredFrames.data[i])) SetError(error, kNonFinite);
    }
}

__global__ void BuildFrames(
    DeviceView<const float3> vertices, DeviceView<const uint32_t> offsets,
    size_t faceCount, DeviceView<const uint32_t> indices,
    DeviceView<const int32_t> rootPrim, DeviceView<const float2> rootUV,
    DeviceView<const float3> normals, RootFrameNormalDomain normalDomain,
    DeviceView<const double> authoredFrames, DeviceView<float3> origin,
    DeviceView<float3> tangent, DeviceView<float3> binormal, DeviceView<float3> normal,
    DeviceView<uint8_t> valid, DeviceView<uint8_t> drop, uint32_t* badRootCount,
    int* error) {
    for (size_t c = size_t(blockIdx.x)*blockDim.x+threadIdx.x; c < rootPrim.size;
         c += size_t(blockDim.x)*gridDim.x) {
        int32_t const faceValue = rootPrim.data[c];
        float2 const uv = rootUV.data[c];
        if (faceValue < 0 || size_t(faceValue) >= faceCount || !Finite(uv) ||
            uv.x < 0 || uv.y < 0) { SetError(error, kBadRoot); continue; }
        uint32_t const begin = offsets.data[faceValue], end = offsets.data[faceValue+1];
        uint32_t const count = end - begin;
        if (end > indices.size || (count != 3 && count != 4)) { SetError(error, kBadTopology); continue; }
        if ((count == 3 && uv.x + uv.y > 1.0f) ||
            (count == 4 && (uv.x > 1.0f || uv.y > 1.0f))) { SetError(error, kBadRoot); continue; }
        for (uint32_t j = begin; j < end; ++j)
            if (indices.data[j] >= vertices.size) { SetError(error, kBadTopology); }
        if (authoredFrames.size) {
            if (!ValidAuthoredFrame(authoredFrames.data + c*16, &origin.data[c], &tangent.data[c],
                                    &binormal.data[c], &normal.data[c])) {
                SetError(error, kBadAuthoredFrame); continue;
            }
            valid.data[c] = 1; drop.data[c] = 0; continue;
        }
        float3 rawNormal = normalDomain == RootFrameNormalDomain::None
            ? GeometricNormal(vertices.data, indices.data, begin, count)
            : AuthoredNormal(normals, normalDomain, c, begin, count, uint32_t(faceValue), indices.data, uv.x, uv.y);
        float3 n;
        if (!Normalize(rawNormal, &n)) { valid.data[c] = 0; drop.data[c] = 1; atomicAdd(badRootCount, 1u); continue; }
        float3 derivative = DpDu(vertices.data, indices.data, begin, count, uv.x, uv.y);
        float3 projected = Sub(derivative, Mul(n, Dot(n, derivative)));
        float3 t;
        if (!Normalize(projected, &t)) {
            float3 edge = Sub(vertices.data[indices.data[begin+1]], vertices.data[indices.data[begin]]);
            projected = Sub(edge, Mul(n, Dot(n, edge)));
            if (!Normalize(projected, &t)) { valid.data[c] = 0; drop.data[c] = 1; atomicAdd(badRootCount, 1u); continue; }
        }
        float3 b = Cross(n, t);
        if (!Normalize(b, &b)) { valid.data[c] = 0; drop.data[c] = 1; atomicAdd(badRootCount, 1u); continue; }
        origin.data[c] = Interpolate(vertices.data, indices.data, begin, count, uv.x, uv.y);
        if (!Finite(origin.data[c])) { valid.data[c] = 0; drop.data[c] = 1; atomicAdd(badRootCount, 1u); continue; }
        tangent.data[c] = t; binormal.data[c] = b; normal.data[c] = n;
        valid.data[c] = 1; drop.data[c] = 0;
    }
}

unsigned Blocks(size_t count) {
    return static_cast<unsigned>(count ? std::min<size_t>((count + 255) / 256, 65535) : 1);
}
cudaError_t CheckStream(int device, cudaStream_t stream) {
    int current = -1;
    if (cudaGetDevice(&current) != cudaSuccess) return cudaErrorUnknown;
    if (device >= 0 && current != device) return cudaErrorInvalidDevice;
    if (stream) { int streamDevice = -1; if (cudaStreamGetDevice(stream, &streamDevice) != cudaSuccess || streamDevice != current) return cudaErrorInvalidDevice; }
    return cudaSuccess;
}

} // namespace

void CudaRestRootFrames::Storage::clear() noexcept {
    origin.reset(0); tangent.reset(0); binormal.reset(0); normal.reset(0); valid.reset(0); drop.reset(0); curveCount = 0;
}
void CudaRestRootFrames::Storage::quarantine() noexcept {
    origin.quarantine(); tangent.quarantine(); binormal.quarantine(); normal.quarantine(); valid.quarantine(); drop.quarantine(); curveCount = 0;
}
void CudaRestRootFrames::Storage::swap(Storage& other) noexcept {
    using std::swap; swap(origin, other.origin); swap(tangent, other.tangent); swap(binormal, other.binormal); swap(normal, other.normal); swap(valid, other.valid); swap(drop, other.drop); swap(curveCount, other.curveCount);
}
cudaError_t CudaRestRootFrames::Storage::recordUse(cudaStream_t stream) {
    cudaError_t e = origin.recordUse(stream); if (e == cudaSuccess) e = tangent.recordUse(stream); if (e == cudaSuccess) e = binormal.recordUse(stream); if (e == cudaSuccess) e = normal.recordUse(stream); if (e == cudaSuccess) e = valid.recordUse(stream); if (e == cudaSuccess) e = drop.recordUse(stream); return e;
}
cudaError_t CudaRestRootFrames::Storage::waitOn(cudaStream_t stream) const {
    cudaError_t e = origin.waitOn(stream); if (e == cudaSuccess) e = tangent.waitOn(stream); if (e == cudaSuccess) e = binormal.waitOn(stream); if (e == cudaSuccess) e = normal.waitOn(stream); if (e == cudaSuccess) e = valid.waitOn(stream); if (e == cudaSuccess) e = drop.waitOn(stream); return e;
}

CudaRestRootFrames::~CudaRestRootFrames() {
    int previous = -1; bool const owns = ready_ || active_.curveCount || pendingStorage_.curveCount || error_.size();
    bool const selected = !owns || (cudaGetDevice(&previous) == cudaSuccess && deviceIndex_ >= 0 && cudaSetDevice(deviceIndex_) == cudaSuccess);
    bool const synchronized = !owns || (selected && (!ready_ || cudaEventSynchronize(ready_) == cudaSuccess) &&
        (!active_.curveCount || (active_.waitOn(nullptr) == cudaSuccess && cudaStreamSynchronize(nullptr) == cudaSuccess)));
    if (!selected || !synchronized) { active_.quarantine(); pendingStorage_.quarantine(); error_.quarantine(); pendingBadRootCount_.quarantine(); ready_ = nullptr; if (selected && previous >= 0 && previous != deviceIndex_) cudaSetDevice(previous); return; }
    if (ready_) cudaEventDestroy(ready_); active_.clear(); pendingStorage_.clear(); error_.reset(0); pendingBadRootCount_.reset(0);
    if (previous >= 0 && previous != deviceIndex_) cudaSetDevice(previous);
}

RootFrameStatus CudaRestRootFrames::fail(RootFrameStatus status, char const* message) { diagnostic_ = message; return status; }
cudaError_t CudaRestRootFrames::validateStream(cudaStream_t stream) const { return CheckStream(deviceIndex_, stream); }
void CudaRestRootFrames::discardPending() noexcept { pendingStorage_.clear(); pendingBadRootCount_.reset(0); pending_ = false; }
void CudaRestRootFrames::quarantinePending() noexcept {
    pendingStorage_.quarantine(); pendingBadRootCount_.quarantine(); error_.quarantine(); pending_ = false;
}

RootFrameStatus CudaRestRootFrames::Apply(
    DeviceView<const float3> vertices, DeviceView<const uint32_t> offsets, size_t faceCount,
    DeviceView<const uint32_t> indices, DeviceView<const int32_t> rootPrim,
    DeviceView<const float2> rootUV, DeviceView<const float3> normals,
    RootFrameNormalDomain normalDomain, DeviceView<const double> authoredFrames,
    cudaStream_t stream) {
    if (pending_) return fail(RootFrameStatus::InvalidArgument, "Finish is required before another Apply");
    if (validateStream(stream) != cudaSuccess) return fail(RootFrameStatus::InvalidArgument, "stream device does not match root frames");
    if (deviceIndex_ < 0 && cudaGetDevice(&deviceIndex_) != cudaSuccess) return fail(RootFrameStatus::CudaError, "cannot identify CUDA device");
    size_t const curveCount = rootPrim.size;
    if ((vertices.size && !vertices.data) || !offsets.data || offsets.size != faceCount + 1 ||
        (indices.size && !indices.data) || (!rootPrim.data && curveCount) ||
        rootUV.size != curveCount || (!rootUV.data && curveCount) ||
        (normals.size && !normals.data) || (authoredFrames.size && !authoredFrames.data) ||
        (normalDomain == RootFrameNormalDomain::None && normals.size) ||
        (normalDomain != RootFrameNormalDomain::None && normalDomain != RootFrameNormalDomain::Constant && normalDomain != RootFrameNormalDomain::Uniform && normalDomain != RootFrameNormalDomain::Vertex && normalDomain != RootFrameNormalDomain::FaceVarying) ||
        (curveCount > std::numeric_limits<size_t>::max() / 16) ||
        (authoredFrames.size && authoredFrames.size != curveCount * 16))
        return fail(RootFrameStatus::InvalidArgument, "invalid root-frame input view shape");
    if (!curveCount && authoredFrames.size) return fail(RootFrameStatus::InvalidArgument, "empty root frames require empty authored matrices");
    if (!ready_ && cudaEventCreateWithFlags(&ready_, cudaEventDisableTiming) != cudaSuccess) return fail(RootFrameStatus::CudaError, "root-frame event allocation failed");
    pendingStorage_.clear(); pendingStorage_.curveCount = curveCount;
    if (error_.reset(1) != cudaSuccess || pendingBadRootCount_.reset(1) != cudaSuccess ||
        pendingStorage_.origin.reset(curveCount) != cudaSuccess || pendingStorage_.tangent.reset(curveCount) != cudaSuccess ||
        pendingStorage_.binormal.reset(curveCount) != cudaSuccess || pendingStorage_.normal.reset(curveCount) != cudaSuccess ||
        pendingStorage_.valid.reset(curveCount) != cudaSuccess || pendingStorage_.drop.reset(curveCount) != cudaSuccess ||
        cudaMemsetAsync(error_.data(), 0, sizeof(int), stream) != cudaSuccess ||
        cudaMemsetAsync(pendingBadRootCount_.data(), 0, sizeof(uint32_t), stream) != cudaSuccess)
        { quarantinePending(); return fail(RootFrameStatus::CudaError, "root-frame allocation failed"); }
    size_t const validationWork = std::max(vertices.size, std::max(indices.size, std::max(faceCount, std::max(normals.size, curveCount))));
    ValidateInput<<<Blocks(validationWork), 256, 0, stream>>>(vertices, offsets, faceCount, indices, rootPrim, rootUV, normals, normalDomain, authoredFrames, error_.data());
    int validationError = 0;
    if (cudaGetLastError() != cudaSuccess || cudaMemcpyAsync(&validationError, error_.data(), sizeof(validationError), cudaMemcpyDeviceToHost, stream) != cudaSuccess || cudaStreamSynchronize(stream) != cudaSuccess) { quarantinePending(); return fail(RootFrameStatus::CudaError, "root-frame validation failed"); }
    if (validationError) { discardPending(); return fail(validationError == kNonFinite ? RootFrameStatus::NonFiniteInput : validationError == kBadTopology ? RootFrameStatus::InvalidTopology : validationError == kBadRoot ? RootFrameStatus::InvalidRootBinding : RootFrameStatus::InvalidArgument, "invalid root-frame input"); }
    if (curveCount && (cudaMemsetAsync(pendingStorage_.origin.data(), 0, curveCount*sizeof(float3), stream) != cudaSuccess ||
        cudaMemsetAsync(pendingStorage_.tangent.data(), 0, curveCount*sizeof(float3), stream) != cudaSuccess ||
        cudaMemsetAsync(pendingStorage_.binormal.data(), 0, curveCount*sizeof(float3), stream) != cudaSuccess ||
        cudaMemsetAsync(pendingStorage_.normal.data(), 0, curveCount*sizeof(float3), stream) != cudaSuccess ||
        cudaMemsetAsync(pendingStorage_.valid.data(), 0, curveCount*sizeof(uint8_t), stream) != cudaSuccess ||
        cudaMemsetAsync(pendingStorage_.drop.data(), 0, curveCount*sizeof(uint8_t), stream) != cudaSuccess)) {
        quarantinePending(); return fail(RootFrameStatus::CudaError, "root-frame output initialization failed");
    }
    BuildFrames<<<Blocks(curveCount), 256, 0, stream>>>(vertices, offsets, faceCount, indices, rootPrim, rootUV, normals, normalDomain, authoredFrames, pendingStorage_.origin.view(), pendingStorage_.tangent.view(), pendingStorage_.binormal.view(), pendingStorage_.normal.view(), pendingStorage_.valid.view(), pendingStorage_.drop.view(), pendingBadRootCount_.data(), error_.data());
    if (cudaGetLastError() != cudaSuccess || cudaEventRecord(ready_, stream) != cudaSuccess) { quarantinePending(); return fail(RootFrameStatus::CudaError, "root-frame kernel launch failed"); }
    pending_ = true; diagnostic_.clear(); return RootFrameStatus::Ok;
}

RootFrameStatus CudaRestRootFrames::Finish(cudaStream_t stream) {
    if (validateStream(stream) != cudaSuccess) return fail(RootFrameStatus::InvalidArgument, "completion stream device does not match root frames");
    if (!pending_) return RootFrameStatus::NoPendingUpdate;
    int error = 0; uint32_t bad = 0;
    if (cudaStreamWaitEvent(stream, ready_, 0) != cudaSuccess || cudaMemcpyAsync(&error, error_.data(), sizeof(error), cudaMemcpyDeviceToHost, stream) != cudaSuccess || cudaMemcpyAsync(&bad, pendingBadRootCount_.data(), sizeof(bad), cudaMemcpyDeviceToHost, stream) != cudaSuccess || cudaStreamSynchronize(stream) != cudaSuccess) { quarantinePending(); return fail(RootFrameStatus::CudaError, "root-frame completion failed"); }
    if (error) { discardPending(); return fail(error == kNonFinite ? RootFrameStatus::NonFiniteInput : error == kBadTopology ? RootFrameStatus::InvalidTopology : error == kBadRoot ? RootFrameStatus::InvalidRootBinding : error == kBadAuthoredFrame ? RootFrameStatus::InvalidAuthoredFrame : RootFrameStatus::InvalidArgument, "invalid root-frame input"); }
    if (active_.curveCount && (active_.waitOn(stream) != cudaSuccess || cudaStreamSynchronize(stream) != cudaSuccess)) { quarantinePending(); return fail(RootFrameStatus::CudaError, "active root-frame consumer fence failed"); }
    active_.swap(pendingStorage_); pendingStorage_.clear(); pendingBadRootCount_.reset(0); badRootCount_ = bad; pending_ = false; ++generation_; diagnostic_.clear(); return RootFrameStatus::Ok;
}

RestRootFrames CudaRestRootFrames::frames() const noexcept { return {active_.tangent.view(), active_.binormal.view(), active_.normal.view()}; }
DeviceView<const float3> CudaRestRootFrames::origins() const noexcept { return active_.origin.view(); }
DeviceView<const uint8_t> CudaRestRootFrames::valid() const noexcept { return active_.valid.view(); }
DeviceView<const uint8_t> CudaRestRootFrames::dropMask() const noexcept { return active_.drop.view(); }
cudaError_t CudaRestRootFrames::recordUse(cudaStream_t stream) { return validateStream(stream) == cudaSuccess ? active_.recordUse(stream) : cudaErrorInvalidDevice; }
cudaError_t CudaRestRootFrames::waitOn(cudaStream_t stream) const { return validateStream(stream) == cudaSuccess ? active_.waitOn(stream) : cudaErrorInvalidDevice; }

} // namespace usdGen::gpu
