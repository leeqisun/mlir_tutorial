// RUN: ns-opt %s --convert-north-satr-to-linalg --outline-north-star-device-kernels --lower-north-star-device-kernels-to-loops --lower-north-star-host-to-npu-calls --lower-north-star-npu-calls-to-runtime --lower-north-star-runtime-stubs-to-cuda-calls --generate-north-star-runtime-json --split-input-file | FileCheck %s
module @NorthStar {
  // CHECK: north_star.runtime_json = "{
  // CHECK-SAME: \22c_api\22: \22north_star_cuda_launch_f32\22
  // CHECK-SAME: \22descriptor_id\22: 0
  // CHECK-SAME: \22device_id\22: 1
  // CHECK-SAME: \22shape\22: [\0A            2,\0A            -1,\0A            -1
  // CHECK-SAME: \22kernel_name\22: \22softmax_2_d_d_softmax_2_d_d__device_1\22
  // CHECK: \22descriptor_id\22: 1
  // CHECK-SAME: \22device_id\22: 2
  // CHECK-SAME: \22shape\22: [\0A            2,\0A            -1,\0A            -1
  // CHECK-SAME: \22kernel_name\22: \22softmax_2_d_d_softmax_2_d_d__device_2\22
  // CHECK: \22target\22: \22nvidia_rtx_5060_cuda\22
  func.func @main(%arg0: !north_star.ns_tensor<5x?x?xf32,0>) -> !north_star.ns_tensor<5x?x?xf32,0> attributes {dp_attr = #north_star.DP<DP = 3 : 0, 1, 2>, host_func} {
    %0:3 = "north_star.buffer_cast"(%arg0) <{distribute_attr = #north_star.DP<DP = 3 : 0, 1, 2>}> : (!north_star.ns_tensor<5x?x?xf32,0>) -> (!north_star.ns_tensor<1x?x?xf32,0>, !north_star.ns_tensor<2x?x?xf32,1>, !north_star.ns_tensor<2x?x?xf32,2>)
    %1 = "north_star.softmax"(%0#0) <{axis = 1 : i64}> : (!north_star.ns_tensor<1x?x?xf32,0>) -> !north_star.ns_tensor<1x?x?xf32,0>
    %2 = "north_star.softmax"(%1) <{axis = 1 : i64}> : (!north_star.ns_tensor<1x?x?xf32,0>) -> !north_star.ns_tensor<1x?x?xf32,0>
    %3 = "north_star.device_region"(%0#1) <{device_id = 1 : i64, sym_name = "softmax_2_d_d_softmax_2_d_d_"}> ({
    ^bb0(%arg1: !north_star.ns_tensor<2x?x?xf32,1>):
      %52 = "north_star.softmax"(%arg1) <{axis = 1 : i64}> : (!north_star.ns_tensor<2x?x?xf32,1>) -> !north_star.ns_tensor<2x?x?xf32,1>
      %62 = "north_star.softmax"(%52) <{axis = 1 : i64}> : (!north_star.ns_tensor<2x?x?xf32,1>) -> !north_star.ns_tensor<2x?x?xf32,1>
      north_star.return %62 : !north_star.ns_tensor<2x?x?xf32,1>
    }) : (!north_star.ns_tensor<2x?x?xf32,1>) -> !north_star.ns_tensor<2x?x?xf32,1>
    %4 = "north_star.device_region"(%0#2) <{device_id = 2 : i64, sym_name = "softmax_2_d_d_softmax_2_d_d_"}> ({
    ^bb0(%arg1: !north_star.ns_tensor<2x?x?xf32,2>):
      %53 = "north_star.softmax"(%arg1) <{axis = 1 : i64}> : (!north_star.ns_tensor<2x?x?xf32,2>) -> !north_star.ns_tensor<2x?x?xf32,2>
      %63 = "north_star.softmax"(%53) <{axis = 1 : i64}> : (!north_star.ns_tensor<2x?x?xf32,2>) -> !north_star.ns_tensor<2x?x?xf32,2>
      north_star.return %63 : !north_star.ns_tensor<2x?x?xf32,2>
    }) : (!north_star.ns_tensor<2x?x?xf32,2>) -> !north_star.ns_tensor<2x?x?xf32,2>
    %5 = "north_star.buffer_cast"(%2, %3, %4) <{distribute_attr = #north_star.DP<DP = 3 : 0, 1, 2>}> : (!north_star.ns_tensor<1x?x?xf32,0>, !north_star.ns_tensor<2x?x?xf32,1>, !north_star.ns_tensor<2x?x?xf32,2>) -> !north_star.ns_tensor<5x?x?xf32,0>
    return %5 : !north_star.ns_tensor<5x?x?xf32,0>
  }
}
