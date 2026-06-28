struct f_inputs {
  uint tint_local_index : SV_GroupIndex;
};


cbuffer cbuffer_u : register(b0) {
  uint4 u[2];
};
groupshared float4x2 w;
float4x2 v(uint start_byte_offset) {
  uint4 v_1 = u[(start_byte_offset / 16u)];
  uint4 v_2 = u[((8u + start_byte_offset) / 16u)];
  uint4 v_3 = u[((16u + start_byte_offset) / 16u)];
  uint4 v_4 = u[((24u + start_byte_offset) / 16u)];
  return float4x2(asfloat(select((((start_byte_offset & 15u) >> 2u) == 2u), v_1.zw, v_1.xy)), asfloat(select(((((8u + start_byte_offset) & 15u) >> 2u) == 2u), v_2.zw, v_2.xy)), asfloat(select(((((16u + start_byte_offset) & 15u) >> 2u) == 2u), v_3.zw, v_3.xy)), asfloat(select(((((24u + start_byte_offset) & 15u) >> 2u) == 2u), v_4.zw, v_4.xy)));
}

void f_inner(uint tint_local_index) {
  if ((tint_local_index < 1u)) {
    w = float4x2((0.0f).xx, (0.0f).xx, (0.0f).xx, (0.0f).xx);
  }
  GroupMemoryBarrierWithGroupSync();
  w = v(0u);
  w[1u] = asfloat(u[0u].xy);
  w[1u] = asfloat(u[0u].xy).yx;
  w[0u].y = asfloat(u[0u].z);
}

[numthreads(1, 1, 1)]
void f(f_inputs inputs) {
  f_inner(inputs.tint_local_index);
}

