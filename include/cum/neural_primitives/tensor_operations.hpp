/**----------------------------------------------
 * ?                    ABOUT
 * @author      : Świadomy Mężczyzna
 * @email       : 
 * @file        : modules/cum/include/cum/neural_primitives/tensor_operations.hpp
 * @createdOn   : 09/12/26 
 * @description : ND tensors operation declarations
 *---------------------------------------------**/

#pragma once

#include "cum/neural_primitives/opaque_types.hpp"
#include "cum/neural_primitives/Memory.hpp"
#include "cum/neural_primitives/Descriptor.hpp"

#include "cum/Core.hpp"

namespace cum { class Tensor; }

namespace cum::neural_primitives
{
    /* Raw handles overloads */
    __event__ add(handles::__memory__& C, const handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& c_desc, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ sub(handles::__memory__& C, const handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& c_desc, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ mul(handles::__memory__& C, const handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& c_desc, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ div(handles::__memory__& C, const handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& c_desc, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ matmul(handles::__memory__& C, const handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& c_desc, const handles::__desc__& a_desc, const handles::__desc__& b_desc);

    __event__ add(handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ sub(handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ mul(handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ div(handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& a_desc, const handles::__desc__& b_desc);
    __event__ matmul(handles::__memory__& A, const handles::__memory__& B, const handles::__desc__& a_desc, const handles::__desc__& b_desc); //! dimensions of multiplied matrices may differ


    /* RAII handles overloads */

    __event__ add(Memory& C, const Memory& A, const Memory& B, const Descriptor& c_desc, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ sub(Memory& C, const Memory& A, const Memory& B, const Descriptor& c_desc, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ mul(Memory& C, const Memory& A, const Memory& B, const Descriptor& c_desc, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ div(Memory& C, const Memory& A, const Memory& B, const Descriptor& c_desc, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ matmul(Memory& C, const Memory& A, const Memory& B, const Descriptor& c_desc, const Descriptor& a_desc, const Descriptor& b_desc);

    __event__ add(Memory& A, const Memory& B, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ sub(Memory& A, const Memory& B, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ mul(Memory& A, const Memory& B, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ div(Memory& A, const Memory& B, const Descriptor& a_desc, const Descriptor& b_desc);
    __event__ matmul(Memory& A, const Memory& B, const Descriptor& a_desc, const Descriptor& b_desc);

    /* Objective tensors overloads */

    __event__ add(Tensor& C, const Tensor& A, const Tensor& B);
    __event__ sub(Tensor& C, const Tensor& A, const Tensor& B);
    __event__ mul(Tensor& C, const Tensor& A, const Tensor& B);
    __event__ div(Tensor& C, const Tensor& A, const Tensor& B);
    __event__ matmul(Tensor& C, const Tensor& A, const Tensor& B);

    __event__ add(Tensor& A, const Tensor& B);
    __event__ sub(Tensor& A, const Tensor& B);
    __event__ mul(Tensor& A, const Tensor& B);
    __event__ div(Tensor& A, const Tensor& B);
    __event__ matmul(Tensor& A, const Tensor& B);

}