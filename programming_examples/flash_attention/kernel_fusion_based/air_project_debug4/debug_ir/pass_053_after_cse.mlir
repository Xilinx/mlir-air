module {
  aie.device(npu2) @attn_seg {
    %shim_noc_tile_0_0 = aie.tile(0, 0)
    %shim_noc_tile_1_0 = aie.tile(1, 0)
    %shim_noc_tile_2_0 = aie.tile(2, 0)
    %shim_noc_tile_3_0 = aie.tile(3, 0)
    %mem_tile_0_1 = aie.tile(0, 1)
    %mem_tile_1_1 = aie.tile(1, 1)
    %mem_tile_2_1 = aie.tile(2, 1)
    %mem_tile_3_1 = aie.tile(3, 1)
    %tile_0_2 = aie.tile(0, 2)
    %tile_1_2 = aie.tile(1, 2)
    %tile_2_2 = aie.tile(2, 2)
    %tile_3_2 = aie.tile(3, 2)
    %tile_0_3 = aie.tile(0, 3)
    %tile_1_3 = aie.tile(1, 3)
    %tile_2_3 = aie.tile(2, 3)
    %tile_3_3 = aie.tile(3, 3)
    %tile_0_4 = aie.tile(0, 4)
    %tile_1_4 = aie.tile(1, 4)
    %tile_2_4 = aie.tile(2, 4)
    %tile_3_4 = aie.tile(3, 4)
    %tile_0_5 = aie.tile(0, 5)
    %tile_1_5 = aie.tile(1, 5)
    %tile_2_5 = aie.tile(2, 5)
    %tile_3_5 = aie.tile(3, 5)
    %lock_3_1 = aie.lock(%mem_tile_3_1, 5) {init = 1 : i32}
    %lock_3_1_0 = aie.lock(%mem_tile_3_1, 4) {init = 0 : i32}
    %lock_3_1_1 = aie.lock(%mem_tile_3_1, 3) {init = 1 : i32}
    %lock_3_1_2 = aie.lock(%mem_tile_3_1, 2) {init = 0 : i32}
    %lock_3_1_3 = aie.lock(%mem_tile_3_1, 1) {init = 1 : i32}
    %lock_3_1_4 = aie.lock(%mem_tile_3_1, 0) {init = 0 : i32}
    %lock_2_1 = aie.lock(%mem_tile_2_1, 5) {init = 1 : i32}
    %lock_2_1_5 = aie.lock(%mem_tile_2_1, 4) {init = 0 : i32}
    %lock_2_1_6 = aie.lock(%mem_tile_2_1, 3) {init = 1 : i32}
    %lock_2_1_7 = aie.lock(%mem_tile_2_1, 2) {init = 0 : i32}
    %lock_2_1_8 = aie.lock(%mem_tile_2_1, 1) {init = 1 : i32}
    %lock_2_1_9 = aie.lock(%mem_tile_2_1, 0) {init = 0 : i32}
    %lock_1_1 = aie.lock(%mem_tile_1_1, 5) {init = 1 : i32}
    %lock_1_1_10 = aie.lock(%mem_tile_1_1, 4) {init = 0 : i32}
    %lock_1_1_11 = aie.lock(%mem_tile_1_1, 3) {init = 1 : i32}
    %lock_1_1_12 = aie.lock(%mem_tile_1_1, 2) {init = 0 : i32}
    %lock_1_1_13 = aie.lock(%mem_tile_1_1, 1) {init = 1 : i32}
    %lock_1_1_14 = aie.lock(%mem_tile_1_1, 0) {init = 0 : i32}
    %lock_0_1 = aie.lock(%mem_tile_0_1, 5) {init = 1 : i32}
    %lock_0_1_15 = aie.lock(%mem_tile_0_1, 4) {init = 0 : i32}
    %lock_0_1_16 = aie.lock(%mem_tile_0_1, 3) {init = 1 : i32}
    %lock_0_1_17 = aie.lock(%mem_tile_0_1, 2) {init = 0 : i32}
    %lock_0_1_18 = aie.lock(%mem_tile_0_1, 1) {init = 1 : i32}
    %lock_0_1_19 = aie.lock(%mem_tile_0_1, 0) {init = 0 : i32}
    %lock_0_2 = aie.lock(%tile_0_2, 5) {init = 2 : i32}
    %lock_0_2_20 = aie.lock(%tile_0_2, 4) {init = 0 : i32}
    %lock_0_2_21 = aie.lock(%tile_0_2, 3) {init = 1 : i32}
    %lock_0_2_22 = aie.lock(%tile_0_2, 2) {init = 0 : i32}
    %lock_0_2_23 = aie.lock(%tile_0_2, 1) {init = 1 : i32}
    %lock_0_2_24 = aie.lock(%tile_0_2, 0) {init = 0 : i32}
    %lock_1_2 = aie.lock(%tile_1_2, 5) {init = 2 : i32}
    %lock_1_2_25 = aie.lock(%tile_1_2, 4) {init = 0 : i32}
    %lock_1_2_26 = aie.lock(%tile_1_2, 3) {init = 1 : i32}
    %lock_1_2_27 = aie.lock(%tile_1_2, 2) {init = 0 : i32}
    %lock_1_2_28 = aie.lock(%tile_1_2, 1) {init = 1 : i32}
    %lock_1_2_29 = aie.lock(%tile_1_2, 0) {init = 0 : i32}
    %lock_2_2 = aie.lock(%tile_2_2, 5) {init = 2 : i32}
    %lock_2_2_30 = aie.lock(%tile_2_2, 4) {init = 0 : i32}
    %lock_2_2_31 = aie.lock(%tile_2_2, 3) {init = 1 : i32}
    %lock_2_2_32 = aie.lock(%tile_2_2, 2) {init = 0 : i32}
    %lock_2_2_33 = aie.lock(%tile_2_2, 1) {init = 1 : i32}
    %lock_2_2_34 = aie.lock(%tile_2_2, 0) {init = 0 : i32}
    %lock_3_2 = aie.lock(%tile_3_2, 5) {init = 2 : i32}
    %lock_3_2_35 = aie.lock(%tile_3_2, 4) {init = 0 : i32}
    %lock_3_2_36 = aie.lock(%tile_3_2, 3) {init = 1 : i32}
    %lock_3_2_37 = aie.lock(%tile_3_2, 2) {init = 0 : i32}
    %lock_3_2_38 = aie.lock(%tile_3_2, 1) {init = 1 : i32}
    %lock_3_2_39 = aie.lock(%tile_3_2, 0) {init = 0 : i32}
    %lock_0_3 = aie.lock(%tile_0_3, 3) {init = 2 : i32}
    %lock_0_3_40 = aie.lock(%tile_0_3, 2) {init = 0 : i32}
    %lock_0_3_41 = aie.lock(%tile_0_3, 1) {init = 1 : i32}
    %lock_0_3_42 = aie.lock(%tile_0_3, 0) {init = 0 : i32}
    %lock_1_3 = aie.lock(%tile_1_3, 3) {init = 2 : i32}
    %lock_1_3_43 = aie.lock(%tile_1_3, 2) {init = 0 : i32}
    %lock_1_3_44 = aie.lock(%tile_1_3, 1) {init = 1 : i32}
    %lock_1_3_45 = aie.lock(%tile_1_3, 0) {init = 0 : i32}
    %lock_2_3 = aie.lock(%tile_2_3, 3) {init = 2 : i32}
    %lock_2_3_46 = aie.lock(%tile_2_3, 2) {init = 0 : i32}
    %lock_2_3_47 = aie.lock(%tile_2_3, 1) {init = 1 : i32}
    %lock_2_3_48 = aie.lock(%tile_2_3, 0) {init = 0 : i32}
    %lock_3_3 = aie.lock(%tile_3_3, 3) {init = 2 : i32}
    %lock_3_3_49 = aie.lock(%tile_3_3, 2) {init = 0 : i32}
    %lock_3_3_50 = aie.lock(%tile_3_3, 1) {init = 1 : i32}
    %lock_3_3_51 = aie.lock(%tile_3_3, 0) {init = 0 : i32}
    %lock_0_4 = aie.lock(%tile_0_4, 3) {init = 2 : i32}
    %lock_0_4_52 = aie.lock(%tile_0_4, 2) {init = 0 : i32}
    %lock_0_4_53 = aie.lock(%tile_0_4, 1) {init = 1 : i32}
    %lock_0_4_54 = aie.lock(%tile_0_4, 0) {init = 0 : i32}
    %lock_1_4 = aie.lock(%tile_1_4, 3) {init = 2 : i32}
    %lock_1_4_55 = aie.lock(%tile_1_4, 2) {init = 0 : i32}
    %lock_1_4_56 = aie.lock(%tile_1_4, 1) {init = 1 : i32}
    %lock_1_4_57 = aie.lock(%tile_1_4, 0) {init = 0 : i32}
    %lock_2_4 = aie.lock(%tile_2_4, 3) {init = 2 : i32}
    %lock_2_4_58 = aie.lock(%tile_2_4, 2) {init = 0 : i32}
    %lock_2_4_59 = aie.lock(%tile_2_4, 1) {init = 1 : i32}
    %lock_2_4_60 = aie.lock(%tile_2_4, 0) {init = 0 : i32}
    %lock_3_4 = aie.lock(%tile_3_4, 3) {init = 2 : i32}
    %lock_3_4_61 = aie.lock(%tile_3_4, 2) {init = 0 : i32}
    %lock_3_4_62 = aie.lock(%tile_3_4, 1) {init = 1 : i32}
    %lock_3_4_63 = aie.lock(%tile_3_4, 0) {init = 0 : i32}
    %lock_0_5 = aie.lock(%tile_0_5, 3) {init = 2 : i32}
    %lock_0_5_64 = aie.lock(%tile_0_5, 2) {init = 0 : i32}
    %lock_0_5_65 = aie.lock(%tile_0_5, 1) {init = 1 : i32}
    %lock_0_5_66 = aie.lock(%tile_0_5, 0) {init = 0 : i32}
    %lock_1_5 = aie.lock(%tile_1_5, 3) {init = 2 : i32}
    %lock_1_5_67 = aie.lock(%tile_1_5, 2) {init = 0 : i32}
    %lock_1_5_68 = aie.lock(%tile_1_5, 1) {init = 1 : i32}
    %lock_1_5_69 = aie.lock(%tile_1_5, 0) {init = 0 : i32}
    %lock_2_5 = aie.lock(%tile_2_5, 3) {init = 2 : i32}
    %lock_2_5_70 = aie.lock(%tile_2_5, 2) {init = 0 : i32}
    %lock_2_5_71 = aie.lock(%tile_2_5, 1) {init = 1 : i32}
    %lock_2_5_72 = aie.lock(%tile_2_5, 0) {init = 0 : i32}
    %lock_3_5 = aie.lock(%tile_3_5, 3) {init = 2 : i32}
    %lock_3_5_73 = aie.lock(%tile_3_5, 2) {init = 0 : i32}
    %lock_3_5_74 = aie.lock(%tile_3_5, 1) {init = 1 : i32}
    %lock_3_5_75 = aie.lock(%tile_3_5, 0) {init = 0 : i32}
    %buf303_unroll_0 = aie.buffer(%mem_tile_0_1) {sym_name = "buf303_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf302_unroll_0 = aie.buffer(%mem_tile_1_1) {sym_name = "buf302_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf301_unroll_0 = aie.buffer(%mem_tile_2_1) {sym_name = "buf301_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf300_unroll_0 = aie.buffer(%mem_tile_3_1) {sym_name = "buf300_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf299_unroll_0 = aie.buffer(%mem_tile_0_1) {sym_name = "buf299_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf298_unroll_0 = aie.buffer(%mem_tile_0_1) {sym_name = "buf298_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf297_unroll_0 = aie.buffer(%mem_tile_1_1) {sym_name = "buf297_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf296_unroll_0 = aie.buffer(%mem_tile_1_1) {sym_name = "buf296_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf295_unroll_0 = aie.buffer(%mem_tile_2_1) {sym_name = "buf295_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf294_unroll_0 = aie.buffer(%mem_tile_2_1) {sym_name = "buf294_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf293_unroll_0 = aie.buffer(%mem_tile_3_1) {sym_name = "buf293_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf292_unroll_0 = aie.buffer(%mem_tile_3_1) {sym_name = "buf292_unroll_0"} : memref<64x64xbf16, 1 : i32> 
    %buf291_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf291_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf290_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf290_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf289_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf289_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf288_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf288_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf287_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf287_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf286_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf286_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf285_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf285_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf284_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf284_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf283_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf283_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf282_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf282_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf281_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf281_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf280_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf280_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf279_unroll_0 = aie.buffer(%tile_3_5) {sym_name = "buf279_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf278_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf278_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf277_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf277_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf276_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf276_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf275_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf275_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf274_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf274_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf273_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf273_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf272_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf272_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf271_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf271_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf270_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf270_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf269_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf269_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf268_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf268_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf267_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf267_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf266_unroll_0 = aie.buffer(%tile_2_5) {sym_name = "buf266_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf265_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf265_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf264_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf264_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf263_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf263_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf262_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf262_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf261_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf261_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf260_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf260_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf259_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf259_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf258_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf258_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf257_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf257_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf256_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf256_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf255_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf255_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf254_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf254_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf253_unroll_0 = aie.buffer(%tile_1_5) {sym_name = "buf253_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf252_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf252_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf251_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf251_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf250_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf250_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf249_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf249_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf248_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf248_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf247_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf247_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf246_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf246_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf245_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf245_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf244_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf244_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf243_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf243_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf242_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf242_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf241_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf241_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf240_unroll_0 = aie.buffer(%tile_0_5) {sym_name = "buf240_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf239_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf239_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf238_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf238_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf237_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf237_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf236_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf236_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf235_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf235_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf234_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf234_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf233_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf233_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf232_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf232_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf231_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf231_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf230_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf230_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf229_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf229_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf228_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf228_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf227_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf227_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf226_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf226_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf225_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf225_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf224_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf224_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf223_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf223_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf222_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf222_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf221_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf221_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf220_unroll_0 = aie.buffer(%tile_3_4) {sym_name = "buf220_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf219_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf219_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf218_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf218_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf217_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf217_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf216_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf216_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf215_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf215_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf214_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf214_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf213_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf213_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf212_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf212_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf211_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf211_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf210_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf210_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf209_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf209_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf208_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf208_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf207_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf207_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf206_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf206_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf205_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf205_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf204_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf204_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf203_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf203_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf202_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf202_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf201_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf201_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf200_unroll_0 = aie.buffer(%tile_2_4) {sym_name = "buf200_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf199_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf199_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf198_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf198_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf197_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf197_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf196_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf196_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf195_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf195_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf194_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf194_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf193_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf193_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf192_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf192_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf191_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf191_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf190_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf190_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf189_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf189_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf188_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf188_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf187_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf187_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf186_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf186_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf185_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf185_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf184_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf184_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf183_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf183_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf182_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf182_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf181_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf181_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf180_unroll_0 = aie.buffer(%tile_1_4) {sym_name = "buf180_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf179_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf179_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf178_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf178_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf177_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf177_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf176_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf176_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf175_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf175_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf174_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf174_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf173_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf173_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf172_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf172_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf171_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf171_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf170_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf170_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf169_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf169_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf168_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf168_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf167_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf167_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf166_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf166_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf165_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf165_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf164_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf164_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf163_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf163_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf162_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf162_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf161_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf161_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf160_unroll_0 = aie.buffer(%tile_0_4) {sym_name = "buf160_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf159_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf159_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf158_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf158_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf157_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf157_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf156_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf156_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf155_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf155_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf154_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf154_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf153_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf153_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf152_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf152_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf151_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf151_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf150_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf150_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf149_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf149_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf148_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf148_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf147_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf147_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf146_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf146_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf145_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf145_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf144_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf144_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf143_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf143_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf142_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf142_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf141_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf141_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf140_unroll_0 = aie.buffer(%tile_3_3) {sym_name = "buf140_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf139_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf139_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf138_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf138_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf137_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf137_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf136_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf136_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf135_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf135_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf134_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf134_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf133_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf133_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf132_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf132_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf131_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf131_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf130_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf130_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf129_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf129_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf128_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf128_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf127_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf127_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf126_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf126_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf125_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf125_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf124_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf124_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf123_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf123_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf122_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf122_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf121_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf121_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf120_unroll_0 = aie.buffer(%tile_2_3) {sym_name = "buf120_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf119_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf119_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf118_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf118_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf117_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf117_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf116_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf116_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf115_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf115_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf114_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf114_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf113_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf113_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf112_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf112_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf111_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf111_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf110_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf110_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf109_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf109_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf108_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf108_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf107_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf107_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf106_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf106_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf105_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf105_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf104_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf104_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf103_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf103_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf102_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf102_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf101_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf101_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf100_unroll_0 = aie.buffer(%tile_1_3) {sym_name = "buf100_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf99_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf99_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf98_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf98_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf97_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf97_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf96_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf96_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf95_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf95_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf94_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf94_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf93_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf93_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf92_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf92_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf91_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf91_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf90_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf90_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf89_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf89_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf88_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf88_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf87_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf87_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf86_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf86_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf85_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf85_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf84_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf84_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf83_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf83_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf82_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf82_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf81_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf81_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf80_unroll_0 = aie.buffer(%tile_0_3) {sym_name = "buf80_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf79_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf79_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf78_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf78_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf77_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf77_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf76_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf76_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf75_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf75_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf74_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf74_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf73_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf73_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf72_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf72_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf71_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf71_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf70_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf70_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf69_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf69_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf68_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf68_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf67_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf67_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf66_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf66_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf65_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf65_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf64_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf64_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf63_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf63_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf62_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf62_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf61_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf61_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf60_unroll_0 = aie.buffer(%tile_3_2) {sym_name = "buf60_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf59_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf59_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf58_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf58_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf57_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf57_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf56_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf56_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf55_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf55_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf54_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf54_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf53_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf53_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf52_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf52_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf51_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf51_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf50_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf50_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf49_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf49_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf48_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf48_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf47_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf47_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf46_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf46_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf45_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf45_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf44_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf44_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf43_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf43_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf42_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf42_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf41_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf41_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf40_unroll_0 = aie.buffer(%tile_2_2) {sym_name = "buf40_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf39_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf39_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf38_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf38_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf37_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf37_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf36_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf36_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf35_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf35_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf34_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf34_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf33_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf33_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf32_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf32_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf31_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf31_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf30_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf30_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf29_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf29_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf28_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf28_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf27_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf27_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf26_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf26_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf25_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf25_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf24_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf24_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf23_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf23_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf22_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf22_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf21_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf21_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf20_unroll_0 = aie.buffer(%tile_1_2) {sym_name = "buf20_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf19_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf19_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf18_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf18_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf17_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf17_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf16_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf16_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf15_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf15_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf14_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf14_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf13_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf13_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf12_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf12_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf11_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf11_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf10_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf10_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf9_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf9_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf8_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf8_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf7_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf7_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf6_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf6_unroll_0"} : memref<64x64xbf16, 2 : i32> 
    %buf5_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf5_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf4_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf4_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf3_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf3_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf2_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf2_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf1_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf1_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %buf0_unroll_0 = aie.buffer(%tile_0_2) {sym_name = "buf0_unroll_0"} : memref<64x1xbf16, 2 : i32> 
    %__air_external_buffer_unroll_0 = aie.external_buffer {sym_name = "__air_external_buffer_unroll_0"} : memref<2x512x64xbf16>
    %__air_external_buffer_1_unroll_0 = aie.external_buffer {sym_name = "__air_external_buffer_1_unroll_0"} : memref<2x512x64xbf16>
    %__air_external_buffer_2_unroll_0 = aie.external_buffer {sym_name = "__air_external_buffer_2_unroll_0"} : memref<2x512x64xbf16>
    %__air_external_buffer_3_unroll_0 = aie.external_buffer {sym_name = "__air_external_buffer_3_unroll_0"} : memref<2x512x64xbf16>
    %mem_3_5 = aie.mem(%tile_3_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_3_5_74, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf288_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_5_75, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_3_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf286_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_5_73, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_3_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf282_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_5_73, Release, 1)
      aie.next_bd ^bb4
    }
    %core_3_5 = aie.core(%tile_3_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf289_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf291_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf290_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_5_75, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_5_74, Release, 1)
      aie.use_lock(%lock_3_5_75, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_5_74, Release, 1)
      aie.use_lock(%lock_3_5_75, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_5_74, Release, 1)
      aie.use_lock(%lock_3_5_75, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf288_unroll_0, %buf287_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf285_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_5_74, Release, 1)
      aie.use_lock(%lock_3_5_75, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_5_73, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf287_unroll_0, %buf288_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf290_unroll_0, %buf284_unroll_0, %buf283_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf283_unroll_0, %buf289_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf286_unroll_0, %buf289_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf291_unroll_0, %buf283_unroll_0, %buf284_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf284_unroll_0, %buf291_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf281_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_5_74, Release, 1)
      aie.use_lock(%lock_3_5_75, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_5_73, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf287_unroll_0, %buf288_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf290_unroll_0, %buf280_unroll_0, %buf279_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf279_unroll_0, %buf289_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf282_unroll_0, %buf289_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf291_unroll_0, %buf279_unroll_0, %buf280_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf280_unroll_0, %buf291_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf289_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf290_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf291_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_3_5_74, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_2_5 = aie.mem(%tile_2_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_2_5_71, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf275_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_5_72, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_2_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf273_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_5_70, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_2_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf269_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_5_70, Release, 1)
      aie.next_bd ^bb4
    }
    %core_2_5 = aie.core(%tile_2_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf276_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf278_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf277_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_5_72, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_5_71, Release, 1)
      aie.use_lock(%lock_2_5_72, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_5_71, Release, 1)
      aie.use_lock(%lock_2_5_72, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf275_unroll_0, %buf274_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_5_71, Release, 1)
      aie.use_lock(%lock_2_5_72, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf272_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_5_71, Release, 1)
      aie.use_lock(%lock_2_5_72, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_5_70, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf274_unroll_0, %buf275_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf277_unroll_0, %buf271_unroll_0, %buf270_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf270_unroll_0, %buf276_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf273_unroll_0, %buf276_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf278_unroll_0, %buf270_unroll_0, %buf271_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf271_unroll_0, %buf278_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf268_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_5_71, Release, 1)
      aie.use_lock(%lock_2_5_72, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_5_70, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf274_unroll_0, %buf275_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf277_unroll_0, %buf267_unroll_0, %buf266_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf266_unroll_0, %buf276_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf269_unroll_0, %buf276_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf278_unroll_0, %buf266_unroll_0, %buf267_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf267_unroll_0, %buf278_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf276_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf277_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf278_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_2_5_71, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_1_5 = aie.mem(%tile_1_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_1_5_68, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf262_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_5_69, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_1_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf260_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_5_67, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_1_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf256_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_5_67, Release, 1)
      aie.next_bd ^bb4
    }
    %core_1_5 = aie.core(%tile_1_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf263_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf265_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf264_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_5_69, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_5_68, Release, 1)
      aie.use_lock(%lock_1_5_69, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf262_unroll_0, %buf261_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_5_68, Release, 1)
      aie.use_lock(%lock_1_5_69, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_5_68, Release, 1)
      aie.use_lock(%lock_1_5_69, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf259_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_5_68, Release, 1)
      aie.use_lock(%lock_1_5_69, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_5_67, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf261_unroll_0, %buf262_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf264_unroll_0, %buf258_unroll_0, %buf257_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf257_unroll_0, %buf263_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf260_unroll_0, %buf263_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf265_unroll_0, %buf257_unroll_0, %buf258_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf258_unroll_0, %buf265_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf255_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_5_68, Release, 1)
      aie.use_lock(%lock_1_5_69, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_5_67, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf261_unroll_0, %buf262_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf264_unroll_0, %buf254_unroll_0, %buf253_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf253_unroll_0, %buf263_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf256_unroll_0, %buf263_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf265_unroll_0, %buf253_unroll_0, %buf254_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf254_unroll_0, %buf265_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf263_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf264_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf265_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_1_5_68, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_0_5 = aie.mem(%tile_0_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_0_5_65, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf249_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_5_66, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_0_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf247_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_5_64, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_0_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf243_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_5_64, Release, 1)
      aie.next_bd ^bb4
    }
    %core_0_5 = aie.core(%tile_0_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf250_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf252_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf251_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_5_66, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf249_unroll_0, %buf248_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_5_65, Release, 1)
      aie.use_lock(%lock_0_5_66, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_5_65, Release, 1)
      aie.use_lock(%lock_0_5_66, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_5_65, Release, 1)
      aie.use_lock(%lock_0_5_66, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf246_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_5_65, Release, 1)
      aie.use_lock(%lock_0_5_66, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_5_64, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf248_unroll_0, %buf249_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf251_unroll_0, %buf245_unroll_0, %buf244_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf244_unroll_0, %buf250_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf247_unroll_0, %buf250_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf252_unroll_0, %buf244_unroll_0, %buf245_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf245_unroll_0, %buf252_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf242_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_5_65, Release, 1)
      aie.use_lock(%lock_0_5_66, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_5_64, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf248_unroll_0, %buf249_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf251_unroll_0, %buf241_unroll_0, %buf240_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf240_unroll_0, %buf250_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf243_unroll_0, %buf250_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf252_unroll_0, %buf240_unroll_0, %buf241_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf241_unroll_0, %buf252_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf250_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf251_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf252_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_0_5_65, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_3_4 = aie.mem(%tile_3_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_3_4_62, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf236_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_4_63, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_3_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf234_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_4_61, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_3_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf230_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_4_61, Release, 1)
      aie.next_bd ^bb4
    }
    %core_3_4 = aie.core(%tile_3_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf237_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf239_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf238_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_4_63, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_4_62, Release, 1)
      aie.use_lock(%lock_3_4_63, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_4_62, Release, 1)
      aie.use_lock(%lock_3_4_63, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_4_62, Release, 1)
      aie.use_lock(%lock_3_4_63, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf236_unroll_0, %buf235_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf233_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_4_62, Release, 1)
      aie.use_lock(%lock_3_4_63, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_4_61, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf235_unroll_0, %buf236_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf238_unroll_0, %buf232_unroll_0, %buf231_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf231_unroll_0, %buf237_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf234_unroll_0, %buf237_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf239_unroll_0, %buf231_unroll_0, %buf232_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf232_unroll_0, %buf239_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf229_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_4_62, Release, 1)
      aie.use_lock(%lock_3_4_63, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_4_61, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf235_unroll_0, %buf236_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf238_unroll_0, %buf228_unroll_0, %buf227_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf227_unroll_0, %buf237_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf230_unroll_0, %buf237_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf239_unroll_0, %buf227_unroll_0, %buf228_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf228_unroll_0, %buf239_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf226_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf225_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf224_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf238_unroll_0, %buf223_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf225_unroll_0, %buf238_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf225_unroll_0, %buf238_unroll_0, %buf222_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf223_unroll_0, %buf238_unroll_0, %buf221_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf222_unroll_0, %buf226_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf221_unroll_0, %buf237_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf237_unroll_0, %buf226_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf220_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf224_unroll_0, %buf222_unroll_0, %buf220_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf239_unroll_0, %buf221_unroll_0, %buf220_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf220_unroll_0, %buf224_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf238_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_3_4_62, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_2_4 = aie.mem(%tile_2_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_2_4_59, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf216_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_4_60, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_2_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf214_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_4_58, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_2_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf210_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_4_58, Release, 1)
      aie.next_bd ^bb4
    }
    %core_2_4 = aie.core(%tile_2_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf217_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf219_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf218_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_4_60, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_4_59, Release, 1)
      aie.use_lock(%lock_2_4_60, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_4_59, Release, 1)
      aie.use_lock(%lock_2_4_60, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf216_unroll_0, %buf215_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_4_59, Release, 1)
      aie.use_lock(%lock_2_4_60, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf213_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_4_59, Release, 1)
      aie.use_lock(%lock_2_4_60, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_4_58, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf215_unroll_0, %buf216_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf218_unroll_0, %buf212_unroll_0, %buf211_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf211_unroll_0, %buf217_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf214_unroll_0, %buf217_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf219_unroll_0, %buf211_unroll_0, %buf212_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf212_unroll_0, %buf219_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf209_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_4_59, Release, 1)
      aie.use_lock(%lock_2_4_60, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_4_58, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf215_unroll_0, %buf216_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf218_unroll_0, %buf208_unroll_0, %buf207_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf207_unroll_0, %buf217_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf210_unroll_0, %buf217_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf219_unroll_0, %buf207_unroll_0, %buf208_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf208_unroll_0, %buf219_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf206_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf205_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf204_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf218_unroll_0, %buf203_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf205_unroll_0, %buf218_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf205_unroll_0, %buf218_unroll_0, %buf202_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf203_unroll_0, %buf218_unroll_0, %buf201_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf202_unroll_0, %buf206_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf201_unroll_0, %buf217_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf217_unroll_0, %buf206_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf200_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf204_unroll_0, %buf202_unroll_0, %buf200_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf219_unroll_0, %buf201_unroll_0, %buf200_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf200_unroll_0, %buf204_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf218_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_2_4_59, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_1_4 = aie.mem(%tile_1_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_1_4_56, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf196_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_4_57, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_1_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf194_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_4_55, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_1_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf190_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_4_55, Release, 1)
      aie.next_bd ^bb4
    }
    %core_1_4 = aie.core(%tile_1_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf197_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf199_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf198_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_4_57, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_4_56, Release, 1)
      aie.use_lock(%lock_1_4_57, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf196_unroll_0, %buf195_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_4_56, Release, 1)
      aie.use_lock(%lock_1_4_57, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_4_56, Release, 1)
      aie.use_lock(%lock_1_4_57, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf193_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_4_56, Release, 1)
      aie.use_lock(%lock_1_4_57, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_4_55, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf195_unroll_0, %buf196_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf198_unroll_0, %buf192_unroll_0, %buf191_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf191_unroll_0, %buf197_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf194_unroll_0, %buf197_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf199_unroll_0, %buf191_unroll_0, %buf192_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf192_unroll_0, %buf199_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf189_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_4_56, Release, 1)
      aie.use_lock(%lock_1_4_57, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_4_55, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf195_unroll_0, %buf196_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf198_unroll_0, %buf188_unroll_0, %buf187_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf187_unroll_0, %buf197_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf190_unroll_0, %buf197_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf199_unroll_0, %buf187_unroll_0, %buf188_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf188_unroll_0, %buf199_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf186_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf185_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf184_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf198_unroll_0, %buf183_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf185_unroll_0, %buf198_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf185_unroll_0, %buf198_unroll_0, %buf182_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf183_unroll_0, %buf198_unroll_0, %buf181_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf182_unroll_0, %buf186_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf181_unroll_0, %buf197_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf197_unroll_0, %buf186_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf180_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf184_unroll_0, %buf182_unroll_0, %buf180_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf199_unroll_0, %buf181_unroll_0, %buf180_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf180_unroll_0, %buf184_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf198_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_1_4_56, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_0_4 = aie.mem(%tile_0_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_0_4_53, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf176_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_4_54, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_0_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf174_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_4_52, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_0_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf170_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_4_52, Release, 1)
      aie.next_bd ^bb4
    }
    %core_0_4 = aie.core(%tile_0_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf177_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf179_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf178_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_4_54, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf176_unroll_0, %buf175_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_4_53, Release, 1)
      aie.use_lock(%lock_0_4_54, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_4_53, Release, 1)
      aie.use_lock(%lock_0_4_54, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_4_53, Release, 1)
      aie.use_lock(%lock_0_4_54, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf173_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_4_53, Release, 1)
      aie.use_lock(%lock_0_4_54, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_4_52, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf175_unroll_0, %buf176_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf178_unroll_0, %buf172_unroll_0, %buf171_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf171_unroll_0, %buf177_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf174_unroll_0, %buf177_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf179_unroll_0, %buf171_unroll_0, %buf172_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf172_unroll_0, %buf179_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf169_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_4_53, Release, 1)
      aie.use_lock(%lock_0_4_54, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_4_52, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf175_unroll_0, %buf176_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf178_unroll_0, %buf168_unroll_0, %buf167_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf167_unroll_0, %buf177_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf170_unroll_0, %buf177_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf179_unroll_0, %buf167_unroll_0, %buf168_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf168_unroll_0, %buf179_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf166_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf165_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf164_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf178_unroll_0, %buf163_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf165_unroll_0, %buf178_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf165_unroll_0, %buf178_unroll_0, %buf162_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf163_unroll_0, %buf178_unroll_0, %buf161_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf162_unroll_0, %buf166_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf161_unroll_0, %buf177_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf177_unroll_0, %buf166_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf160_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf164_unroll_0, %buf162_unroll_0, %buf160_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf179_unroll_0, %buf161_unroll_0, %buf160_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf160_unroll_0, %buf164_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf178_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_0_4_53, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_3_3 = aie.mem(%tile_3_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_3_3_50, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf156_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_3_51, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_3_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf154_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_3_49, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_3_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf150_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_3_49, Release, 1)
      aie.next_bd ^bb4
    }
    %core_3_3 = aie.core(%tile_3_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf157_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf159_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf158_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_3_51, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_3_50, Release, 1)
      aie.use_lock(%lock_3_3_51, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_3_50, Release, 1)
      aie.use_lock(%lock_3_3_51, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_3_50, Release, 1)
      aie.use_lock(%lock_3_3_51, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf156_unroll_0, %buf155_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf153_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_3_50, Release, 1)
      aie.use_lock(%lock_3_3_51, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_3_49, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf155_unroll_0, %buf156_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf158_unroll_0, %buf152_unroll_0, %buf151_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf151_unroll_0, %buf157_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf154_unroll_0, %buf157_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf159_unroll_0, %buf151_unroll_0, %buf152_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf152_unroll_0, %buf159_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf149_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_3_50, Release, 1)
      aie.use_lock(%lock_3_3_51, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_3_49, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf155_unroll_0, %buf156_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf158_unroll_0, %buf148_unroll_0, %buf147_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf147_unroll_0, %buf157_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf150_unroll_0, %buf157_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf159_unroll_0, %buf147_unroll_0, %buf148_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf148_unroll_0, %buf159_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf146_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf145_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf144_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf158_unroll_0, %buf143_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf145_unroll_0, %buf158_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf145_unroll_0, %buf158_unroll_0, %buf142_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf143_unroll_0, %buf158_unroll_0, %buf141_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf142_unroll_0, %buf146_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf141_unroll_0, %buf157_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf157_unroll_0, %buf146_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf140_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf144_unroll_0, %buf142_unroll_0, %buf140_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf159_unroll_0, %buf141_unroll_0, %buf140_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf140_unroll_0, %buf144_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf158_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_3_3_50, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_2_3 = aie.mem(%tile_2_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_2_3_47, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf136_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_3_48, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_2_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf134_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_3_46, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_2_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf130_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_3_46, Release, 1)
      aie.next_bd ^bb4
    }
    %core_2_3 = aie.core(%tile_2_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf137_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf139_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf138_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_3_48, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_3_47, Release, 1)
      aie.use_lock(%lock_2_3_48, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_3_47, Release, 1)
      aie.use_lock(%lock_2_3_48, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf136_unroll_0, %buf135_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_3_47, Release, 1)
      aie.use_lock(%lock_2_3_48, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf133_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_3_47, Release, 1)
      aie.use_lock(%lock_2_3_48, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_3_46, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf135_unroll_0, %buf136_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf138_unroll_0, %buf132_unroll_0, %buf131_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf131_unroll_0, %buf137_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf134_unroll_0, %buf137_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf139_unroll_0, %buf131_unroll_0, %buf132_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf132_unroll_0, %buf139_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf129_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_3_47, Release, 1)
      aie.use_lock(%lock_2_3_48, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_3_46, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf135_unroll_0, %buf136_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf138_unroll_0, %buf128_unroll_0, %buf127_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf127_unroll_0, %buf137_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf130_unroll_0, %buf137_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf139_unroll_0, %buf127_unroll_0, %buf128_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf128_unroll_0, %buf139_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf126_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf125_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf124_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf138_unroll_0, %buf123_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf125_unroll_0, %buf138_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf125_unroll_0, %buf138_unroll_0, %buf122_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf123_unroll_0, %buf138_unroll_0, %buf121_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf122_unroll_0, %buf126_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf121_unroll_0, %buf137_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf137_unroll_0, %buf126_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf120_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf124_unroll_0, %buf122_unroll_0, %buf120_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf139_unroll_0, %buf121_unroll_0, %buf120_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf120_unroll_0, %buf124_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf138_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_2_3_47, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_1_3 = aie.mem(%tile_1_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_1_3_44, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf116_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_3_45, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_1_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf114_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_3_43, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_1_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf110_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_3_43, Release, 1)
      aie.next_bd ^bb4
    }
    %core_1_3 = aie.core(%tile_1_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf117_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf119_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf118_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_3_45, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_3_44, Release, 1)
      aie.use_lock(%lock_1_3_45, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf116_unroll_0, %buf115_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_3_44, Release, 1)
      aie.use_lock(%lock_1_3_45, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_3_44, Release, 1)
      aie.use_lock(%lock_1_3_45, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf113_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_3_44, Release, 1)
      aie.use_lock(%lock_1_3_45, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_3_43, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf115_unroll_0, %buf116_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf118_unroll_0, %buf112_unroll_0, %buf111_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf111_unroll_0, %buf117_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf114_unroll_0, %buf117_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf119_unroll_0, %buf111_unroll_0, %buf112_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf112_unroll_0, %buf119_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf109_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_3_44, Release, 1)
      aie.use_lock(%lock_1_3_45, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_3_43, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf115_unroll_0, %buf116_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf118_unroll_0, %buf108_unroll_0, %buf107_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf107_unroll_0, %buf117_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf110_unroll_0, %buf117_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf119_unroll_0, %buf107_unroll_0, %buf108_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf108_unroll_0, %buf119_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf106_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf105_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf104_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf118_unroll_0, %buf103_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf105_unroll_0, %buf118_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf105_unroll_0, %buf118_unroll_0, %buf102_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf103_unroll_0, %buf118_unroll_0, %buf101_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf102_unroll_0, %buf106_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf101_unroll_0, %buf117_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf117_unroll_0, %buf106_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf100_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf104_unroll_0, %buf102_unroll_0, %buf100_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf119_unroll_0, %buf101_unroll_0, %buf100_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf100_unroll_0, %buf104_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf118_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_1_3_44, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_0_3 = aie.mem(%tile_0_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_0_3_41, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf96_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_3_42, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_0_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf94_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_3_40, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_0_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf90_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_3_40, Release, 1)
      aie.next_bd ^bb4
    }
    %core_0_3 = aie.core(%tile_0_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf97_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf99_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf98_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_3_42, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf96_unroll_0, %buf95_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_3_41, Release, 1)
      aie.use_lock(%lock_0_3_42, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_3_41, Release, 1)
      aie.use_lock(%lock_0_3_42, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_3_41, Release, 1)
      aie.use_lock(%lock_0_3_42, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf93_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_3_41, Release, 1)
      aie.use_lock(%lock_0_3_42, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_3_40, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf95_unroll_0, %buf96_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf98_unroll_0, %buf92_unroll_0, %buf91_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf91_unroll_0, %buf97_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf94_unroll_0, %buf97_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf99_unroll_0, %buf91_unroll_0, %buf92_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf92_unroll_0, %buf99_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf89_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_3_41, Release, 1)
      aie.use_lock(%lock_0_3_42, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_3_40, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf95_unroll_0, %buf96_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf98_unroll_0, %buf88_unroll_0, %buf87_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf87_unroll_0, %buf97_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf90_unroll_0, %buf97_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf99_unroll_0, %buf87_unroll_0, %buf88_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf88_unroll_0, %buf99_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf86_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf85_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf84_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf98_unroll_0, %buf83_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf85_unroll_0, %buf98_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf85_unroll_0, %buf98_unroll_0, %buf82_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf83_unroll_0, %buf98_unroll_0, %buf81_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf82_unroll_0, %buf86_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf81_unroll_0, %buf97_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf97_unroll_0, %buf86_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf80_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf84_unroll_0, %buf82_unroll_0, %buf80_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf99_unroll_0, %buf81_unroll_0, %buf80_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf80_unroll_0, %buf84_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf98_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_0_3_41, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_3_2 = aie.mem(%tile_3_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_3_2_39, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf66_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_3_2_38, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_3_2_36, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf76_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_2_37, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_3_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf74_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_2_35, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_3_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf70_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_2_35, Release, 1)
      aie.next_bd ^bb6
    }
    %core_3_2 = aie.core(%tile_3_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_3_2_38, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf77_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf79_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf78_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_2_37, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_2_36, Release, 1)
      aie.use_lock(%lock_3_2_37, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_2_36, Release, 1)
      aie.use_lock(%lock_3_2_37, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_2_36, Release, 1)
      aie.use_lock(%lock_3_2_37, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf76_unroll_0, %buf75_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf73_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_2_36, Release, 1)
      aie.use_lock(%lock_3_2_37, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_2_35, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf75_unroll_0, %buf76_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf78_unroll_0, %buf72_unroll_0, %buf71_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf71_unroll_0, %buf77_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf74_unroll_0, %buf77_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf79_unroll_0, %buf71_unroll_0, %buf72_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf72_unroll_0, %buf79_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf69_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_2_36, Release, 1)
      aie.use_lock(%lock_3_2_37, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_3_2_35, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf75_unroll_0, %buf76_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf78_unroll_0, %buf68_unroll_0, %buf67_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf67_unroll_0, %buf77_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf70_unroll_0, %buf77_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf79_unroll_0, %buf67_unroll_0, %buf68_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf68_unroll_0, %buf79_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf66_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf65_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf64_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf78_unroll_0, %buf63_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf65_unroll_0, %buf78_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf65_unroll_0, %buf78_unroll_0, %buf62_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf63_unroll_0, %buf78_unroll_0, %buf61_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf62_unroll_0, %buf66_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf61_unroll_0, %buf77_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf77_unroll_0, %buf66_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf60_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf64_unroll_0, %buf62_unroll_0, %buf60_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf79_unroll_0, %buf61_unroll_0, %buf60_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf60_unroll_0, %buf64_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf64_unroll_0, %buf66_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_3_2_39, Release, 1)
      aie.use_lock(%lock_3_2_36, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_2_2 = aie.mem(%tile_2_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_2_2_34, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf46_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_2_2_33, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_2_2_31, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf56_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_2_32, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_2_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf54_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_2_30, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_2_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf50_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_2_30, Release, 1)
      aie.next_bd ^bb6
    }
    %core_2_2 = aie.core(%tile_2_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_2_2_33, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf57_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf59_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf58_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_2_32, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_2_31, Release, 1)
      aie.use_lock(%lock_2_2_32, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_2_31, Release, 1)
      aie.use_lock(%lock_2_2_32, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf56_unroll_0, %buf55_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_2_31, Release, 1)
      aie.use_lock(%lock_2_2_32, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf53_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_2_31, Release, 1)
      aie.use_lock(%lock_2_2_32, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_2_30, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf55_unroll_0, %buf56_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf58_unroll_0, %buf52_unroll_0, %buf51_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf51_unroll_0, %buf57_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf54_unroll_0, %buf57_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf59_unroll_0, %buf51_unroll_0, %buf52_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf52_unroll_0, %buf59_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf49_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_2_31, Release, 1)
      aie.use_lock(%lock_2_2_32, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_2_2_30, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf55_unroll_0, %buf56_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf58_unroll_0, %buf48_unroll_0, %buf47_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf47_unroll_0, %buf57_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf50_unroll_0, %buf57_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf59_unroll_0, %buf47_unroll_0, %buf48_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf48_unroll_0, %buf59_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf46_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf45_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf44_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf58_unroll_0, %buf43_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf45_unroll_0, %buf58_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf45_unroll_0, %buf58_unroll_0, %buf42_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf43_unroll_0, %buf58_unroll_0, %buf41_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf42_unroll_0, %buf46_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf41_unroll_0, %buf57_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf57_unroll_0, %buf46_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf40_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf44_unroll_0, %buf42_unroll_0, %buf40_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf59_unroll_0, %buf41_unroll_0, %buf40_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf40_unroll_0, %buf44_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf44_unroll_0, %buf46_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_2_2_34, Release, 1)
      aie.use_lock(%lock_2_2_31, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_1_2 = aie.mem(%tile_1_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_1_2_29, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf26_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_1_2_28, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_1_2_26, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf36_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_2_27, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_1_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf34_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_2_25, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_1_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf30_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_2_25, Release, 1)
      aie.next_bd ^bb6
    }
    %core_1_2 = aie.core(%tile_1_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_1_2_28, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf37_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf39_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf38_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_2_27, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_2_26, Release, 1)
      aie.use_lock(%lock_1_2_27, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf36_unroll_0, %buf35_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_2_26, Release, 1)
      aie.use_lock(%lock_1_2_27, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_2_26, Release, 1)
      aie.use_lock(%lock_1_2_27, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf33_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_2_26, Release, 1)
      aie.use_lock(%lock_1_2_27, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_2_25, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf35_unroll_0, %buf36_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf38_unroll_0, %buf32_unroll_0, %buf31_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf31_unroll_0, %buf37_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf34_unroll_0, %buf37_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf39_unroll_0, %buf31_unroll_0, %buf32_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf32_unroll_0, %buf39_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf29_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_2_26, Release, 1)
      aie.use_lock(%lock_1_2_27, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_1_2_25, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf35_unroll_0, %buf36_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf38_unroll_0, %buf28_unroll_0, %buf27_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf27_unroll_0, %buf37_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf30_unroll_0, %buf37_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf39_unroll_0, %buf27_unroll_0, %buf28_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf28_unroll_0, %buf39_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf26_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf25_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf24_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf38_unroll_0, %buf23_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf25_unroll_0, %buf38_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf25_unroll_0, %buf38_unroll_0, %buf22_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf23_unroll_0, %buf38_unroll_0, %buf21_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf22_unroll_0, %buf26_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf21_unroll_0, %buf37_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf37_unroll_0, %buf26_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf20_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf24_unroll_0, %buf22_unroll_0, %buf20_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf39_unroll_0, %buf21_unroll_0, %buf20_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf20_unroll_0, %buf24_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf24_unroll_0, %buf26_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_1_2_29, Release, 1)
      aie.use_lock(%lock_1_2_26, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_0_2 = aie.mem(%tile_0_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_0_2_24, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf6_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_0_2_23, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_0_2_21, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf16_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_2_22, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_0_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf14_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_2_20, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_0_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf10_unroll_0 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_2_20, Release, 1)
      aie.next_bd ^bb6
    }
    %core_0_2 = aie.core(%tile_0_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_0_2_23, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf17_unroll_0) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf19_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf18_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_2_22, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf16_unroll_0, %buf15_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_2_21, Release, 1)
      aie.use_lock(%lock_0_2_22, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_2_21, Release, 1)
      aie.use_lock(%lock_0_2_22, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_2_21, Release, 1)
      aie.use_lock(%lock_0_2_22, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf13_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_2_21, Release, 1)
      aie.use_lock(%lock_0_2_22, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_2_20, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf15_unroll_0, %buf16_unroll_0, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf18_unroll_0, %buf12_unroll_0, %buf11_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf11_unroll_0, %buf17_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf14_unroll_0, %buf17_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf19_unroll_0, %buf11_unroll_0, %buf12_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf12_unroll_0, %buf19_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf9_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_2_21, Release, 1)
      aie.use_lock(%lock_0_2_22, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_0_2_20, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf15_unroll_0, %buf16_unroll_0, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf18_unroll_0, %buf8_unroll_0, %buf7_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf7_unroll_0, %buf17_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf10_unroll_0, %buf17_unroll_0) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf19_unroll_0, %buf7_unroll_0, %buf8_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf8_unroll_0, %buf19_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf6_unroll_0 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf5_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf4_unroll_0 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf18_unroll_0, %buf3_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf5_unroll_0, %buf18_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf5_unroll_0, %buf18_unroll_0, %buf2_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf3_unroll_0, %buf18_unroll_0, %buf1_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf2_unroll_0, %buf6_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf1_unroll_0, %buf17_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf17_unroll_0, %buf6_unroll_0) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf0_unroll_0) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf4_unroll_0, %buf2_unroll_0, %buf0_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf19_unroll_0, %buf1_unroll_0, %buf0_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf0_unroll_0, %buf4_unroll_0) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf4_unroll_0, %buf6_unroll_0) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_0_2_24, Release, 1)
      aie.use_lock(%lock_0_2_21, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    func.func private @zero_fill_gp_bf16(memref<64x64xbf16, 2 : i32>)
    func.func private @zero_fill_sp_bf16(memref<64x1xbf16, 2 : i32>)
    func.func private @neg_inf_fill_up_bf16(memref<64x1xbf16, 2 : i32>)
    func.func private @copy_tile(memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>)
    func.func private @zero_fill_g_bf16(memref<4096xbf16, 2 : i32>)
    func.func private @matmul_a_b_bf16(memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>)
    func.func private @fused_softmax(memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>)
    func.func private @mul_r_gp(memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>)
    func.func private @matmul_g_b_bf16(memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>)
    func.func private @accum_sp_r_s(memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>)
    func.func private @vector_copy_32elems(i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>)
    func.func private @maximum_up_u_bf16(memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>)
    func.func private @exp_up_minus_u(memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>)
    func.func private @add_gp_g(memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>)
    func.func private @div_gp_sp(memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>)
    aie.flow(%shim_noc_tile_0_0, DMA : 0, %tile_0_2, DMA : 0)
    aie.flow(%shim_noc_tile_0_0, DMA : 0, %tile_1_2, DMA : 0)
    aie.flow(%shim_noc_tile_0_0, DMA : 0, %tile_2_2, DMA : 0)
    aie.flow(%shim_noc_tile_0_0, DMA : 0, %tile_3_2, DMA : 0)
    aie.flow(%shim_noc_tile_0_0, DMA : 1, %tile_0_3, DMA : 0)
    aie.flow(%shim_noc_tile_0_0, DMA : 1, %tile_1_3, DMA : 0)
    aie.flow(%shim_noc_tile_0_0, DMA : 1, %tile_2_3, DMA : 0)
    aie.flow(%shim_noc_tile_0_0, DMA : 1, %tile_3_3, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 0, %tile_0_4, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 0, %tile_1_4, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 0, %tile_2_4, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 0, %tile_3_4, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 1, %tile_0_5, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 1, %tile_1_5, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 1, %tile_2_5, DMA : 0)
    aie.flow(%shim_noc_tile_1_0, DMA : 1, %tile_3_5, DMA : 0)
    aie.flow(%shim_noc_tile_2_0, DMA : 0, %mem_tile_0_1, DMA : 0)
    aie.flow(%shim_noc_tile_2_0, DMA : 1, %mem_tile_1_1, DMA : 0)
    aie.flow(%shim_noc_tile_3_0, DMA : 0, %mem_tile_2_1, DMA : 0)
    aie.flow(%shim_noc_tile_3_0, DMA : 1, %mem_tile_3_1, DMA : 0)
    aie.flow(%mem_tile_0_1, DMA : 0, %shim_noc_tile_0_0, DMA : 0)
    aie.flow(%mem_tile_1_1, DMA : 0, %shim_noc_tile_1_0, DMA : 0)
    aie.flow(%mem_tile_2_1, DMA : 0, %shim_noc_tile_2_0, DMA : 0)
    aie.flow(%mem_tile_3_1, DMA : 0, %shim_noc_tile_3_0, DMA : 0)
    aie.flow(%mem_tile_0_1, DMA : 1, %tile_0_2, DMA : 1)
    aie.flow(%mem_tile_0_1, DMA : 1, %tile_1_2, DMA : 1)
    aie.flow(%mem_tile_0_1, DMA : 1, %tile_2_2, DMA : 1)
    aie.flow(%mem_tile_0_1, DMA : 1, %tile_3_2, DMA : 1)
    aie.flow(%mem_tile_1_1, DMA : 1, %tile_0_3, DMA : 1)
    aie.flow(%mem_tile_1_1, DMA : 1, %tile_1_3, DMA : 1)
    aie.flow(%mem_tile_1_1, DMA : 1, %tile_2_3, DMA : 1)
    aie.flow(%mem_tile_1_1, DMA : 1, %tile_3_3, DMA : 1)
    aie.flow(%mem_tile_2_1, DMA : 1, %tile_0_4, DMA : 1)
    aie.flow(%mem_tile_2_1, DMA : 1, %tile_1_4, DMA : 1)
    aie.flow(%mem_tile_2_1, DMA : 1, %tile_2_4, DMA : 1)
    aie.flow(%mem_tile_2_1, DMA : 1, %tile_3_4, DMA : 1)
    aie.flow(%mem_tile_3_1, DMA : 1, %tile_0_5, DMA : 1)
    aie.flow(%mem_tile_3_1, DMA : 1, %tile_1_5, DMA : 1)
    aie.flow(%mem_tile_3_1, DMA : 1, %tile_2_5, DMA : 1)
    aie.flow(%mem_tile_3_1, DMA : 1, %tile_3_5, DMA : 1)
    aie.flow(%tile_0_2, DMA : 0, %mem_tile_0_1, DMA : 1)
    aie.flow(%tile_1_2, DMA : 0, %mem_tile_1_1, DMA : 1)
    aie.flow(%tile_2_2, DMA : 0, %mem_tile_2_1, DMA : 1)
    aie.flow(%tile_3_2, DMA : 0, %mem_tile_3_1, DMA : 1)
    aie.cascade_flow(%tile_3_5, %tile_3_4)
    aie.cascade_flow(%tile_2_5, %tile_2_4)
    aie.cascade_flow(%tile_1_5, %tile_1_4)
    aie.cascade_flow(%tile_0_5, %tile_0_4)
    aie.cascade_flow(%tile_3_4, %tile_3_3)
    aie.cascade_flow(%tile_2_4, %tile_2_3)
    aie.cascade_flow(%tile_1_4, %tile_1_3)
    aie.cascade_flow(%tile_0_4, %tile_0_3)
    aie.cascade_flow(%tile_3_3, %tile_3_2)
    aie.cascade_flow(%tile_2_3, %tile_2_2)
    aie.cascade_flow(%tile_1_3, %tile_1_2)
    aie.cascade_flow(%tile_0_3, %tile_0_2)
    %memtile_dma_0_1 = aie.memtile_dma(%mem_tile_0_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_0_1_19, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf303_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_1_18, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_0_1_17, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf299_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_0_1_16, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_0_1_15, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf298_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_0_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_0_1_16, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf299_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_1_17, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_0_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf298_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_1_15, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_0_1_18, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf303_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_0_1_19, Release, 1)
      aie.next_bd ^bb10
    }
    %memtile_dma_1_1 = aie.memtile_dma(%mem_tile_1_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_1_1_14, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf302_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_1_13, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_1_1_12, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf297_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_1_1_11, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_1_1_10, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf296_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_1_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_1_1_11, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf297_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_1_12, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_1_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf296_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_1_10, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_1_1_13, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf302_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_1_1_14, Release, 1)
      aie.next_bd ^bb10
    }
    %memtile_dma_2_1 = aie.memtile_dma(%mem_tile_2_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_2_1_9, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf301_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_1_8, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_2_1_7, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf295_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_2_1_6, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_2_1_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf294_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_2_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_2_1_6, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf295_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_1_7, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_2_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf294_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_1_5, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_2_1_8, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf301_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_2_1_9, Release, 1)
      aie.next_bd ^bb10
    }
    %memtile_dma_3_1 = aie.memtile_dma(%mem_tile_3_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_3_1_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf300_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_1_3, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_3_1_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf293_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_3_1_1, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_3_1_0, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf292_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_3_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_3_1_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf293_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_1_2, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_3_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf292_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_1_0, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_3_1_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf300_unroll_0 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_3_1_4, Release, 1)
      aie.next_bd ^bb10
    }
    aie.shim_dma_allocation @air_channel_0_0_0_0(%shim_noc_tile_0_0, S2MM, 0)
    aie.shim_dma_allocation @air_channel_0_0_0_1(%shim_noc_tile_1_0, S2MM, 0)
    aie.shim_dma_allocation @air_channel_0_0_0_2(%shim_noc_tile_2_0, S2MM, 0)
    aie.shim_dma_allocation @air_channel_0_0_0_3(%shim_noc_tile_3_0, S2MM, 0)
    aie.shim_dma_allocation @air_QK2L1_0_0_0_0(%shim_noc_tile_0_0, MM2S, 0)
    aie.shim_dma_allocation @air_QK2L1_0_1_0_0(%shim_noc_tile_0_0, MM2S, 1)
    aie.shim_dma_allocation @air_QK2L1_0_2_0_0(%shim_noc_tile_1_0, MM2S, 0)
    aie.shim_dma_allocation @air_QK2L1_0_3_0_0(%shim_noc_tile_1_0, MM2S, 1)
    aie.shim_dma_allocation @air_VIn_0_0_0(%shim_noc_tile_2_0, MM2S, 0)
    aie.shim_dma_allocation @air_VIn_1_0_0(%shim_noc_tile_2_0, MM2S, 1)
    aie.shim_dma_allocation @air_VIn_2_0_0(%shim_noc_tile_3_0, MM2S, 0)
    aie.shim_dma_allocation @air_VIn_3_0_0(%shim_noc_tile_3_0, MM2S, 1)
    %shim_noc_tile_4_0 = aie.tile(4, 0)
    %shim_noc_tile_5_0 = aie.tile(5, 0)
    %shim_noc_tile_6_0 = aie.tile(6, 0)
    %shim_noc_tile_7_0 = aie.tile(7, 0)
    %mem_tile_4_1 = aie.tile(4, 1)
    %mem_tile_5_1 = aie.tile(5, 1)
    %mem_tile_6_1 = aie.tile(6, 1)
    %mem_tile_7_1 = aie.tile(7, 1)
    %tile_4_2 = aie.tile(4, 2)
    %tile_5_2 = aie.tile(5, 2)
    %tile_6_2 = aie.tile(6, 2)
    %tile_7_2 = aie.tile(7, 2)
    %tile_4_3 = aie.tile(4, 3)
    %tile_5_3 = aie.tile(5, 3)
    %tile_6_3 = aie.tile(6, 3)
    %tile_7_3 = aie.tile(7, 3)
    %tile_4_4 = aie.tile(4, 4)
    %tile_5_4 = aie.tile(5, 4)
    %tile_6_4 = aie.tile(6, 4)
    %tile_7_4 = aie.tile(7, 4)
    %tile_4_5 = aie.tile(4, 5)
    %tile_5_5 = aie.tile(5, 5)
    %tile_6_5 = aie.tile(6, 5)
    %tile_7_5 = aie.tile(7, 5)
    %lock_7_1 = aie.lock(%mem_tile_7_1, 5) {init = 1 : i32}
    %lock_7_1_76 = aie.lock(%mem_tile_7_1, 4) {init = 0 : i32}
    %lock_7_1_77 = aie.lock(%mem_tile_7_1, 3) {init = 1 : i32}
    %lock_7_1_78 = aie.lock(%mem_tile_7_1, 2) {init = 0 : i32}
    %lock_7_1_79 = aie.lock(%mem_tile_7_1, 1) {init = 1 : i32}
    %lock_7_1_80 = aie.lock(%mem_tile_7_1, 0) {init = 0 : i32}
    %lock_6_1 = aie.lock(%mem_tile_6_1, 5) {init = 1 : i32}
    %lock_6_1_81 = aie.lock(%mem_tile_6_1, 4) {init = 0 : i32}
    %lock_6_1_82 = aie.lock(%mem_tile_6_1, 3) {init = 1 : i32}
    %lock_6_1_83 = aie.lock(%mem_tile_6_1, 2) {init = 0 : i32}
    %lock_6_1_84 = aie.lock(%mem_tile_6_1, 1) {init = 1 : i32}
    %lock_6_1_85 = aie.lock(%mem_tile_6_1, 0) {init = 0 : i32}
    %lock_5_1 = aie.lock(%mem_tile_5_1, 5) {init = 1 : i32}
    %lock_5_1_86 = aie.lock(%mem_tile_5_1, 4) {init = 0 : i32}
    %lock_5_1_87 = aie.lock(%mem_tile_5_1, 3) {init = 1 : i32}
    %lock_5_1_88 = aie.lock(%mem_tile_5_1, 2) {init = 0 : i32}
    %lock_5_1_89 = aie.lock(%mem_tile_5_1, 1) {init = 1 : i32}
    %lock_5_1_90 = aie.lock(%mem_tile_5_1, 0) {init = 0 : i32}
    %lock_4_1 = aie.lock(%mem_tile_4_1, 5) {init = 1 : i32}
    %lock_4_1_91 = aie.lock(%mem_tile_4_1, 4) {init = 0 : i32}
    %lock_4_1_92 = aie.lock(%mem_tile_4_1, 3) {init = 1 : i32}
    %lock_4_1_93 = aie.lock(%mem_tile_4_1, 2) {init = 0 : i32}
    %lock_4_1_94 = aie.lock(%mem_tile_4_1, 1) {init = 1 : i32}
    %lock_4_1_95 = aie.lock(%mem_tile_4_1, 0) {init = 0 : i32}
    %lock_4_2 = aie.lock(%tile_4_2, 5) {init = 2 : i32}
    %lock_4_2_96 = aie.lock(%tile_4_2, 4) {init = 0 : i32}
    %lock_4_2_97 = aie.lock(%tile_4_2, 3) {init = 1 : i32}
    %lock_4_2_98 = aie.lock(%tile_4_2, 2) {init = 0 : i32}
    %lock_4_2_99 = aie.lock(%tile_4_2, 1) {init = 1 : i32}
    %lock_4_2_100 = aie.lock(%tile_4_2, 0) {init = 0 : i32}
    %lock_5_2 = aie.lock(%tile_5_2, 5) {init = 2 : i32}
    %lock_5_2_101 = aie.lock(%tile_5_2, 4) {init = 0 : i32}
    %lock_5_2_102 = aie.lock(%tile_5_2, 3) {init = 1 : i32}
    %lock_5_2_103 = aie.lock(%tile_5_2, 2) {init = 0 : i32}
    %lock_5_2_104 = aie.lock(%tile_5_2, 1) {init = 1 : i32}
    %lock_5_2_105 = aie.lock(%tile_5_2, 0) {init = 0 : i32}
    %lock_6_2 = aie.lock(%tile_6_2, 5) {init = 2 : i32}
    %lock_6_2_106 = aie.lock(%tile_6_2, 4) {init = 0 : i32}
    %lock_6_2_107 = aie.lock(%tile_6_2, 3) {init = 1 : i32}
    %lock_6_2_108 = aie.lock(%tile_6_2, 2) {init = 0 : i32}
    %lock_6_2_109 = aie.lock(%tile_6_2, 1) {init = 1 : i32}
    %lock_6_2_110 = aie.lock(%tile_6_2, 0) {init = 0 : i32}
    %lock_7_2 = aie.lock(%tile_7_2, 5) {init = 2 : i32}
    %lock_7_2_111 = aie.lock(%tile_7_2, 4) {init = 0 : i32}
    %lock_7_2_112 = aie.lock(%tile_7_2, 3) {init = 1 : i32}
    %lock_7_2_113 = aie.lock(%tile_7_2, 2) {init = 0 : i32}
    %lock_7_2_114 = aie.lock(%tile_7_2, 1) {init = 1 : i32}
    %lock_7_2_115 = aie.lock(%tile_7_2, 0) {init = 0 : i32}
    %lock_4_3 = aie.lock(%tile_4_3, 3) {init = 2 : i32}
    %lock_4_3_116 = aie.lock(%tile_4_3, 2) {init = 0 : i32}
    %lock_4_3_117 = aie.lock(%tile_4_3, 1) {init = 1 : i32}
    %lock_4_3_118 = aie.lock(%tile_4_3, 0) {init = 0 : i32}
    %lock_5_3 = aie.lock(%tile_5_3, 3) {init = 2 : i32}
    %lock_5_3_119 = aie.lock(%tile_5_3, 2) {init = 0 : i32}
    %lock_5_3_120 = aie.lock(%tile_5_3, 1) {init = 1 : i32}
    %lock_5_3_121 = aie.lock(%tile_5_3, 0) {init = 0 : i32}
    %lock_6_3 = aie.lock(%tile_6_3, 3) {init = 2 : i32}
    %lock_6_3_122 = aie.lock(%tile_6_3, 2) {init = 0 : i32}
    %lock_6_3_123 = aie.lock(%tile_6_3, 1) {init = 1 : i32}
    %lock_6_3_124 = aie.lock(%tile_6_3, 0) {init = 0 : i32}
    %lock_7_3 = aie.lock(%tile_7_3, 3) {init = 2 : i32}
    %lock_7_3_125 = aie.lock(%tile_7_3, 2) {init = 0 : i32}
    %lock_7_3_126 = aie.lock(%tile_7_3, 1) {init = 1 : i32}
    %lock_7_3_127 = aie.lock(%tile_7_3, 0) {init = 0 : i32}
    %lock_4_4 = aie.lock(%tile_4_4, 3) {init = 2 : i32}
    %lock_4_4_128 = aie.lock(%tile_4_4, 2) {init = 0 : i32}
    %lock_4_4_129 = aie.lock(%tile_4_4, 1) {init = 1 : i32}
    %lock_4_4_130 = aie.lock(%tile_4_4, 0) {init = 0 : i32}
    %lock_5_4 = aie.lock(%tile_5_4, 3) {init = 2 : i32}
    %lock_5_4_131 = aie.lock(%tile_5_4, 2) {init = 0 : i32}
    %lock_5_4_132 = aie.lock(%tile_5_4, 1) {init = 1 : i32}
    %lock_5_4_133 = aie.lock(%tile_5_4, 0) {init = 0 : i32}
    %lock_6_4 = aie.lock(%tile_6_4, 3) {init = 2 : i32}
    %lock_6_4_134 = aie.lock(%tile_6_4, 2) {init = 0 : i32}
    %lock_6_4_135 = aie.lock(%tile_6_4, 1) {init = 1 : i32}
    %lock_6_4_136 = aie.lock(%tile_6_4, 0) {init = 0 : i32}
    %lock_7_4 = aie.lock(%tile_7_4, 3) {init = 2 : i32}
    %lock_7_4_137 = aie.lock(%tile_7_4, 2) {init = 0 : i32}
    %lock_7_4_138 = aie.lock(%tile_7_4, 1) {init = 1 : i32}
    %lock_7_4_139 = aie.lock(%tile_7_4, 0) {init = 0 : i32}
    %lock_4_5 = aie.lock(%tile_4_5, 3) {init = 2 : i32}
    %lock_4_5_140 = aie.lock(%tile_4_5, 2) {init = 0 : i32}
    %lock_4_5_141 = aie.lock(%tile_4_5, 1) {init = 1 : i32}
    %lock_4_5_142 = aie.lock(%tile_4_5, 0) {init = 0 : i32}
    %lock_5_5 = aie.lock(%tile_5_5, 3) {init = 2 : i32}
    %lock_5_5_143 = aie.lock(%tile_5_5, 2) {init = 0 : i32}
    %lock_5_5_144 = aie.lock(%tile_5_5, 1) {init = 1 : i32}
    %lock_5_5_145 = aie.lock(%tile_5_5, 0) {init = 0 : i32}
    %lock_6_5 = aie.lock(%tile_6_5, 3) {init = 2 : i32}
    %lock_6_5_146 = aie.lock(%tile_6_5, 2) {init = 0 : i32}
    %lock_6_5_147 = aie.lock(%tile_6_5, 1) {init = 1 : i32}
    %lock_6_5_148 = aie.lock(%tile_6_5, 0) {init = 0 : i32}
    %lock_7_5 = aie.lock(%tile_7_5, 3) {init = 2 : i32}
    %lock_7_5_149 = aie.lock(%tile_7_5, 2) {init = 0 : i32}
    %lock_7_5_150 = aie.lock(%tile_7_5, 1) {init = 1 : i32}
    %lock_7_5_151 = aie.lock(%tile_7_5, 0) {init = 0 : i32}
    %buf607_unroll_1 = aie.buffer(%mem_tile_4_1) {sym_name = "buf607_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf606_unroll_1 = aie.buffer(%mem_tile_5_1) {sym_name = "buf606_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf605_unroll_1 = aie.buffer(%mem_tile_6_1) {sym_name = "buf605_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf604_unroll_1 = aie.buffer(%mem_tile_7_1) {sym_name = "buf604_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf603_unroll_1 = aie.buffer(%mem_tile_4_1) {sym_name = "buf603_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf602_unroll_1 = aie.buffer(%mem_tile_4_1) {sym_name = "buf602_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf601_unroll_1 = aie.buffer(%mem_tile_5_1) {sym_name = "buf601_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf600_unroll_1 = aie.buffer(%mem_tile_5_1) {sym_name = "buf600_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf599_unroll_1 = aie.buffer(%mem_tile_6_1) {sym_name = "buf599_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf598_unroll_1 = aie.buffer(%mem_tile_6_1) {sym_name = "buf598_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf597_unroll_1 = aie.buffer(%mem_tile_7_1) {sym_name = "buf597_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf596_unroll_1 = aie.buffer(%mem_tile_7_1) {sym_name = "buf596_unroll_1"} : memref<64x64xbf16, 1 : i32> 
    %buf595_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf595_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf594_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf594_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf593_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf593_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf592_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf592_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf591_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf591_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf590_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf590_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf589_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf589_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf588_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf588_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf587_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf587_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf586_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf586_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf585_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf585_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf584_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf584_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf583_unroll_1 = aie.buffer(%tile_7_5) {sym_name = "buf583_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf582_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf582_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf581_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf581_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf580_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf580_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf579_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf579_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf578_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf578_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf577_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf577_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf576_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf576_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf575_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf575_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf574_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf574_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf573_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf573_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf572_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf572_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf571_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf571_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf570_unroll_1 = aie.buffer(%tile_6_5) {sym_name = "buf570_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf569_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf569_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf568_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf568_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf567_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf567_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf566_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf566_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf565_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf565_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf564_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf564_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf563_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf563_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf562_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf562_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf561_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf561_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf560_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf560_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf559_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf559_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf558_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf558_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf557_unroll_1 = aie.buffer(%tile_5_5) {sym_name = "buf557_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf556_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf556_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf555_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf555_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf554_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf554_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf553_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf553_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf552_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf552_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf551_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf551_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf550_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf550_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf549_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf549_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf548_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf548_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf547_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf547_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf546_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf546_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf545_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf545_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf544_unroll_1 = aie.buffer(%tile_4_5) {sym_name = "buf544_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf543_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf543_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf542_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf542_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf541_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf541_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf540_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf540_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf539_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf539_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf538_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf538_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf537_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf537_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf536_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf536_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf535_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf535_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf534_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf534_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf533_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf533_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf532_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf532_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf531_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf531_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf530_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf530_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf529_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf529_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf528_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf528_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf527_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf527_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf526_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf526_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf525_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf525_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf524_unroll_1 = aie.buffer(%tile_7_4) {sym_name = "buf524_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf523_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf523_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf522_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf522_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf521_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf521_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf520_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf520_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf519_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf519_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf518_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf518_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf517_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf517_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf516_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf516_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf515_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf515_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf514_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf514_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf513_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf513_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf512_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf512_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf511_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf511_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf510_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf510_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf509_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf509_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf508_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf508_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf507_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf507_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf506_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf506_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf505_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf505_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf504_unroll_1 = aie.buffer(%tile_6_4) {sym_name = "buf504_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf503_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf503_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf502_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf502_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf501_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf501_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf500_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf500_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf499_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf499_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf498_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf498_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf497_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf497_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf496_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf496_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf495_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf495_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf494_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf494_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf493_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf493_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf492_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf492_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf491_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf491_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf490_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf490_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf489_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf489_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf488_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf488_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf487_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf487_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf486_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf486_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf485_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf485_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf484_unroll_1 = aie.buffer(%tile_5_4) {sym_name = "buf484_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf483_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf483_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf482_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf482_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf481_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf481_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf480_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf480_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf479_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf479_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf478_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf478_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf477_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf477_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf476_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf476_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf475_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf475_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf474_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf474_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf473_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf473_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf472_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf472_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf471_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf471_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf470_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf470_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf469_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf469_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf468_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf468_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf467_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf467_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf466_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf466_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf465_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf465_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf464_unroll_1 = aie.buffer(%tile_4_4) {sym_name = "buf464_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf463_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf463_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf462_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf462_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf461_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf461_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf460_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf460_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf459_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf459_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf458_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf458_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf457_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf457_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf456_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf456_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf455_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf455_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf454_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf454_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf453_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf453_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf452_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf452_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf451_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf451_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf450_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf450_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf449_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf449_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf448_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf448_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf447_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf447_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf446_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf446_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf445_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf445_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf444_unroll_1 = aie.buffer(%tile_7_3) {sym_name = "buf444_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf443_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf443_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf442_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf442_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf441_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf441_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf440_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf440_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf439_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf439_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf438_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf438_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf437_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf437_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf436_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf436_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf435_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf435_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf434_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf434_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf433_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf433_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf432_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf432_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf431_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf431_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf430_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf430_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf429_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf429_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf428_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf428_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf427_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf427_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf426_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf426_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf425_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf425_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf424_unroll_1 = aie.buffer(%tile_6_3) {sym_name = "buf424_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf423_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf423_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf422_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf422_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf421_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf421_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf420_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf420_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf419_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf419_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf418_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf418_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf417_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf417_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf416_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf416_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf415_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf415_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf414_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf414_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf413_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf413_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf412_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf412_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf411_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf411_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf410_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf410_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf409_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf409_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf408_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf408_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf407_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf407_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf406_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf406_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf405_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf405_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf404_unroll_1 = aie.buffer(%tile_5_3) {sym_name = "buf404_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf403_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf403_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf402_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf402_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf401_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf401_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf400_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf400_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf399_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf399_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf398_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf398_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf397_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf397_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf396_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf396_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf395_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf395_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf394_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf394_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf393_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf393_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf392_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf392_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf391_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf391_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf390_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf390_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf389_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf389_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf388_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf388_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf387_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf387_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf386_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf386_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf385_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf385_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf384_unroll_1 = aie.buffer(%tile_4_3) {sym_name = "buf384_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf383_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf383_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf382_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf382_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf381_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf381_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf380_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf380_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf379_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf379_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf378_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf378_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf377_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf377_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf376_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf376_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf375_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf375_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf374_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf374_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf373_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf373_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf372_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf372_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf371_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf371_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf370_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf370_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf369_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf369_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf368_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf368_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf367_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf367_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf366_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf366_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf365_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf365_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf364_unroll_1 = aie.buffer(%tile_7_2) {sym_name = "buf364_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf363_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf363_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf362_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf362_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf361_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf361_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf360_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf360_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf359_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf359_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf358_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf358_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf357_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf357_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf356_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf356_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf355_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf355_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf354_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf354_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf353_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf353_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf352_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf352_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf351_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf351_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf350_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf350_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf349_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf349_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf348_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf348_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf347_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf347_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf346_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf346_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf345_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf345_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf344_unroll_1 = aie.buffer(%tile_6_2) {sym_name = "buf344_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf343_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf343_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf342_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf342_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf341_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf341_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf340_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf340_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf339_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf339_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf338_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf338_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf337_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf337_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf336_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf336_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf335_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf335_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf334_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf334_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf333_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf333_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf332_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf332_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf331_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf331_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf330_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf330_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf329_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf329_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf328_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf328_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf327_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf327_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf326_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf326_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf325_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf325_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf324_unroll_1 = aie.buffer(%tile_5_2) {sym_name = "buf324_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf323_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf323_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf322_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf322_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf321_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf321_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf320_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf320_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf319_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf319_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf318_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf318_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf317_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf317_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf316_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf316_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf315_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf315_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf314_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf314_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf313_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf313_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf312_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf312_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf311_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf311_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf310_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf310_unroll_1"} : memref<64x64xbf16, 2 : i32> 
    %buf309_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf309_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf308_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf308_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf307_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf307_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf306_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf306_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf305_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf305_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %buf304_unroll_1 = aie.buffer(%tile_4_2) {sym_name = "buf304_unroll_1"} : memref<64x1xbf16, 2 : i32> 
    %__air_external_buffer_unroll_1 = aie.external_buffer {sym_name = "__air_external_buffer_unroll_1"} : memref<2x512x64xbf16>
    %__air_external_buffer_1_unroll_1 = aie.external_buffer {sym_name = "__air_external_buffer_1_unroll_1"} : memref<2x512x64xbf16>
    %__air_external_buffer_2_unroll_1 = aie.external_buffer {sym_name = "__air_external_buffer_2_unroll_1"} : memref<2x512x64xbf16>
    %__air_external_buffer_3_unroll_1 = aie.external_buffer {sym_name = "__air_external_buffer_3_unroll_1"} : memref<2x512x64xbf16>
    %mem_7_5 = aie.mem(%tile_7_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_7_5_150, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf592_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_5_151, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_7_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf590_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_5_149, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_7_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf586_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_5_149, Release, 1)
      aie.next_bd ^bb4
    }
    %core_7_5 = aie.core(%tile_7_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf593_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf595_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf594_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_5_151, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_5_150, Release, 1)
      aie.use_lock(%lock_7_5_151, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_5_150, Release, 1)
      aie.use_lock(%lock_7_5_151, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_5_150, Release, 1)
      aie.use_lock(%lock_7_5_151, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf592_unroll_1, %buf591_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf589_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_5_150, Release, 1)
      aie.use_lock(%lock_7_5_151, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_5_149, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf591_unroll_1, %buf592_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf594_unroll_1, %buf588_unroll_1, %buf587_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf587_unroll_1, %buf593_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf590_unroll_1, %buf593_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf595_unroll_1, %buf587_unroll_1, %buf588_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf588_unroll_1, %buf595_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf585_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_5_150, Release, 1)
      aie.use_lock(%lock_7_5_151, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_5_149, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf591_unroll_1, %buf592_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf594_unroll_1, %buf584_unroll_1, %buf583_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf583_unroll_1, %buf593_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf586_unroll_1, %buf593_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf595_unroll_1, %buf583_unroll_1, %buf584_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf584_unroll_1, %buf595_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf593_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf594_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf595_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_7_5_150, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_6_5 = aie.mem(%tile_6_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_6_5_147, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf579_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_5_148, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_6_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf577_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_5_146, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_6_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf573_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_5_146, Release, 1)
      aie.next_bd ^bb4
    }
    %core_6_5 = aie.core(%tile_6_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf580_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf582_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf581_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_5_148, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_5_147, Release, 1)
      aie.use_lock(%lock_6_5_148, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_5_147, Release, 1)
      aie.use_lock(%lock_6_5_148, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf579_unroll_1, %buf578_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_5_147, Release, 1)
      aie.use_lock(%lock_6_5_148, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf576_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_5_147, Release, 1)
      aie.use_lock(%lock_6_5_148, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_5_146, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf578_unroll_1, %buf579_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf581_unroll_1, %buf575_unroll_1, %buf574_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf574_unroll_1, %buf580_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf577_unroll_1, %buf580_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf582_unroll_1, %buf574_unroll_1, %buf575_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf575_unroll_1, %buf582_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf572_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_5_147, Release, 1)
      aie.use_lock(%lock_6_5_148, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_5_146, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf578_unroll_1, %buf579_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf581_unroll_1, %buf571_unroll_1, %buf570_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf570_unroll_1, %buf580_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf573_unroll_1, %buf580_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf582_unroll_1, %buf570_unroll_1, %buf571_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf571_unroll_1, %buf582_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf580_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf581_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf582_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_6_5_147, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_5_5 = aie.mem(%tile_5_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_5_5_144, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf566_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_5_145, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_5_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf564_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_5_143, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_5_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf560_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_5_143, Release, 1)
      aie.next_bd ^bb4
    }
    %core_5_5 = aie.core(%tile_5_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf567_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf569_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf568_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_5_145, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_5_144, Release, 1)
      aie.use_lock(%lock_5_5_145, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf566_unroll_1, %buf565_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_5_144, Release, 1)
      aie.use_lock(%lock_5_5_145, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_5_144, Release, 1)
      aie.use_lock(%lock_5_5_145, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf563_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_5_144, Release, 1)
      aie.use_lock(%lock_5_5_145, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_5_143, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf565_unroll_1, %buf566_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf568_unroll_1, %buf562_unroll_1, %buf561_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf561_unroll_1, %buf567_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf564_unroll_1, %buf567_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf569_unroll_1, %buf561_unroll_1, %buf562_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf562_unroll_1, %buf569_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf559_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_5_144, Release, 1)
      aie.use_lock(%lock_5_5_145, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_5_143, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf565_unroll_1, %buf566_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf568_unroll_1, %buf558_unroll_1, %buf557_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf557_unroll_1, %buf567_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf560_unroll_1, %buf567_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf569_unroll_1, %buf557_unroll_1, %buf558_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf558_unroll_1, %buf569_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf567_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf568_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf569_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_5_5_144, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_4_5 = aie.mem(%tile_4_5) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_4_5_141, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf553_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_5_142, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_4_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf551_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_5_140, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_4_5, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf547_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_5_140, Release, 1)
      aie.next_bd ^bb4
    }
    %core_4_5 = aie.core(%tile_4_5) {
      %c64 = arith.constant 64 : index
      %cst = arith.constant 0.000000e+00 : bf16
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf554_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf556_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf555_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_5_142, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf553_unroll_1, %buf552_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_5_141, Release, 1)
      aie.use_lock(%lock_4_5_142, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_5_141, Release, 1)
      aie.use_lock(%lock_4_5_142, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_5_141, Release, 1)
      aie.use_lock(%lock_4_5_142, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf550_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_5_141, Release, 1)
      aie.use_lock(%lock_4_5_142, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_5_140, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf552_unroll_1, %buf553_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf555_unroll_1, %buf549_unroll_1, %buf548_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf548_unroll_1, %buf554_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf551_unroll_1, %buf554_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf556_unroll_1, %buf548_unroll_1, %buf549_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf549_unroll_1, %buf556_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_5, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf546_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_5_141, Release, 1)
      aie.use_lock(%lock_4_5_142, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_5_140, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf552_unroll_1, %buf553_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf555_unroll_1, %buf545_unroll_1, %buf544_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf544_unroll_1, %buf554_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf547_unroll_1, %buf554_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf556_unroll_1, %buf544_unroll_1, %buf545_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf545_unroll_1, %buf556_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_5, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf554_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_154 = memref.collapse_shape %buf555_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_155 = memref.collapse_shape %buf556_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_4_5_141, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_7_4 = aie.mem(%tile_7_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_7_4_138, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf540_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_4_139, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_7_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf538_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_4_137, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_7_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf534_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_4_137, Release, 1)
      aie.next_bd ^bb4
    }
    %core_7_4 = aie.core(%tile_7_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf541_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf543_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf542_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_4_139, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_4_138, Release, 1)
      aie.use_lock(%lock_7_4_139, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_4_138, Release, 1)
      aie.use_lock(%lock_7_4_139, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_4_138, Release, 1)
      aie.use_lock(%lock_7_4_139, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf540_unroll_1, %buf539_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf537_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_4_138, Release, 1)
      aie.use_lock(%lock_7_4_139, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_4_137, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf539_unroll_1, %buf540_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf542_unroll_1, %buf536_unroll_1, %buf535_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf535_unroll_1, %buf541_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf538_unroll_1, %buf541_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf543_unroll_1, %buf535_unroll_1, %buf536_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf536_unroll_1, %buf543_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf533_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_4_138, Release, 1)
      aie.use_lock(%lock_7_4_139, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_4_137, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf539_unroll_1, %buf540_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf542_unroll_1, %buf532_unroll_1, %buf531_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf531_unroll_1, %buf541_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf534_unroll_1, %buf541_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf543_unroll_1, %buf531_unroll_1, %buf532_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf532_unroll_1, %buf543_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf530_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf529_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf528_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf542_unroll_1, %buf527_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf529_unroll_1, %buf542_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf529_unroll_1, %buf542_unroll_1, %buf526_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf527_unroll_1, %buf542_unroll_1, %buf525_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf526_unroll_1, %buf530_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf525_unroll_1, %buf541_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf541_unroll_1, %buf530_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf524_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf528_unroll_1, %buf526_unroll_1, %buf524_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf543_unroll_1, %buf525_unroll_1, %buf524_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf524_unroll_1, %buf528_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf542_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_7_4_138, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_6_4 = aie.mem(%tile_6_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_6_4_135, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf520_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_4_136, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_6_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf518_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_4_134, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_6_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf514_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_4_134, Release, 1)
      aie.next_bd ^bb4
    }
    %core_6_4 = aie.core(%tile_6_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf521_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf523_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf522_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_4_136, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_4_135, Release, 1)
      aie.use_lock(%lock_6_4_136, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_4_135, Release, 1)
      aie.use_lock(%lock_6_4_136, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf520_unroll_1, %buf519_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_4_135, Release, 1)
      aie.use_lock(%lock_6_4_136, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf517_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_4_135, Release, 1)
      aie.use_lock(%lock_6_4_136, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_4_134, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf519_unroll_1, %buf520_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf522_unroll_1, %buf516_unroll_1, %buf515_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf515_unroll_1, %buf521_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf518_unroll_1, %buf521_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf523_unroll_1, %buf515_unroll_1, %buf516_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf516_unroll_1, %buf523_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf513_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_4_135, Release, 1)
      aie.use_lock(%lock_6_4_136, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_4_134, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf519_unroll_1, %buf520_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf522_unroll_1, %buf512_unroll_1, %buf511_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf511_unroll_1, %buf521_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf514_unroll_1, %buf521_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf523_unroll_1, %buf511_unroll_1, %buf512_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf512_unroll_1, %buf523_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf510_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf509_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf508_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf522_unroll_1, %buf507_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf509_unroll_1, %buf522_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf509_unroll_1, %buf522_unroll_1, %buf506_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf507_unroll_1, %buf522_unroll_1, %buf505_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf506_unroll_1, %buf510_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf505_unroll_1, %buf521_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf521_unroll_1, %buf510_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf504_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf508_unroll_1, %buf506_unroll_1, %buf504_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf523_unroll_1, %buf505_unroll_1, %buf504_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf504_unroll_1, %buf508_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf522_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_6_4_135, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_5_4 = aie.mem(%tile_5_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_5_4_132, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf500_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_4_133, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_5_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf498_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_4_131, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_5_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf494_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_4_131, Release, 1)
      aie.next_bd ^bb4
    }
    %core_5_4 = aie.core(%tile_5_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf501_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf503_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf502_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_4_133, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_4_132, Release, 1)
      aie.use_lock(%lock_5_4_133, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf500_unroll_1, %buf499_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_4_132, Release, 1)
      aie.use_lock(%lock_5_4_133, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_4_132, Release, 1)
      aie.use_lock(%lock_5_4_133, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf497_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_4_132, Release, 1)
      aie.use_lock(%lock_5_4_133, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_4_131, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf499_unroll_1, %buf500_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf502_unroll_1, %buf496_unroll_1, %buf495_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf495_unroll_1, %buf501_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf498_unroll_1, %buf501_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf503_unroll_1, %buf495_unroll_1, %buf496_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf496_unroll_1, %buf503_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf493_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_4_132, Release, 1)
      aie.use_lock(%lock_5_4_133, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_4_131, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf499_unroll_1, %buf500_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf502_unroll_1, %buf492_unroll_1, %buf491_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf491_unroll_1, %buf501_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf494_unroll_1, %buf501_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf503_unroll_1, %buf491_unroll_1, %buf492_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf492_unroll_1, %buf503_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf490_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf489_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf488_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf502_unroll_1, %buf487_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf489_unroll_1, %buf502_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf489_unroll_1, %buf502_unroll_1, %buf486_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf487_unroll_1, %buf502_unroll_1, %buf485_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf486_unroll_1, %buf490_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf485_unroll_1, %buf501_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf501_unroll_1, %buf490_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf484_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf488_unroll_1, %buf486_unroll_1, %buf484_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf503_unroll_1, %buf485_unroll_1, %buf484_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf484_unroll_1, %buf488_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf502_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_5_4_132, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_4_4 = aie.mem(%tile_4_4) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_4_4_129, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf480_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_4_130, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_4_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf478_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_4_128, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_4_4, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf474_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_4_128, Release, 1)
      aie.next_bd ^bb4
    }
    %core_4_4 = aie.core(%tile_4_4) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf481_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf483_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf482_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_4_130, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf480_unroll_1, %buf479_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_4_129, Release, 1)
      aie.use_lock(%lock_4_4_130, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_4_129, Release, 1)
      aie.use_lock(%lock_4_4_130, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_4_129, Release, 1)
      aie.use_lock(%lock_4_4_130, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf477_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_4_129, Release, 1)
      aie.use_lock(%lock_4_4_130, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_4_128, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf479_unroll_1, %buf480_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf482_unroll_1, %buf476_unroll_1, %buf475_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf475_unroll_1, %buf481_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf478_unroll_1, %buf481_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf483_unroll_1, %buf475_unroll_1, %buf476_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf476_unroll_1, %buf483_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_4, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf473_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_4_129, Release, 1)
      aie.use_lock(%lock_4_4_130, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_4_128, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf479_unroll_1, %buf480_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf482_unroll_1, %buf472_unroll_1, %buf471_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf471_unroll_1, %buf481_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf474_unroll_1, %buf481_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf483_unroll_1, %buf471_unroll_1, %buf472_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf472_unroll_1, %buf483_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_4, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf470_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf469_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf468_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf482_unroll_1, %buf467_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf469_unroll_1, %buf482_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf469_unroll_1, %buf482_unroll_1, %buf466_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf467_unroll_1, %buf482_unroll_1, %buf465_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf466_unroll_1, %buf470_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf465_unroll_1, %buf481_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf481_unroll_1, %buf470_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf464_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf468_unroll_1, %buf466_unroll_1, %buf464_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf483_unroll_1, %buf465_unroll_1, %buf464_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf464_unroll_1, %buf468_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf482_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_4_4_129, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_7_3 = aie.mem(%tile_7_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_7_3_126, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf460_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_3_127, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_7_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf458_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_3_125, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_7_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf454_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_3_125, Release, 1)
      aie.next_bd ^bb4
    }
    %core_7_3 = aie.core(%tile_7_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf461_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf463_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf462_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_3_127, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_3_126, Release, 1)
      aie.use_lock(%lock_7_3_127, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_3_126, Release, 1)
      aie.use_lock(%lock_7_3_127, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_3_126, Release, 1)
      aie.use_lock(%lock_7_3_127, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf460_unroll_1, %buf459_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf457_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_3_126, Release, 1)
      aie.use_lock(%lock_7_3_127, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_3_125, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf459_unroll_1, %buf460_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf462_unroll_1, %buf456_unroll_1, %buf455_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf455_unroll_1, %buf461_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf458_unroll_1, %buf461_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf463_unroll_1, %buf455_unroll_1, %buf456_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf456_unroll_1, %buf463_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf453_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_3_126, Release, 1)
      aie.use_lock(%lock_7_3_127, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_3_125, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf459_unroll_1, %buf460_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf462_unroll_1, %buf452_unroll_1, %buf451_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf451_unroll_1, %buf461_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf454_unroll_1, %buf461_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf463_unroll_1, %buf451_unroll_1, %buf452_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf452_unroll_1, %buf463_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf450_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf449_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf448_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf462_unroll_1, %buf447_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf449_unroll_1, %buf462_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf449_unroll_1, %buf462_unroll_1, %buf446_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf447_unroll_1, %buf462_unroll_1, %buf445_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf446_unroll_1, %buf450_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf445_unroll_1, %buf461_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf461_unroll_1, %buf450_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf444_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf448_unroll_1, %buf446_unroll_1, %buf444_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf463_unroll_1, %buf445_unroll_1, %buf444_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf444_unroll_1, %buf448_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf462_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_7_3_126, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_6_3 = aie.mem(%tile_6_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_6_3_123, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf440_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_3_124, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_6_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf438_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_3_122, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_6_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf434_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_3_122, Release, 1)
      aie.next_bd ^bb4
    }
    %core_6_3 = aie.core(%tile_6_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf441_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf443_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf442_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_3_124, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_3_123, Release, 1)
      aie.use_lock(%lock_6_3_124, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_3_123, Release, 1)
      aie.use_lock(%lock_6_3_124, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf440_unroll_1, %buf439_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_3_123, Release, 1)
      aie.use_lock(%lock_6_3_124, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf437_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_3_123, Release, 1)
      aie.use_lock(%lock_6_3_124, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_3_122, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf439_unroll_1, %buf440_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf442_unroll_1, %buf436_unroll_1, %buf435_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf435_unroll_1, %buf441_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf438_unroll_1, %buf441_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf443_unroll_1, %buf435_unroll_1, %buf436_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf436_unroll_1, %buf443_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf433_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_3_123, Release, 1)
      aie.use_lock(%lock_6_3_124, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_3_122, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf439_unroll_1, %buf440_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf442_unroll_1, %buf432_unroll_1, %buf431_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf431_unroll_1, %buf441_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf434_unroll_1, %buf441_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf443_unroll_1, %buf431_unroll_1, %buf432_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf432_unroll_1, %buf443_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf430_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf429_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf428_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf442_unroll_1, %buf427_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf429_unroll_1, %buf442_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf429_unroll_1, %buf442_unroll_1, %buf426_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf427_unroll_1, %buf442_unroll_1, %buf425_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf426_unroll_1, %buf430_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf425_unroll_1, %buf441_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf441_unroll_1, %buf430_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf424_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf428_unroll_1, %buf426_unroll_1, %buf424_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf443_unroll_1, %buf425_unroll_1, %buf424_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf424_unroll_1, %buf428_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf442_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_6_3_123, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_5_3 = aie.mem(%tile_5_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_5_3_120, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf420_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_3_121, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_5_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf418_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_3_119, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_5_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf414_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_3_119, Release, 1)
      aie.next_bd ^bb4
    }
    %core_5_3 = aie.core(%tile_5_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf421_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf423_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf422_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_3_121, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_3_120, Release, 1)
      aie.use_lock(%lock_5_3_121, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf420_unroll_1, %buf419_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_3_120, Release, 1)
      aie.use_lock(%lock_5_3_121, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_3_120, Release, 1)
      aie.use_lock(%lock_5_3_121, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf417_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_3_120, Release, 1)
      aie.use_lock(%lock_5_3_121, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_3_119, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf419_unroll_1, %buf420_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf422_unroll_1, %buf416_unroll_1, %buf415_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf415_unroll_1, %buf421_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf418_unroll_1, %buf421_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf423_unroll_1, %buf415_unroll_1, %buf416_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf416_unroll_1, %buf423_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf413_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_3_120, Release, 1)
      aie.use_lock(%lock_5_3_121, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_3_119, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf419_unroll_1, %buf420_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf422_unroll_1, %buf412_unroll_1, %buf411_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf411_unroll_1, %buf421_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf414_unroll_1, %buf421_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf423_unroll_1, %buf411_unroll_1, %buf412_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf412_unroll_1, %buf423_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf410_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf409_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf408_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf422_unroll_1, %buf407_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf409_unroll_1, %buf422_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf409_unroll_1, %buf422_unroll_1, %buf406_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf407_unroll_1, %buf422_unroll_1, %buf405_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf406_unroll_1, %buf410_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf405_unroll_1, %buf421_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf421_unroll_1, %buf410_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf404_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf408_unroll_1, %buf406_unroll_1, %buf404_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf423_unroll_1, %buf405_unroll_1, %buf404_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf404_unroll_1, %buf408_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf422_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_5_3_120, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_4_3 = aie.mem(%tile_4_3) {
      %0 = aie.dma_start(S2MM, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_4_3_117, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf400_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_3_118, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb3
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 1, ^bb4, ^bb2)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_4_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf398_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_3_116, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_4_3, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf394_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_3_116, Release, 1)
      aie.next_bd ^bb4
    }
    %core_4_3 = aie.core(%tile_4_3) {
      %cst = arith.constant 0.000000e+00 : bf16
      %c64 = arith.constant 64 : index
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      func.call @zero_fill_gp_bf16(%buf401_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf403_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf402_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_3_118, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf400_unroll_1, %buf399_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_3_117, Release, 1)
      aie.use_lock(%lock_4_3_118, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_3_117, Release, 1)
      aie.use_lock(%lock_4_3_118, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_3_117, Release, 1)
      aie.use_lock(%lock_4_3_118, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf397_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_3_117, Release, 1)
      aie.use_lock(%lock_4_3_118, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_3_116, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf399_unroll_1, %buf400_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf402_unroll_1, %buf396_unroll_1, %buf395_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf395_unroll_1, %buf401_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf398_unroll_1, %buf401_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf403_unroll_1, %buf395_unroll_1, %buf396_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf396_unroll_1, %buf403_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_3, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf393_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_3_117, Release, 1)
      aie.use_lock(%lock_4_3_118, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_3_116, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf399_unroll_1, %buf400_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf402_unroll_1, %buf392_unroll_1, %buf391_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf391_unroll_1, %buf401_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf394_unroll_1, %buf401_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf403_unroll_1, %buf391_unroll_1, %buf392_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf392_unroll_1, %buf403_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_3, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf390_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf389_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf388_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf402_unroll_1, %buf387_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf389_unroll_1, %buf402_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf389_unroll_1, %buf402_unroll_1, %buf386_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf387_unroll_1, %buf402_unroll_1, %buf385_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf386_unroll_1, %buf390_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf385_unroll_1, %buf401_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf401_unroll_1, %buf390_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf384_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf388_unroll_1, %buf386_unroll_1, %buf384_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf403_unroll_1, %buf385_unroll_1, %buf384_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf384_unroll_1, %buf388_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      %collapse_shape_156 = memref.collapse_shape %buf402_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_156[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = vector.transfer_read %subview[%c0], %cst {in_bounds = [true]} : memref<32xbf16, strided<[1], offset: ?>, 2 : i32>, vector<32xbf16>
        aie.put_cascade(%0 : vector<32xbf16>)
      }
      aie.use_lock(%lock_4_3_117, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_7_2 = aie.mem(%tile_7_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_7_2_115, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf370_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_7_2_114, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_7_2_112, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf380_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_2_113, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_7_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf378_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_2_111, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_7_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf374_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_2_111, Release, 1)
      aie.next_bd ^bb6
    }
    %core_7_2 = aie.core(%tile_7_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_7_2_114, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf381_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf383_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf382_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_2_113, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_2_112, Release, 1)
      aie.use_lock(%lock_7_2_113, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_2_112, Release, 1)
      aie.use_lock(%lock_7_2_113, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_2_112, Release, 1)
      aie.use_lock(%lock_7_2_113, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf380_unroll_1, %buf379_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      %collapse_shape = memref.collapse_shape %buf377_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_2_112, Release, 1)
      aie.use_lock(%lock_7_2_113, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_2_111, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf379_unroll_1, %buf380_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf382_unroll_1, %buf376_unroll_1, %buf375_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf375_unroll_1, %buf381_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf378_unroll_1, %buf381_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf383_unroll_1, %buf375_unroll_1, %buf376_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf376_unroll_1, %buf383_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf373_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_2_112, Release, 1)
      aie.use_lock(%lock_7_2_113, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_7_2_111, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf379_unroll_1, %buf380_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf382_unroll_1, %buf372_unroll_1, %buf371_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf371_unroll_1, %buf381_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf374_unroll_1, %buf381_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf383_unroll_1, %buf371_unroll_1, %buf372_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf372_unroll_1, %buf383_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf370_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf369_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf368_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf382_unroll_1, %buf367_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf369_unroll_1, %buf382_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf369_unroll_1, %buf382_unroll_1, %buf366_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf367_unroll_1, %buf382_unroll_1, %buf365_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf366_unroll_1, %buf370_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf365_unroll_1, %buf381_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf381_unroll_1, %buf370_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf364_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf368_unroll_1, %buf366_unroll_1, %buf364_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf383_unroll_1, %buf365_unroll_1, %buf364_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf364_unroll_1, %buf368_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf368_unroll_1, %buf370_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_7_2_115, Release, 1)
      aie.use_lock(%lock_7_2_112, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_6_2 = aie.mem(%tile_6_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_6_2_110, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf350_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_6_2_109, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_6_2_107, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf360_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_2_108, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_6_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf358_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_2_106, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_6_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf354_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_2_106, Release, 1)
      aie.next_bd ^bb6
    }
    %core_6_2 = aie.core(%tile_6_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_6_2_109, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf361_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf363_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf362_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_2_108, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_2_107, Release, 1)
      aie.use_lock(%lock_6_2_108, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_2_107, Release, 1)
      aie.use_lock(%lock_6_2_108, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf360_unroll_1, %buf359_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_2_107, Release, 1)
      aie.use_lock(%lock_6_2_108, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf357_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_2_107, Release, 1)
      aie.use_lock(%lock_6_2_108, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_2_106, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf359_unroll_1, %buf360_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf362_unroll_1, %buf356_unroll_1, %buf355_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf355_unroll_1, %buf361_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf358_unroll_1, %buf361_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf363_unroll_1, %buf355_unroll_1, %buf356_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf356_unroll_1, %buf363_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf353_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_2_107, Release, 1)
      aie.use_lock(%lock_6_2_108, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_6_2_106, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf359_unroll_1, %buf360_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf362_unroll_1, %buf352_unroll_1, %buf351_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf351_unroll_1, %buf361_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf354_unroll_1, %buf361_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf363_unroll_1, %buf351_unroll_1, %buf352_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf352_unroll_1, %buf363_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf350_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf349_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf348_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf362_unroll_1, %buf347_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf349_unroll_1, %buf362_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf349_unroll_1, %buf362_unroll_1, %buf346_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf347_unroll_1, %buf362_unroll_1, %buf345_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf346_unroll_1, %buf350_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf345_unroll_1, %buf361_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf361_unroll_1, %buf350_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf344_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf348_unroll_1, %buf346_unroll_1, %buf344_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf363_unroll_1, %buf345_unroll_1, %buf344_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf344_unroll_1, %buf348_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf348_unroll_1, %buf350_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_6_2_110, Release, 1)
      aie.use_lock(%lock_6_2_107, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_5_2 = aie.mem(%tile_5_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_5_2_105, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf330_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_5_2_104, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_5_2_102, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf340_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_2_103, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_5_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf338_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_2_101, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_5_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf334_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_2_101, Release, 1)
      aie.next_bd ^bb6
    }
    %core_5_2 = aie.core(%tile_5_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_5_2_104, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf341_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf343_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf342_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_2_103, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_2_102, Release, 1)
      aie.use_lock(%lock_5_2_103, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf340_unroll_1, %buf339_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_2_102, Release, 1)
      aie.use_lock(%lock_5_2_103, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_2_102, Release, 1)
      aie.use_lock(%lock_5_2_103, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf337_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_2_102, Release, 1)
      aie.use_lock(%lock_5_2_103, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_2_101, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf339_unroll_1, %buf340_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf342_unroll_1, %buf336_unroll_1, %buf335_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf335_unroll_1, %buf341_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf338_unroll_1, %buf341_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf343_unroll_1, %buf335_unroll_1, %buf336_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf336_unroll_1, %buf343_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf333_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_2_102, Release, 1)
      aie.use_lock(%lock_5_2_103, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_5_2_101, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf339_unroll_1, %buf340_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf342_unroll_1, %buf332_unroll_1, %buf331_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf331_unroll_1, %buf341_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf334_unroll_1, %buf341_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf343_unroll_1, %buf331_unroll_1, %buf332_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf332_unroll_1, %buf343_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf330_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf329_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf328_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf342_unroll_1, %buf327_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf329_unroll_1, %buf342_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf329_unroll_1, %buf342_unroll_1, %buf326_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf327_unroll_1, %buf342_unroll_1, %buf325_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf326_unroll_1, %buf330_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf325_unroll_1, %buf341_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf341_unroll_1, %buf330_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf324_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf328_unroll_1, %buf326_unroll_1, %buf324_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf343_unroll_1, %buf325_unroll_1, %buf324_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf324_unroll_1, %buf328_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf328_unroll_1, %buf330_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_5_2_105, Release, 1)
      aie.use_lock(%lock_5_2_102, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    %mem_4_2 = aie.mem(%tile_4_2) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_4_2_100, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf310_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096, [<size = 64, stride = 8>, <size = 8, stride = 512>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_4_2_99, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb5
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(S2MM, 0, ^bb4, ^bb5)
    ^bb4:  // 2 preds: ^bb3, ^bb4
      aie.use_lock(%lock_4_2_97, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf320_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_2_98, Release, 1)
      aie.next_bd ^bb4
    ^bb5:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 1, ^bb6, ^bb2)
    ^bb6:  // 2 preds: ^bb5, ^bb7
      aie.use_lock(%lock_4_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf318_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_2_96, Release, 1)
      aie.next_bd ^bb7
    ^bb7:  // pred: ^bb6
      aie.use_lock(%lock_4_2, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf314_unroll_1 : memref<64x64xbf16, 2 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_2_96, Release, 1)
      aie.next_bd ^bb6
    }
    %core_4_2 = aie.core(%tile_4_2) {
      %c32 = arith.constant 32 : index
      %c4096 = arith.constant 4096 : index
      %c0_i32 = arith.constant 0 : i32
      %c64 = arith.constant 64 : index
      %c0 = arith.constant 0 : index
      cf.br ^bb1
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_4_2_99, AcquireGreaterEqual, 1)
      func.call @zero_fill_gp_bf16(%buf321_unroll_1) : (memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf323_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @neg_inf_fill_up_bf16(%buf322_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_2_98, AcquireGreaterEqual, 1)
      func.call @copy_tile(%buf320_unroll_1, %buf319_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_2_97, Release, 1)
      aie.use_lock(%lock_4_2_98, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_2_97, Release, 1)
      aie.use_lock(%lock_4_2_98, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_2_97, Release, 1)
      aie.use_lock(%lock_4_2_98, AcquireGreaterEqual, 1)
      %collapse_shape = memref.collapse_shape %buf317_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_2_97, Release, 1)
      aie.use_lock(%lock_4_2_98, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_2_96, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf319_unroll_1, %buf320_unroll_1, %collapse_shape) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape, %buf322_unroll_1, %buf316_unroll_1, %buf315_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf315_unroll_1, %buf321_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape, %buf318_unroll_1, %buf321_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf323_unroll_1, %buf315_unroll_1, %buf316_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf316_unroll_1, %buf323_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_2, Release, 1)
      %collapse_shape_152 = memref.collapse_shape %buf313_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      func.call @zero_fill_g_bf16(%collapse_shape_152) : (memref<4096xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_2_97, Release, 1)
      aie.use_lock(%lock_4_2_98, AcquireGreaterEqual, 1)
      aie.use_lock(%lock_4_2_96, AcquireGreaterEqual, 1)
      func.call @matmul_a_b_bf16(%buf319_unroll_1, %buf320_unroll_1, %collapse_shape_152) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<4096xbf16, 2 : i32>) -> ()
      func.call @fused_softmax(%collapse_shape_152, %buf322_unroll_1, %buf312_unroll_1, %buf311_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf311_unroll_1, %buf321_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @matmul_g_b_bf16(%collapse_shape_152, %buf314_unroll_1, %buf321_unroll_1) : (memref<4096xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf323_unroll_1, %buf311_unroll_1, %buf312_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf312_unroll_1, %buf323_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_2, Release, 1)
      %collapse_shape_153 = memref.collapse_shape %buf310_unroll_1 [[0, 1]] : memref<64x64xbf16, 2 : i32> into memref<4096xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c4096 step %c32 {
        %subview = memref.subview %collapse_shape_153[%arg0] [32] [1] : memref<4096xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_154 = memref.collapse_shape %buf309_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_154[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      %collapse_shape_155 = memref.collapse_shape %buf308_unroll_1 [[0, 1]] : memref<64x1xbf16, 2 : i32> into memref<64xbf16, 2 : i32>
      scf.for %arg0 = %c0 to %c64 step %c32 {
        %subview = memref.subview %collapse_shape_155[%arg0] [32] [1] : memref<64xbf16, 2 : i32> to memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
        %0 = aie.get_cascade() : vector<32xbf16>
        vector.transfer_write %0, %subview[%c0] {in_bounds = [true]} : vector<32xbf16>, memref<32xbf16, strided<[1], offset: ?>, 2 : i32>
      }
      func.call @vector_copy_32elems(%c0_i32, %buf322_unroll_1, %buf307_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @maximum_up_u_bf16(%buf309_unroll_1, %buf322_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf309_unroll_1, %buf322_unroll_1, %buf306_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @exp_up_minus_u(%buf307_unroll_1, %buf322_unroll_1, %buf305_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf306_unroll_1, %buf310_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @mul_r_gp(%buf305_unroll_1, %buf321_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @add_gp_g(%buf321_unroll_1, %buf310_unroll_1) : (memref<64x64xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      func.call @zero_fill_sp_bf16(%buf304_unroll_1) : (memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf308_unroll_1, %buf306_unroll_1, %buf304_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @accum_sp_r_s(%buf323_unroll_1, %buf305_unroll_1, %buf304_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @vector_copy_32elems(%c0_i32, %buf304_unroll_1, %buf308_unroll_1) : (i32, memref<64x1xbf16, 2 : i32>, memref<64x1xbf16, 2 : i32>) -> ()
      func.call @div_gp_sp(%buf308_unroll_1, %buf310_unroll_1) : (memref<64x1xbf16, 2 : i32>, memref<64x64xbf16, 2 : i32>) -> ()
      aie.use_lock(%lock_4_2_100, Release, 1)
      aie.use_lock(%lock_4_2_97, Release, 1)
      cf.br ^bb1
    } {link_with = "attn.o"}
    aie.flow(%shim_noc_tile_4_0, DMA : 0, %tile_4_2, DMA : 0)
    aie.flow(%shim_noc_tile_4_0, DMA : 0, %tile_5_2, DMA : 0)
    aie.flow(%shim_noc_tile_4_0, DMA : 0, %tile_6_2, DMA : 0)
    aie.flow(%shim_noc_tile_4_0, DMA : 0, %tile_7_2, DMA : 0)
    aie.flow(%shim_noc_tile_4_0, DMA : 1, %tile_4_3, DMA : 0)
    aie.flow(%shim_noc_tile_4_0, DMA : 1, %tile_5_3, DMA : 0)
    aie.flow(%shim_noc_tile_4_0, DMA : 1, %tile_6_3, DMA : 0)
    aie.flow(%shim_noc_tile_4_0, DMA : 1, %tile_7_3, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 0, %tile_4_4, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 0, %tile_5_4, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 0, %tile_6_4, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 0, %tile_7_4, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 1, %tile_4_5, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 1, %tile_5_5, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 1, %tile_6_5, DMA : 0)
    aie.flow(%shim_noc_tile_5_0, DMA : 1, %tile_7_5, DMA : 0)
    aie.flow(%shim_noc_tile_6_0, DMA : 0, %mem_tile_4_1, DMA : 0)
    aie.flow(%shim_noc_tile_6_0, DMA : 1, %mem_tile_5_1, DMA : 0)
    aie.flow(%shim_noc_tile_7_0, DMA : 0, %mem_tile_6_1, DMA : 0)
    aie.flow(%shim_noc_tile_7_0, DMA : 1, %mem_tile_7_1, DMA : 0)
    aie.flow(%mem_tile_4_1, DMA : 0, %shim_noc_tile_4_0, DMA : 0)
    aie.flow(%mem_tile_5_1, DMA : 0, %shim_noc_tile_5_0, DMA : 0)
    aie.flow(%mem_tile_6_1, DMA : 0, %shim_noc_tile_6_0, DMA : 0)
    aie.flow(%mem_tile_7_1, DMA : 0, %shim_noc_tile_7_0, DMA : 0)
    aie.flow(%mem_tile_4_1, DMA : 1, %tile_4_2, DMA : 1)
    aie.flow(%mem_tile_4_1, DMA : 1, %tile_5_2, DMA : 1)
    aie.flow(%mem_tile_4_1, DMA : 1, %tile_6_2, DMA : 1)
    aie.flow(%mem_tile_4_1, DMA : 1, %tile_7_2, DMA : 1)
    aie.flow(%mem_tile_5_1, DMA : 1, %tile_4_3, DMA : 1)
    aie.flow(%mem_tile_5_1, DMA : 1, %tile_5_3, DMA : 1)
    aie.flow(%mem_tile_5_1, DMA : 1, %tile_6_3, DMA : 1)
    aie.flow(%mem_tile_5_1, DMA : 1, %tile_7_3, DMA : 1)
    aie.flow(%mem_tile_6_1, DMA : 1, %tile_4_4, DMA : 1)
    aie.flow(%mem_tile_6_1, DMA : 1, %tile_5_4, DMA : 1)
    aie.flow(%mem_tile_6_1, DMA : 1, %tile_6_4, DMA : 1)
    aie.flow(%mem_tile_6_1, DMA : 1, %tile_7_4, DMA : 1)
    aie.flow(%mem_tile_7_1, DMA : 1, %tile_4_5, DMA : 1)
    aie.flow(%mem_tile_7_1, DMA : 1, %tile_5_5, DMA : 1)
    aie.flow(%mem_tile_7_1, DMA : 1, %tile_6_5, DMA : 1)
    aie.flow(%mem_tile_7_1, DMA : 1, %tile_7_5, DMA : 1)
    aie.flow(%tile_4_2, DMA : 0, %mem_tile_4_1, DMA : 1)
    aie.flow(%tile_5_2, DMA : 0, %mem_tile_5_1, DMA : 1)
    aie.flow(%tile_6_2, DMA : 0, %mem_tile_6_1, DMA : 1)
    aie.flow(%tile_7_2, DMA : 0, %mem_tile_7_1, DMA : 1)
    aie.cascade_flow(%tile_7_5, %tile_7_4)
    aie.cascade_flow(%tile_6_5, %tile_6_4)
    aie.cascade_flow(%tile_5_5, %tile_5_4)
    aie.cascade_flow(%tile_4_5, %tile_4_4)
    aie.cascade_flow(%tile_7_4, %tile_7_3)
    aie.cascade_flow(%tile_6_4, %tile_6_3)
    aie.cascade_flow(%tile_5_4, %tile_5_3)
    aie.cascade_flow(%tile_4_4, %tile_4_3)
    aie.cascade_flow(%tile_7_3, %tile_7_2)
    aie.cascade_flow(%tile_6_3, %tile_6_2)
    aie.cascade_flow(%tile_5_3, %tile_5_2)
    aie.cascade_flow(%tile_4_3, %tile_4_2)
    %memtile_dma_4_1 = aie.memtile_dma(%mem_tile_4_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_4_1_95, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf607_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_1_94, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_4_1_93, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf603_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_4_1_92, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_4_1_91, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf602_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_4_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_4_1_92, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf603_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_1_93, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_4_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf602_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_1_91, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_4_1_94, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf607_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_4_1_95, Release, 1)
      aie.next_bd ^bb10
    }
    %memtile_dma_5_1 = aie.memtile_dma(%mem_tile_5_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_5_1_90, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf606_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_1_89, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_5_1_88, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf601_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_5_1_87, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_5_1_86, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf600_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_5_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_5_1_87, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf601_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_1_88, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_5_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf600_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_1_86, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_5_1_89, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf606_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_5_1_90, Release, 1)
      aie.next_bd ^bb10
    }
    %memtile_dma_6_1 = aie.memtile_dma(%mem_tile_6_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_6_1_85, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf605_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_1_84, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_6_1_83, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf599_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_6_1_82, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_6_1_81, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf598_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_6_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_6_1_82, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf599_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_1_83, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_6_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf598_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_1_81, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_6_1_84, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf605_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_6_1_85, Release, 1)
      aie.next_bd ^bb10
    }
    %memtile_dma_7_1 = aie.memtile_dma(%mem_tile_7_1) {
      %0 = aie.dma_start(MM2S, 0, ^bb1, ^bb3)
    ^bb1:  // 2 preds: ^bb0, ^bb1
      aie.use_lock(%lock_7_1_80, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf604_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_1_79, Release, 1)
      aie.next_bd ^bb1
    ^bb2:  // pred: ^bb9
      aie.end
    ^bb3:  // pred: ^bb0
      %1 = aie.dma_start(MM2S, 1, ^bb4, ^bb6)
    ^bb4:  // 2 preds: ^bb3, ^bb5
      aie.use_lock(%lock_7_1_78, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf597_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_7_1_77, Release, 1)
      aie.next_bd ^bb5
    ^bb5:  // pred: ^bb4
      aie.use_lock(%lock_7_1_76, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf596_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096, [<size = 8, stride = 8>, <size = 64, stride = 64>, <size = 8, stride = 1>]) {task_id = 0 : i32}
      aie.use_lock(%lock_7_1, Release, 1)
      aie.next_bd ^bb4
    ^bb6:  // pred: ^bb3
      %2 = aie.dma_start(S2MM, 0, ^bb7, ^bb9)
    ^bb7:  // 2 preds: ^bb6, ^bb8
      aie.use_lock(%lock_7_1_77, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf597_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_1_78, Release, 1)
      aie.next_bd ^bb8
    ^bb8:  // pred: ^bb7
      aie.use_lock(%lock_7_1, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf596_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_1_76, Release, 1)
      aie.next_bd ^bb7
    ^bb9:  // pred: ^bb6
      %3 = aie.dma_start(S2MM, 1, ^bb10, ^bb2)
    ^bb10:  // 2 preds: ^bb9, ^bb10
      aie.use_lock(%lock_7_1_79, AcquireGreaterEqual, 1)
      aie.dma_bd(%buf604_unroll_1 : memref<64x64xbf16, 1 : i32>, 0, 4096) {task_id = 0 : i32}
      aie.use_lock(%lock_7_1_80, Release, 1)
      aie.next_bd ^bb10
    }
    aie.shim_dma_allocation @air_channel_0_1_0_4(%shim_noc_tile_4_0, S2MM, 0)
    aie.shim_dma_allocation @air_channel_0_1_0_5(%shim_noc_tile_5_0, S2MM, 0)
    aie.shim_dma_allocation @air_channel_0_1_0_6(%shim_noc_tile_6_0, S2MM, 0)
    aie.shim_dma_allocation @air_channel_0_1_0_7(%shim_noc_tile_7_0, S2MM, 0)
    aie.shim_dma_allocation @air_VIn_0_1_0_1(%shim_noc_tile_6_0, MM2S, 0)
    aie.shim_dma_allocation @air_VIn_1_1_0_1(%shim_noc_tile_6_0, MM2S, 1)
    aie.shim_dma_allocation @air_VIn_2_1_0_1(%shim_noc_tile_7_0, MM2S, 0)
    aie.shim_dma_allocation @air_VIn_3_1_0_1(%shim_noc_tile_7_0, MM2S, 1)
    aie.shim_dma_allocation @air_QK2L1_1_0_1_0(%shim_noc_tile_4_0, MM2S, 0)
    aie.shim_dma_allocation @air_QK2L1_1_1_1_0(%shim_noc_tile_4_0, MM2S, 1)
    aie.shim_dma_allocation @air_QK2L1_1_2_1_0(%shim_noc_tile_5_0, MM2S, 0)
    aie.shim_dma_allocation @air_QK2L1_1_3_1_0(%shim_noc_tile_5_0, MM2S, 1)
  } {dlti.dl_spec = #dlti.dl_spec<index = 32 : i64>}
  airrt.module_metadata{
    airrt.segment_metadata attributes {dma_allocations = [{channel = 2 : i64, col = 0 : i64, id = 33 : i64, location = 2 : i64, row = -1 : i64}, {channel = 2 : i64, col = 0 : i64, id = 36 : i64, location = 2 : i64, row = -1 : i64}, {channel = 3 : i64, col = 1 : i64, id = 39 : i64, location = 2 : i64, row = -1 : i64}, {channel = 3 : i64, col = 1 : i64, id = 42 : i64, location = 2 : i64, row = -1 : i64}, {channel = 2 : i64, col = 2 : i64, id = 45 : i64, location = 3 : i64, row = -1 : i64}, {channel = 2 : i64, col = 2 : i64, id = 48 : i64, location = 3 : i64, row = -1 : i64}, {channel = 3 : i64, col = 3 : i64, id = 51 : i64, location = 3 : i64, row = -1 : i64}, {channel = 3 : i64, col = 3 : i64, id = 54 : i64, location = 3 : i64, row = -1 : i64}], sym_name = "attn_seg"}{
      airrt.herd_metadata {dma_allocations = [{channel = 2 : i64, col = 0 : i64, id = 65 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 73 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 81 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 89 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 97 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 113 : i64, location = 0 : i64, row = 0 : i64}, {channel = 3 : i64, col = 0 : i64, id = 66 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 74 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 82 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 90 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 98 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 114 : i64, location = 0 : i64, row = 1 : i64}, {channel = 2 : i64, col = 0 : i64, id = 67 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 75 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 83 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 91 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 99 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 115 : i64, location = 1 : i64, row = 2 : i64}, {channel = 3 : i64, col = 0 : i64, id = 68 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 76 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 84 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 92 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 100 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 116 : i64, location = 1 : i64, row = 3 : i64}], loc_x = 0 : i64, loc_y = 2 : i64, size_x = 4 : i64, size_y = 4 : i64, sym_name = "herd_0"}
      airrt.herd_metadata {dma_allocations = [{channel = 2 : i64, col = 0 : i64, id = 69 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 77 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 85 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 93 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 101 : i64, location = 0 : i64, row = 0 : i64}, {channel = 2 : i64, col = 0 : i64, id = 117 : i64, location = 0 : i64, row = 0 : i64}, {channel = 3 : i64, col = 0 : i64, id = 70 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 78 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 86 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 94 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 102 : i64, location = 0 : i64, row = 1 : i64}, {channel = 3 : i64, col = 0 : i64, id = 118 : i64, location = 0 : i64, row = 1 : i64}, {channel = 2 : i64, col = 0 : i64, id = 71 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 79 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 87 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 95 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 103 : i64, location = 1 : i64, row = 2 : i64}, {channel = 2 : i64, col = 0 : i64, id = 119 : i64, location = 1 : i64, row = 2 : i64}, {channel = 3 : i64, col = 0 : i64, id = 72 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 80 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 88 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 96 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 104 : i64, location = 1 : i64, row = 3 : i64}, {channel = 3 : i64, col = 0 : i64, id = 120 : i64, location = 1 : i64, row = 3 : i64}], loc_x = 0 : i64, loc_y = 2 : i64, size_x = 4 : i64, size_y = 4 : i64, sym_name = "herd_0"}
    }
  }
  func.func @attention_bf16(%arg0: memref<2x512x64xbf16>, %arg1: memref<2x512x64xbf16>, %arg2: memref<2x512x64xbf16>, %arg3: memref<2x512x64xbf16>) {
    %c57344_i64 = arith.constant 57344 : i64
    %c40960_i64 = arith.constant 40960 : i64
    %c49152_i64 = arith.constant 49152 : i64
    %c32768_i64 = arith.constant 32768 : i64
    %c192_i64 = arith.constant 192 : i64
    %c128_i64 = arith.constant 128 : i64
    %c16_i64 = arith.constant 16 : i64
    %c512_i64 = arith.constant 512 : i64
    %c24576_i64 = arith.constant 24576 : i64
    %c8192_i64 = arith.constant 8192 : i64
    %c16384_i64 = arith.constant 16384 : i64
    %c2_i64 = arith.constant 2 : i64
    %c4_i64 = arith.constant 4 : i64
    %c1_i64 = arith.constant 1 : i64
    %c64_i64 = arith.constant 64 : i64
    %c8_i64 = arith.constant 8 : i64
    %c4096_i64 = arith.constant 4096 : i64
    %c72_i32 = arith.constant 72 : i32
    %c71_i32 = arith.constant 71 : i32
    %c70_i32 = arith.constant 70 : i32
    %c69_i32 = arith.constant 69 : i32
    %c61_i32 = arith.constant 61 : i32
    %c51_i32 = arith.constant 51 : i32
    %c45_i32 = arith.constant 45 : i32
    %c39_i32 = arith.constant 39 : i32
    %c33_i32 = arith.constant 33 : i32
    %c68_i32 = arith.constant 68 : i32
    %c67_i32 = arith.constant 67 : i32
    %c66_i32 = arith.constant 66 : i32
    %c65_i32 = arith.constant 65 : i32
    %c0_i64 = arith.constant 0 : i64
    %c2 = arith.constant 2 : index
    %c0 = arith.constant 0 : index
    %c1 = arith.constant 1 : index
    affine.for %arg4 = 0 to 1 {
      %p = airrt.segment_load "attn_seg" : i64
      %0 = airrt.wait_all : !airrt.event
      %1 = arith.index_cast %arg4 : index to i64
      %2 = airrt.dma_memcpy_nd(%c65_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_0, metadata = @air_QK2L1_0_0_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %3 = airrt.dma_memcpy_nd(%c65_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_0, metadata = @air_QK2L1_0_0_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %4 = airrt.dma_memcpy_nd(%c65_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c16384_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_0, metadata = @air_QK2L1_0_0_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %5 = airrt.dma_memcpy_nd(%c65_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_0, metadata = @air_QK2L1_0_0_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %6 = airrt.dma_memcpy_nd(%c66_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_1, metadata = @air_QK2L1_0_1_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %7 = airrt.dma_memcpy_nd(%c66_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c8192_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_1, metadata = @air_QK2L1_0_1_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %8 = airrt.dma_memcpy_nd(%c66_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c16384_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_1, metadata = @air_QK2L1_0_1_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %9 = airrt.dma_memcpy_nd(%c66_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c8192_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_1, metadata = @air_QK2L1_0_1_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %10 = airrt.dma_memcpy_nd(%c67_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_2, metadata = @air_QK2L1_0_2_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %11 = airrt.dma_memcpy_nd(%c67_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c16384_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_2, metadata = @air_QK2L1_0_2_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %12 = airrt.dma_memcpy_nd(%c67_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c16384_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_2, metadata = @air_QK2L1_0_2_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %13 = airrt.dma_memcpy_nd(%c67_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c16384_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_2, metadata = @air_QK2L1_0_2_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %14 = airrt.dma_memcpy_nd(%c68_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_3, metadata = @air_QK2L1_0_3_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %15 = airrt.dma_memcpy_nd(%c68_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c24576_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_3, metadata = @air_QK2L1_0_3_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %16 = airrt.dma_memcpy_nd(%c68_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c16384_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_3, metadata = @air_QK2L1_0_3_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %17 = airrt.dma_memcpy_nd(%c68_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c24576_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_0_3, metadata = @air_QK2L1_0_3_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %18 = airrt.dma_memcpy_nd(%c33_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_0, metadata = @air_VIn_0_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %19 = airrt.dma_memcpy_nd(%c39_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c8192_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_1, metadata = @air_VIn_1_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %20 = airrt.dma_memcpy_nd(%c45_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c16384_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_2, metadata = @air_VIn_2_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %21 = airrt.dma_memcpy_nd(%c51_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c24576_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_3, metadata = @air_VIn_3_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %22 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c0_i64, %c0_i64], [%c1_i64, %c2_i64, %c8_i64, %c512_i64], [%c0_i64, %c16384_i64, %c512_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_0_0_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %23 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c64_i64, %c0_i64], [%c1_i64, %c2_i64, %c64_i64, %c64_i64], [%c0_i64, %c16384_i64, %c64_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_0_0_2} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %24 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c128_i64, %c0_i64], [%c1_i64, %c2_i64, %c64_i64, %c64_i64], [%c0_i64, %c16384_i64, %c64_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_1_0_4} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %25 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c192_i64, %c0_i64], [%c1_i64, %c2_i64, %c64_i64, %c64_i64], [%c0_i64, %c16384_i64, %c64_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_1_0_6} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %26 = airrt.dma_memcpy_nd(%c69_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_0, metadata = @air_QK2L1_1_0_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %27 = airrt.dma_memcpy_nd(%c69_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_0, metadata = @air_QK2L1_1_0_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %28 = airrt.dma_memcpy_nd(%c69_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c49152_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_0, metadata = @air_QK2L1_1_0_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %29 = airrt.dma_memcpy_nd(%c69_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_0, metadata = @air_QK2L1_1_0_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %30 = airrt.dma_memcpy_nd(%c70_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_1, metadata = @air_QK2L1_1_1_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %31 = airrt.dma_memcpy_nd(%c70_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c40960_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_1, metadata = @air_QK2L1_1_1_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %32 = airrt.dma_memcpy_nd(%c70_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c49152_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_1, metadata = @air_QK2L1_1_1_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %33 = airrt.dma_memcpy_nd(%c70_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c40960_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_1, metadata = @air_QK2L1_1_1_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %34 = airrt.dma_memcpy_nd(%c71_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_2, metadata = @air_QK2L1_1_2_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %35 = airrt.dma_memcpy_nd(%c71_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c49152_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_2, metadata = @air_QK2L1_1_2_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %36 = airrt.dma_memcpy_nd(%c71_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c49152_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_2, metadata = @air_QK2L1_1_2_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %37 = airrt.dma_memcpy_nd(%c71_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c49152_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_2, metadata = @air_QK2L1_1_2_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %38 = airrt.dma_memcpy_nd(%c72_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_3, metadata = @air_QK2L1_1_3_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %39 = airrt.dma_memcpy_nd(%c72_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c57344_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_3, metadata = @air_QK2L1_1_3_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %40 = airrt.dma_memcpy_nd(%c72_i32, %1, %c0_i64, %arg0[%c0_i64, %c0_i64, %c0_i64, %c49152_i64], [%c4_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_3, metadata = @air_QK2L1_1_3_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %41 = airrt.dma_memcpy_nd(%c72_i32, %1, %c0_i64, %arg1[%c0_i64, %c0_i64, %c0_i64, %c57344_i64], [%c2_i64, %c8_i64, %c64_i64, %c8_i64], [%c4096_i64, %c8_i64, %c64_i64, %c1_i64]) {chan_name = @QK2L1_1_3, metadata = @air_QK2L1_1_3_1_0} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %42 = airrt.dma_memcpy_nd(%c33_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_0, metadata = @air_VIn_0_1_0_1} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %43 = airrt.dma_memcpy_nd(%c39_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c40960_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_1, metadata = @air_VIn_1_1_0_1} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %44 = airrt.dma_memcpy_nd(%c45_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c49152_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_2, metadata = @air_VIn_2_1_0_1} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %45 = airrt.dma_memcpy_nd(%c51_i32, %1, %c0_i64, %arg2[%c0_i64, %c0_i64, %c0_i64, %c57344_i64], [%c2_i64, %c1_i64, %c16_i64, %c512_i64], [%c0_i64, %c0_i64, %c512_i64, %c1_i64]) {chan_name = @VIn_3, metadata = @air_VIn_3_1_0_1} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %46 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c0_i64, %c32768_i64], [%c1_i64, %c2_i64, %c8_i64, %c512_i64], [%c0_i64, %c16384_i64, %c512_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_0_0_1} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %47 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c64_i64, %c32768_i64], [%c1_i64, %c2_i64, %c64_i64, %c64_i64], [%c0_i64, %c16384_i64, %c64_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_0_0_3} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %48 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c128_i64, %c32768_i64], [%c1_i64, %c2_i64, %c64_i64, %c64_i64], [%c0_i64, %c16384_i64, %c64_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_1_0_5} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %49 = airrt.dma_memcpy_nd(%c61_i32, %1, %c0_i64, %arg3[%c0_i64, %c0_i64, %c192_i64, %c32768_i64], [%c1_i64, %c2_i64, %c64_i64, %c64_i64], [%c0_i64, %c16384_i64, %c64_i64, %c1_i64]) {chan_name = @channel_0, metadata = @air_channel_0_1_0_7} : (i32, i64, i64, memref<2x512x64xbf16>, [i64, i64, i64, i64], [i64, i64, i64, i64], [i64, i64, i64, i64]) : !airrt.event
      %50 = scf.for %arg5 = %c0 to %c2 step %c1 iter_args(%arg6 = %0) -> (!airrt.event) {
        affine.for %arg7 = 0 to 2 {
          affine.for %arg8 = 0 to 1 {
            %h = airrt.herd_load "herd_0" (%arg7) {segment_name = "attn_seg"} : (index) -> i64
          }
        }
        scf.parallel (%arg7) = (%c0) to (%c2) step (%c1) {
          %h = airrt.herd_load "herd_0" (%arg7) {segment_name = "attn_seg"} : (index) -> i64
          scf.reduce 
        }
        %51 = airrt.wait_all %arg6 : !airrt.event
        scf.yield %51 : !airrt.event
      }
      airrt.wait_all %50, %18, %19, %20, %21, %22, %23, %24, %25, %42, %43, %44, %45, %46, %47, %48, %49, %3, %2, %4, %5, %7, %6, %8, %9, %11, %10, %12, %13, %15, %14, %16, %17, %27, %26, %28, %29, %31, %30, %32, %33, %35, %34, %36, %37, %39, %38, %40, %41 {air.launch_end}
    } {affine_opt_label = "tiling"}
    return
  }
}
