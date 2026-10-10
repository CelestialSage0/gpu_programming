/* ==========================================================================
 *  CS6023: GPU Programming  --  Assignment 1
 *  "The Wizard's Lens": An Image Preprocessing Pipeline on the GPU
 *
 *  FILE: pipeline.cu
 *
 *  --------------------------------------------------------------------
 *   READ THIS FIRST
 *  --------------------------------------------------------------------
 *   1. DO NOT MODIFY any code outside the regions marked
 *          // ==== TODO n : ... ====
 *          ... your code here ...
 *          // ==== END TODO n ====
 *      The input parser, the output printer and the kernel signatures are
 *      checked automatically during grading.
 *
 *   2. DO NOT print anything extra to stdout. Whatever is on stdout is your
 *      answer. Use fprintf(stderr, ...) for debugging.
 *
 *   3. Everything must stay inside this single .cu file.
 *
 *   4. Rename this file to <YourRollNumber>.cu before submitting.
        Example: CS24S009.cu
 *
 *  --------------------------------------------------------------------
 *   WHAT YOU HAVE TO WRITE  (9 TODOs)
 *  --------------------------------------------------------------------
 *      TODO 1 : grayscaleKernel   body
 *      TODO 2 : resizeKernel      body
 *      TODO 3 : cropKernel        body
 *      TODO 4 : normalizeKernel   body
 *      TODO 5 : allocate device memory
 *      TODO 6 : copy host -> device
 *      TODO 7 : configure and launch the four kernels
 *      TODO 8 : copy device -> host
 *      TODO 9 : free device memory
 *
 *   See README.md for how to build and test.
 * ========================================================================== */

/* ---------------- DO NOT MODIFY : INCLUDES AND MACROS ---------------- */
#include <cuda_runtime.h>
#include <math.h>
#include <stdio.h>
#include <stdlib.h>

/* Integer ceiling division: how many blocks of size b cover n items. */
#define CEIL_DIV(n, b) (((n) + (b) - (int)1) / (b))

/* Luma weights, ITU-R BT.601. Use exactly these constants. */
#define W_RED 0.299f
#define W_GREEN 0.587f
#define W_BLUE 0.114f
/* -------------------- END DO NOT MODIFY (macros) --------------------- */

/* ==========================================================================
 *  STAGE 1  --  GRAYSCALE
 *  --------------------------------------------------------------------
 *  d_rgb  : H*W*3 bytes, row-major, channel-interleaved (R,G,B,R,G,B,...)
 *           the pixel at (y, x) starts at index 3*(y*W + x)
 *  d_gray : H*W floats, row-major.  d_gray[y*W + x] is the pixel at (y, x)
 *
 *      gray(y,x) = 0.299*R(y,x) + 0.587*G(y,x) + 0.114*B(y,x)
 *
 *  The result stays on the 0 ... 255 scale (as a float, not rounded).
 * ========================================================================== */
__global__ void grayscaleKernel(const unsigned char *d_rgb, float *d_gray,
                                int H, int W) {
  // ==== TODO 1 : write the grayscale kernel ====
  //
  // Hints:
  //   * Cast the unsigned char values to float before doing arithmetic.
  int idx = (blockIdx.x * blockDim.x + threadIdx.x);
  if (idx >= H * W) return;

  int rgb_idx = 3 * idx;

  float R = (float)d_rgb[rgb_idx];
  float G = (float)d_rgb[rgb_idx + 1];
  float B = (float)d_rgb[rgb_idx + 2];

  d_gray[idx] = 0.299f * R + 0.587f * G + 0.114f * B;
  // ==== END TODO 1 ====
}

/* ==========================================================================
 *  STAGE 2  --  BILINEAR RESIZE   (H x W)  ->  (Hr x Wr)
 *  --------------------------------------------------------------------
 *  Use the "align corners" mapping: the four corner pixels of the input
 *  land exactly on the four corner pixels of the output.
 *
 *      scaleY = (Hr > 1) ? (float)(H - 1) / (float)(Hr - 1) : 0.0f
 *      scaleX = (Wr > 1) ? (float)(W - 1) / (float)(Wr - 1) : 0.0f
 *
 *  For an output pixel (oy, ox):
 *
 *      fy = oy * scaleY          fx = ox * scaleX
 *      y0 = floor(fy)            x0 = floor(fx)
 *      y1 = min(y0 + 1, H - 1)   x1 = min(x0 + 1, W - 1)
 *      wy = fy - y0              wx = fx - x0
 *
 *      top    = in(y0,x0)*(1-wx) + in(y0,x1)*wx
 *      bottom = in(y1,x0)*(1-wx) + in(y1,x1)*wx
 *      out(oy,ox) = top*(1-wy) + bottom*wy
 * ========================================================================== */
__global__ void resizeKernel(const float *d_gray, float *d_resized, int H,
                             int W, int Hr, int Wr) {
  // ==== TODO 2 : write the bilinear resize kernel ====
  //
  // Hints:
  //   * floorf() and min() are available inside device code.
  int ox = blockIdx.x * blockDim.x + threadIdx.x;
  int oy = blockIdx.y * blockDim.y + threadIdx.y;
  if (ox >= Wr || oy >= Hr) return;

  float scaleY = (Hr > 1) ? (float)(H - 1) / (float)(Hr - 1) : 0.0f;
  float scaleX = (Wr > 1) ? (float)(W - 1) / (float)(Wr - 1) : 0.0f;

  float fy = oy * scaleY;
  float fx = ox * scaleX;

  int y0 = (int)floorf(fy);
  int x0 = (int)floorf(fx);
  int y1 = min(y0 + 1, H - 1);
  int x1 = min(x0 + 1, W - 1);

  float wy = fy - y0;
  float wx = fx - x0;

  float p00 = d_gray[y0 * W + x0];
  float p01 = d_gray[y0 * W + x1];
  float p10 = d_gray[y1 * W + x0];
  float p11 = d_gray[y1 * W + x1];

  float top = p00 * (1.0f - wx) + p01 * wx;
  float bottom = p10 * (1.0f - wx) + p11 * wx;

  d_resized[oy * Wr + ox] = top * (1.0f - wy) + bottom * wy;
  // ==== END TODO 2 ====
}

/* ==========================================================================
 *  STAGE 3  --  CENTER CROP   (Hr x Wr)  ->  (Hc x Wc)
 *  --------------------------------------------------------------------
 *      offsetY = (Hr - Hc) / 2        <-- integer division, rounds down
 *      offsetX = (Wr - Wc) / 2
 *
 *      out(y, x) = in(y + offsetY, x + offsetX)
 *
 *  It is guaranteed that Hc <= Hr and Wc <= Wr.
 * ========================================================================== */
__global__ void cropKernel(const float *d_resized, float *d_cropped, int Hr,
                           int Wr, int Hc, int Wc) {
  // ==== TODO 3 : write the center-crop kernel ====
  //
  // Hints:
  //   * Pure index arithmetic - no interpolation.
  //   * The input row stride is Wr, the output row stride is Wc.
  int x = blockIdx.x * blockDim.x + threadIdx.x;
  int y = blockIdx.y * blockDim.y + threadIdx.y;

  int offsetY = (Hr - Hc) / 2;
  int offsetX = (Wr - Wc) / 2;

  if (x < Wc && y < Hc) {
    d_cropped[y * Wc + x] = d_resized[(y + offsetY) * Wr + (x + offsetX)];
  }
  // ==== END TODO 3 ====
}

/* ==========================================================================
 *  STAGE 4  --  NORMALIZE
 *  --------------------------------------------------------------------
 *      out(y,x) = ( in(y,x) / 255.0 - mean ) / std
 *
 *  This is the last step: it turns 0..255 brightness values into the small
 *  zero-centred numbers a neural network expects.
 * ========================================================================== */
__global__ void normalizeKernel(const float *d_cropped, float *d_out, int Hc,
                                int Wc, float mean, float stdv) {
  // ==== TODO 4 : write the normalize kernel ====
  //
  // Hints:
  //   * Element-wise, so a 1-D grid over Hc*Wc elements works.
  int idx = blockIdx.x * blockDim.x + threadIdx.x;
  if (idx >= Hc * Wc) return;

  d_out[idx] = (d_cropped[idx] / 255.0f - mean) / stdv;
  // ==== END TODO 4 ====
}

/* ==========================================================================
 *                                  MAIN
 * ========================================================================== */
int main(int argc, char **argv) {
  /* ================= DO NOT MODIFY : INPUT PARSING ================== */
  FILE *fin = stdin;
  if (argc >= 2) {
    fin = fopen(argv[1], "r");
    if (!fin) {
      fprintf(stderr, "ERROR: cannot open input file '%s'\n", argv[1]);
      return EXIT_FAILURE;
    }
  }

  int H, W, Hr, Wr, Hc, Wc;
  float mean, stdv;

  if (fscanf(fin, "%d %d", &H, &W) != 2) {
    fprintf(stderr, "ERROR: malformed input (image dimensions)\n");
    return EXIT_FAILURE;
  }
  if (fscanf(fin, "%d %d", &Hr, &Wr) != 2) {
    fprintf(stderr, "ERROR: malformed input (resize dimensions)\n");
    return EXIT_FAILURE;
  }
  if (fscanf(fin, "%d %d", &Hc, &Wc) != 2) {
    fprintf(stderr, "ERROR: malformed input (crop dimensions)\n");
    return EXIT_FAILURE;
  }
  if (fscanf(fin, "%f %f", &mean, &stdv) != 2) {
    fprintf(stderr, "ERROR: malformed input (mean / std)\n");
    return EXIT_FAILURE;
  }

  if (H <= 0 || W <= 0 || Hr <= 0 || Wr <= 0 || Hc <= 0 || Wc <= 0) {
    fprintf(stderr, "ERROR: dimensions must be positive\n");
    return EXIT_FAILURE;
  }
  if (Hc > Hr || Wc > Wr) {
    fprintf(stderr, "ERROR: crop size must not exceed resize size\n");
    return EXIT_FAILURE;
  }

  const size_t nPixIn = (size_t)H * (size_t)W;
  const size_t nRgb = nPixIn * 3u;
  const size_t nPixRes = (size_t)Hr * (size_t)Wr;
  const size_t nPixCrop = (size_t)Hc * (size_t)Wc;

  unsigned char *h_rgb = (unsigned char *)malloc(nRgb * sizeof(unsigned char));
  float *h_out = (float *)calloc(nPixCrop, sizeof(float));
  if (!h_rgb || !h_out) {
    fprintf(stderr, "ERROR: host allocation failed\n");
    return EXIT_FAILURE;
  }

  for (size_t i = 0; i < nRgb; ++i) {
    int v;
    if (fscanf(fin, "%d", &v) != 1) {
      fprintf(stderr, "ERROR: expected %zu pixel values, got %zu\n", nRgb, i);
      return EXIT_FAILURE;
    }
    h_rgb[i] = (unsigned char)v;
  }
  if (fin != stdin)
    fclose(fin);
  /* =============== END DO NOT MODIFY : INPUT PARSING ================ */

  /* ---- Device pointers. Allocate them in TODO 5, free them in TODO 9.
   *      Until you complete TODO 5 and TODO 6, the compiler will warn that
   *      these are unused. That is expected on a fresh checkout.          */
  unsigned char *d_rgb = NULL; /* H  x W  x 3  bytes   */
  float *d_gray = NULL;        /* H  x W       floats  */
  float *d_resized = NULL;     /* Hr x Wr      floats  */
  float *d_cropped = NULL;     /* Hc x Wc      floats  */
  float *d_out = NULL;         /* Hc x Wc      floats  */

  // ==== TODO 5 : allocate device memory ====
  //
  // Allocate all five buffers above with cudaMalloc.
  cudaMalloc(&d_rgb, nRgb * sizeof(unsigned char));
  cudaMalloc(&d_gray, nPixIn * sizeof(float));
  cudaMalloc(&d_resized, nPixRes * sizeof(float));
  cudaMalloc(&d_cropped, nPixCrop * sizeof(float));
  cudaMalloc(&d_out, nPixCrop * sizeof(float));
  // ==== END TODO 5 ====

  // ==== TODO 6 : copy the input image from host to device ====
  //
  // Copy h_rgb (nRgb bytes) into d_rgb
  cudaMemcpy(d_rgb, h_rgb, nRgb * sizeof(unsigned char),
             cudaMemcpyHostToDevice);
  // ==== END TODO 6 ====

  // ==== TODO 7 : configure and launch the four kernels, in order ====
  //
  // Launch order:  grayscale -> resize -> crop -> normalize
  // Data flow   :  d_rgb -> d_gray -> d_resized -> d_cropped -> d_out
  int threads1D = 256;

  // Stage 1: Grayscale
  int blocksGray = (nPixIn + threads1D - 1) / threads1D;

  grayscaleKernel<<<blocksGray, threads1D>>>(d_rgb, d_gray, H, W);

  // 2-D configuration
  dim3 threads2D(16, 16);

  // Stage 2: Bilinear resize
  dim3 blocksResize((Wr + threads2D.x - 1) / threads2D.x,
                    (Hr + threads2D.y - 1) / threads2D.y);

  resizeKernel<<<blocksResize, threads2D>>>(d_gray, d_resized, H, W, Hr, Wr);

  // Stage 3: Center crop
  dim3 blocksCrop((Wc + threads2D.x - 1) / threads2D.x,
                  (Hc + threads2D.y - 1) / threads2D.y);

  cropKernel<<<blocksCrop, threads2D>>>(d_resized, d_cropped, Hr, Wr, Hc, Wc);

  // Stage 4: Normalize
  int blocksNormalize = (nPixCrop + threads1D - 1) / threads1D;

  normalizeKernel<<<blocksNormalize, threads1D>>>(d_cropped, d_out, Hc, Wc,
                                                  mean, stdv);
  // ==== END TODO 7 ====

  // ==== TODO 8 : copy the final result from device to host ====
  //
  // Copy nPixCrop floats from d_out into h_out.
  cudaMemcpy(h_out, d_out, nPixCrop * sizeof(float), cudaMemcpyDeviceToHost);
  // ==== END TODO 8 ====

  /* ================= DO NOT MODIFY : OUTPUT PRINTING ================ */
  printf("%d %d\n", Hc, Wc);
  for (int y = 0; y < Hc; ++y) {
    for (int x = 0; x < Wc; ++x) {
      printf("%.6f%c", h_out[(size_t)y * (size_t)Wc + (size_t)x],
             (x == Wc - 1) ? '\n' : ' ');
    }
  }
  fflush(stdout);
  /* =============== END DO NOT MODIFY : OUTPUT PRINTING ============== */

  // ==== TODO 9 : free all device memory ====
  //
  // One cudaFree per cudaMalloc.
  cudaFree(d_rgb);
  cudaFree(d_gray);
  cudaFree(d_resized);
  cudaFree(d_cropped);
  cudaFree(d_out);
  // ==== END TODO 9 ====

  /* ---------------- DO NOT MODIFY : host cleanup ---------------- */
  free(h_rgb);
  free(h_out);
  return EXIT_SUCCESS;
}
