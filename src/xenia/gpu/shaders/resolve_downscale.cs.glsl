/**
 ******************************************************************************
 * Xenia : Xbox 360 Emulator Research Project                                 *
 ******************************************************************************
 * Copyright 2025 Ben Vanik. All rights reserved.                             *
 * Released under the BSD license - see LICENSE in the root for more details. *
 ******************************************************************************
 */

#version 460

// Compute shader to downscale scaled resolve buffer data back to 1x resolution.
// Operates on 32x32 tiled data format used by Xbox 360.
// Each thread handles one output pixel (one 32x32 tile = 1024 threads).
//
// The scaling picks the top-left pixel of each scale_x * scale_y block,
// effectively point-sampling the scaled data back to original resolution.

layout(local_size_x = 32, local_size_y = 32, local_size_z = 1) in;

layout(push_constant) uniform ResolveDownscaleConstants {
  uint xe_downscale_scale_x;           // 1 to kMaxDrawResolutionScaleAlongAxis
  uint xe_downscale_scale_y;           // 1 to kMaxDrawResolutionScaleAlongAxis
  uint xe_downscale_pixel_size_log2;   // 0=8bit, 1=16bit, 2=32bit, 3=64bit
  uint xe_downscale_tile_count;        // Number of 32x32 tiles to process
  uint xe_downscale_source_offset_bytes;   // Byte offset into source buffer
};

// Source buffer (scaled resolve data)
layout(std430, set = 0, binding = 0) readonly buffer SourceBuffer {
  uint data[];
} xe_resolve_source;

// Destination buffer (1x resolution)
layout(std430, set = 0, binding = 1) writeonly buffer DestBuffer {
  uint data[];
} xe_resolve_dest;

// Groupshared memory for coalescing sub-32-bit writes
shared uint gs_tile_data[32 * 32];

void main() {
  uint tile_index = gl_WorkGroupID.x;

  // Early out if beyond tile count
  if (tile_index >= xe_downscale_tile_count) {
    return;
  }

  uint row = gl_LocalInvocationID.y;
  uint column = gl_LocalInvocationID.x;
  uint pixel_index = row * 32u + column;  // 0-1023

  uint pixel_size = 1u << xe_downscale_pixel_size_log2;
  uint tile_size_1x = 32u * 32u * pixel_size;
  uint scale_xy = xe_downscale_scale_x * xe_downscale_scale_y;
  uint tile_size_scaled = tile_size_1x * scale_xy;

  // Source offset: pick every (scale_x * scale_y)th pixel
  // Add source_offset_bytes to handle buffer-relative addressing
  // This must be done before division to preserve sub-dword byte position
  uint src_byte_offset = xe_downscale_source_offset_bytes +
                         tile_index * tile_size_scaled +
                         pixel_index * pixel_size * scale_xy;
  uint src_offset = src_byte_offset >> 2u;

  // Destination offset in 1x buffer
  uint dst_byte_offset = tile_index * tile_size_1x +
                         pixel_index * pixel_size;
  uint dst_offset = dst_byte_offset >> 2u;

  // Copy pixel based on size
  switch (xe_downscale_pixel_size_log2) {
    case 0u: {  // 8-bit - use groupshared to coalesce 4 bytes into 32-bit writes
      // Load the byte value
      uint src_word = xe_resolve_source.data[src_offset];
      uint byte_val = (src_word >> ((src_byte_offset & 3u) * 8u)) & 0xFFu;

      // Each group of 4 threads packs into one uint
      uint pack_index = pixel_index >> 2u;   // Which uint (0-255)
      uint byte_pos = pixel_index & 3u;      // Which byte in uint (0-3)

      // Pack byte into shared memory
      uint contribution = byte_val << (byte_pos * 8u);
      if (byte_pos == 0u) {
        gs_tile_data[pack_index] = contribution;
      }
      barrier();
      if (byte_pos != 0u) {
        atomicOr(gs_tile_data[pack_index], contribution);
      }
      barrier();

      // First thread of each 4 writes the packed uint
      if (byte_pos == 0u) {
        xe_resolve_dest.data[tile_index * (32u * 32u / 4u) + pack_index] =
            gs_tile_data[pack_index];
      }
      break;
    }
    case 1u: {  // 16-bit - use groupshared to coalesce 2 shorts into 32-bit writes
      // Load the short value
      uint src_word = xe_resolve_source.data[src_offset];
      uint short_val = (src_word >> ((src_byte_offset & 2u) * 8u)) & 0xFFFFu;

      // Each group of 2 threads packs into one uint
      uint pack_index = pixel_index >> 1u;   // Which uint (0-511)
      uint short_pos = pixel_index & 1u;     // Which short in uint (0-1)

      // Pack short into shared memory
      uint contribution = short_val << (short_pos * 16u);
      if (short_pos == 0u) {
        gs_tile_data[pack_index] = contribution;
      }
      barrier();
      if (short_pos != 0u) {
        atomicOr(gs_tile_data[pack_index], contribution);
      }
      barrier();

      // First thread of each 2 writes the packed uint
      if (short_pos == 0u) {
        xe_resolve_dest.data[tile_index * (32u * 32u * 2u / 4u) + pack_index] =
            gs_tile_data[pack_index];
      }
      break;
    }
    case 2u: {  // 32-bit - direct copy
      xe_resolve_dest.data[dst_offset] = xe_resolve_source.data[src_offset];
      break;
    }
    case 3u: {  // 64-bit - direct copy (2 uints)
      xe_resolve_dest.data[dst_offset] = xe_resolve_source.data[src_offset];
      xe_resolve_dest.data[dst_offset + 1u] =
          xe_resolve_source.data[src_offset + 1u];
      break;
    }
  }
}
