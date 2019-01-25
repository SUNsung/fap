
        
        
#define TegraCvtColor_Invoker(name, func, ...) \
class TegraCvtColor_##name##_Invoker : public cv::ParallelLoopBody \
{ \
public: \
    TegraCvtColor_##name##_Invoker(const uchar * src_data_, size_t src_step_, uchar * dst_data_, size_t dst_step_, int width_, int height_) : \
        cv::ParallelLoopBody(), src_data(src_data_), src_step(src_step_), dst_data(dst_data_), dst_step(dst_step_), width(width_), height(height_) {} \
    virtual void operator()(const cv::Range& range) const CV_OVERRIDE \
    { \
        CAROTENE_NS::func(CAROTENE_NS::Size2D(width, range.end-range.start), __VA_ARGS__); \
    } \
private: \
    const uchar * src_data; \
    size_t src_step; \
    uchar * dst_data; \
    size_t dst_step; \
    int width, height; \
    const TegraCvtColor_##name##_Invoker& operator= (const TegraCvtColor_##name##_Invoker&); \
};
    
        typedef int8_t   s8;
    typedef uint8_t  u8;
    typedef int16_t  s16;
    typedef uint16_t u16;
    typedef int32_t  s32;
    typedef uint32_t u32;
    typedef float    f32;
    typedef int64_t  s64;
    typedef uint64_t u64;
    typedef double   f64;
    
    #define MUL2(val) (val << 1)
#define MUL3(val) (MUL2(val) + val)
#define MUL4(val) (val << 2)
    
                for (size_t i = 0; i < size.height; ++i)
            {
                const s16 * src = internal::getRowPtr(srcBase, srcStride, i);
                u8 * dst = internal::getRowPtr(dstBase, dstStride, i);
                size_t j = 0;
    }
    
    #if !defined(__aarch64__) && defined(__GNUC__) && __GNUC__ == 4 &&  __GNUC_MINOR__ < 7 && !defined(__clang__)
CVTS_FUNC(s16, u16, 8,
    register float32x4_t vscale asm ('q0') = vdupq_n_f32((f32)alpha);
    register float32x4_t vshift asm ('q1') = vdupq_n_f32((f32)beta + 0.5f);,
{
    for (size_t i = 0; i < w; i += 8)
    {
        internal::prefetch(_src + i);
        __asm__ (
            'vld1.16 {d4-d5}, [%[src]]                              \n\t'
            'vmovl.s16 q3, d4                                       \n\t'
            'vmovl.s16 q4, d5                                       \n\t'
            'vcvt.f32.s32 q5, q3                                    \n\t'
            'vcvt.f32.s32 q6, q4                                    \n\t'
            'vmul.f32 q7, q5, q0                                    \n\t'
            'vmul.f32 q8, q6, q0                                    \n\t'
            'vadd.f32 q9, q7, q1                                    \n\t'
            'vadd.f32 q10, q8, q1                                   \n\t'
            'vcvt.s32.f32 q11, q9                                   \n\t'
            'vcvt.s32.f32 q12, q10                                  \n\t'
            'vqmovun.s32 d26, q11                                   \n\t'
            'vqmovun.s32 d27, q12                                   \n\t'
            'vst1.16 {d26-d27}, [%[dst]]                            \n\t'
            : /*no output*/
            : [src] 'r' (_src + i),
              [dst] 'r' (_dst + i + 0),
              'w'  (vscale), 'w' (vshift)
            : 'd4','d5','d6','d7','d8','d9','d10','d11','d12','d13','d14','d15','d16','d17','d18','d19','d20','d21','d22','d23','d24','d25','d26','d27'
        );
    }
})
#else
CVTS_FUNC(s16, u16, 8,
    float32x4_t vscale = vdupq_n_f32((f32)alpha);
    float32x4_t vshift = vdupq_n_f32((f32)beta + 0.5f);,
{
    for (size_t i = 0; i < w; i += 8)
    {
        internal::prefetch(_src + i);
        int16x8_t vline = vld1q_s16(_src + i);
        int32x4_t vline1_s32 = vmovl_s16(vget_low_s16 (vline));
        int32x4_t vline2_s32 = vmovl_s16(vget_high_s16(vline));
        float32x4_t vline1_f32 = vcvtq_f32_s32(vline1_s32);
        float32x4_t vline2_f32 = vcvtq_f32_s32(vline2_s32);
        vline1_f32 = vmulq_f32(vline1_f32, vscale);
        vline2_f32 = vmulq_f32(vline2_f32, vscale);
        vline1_f32 = vaddq_f32(vline1_f32, vshift);
        vline2_f32 = vaddq_f32(vline2_f32, vshift);
        vline1_s32 = vcvtq_s32_f32(vline1_f32);
        vline2_s32 = vcvtq_s32_f32(vline2_f32);
        uint16x4_t vRes1 = vqmovun_s32(vline1_s32);
        uint16x4_t vRes2 = vqmovun_s32(vline2_s32);
        vst1q_u16(_dst + i, vcombine_u16(vRes1, vRes2));
    }
})
#endif
    
            for (; i < roiw4; i += 4 )
        {
            internal::prefetch(src + i);
            uint32x4_t vln = vld1q_u32(src + i);
            uint32x4_t vnz = vminq_u32(vln, vc1);
            vs = vqaddq_u32(vs, vnz);
        }
    
    namespace CAROTENE_NS {
    }
    
                        tprev1 = vextq_s16(tnext1, tnext1, 6);
                    tprev1 = vsetq_lane_s16(vgetq_lane_s16(tprev1, 3),tprev1, 0);
                    tprev1 = vsetq_lane_s16(vgetq_lane_s16(tprev1, 2),tprev1, 1);
                } else if (border == BORDER_MODE_REFLECT101) {
                    tpprev1 = vextq_s16(tnext2, tnext2, 7);
                    tpprev1 = vsetq_lane_s16(vgetq_lane_s16(tpprev1, 2),tpprev1, 0);
    
    // Disable the copy and assignment operator for a class.
#define DISABLE_COPY_AND_ASSIGN(classname) \
private:\
  classname(const classname&);\
  classname& operator=(const classname&)
    
      virtual void Forward_cpu(const vector<Blob<Dtype>*>& bottom,
      const vector<Blob<Dtype>*>& top);
  virtual void Forward_gpu(const vector<Blob<Dtype>*>& bottom,
      const vector<Blob<Dtype>*>& top);
    
     protected:
  virtual void Forward_cpu(const vector<Blob<Dtype>*>& bottom,
      const vector<Blob<Dtype>*>& top);
  virtual void Backward_cpu(const vector<Blob<Dtype>*>& top,
      const vector<bool>& propagate_down, const vector<Blob<Dtype>*>& bottom);
  virtual void Forward_gpu(const vector<Blob<Dtype>*>& bottom,
      const vector<Blob<Dtype>*>& top);
  virtual void Backward_gpu(const vector<Blob<Dtype>*>& top,
      const vector<bool>& propagate_down, const vector<Blob<Dtype>*>& bottom);
    
     protected:
  virtual void Forward_gpu(const vector<Blob<Dtype>*>& bottom,
                           const vector<Blob<Dtype>*>& top);
  virtual void Backward_gpu(const vector<Blob<Dtype>*>& top,
                            const vector<bool>& propagate_down,
                            const vector<Blob<Dtype>*>& bottom);
    
    
    {  size_t tempDataSize;
  void *tempData1, *tempData2;
};
#endif
    
    #endif  // CAFFE_CUDNN_SOFTMAX_LAYER_HPP_

    
    const std::string DHTResponseMessage::R('r');
    
    void DHTRoutingTableSerializer::setNodes(
    const std::vector<std::shared_ptr<DHTNode>>& nodes)
{
  nodes_ = nodes;
}
    
    namespace aria2 {
    }
    
      virtual void startup() = 0;
    
    #include 'common.h'
    
    void DHTTaskQueueImpl::addImmediateTask(const std::shared_ptr<DHTTask>& task)
{
  immediateTaskQueue_.addTask(task);
}
    
      unsigned char secret_[2][SECRET_SIZE];
    
    TEST(EsdCanClientTest, simple_test) {
  CANCardParameter param;
  param.set_brand(CANCardParameter::ESD_CAN);
  param.set_channel_id(CANCardParameter::CHANNEL_ID_ZERO);
    }
    
    #include 'modules/canbus/proto/chassis_detail.pb.h'
    
    TEST(ByteTest, SetBit) {
  unsigned char byte_value = 0xFF;
  Byte value(&byte_value);
  value.set_bit_0(1);
  EXPECT_EQ(0xFD, value.get_byte());
  value.set_bit_0(7);
  EXPECT_EQ(0x7D, value.get_byte());
  value.set_bit_1(7);
  EXPECT_EQ(0xFD, value.get_byte());
  value.set_value(0x77);
  value.set_bit_1(0);
  EXPECT_EQ(0x77, value.get_byte());
    }
    
    double ObjectExtendedInfo60D::longitude_accel(const std::uint8_t* bytes,
                                              int32_t length) const {
  Byte t0(bytes + 1);
  int32_t x = t0.get_byte(0, 8);
    }
    
    double ObjectGeneralInfo60B::lateral_vel(const std::uint8_t* bytes,
                                         int32_t length) const {
  Byte t0(bytes + 5);
  int32_t x = t0.get_byte(0, 6);
    }
    
    
    {  int ret = x;
  return ret;
}
    
    Unless required by applicable law or agreed to in writing, software
distributed under the License is distributed on an 'AS IS' BASIS,
WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
See the License for the specific language governing permissions and
limitations under the License.
=========================================================================*/
    
    #include 'gflags/gflags.h'
#include 'gtest/gtest.h'
    
    const PolynomialXd& Spline1dSeg::spline_func() const { return spline_func_; }
    
    Eigen::MatrixXd SplineSegKernel::NthDerivativeKernel(
    const uint32_t n, const uint32_t num_params, const double accumulated_x) {
  if (n == 1) {
    return DerivativeKernel(num_params, accumulated_x);
  } else if (n == 2) {
    return SecondOrderDerivativeKernel(num_params, accumulated_x);
  } else if (n == 3) {
    return ThirdOrderDerivativeKernel(num_params, accumulated_x);
  } else {
    return Eigen::MatrixXd::Zero(num_params, num_params);
  }
}
    
    const std::string& NodeWithRange::LaneId() const {
  return topo_node_->LaneId();
}
    
    #include 'modules/canbus/vehicle/gem/protocol/accel_cmd_67.h'
#include 'modules/canbus/vehicle/gem/protocol/accel_rpt_68.h'
#include 'modules/canbus/vehicle/gem/protocol/brake_cmd_6b.h'
#include 'modules/canbus/vehicle/gem/protocol/brake_motor_rpt_1_70.h'
#include 'modules/canbus/vehicle/gem/protocol/brake_motor_rpt_2_71.h'
#include 'modules/canbus/vehicle/gem/protocol/brake_motor_rpt_3_72.h'
#include 'modules/canbus/vehicle/gem/protocol/brake_rpt_6c.h'
#include 'modules/canbus/vehicle/gem/protocol/date_time_rpt_83.h'
#include 'modules/canbus/vehicle/gem/protocol/global_cmd_69.h'
#include 'modules/canbus/vehicle/gem/protocol/global_rpt_6a.h'
#include 'modules/canbus/vehicle/gem/protocol/headlight_cmd_76.h'
#include 'modules/canbus/vehicle/gem/protocol/headlight_rpt_77.h'
#include 'modules/canbus/vehicle/gem/protocol/horn_cmd_78.h'
#include 'modules/canbus/vehicle/gem/protocol/horn_rpt_79.h'
#include 'modules/canbus/vehicle/gem/protocol/lat_lon_heading_rpt_82.h'
#include 'modules/canbus/vehicle/gem/protocol/parking_brake_status_rpt_80.h'
#include 'modules/canbus/vehicle/gem/protocol/shift_cmd_65.h'
#include 'modules/canbus/vehicle/gem/protocol/shift_rpt_66.h'
#include 'modules/canbus/vehicle/gem/protocol/steering_cmd_6d.h'
#include 'modules/canbus/vehicle/gem/protocol/steering_motor_rpt_1_73.h'
#include 'modules/canbus/vehicle/gem/protocol/steering_motor_rpt_2_74.h'
#include 'modules/canbus/vehicle/gem/protocol/steering_motor_rpt_3_75.h'
#include 'modules/canbus/vehicle/gem/protocol/steering_rpt_1_6e.h'
#include 'modules/canbus/vehicle/gem/protocol/turn_cmd_63.h'
#include 'modules/canbus/vehicle/gem/protocol/turn_rpt_64.h'
#include 'modules/canbus/vehicle/gem/protocol/vehicle_speed_rpt_6f.h'
#include 'modules/canbus/vehicle/gem/protocol/wheel_speed_rpt_7a.h'
#include 'modules/canbus/vehicle/gem/protocol/wiper_cmd_90.h'
#include 'modules/canbus/vehicle/gem/protocol/wiper_rpt_91.h'
#include 'modules/canbus/vehicle/gem/protocol/yaw_rate_rpt_81.h'
    
    #include <folly/Expected.h>
#include <folly/Portability.h>
#include <folly/ScopeGuard.h>
#include <folly/portability/GTest.h>
    
    namespace folly {
    }
    
    
    {    ts.tv_sec = 0;
    ts.tv_nsec = std::numeric_limits<int64_t>::max();
    EXPECT_EQ(std::numeric_limits<int64_t>::max(), to<nsec_i64>(ts).count());
    ts.tv_sec = 1;
    ts.tv_nsec = std::numeric_limits<int64_t>::max() - std::nano::den;
    EXPECT_EQ(std::numeric_limits<int64_t>::max(), to<nsec_i64>(ts).count());
    ts.tv_sec = 1;
    ts.tv_nsec = std::numeric_limits<int64_t>::max() - std::nano::den + 1;
    EXPECT_THROW(to<nsec_i64>(ts), std::range_error);
  }
    
      // Install a pointer to ourselves as the allocator.
  *reinterpret_cast<SimpleAllocator**>(mem_) = this;
  static_assert(max_align_v >= sizeof(SimpleAllocator*), 'alignment too small');
  mem_ += std::min(sz_, max_align_v);
    
    
    {  T* get() const {
    return p_;
  }
  T* operator->() const {
    return p_;
  }
  explicit operator bool() const {
    return p_ == nullptr ? false : true;
  }
  bool operator==(const counted_ptr<T, Atom>& p) const {
    return get() == p.get();
  }
};